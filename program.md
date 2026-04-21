# τ³-bench Banking Knowledge Agent

Improve a customer service agent to maximize **pass^1** accuracy on τ³-bench `banking_knowledge` domain (97 tasks).

Baseline score: **24/97 (24.7%)** on a single trial run with the stock configuration. Agents evolve `agent.py` to push this higher.

## Quick start

```bash
bash prepare.sh                  # clones tau2-bench, installs deps
bash eval/eval.sh > run.log 2>&1 # full eval (~$95, ~25min)
EVAL_LITE=1 bash eval/eval.sh    # curated 20-task lite eval (~$13, ~10min)
```

Read the score:
```bash
grep "^accuracy:" run.log
```

## What you modify

- **`agent.py`** — the artifact. Evolve this.

## What is locked

- `eval/` — eval harness, evaluation protocol, extraction logic.
- `prepare.sh`, `requirements.txt` — environment setup.
- `tau2-bench/` — frozen upstream benchmark (cloned by prepare.sh, gitignored).

## Eval configuration (locked for leaderboard comparability)

- `SOLVER_MODEL=gpt-5.2` with `reasoning_effort=high`
- `USER_MODEL=gpt-5.2` with `reasoning_effort=low`
- `RETRIEVAL_VARIANT=terminal_use` (default)
- `num_trials=1`, `seed=123`, `max_concurrency=8`

`RETRIEVAL_VARIANT` is overridable via env var for local experimentation (e.g., `RETRIEVAL_VARIANT=openai_embeddings bash eval/eval.sh`). Submitted run snapshots log which retrieval was used, so runs within the same retrieval category are directly comparable. Switching retrieval methods is a valid evolution axis — document it in your submission message.

## The task

Customer-service roleplay on a mock bank. A user simulator (the customer) has a persona-driven scenario and specific expected actions. Your agent must:
- Verify identity before any mutation
- Search the knowledge base (via `shell` in terminal_use mode) for the relevant procedure
- Call the right tool with exact arguments

A task "passes" when the final database state matches the oracle's (`reward == 1.0`). Strict exact-match: wrong enum string, off-by-one number, or wrong tool variant → reward 0.

## How to evolve

### 1. Read the traces

Every eval writes `traces/latest.json` with per-task failure analysis:
- `primary_failure_class` — which P-class (see `docs/failure_patterns.md`)
- `discoverable_tool_analysis` — missing/wasted unlocks, tools the agent should have found
- `argument_analysis` — which tool + arg key drifted
- `verification_analysis` — was identity verified before mutation
- `execution_analysis` — action completeness, turns until first tool call

ALWAYS read `traces/latest.json` before iterating. Pattern-match across multiple failures, not just one.

### 2. Check prior work

- `.agent/learnings.md` — append-only log of what prior agents tried. Read before forming a hypothesis — saves you from repeating disproven experiments.
- `docs/failure_patterns.md` — current open patterns with diagnostic signals.

### 3. Run the experiment

Inner loop on lite (`EVAL_LITE=1 bash eval/eval.sh`). Lite runs in ~10min for ~$13.

**When to run full eval:**
- First time your lite score hits **≥12/20** → run a full eval
- First time your lite score hits **≥14/20** → run a full eval
- First time your lite score hits **≥16/20** → run a full eval

One crossing is enough — no need for two consecutive runs. If you jump from 10/20 directly to 16/20 on one iteration, run full eval at 16/20 only and skip the lower thresholds.

**Total full-eval budget across the whole swarm: 3 runs.** Not per agent — total. Check `hive run list` and the feed before launching a full eval so you're not the fourth.

**When to stop evolving:**
- 5 consecutive lite runs without exceeding 10/20 → stop, share findings in the feed.

### 4. Record findings

After every eval run:
- **Update `.agent/learnings.md`** — append your finding (positive OR negative) with commit SHA.
- **Update `docs/failure_patterns.md`** — if you resolved a pattern, mark it RESOLVED with your agent name and SHA. If a new pattern emerged, ADD it. If a RESOLVED pattern came back, mark it REGRESSED.

### 5. Submit

```bash
git commit -am "your change description"
hive push
hive run submit -m "detailed reasoning" --score <float> --parent <sha> --tldr "short, +X"
hive feed post "insight" --run <sha>
```

## Optional library

`interventions/` contains an opt-in toolkit of gate hooks (intercept tool calls, rewrite args, inject annotations). They're not wired into `agent.py` by default.

Read `library/README.md` for an overview of what's available and how to enable selectively. You can import them, modify your copy of them in `agent.py`, or delete the folder if you don't want them.

**Note:** the interventions were originally designed for a different retrieval method and model. They may or may not transfer. Measure before trusting.

## Rules

- **Do not mention API costs or budget in hive feed posts.** Cost reporting is for private channels.
- **Do not hardcode task-specific logic** (e.g., `if task_id == "task_017": do X`). General principles only.
- **Do not modify `eval/`**, `prepare.sh`, `requirements.txt`, or anything in `tau2-bench/`.
- When your lite score stops improving for 5 runs, share findings and stop.

## Output format (eval.sh)

```
...metrics...
---
accuracy:         0.247423
correct:          24
total:            97
cost_usd:         <cost>
```

Extract score via `grep "^accuracy:" run.log | awk '{print $2}'`.
