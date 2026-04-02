
## README

## What this repo is

This repository studies whether LLM judges fail to penalize the most consequential errors in agentic trajectories.

Core idea:
some trajectory errors are much more damaging than others, but judges may not score them in proportion to their true downstream impact.

---

## Repo layout

- `src/` — all code
- `tests/` — all tests
- `agent_tasks/` — restartable task folders
- `data/` — datasets and dataset artifacts
- `results/` — experiment outputs
- `paper/` — notes, deep dives, outlines, drafts

---

## How to start or restart work

Read in this order:
1. `README.md`
2. `Agents.MD`
3. `agent_tasks/<task_name>/Requirements.MD`
4. `agent_tasks/<task_name>/state.json` if present

That should be enough to resume most work.

---

## Task format

Example:

```text
agent_tasks/create_scaffolding_for_mongodb/
├── Requirements.MD
├── state.json
├── inputs/
├── outputs/
└── artifacts/