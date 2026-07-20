---
name: interactive-game-solver
description: Solve an interactive grid game by learning a compressed world model (encode state to a latent z, learn a predict function), planning action sequences by search over it, and recording hypotheses, plans and knowledge to memory.
---

# Interactive Game Solver

## The game
The game presents a **64×64 grid** of colors (hex `0`–`f`), one state per turn on your
`game_states` queue (each state carries a live status header). Games have multiple
**levels** to clear. Discover the unknown rules by experiment.
Legal actions are those in `available_actions`: `UP`/`DOWN`/`LEFT`/`RIGHT`, `USE` (interact),
`CLICK x y` (column x, row y, 0-indexed), `RESET` (restart level), `UNDO`. Parse with
`self.grid_array(state["grid_rows"])` and compute in numpy; `self.trajectory()` is the full
history and `diff_summary` reports changed cells. Reply with `self.submit_actions([...],
rationale)` — the **sequence** of actions that carries out your current plan.

## Scoring (RHAE)
Score = per-level **action efficiency** relative to an unseen human baseline, **squared**.
Every action spent on a level counts (exploration, failed attempts, RESET, UNDO); an
unsolved level scores 0. Level i of n carries weight i: the environment score is the
weighted mean of the level scores, capped by the weighted share of completed levels.

## World model
Persist a compressed model as helpers (`self.write_helper(name, src)`; reload with
`self.load_helpers()`, call `self.h.<module>.<fn>`):
1. **`encode(grid) -> z`** — the **latent state**: the few fields that drive the game, each
   named in a `Z_SCHEMA` with type + range.
2. **`predict(z, action) -> z'`** — the dynamics.
3. **Retrodict each turn** — compare `predict(z, a)` to the real next state; a mismatch is the
   signal to refine `encode`/`predict` until predictions hold.

## Search & planning
Once `predict` is trustworthy, **plan with it**: search (BFS / greedy / best-first) over
action sequences in latent space for one reaching the goal or a sub-goal, then
`submit_actions` the plan. While `predict` is weak, explore to discover the mechanics.

## Long-Term Memory
Consult your store (`<knowledge_api>`) before deciding; at a new level, recall the relevant
prior knowledge first. Each turn, after seeing results, record **hypotheses** (status +
deciding test), **knowledge** (confirmed dynamics, action semantics, failures),
and **long-term plans** (the sub-goal chain and solve procedure).

Reflect at level boundaries. On completion, summarize what generalizes (mechanic, winning
policy, transferable `encode`/`predict`, ruled-out hypotheses) and carry it forward. Before a
RESET, record what the attempt confirmed, what failed, and the next-attempt plan.

## Turn contract
Every turn ends with one call: `self.submit_actions([...], rationale="predict: ...")` with at
least one action — it submits your move and ends the turn. Do your analysis and any
knowledge/helper writes before it.
