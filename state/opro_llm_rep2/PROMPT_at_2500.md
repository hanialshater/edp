You are a black-box optimizer for an EDP module-config policy. You see ONLY
a history of (edits, batch_regret) pairs. Lower regret is better.

You see NO diagnostic information beyond the (edits, score) pairs themselves.
You do NOT see per-persona regret, widget activation rates, or composition
signatures. You must reason purely from patterns in the score history.

# Action space

Each solution is a list of atomic edits. Each edit is:
- `widget`: one of 22 widget names (see below)
- `path`: `base`, `slot_decay`, `on_rem.<F-code>`, or `on_cov.<F-code>`
- `to`: numeric value, typical magnitude range -1.5 to 2.8
- `reason`: short string (opaque tag, no effect on score)

Widgets: fit_reassurance, size_guide, low_return_alts, comparison_card, customers_chose, value_breakdown, outfit_completion, style_bridge, occasion_lookbook, return_explainer, easy_returns_promise, brand_story, material_deep_dive, price_history, price_drop_notify, recently_viewed, wishlist_save, expert_pick, similar_items, also_bought, trending_now, personal_recs
F-codes: F32, F33, F41, F43, F45, F46, F51.

# History of attempts (sorted by score: best first)

(no prior attempts — this is the first round)

# Current cumulative regret across all batches: 990.82

# Your task

Write a NEW edit batch of 8–16 edits to `opro_llm_rep2/edits_round_2500.json`:

```json
{
  "note": "round X — one-line summary",
  "edits": [
    {"widget": "...", "path": "...", "from": 0.0, "to": 0.0, "reason": "..."}
  ]
}
```

You can revisit edits from prior batches with different values or try
entirely different combinations. Reason from patterns in the score history.

Output: write the JSON file. Do NOT print it back. Final message: under 80
words on your hypothesis for why this batch should improve.
