---
title: Business Policy Compliance Environment
emoji: "✅"
colorFrom: blue
colorTo: indigo
sdk: docker
app_port: 7860
short_description: Policy-aware customer support OpenEnv benchmark.
---

# Business Policy Compliance and Customer Resolution Environment

This repository is an OpenEnv-style evaluation environment for policy-aware support agents.  
Agents must route, prioritize, escalate, request clarification, flag fraud, and respond while following explicit business rules.

## What Makes This Hard

- Adversarial users: contradictory refund claims, policy-gaming pressure, and keyword traps that punish naive routing.
- Policy drift: episodes can switch from `v1` to `v2` mid-trajectory, requiring dynamic adaptation without advance shift disclosure.
- Delayed fraud detection: hidden-risk scenarios require timely fraud flagging; late detection loses proportional credit.
- Multimodal evidence: attachment summaries/signals force reasoning across text + precomputed visual cues.

## What Makes This Environment Useful

- Multi-domain tickets across billing, technical support, returns, legal, customer success, and spam.
- Cross-vertical coverage beyond generic support: HR operations compliance and financial-services compliance.
- 54 canonical scenario templates (`10 easy`, `16 medium`, `28 hard`) plus deterministic reset-time variation.
- Every episode is a seeded scenario variant via `_materialize_variant()` in `environment.py`:
  age jitter (`±15%`), refund jitter (`±20%`), and account-flag permutation while preserving policy-threshold semantics.
- Session-isolated API for concurrent judges and agents using `X-Session-Id`.
- Multi-turn state machine (`episode_phase`) for clarification-sensitive workflows.
- Policy versioning (`v1` and `v2`) to prevent fixed-policy memorization.
- Dynamic policy drift in selected scenarios (`v1 -> v2` mid-episode).
- Operational action-cost budgets that reward efficient trajectories.
- Adversarial/deceptive users: contradiction, policy-gaming, keyword traps, sarcasm, mixed-intent threads.
- Partial observability via hidden internal risk flags not exposed in normal observations.
- Multi-agent interaction through `consult_specialist` and specialist feedback loops.
- Adaptive difficulty: when `task_name` is omitted, scenario difficulty responds to recent performance.
- Browser-based Gradio judge UI.

## Policy Sets

Observations include `policy_version` and the active rule list.

`v1`:
- Refunds over `$500` require escalation.
- VIP customers require `high` or `urgent` priority.
- Issues open over `72` hours require `urgent` priority.
- Complaints mentioning legal action or lawsuits require immediate escalation.
- Suspended accounts must be routed to the billing team.

`v2` (all `v1` rules plus):
- Premier accounts require same-day response regardless of issue type.
- Fraud indicators require `flag_fraud` before any resolution action.

## Observation Space

Each observation includes:
- Current email and visible thread.
- Sender tier, account flags, refund amount, and issue age.
- Action history, policy rules, and task objective.
- `agent_notes`: rolling reasoning memory synthesized from submitted action rationale.
- `policy_version` and `episode_phase`.
- Multimodal attachment fields: `attachment_present`, `attachment_summary`, `attachment_signals`.
- Policy-shift timing is intentionally hidden from agent-facing observations (no advance drift signal).
- `specialist_feedback` when a specialist review has been requested.
- Clarification is progressive for ambiguous cases (`emails_remaining` decrements as each round is revealed).
- Only visible account flags (hidden risk flags stay internal for partial observability).
- Raw attachment path is internal only (not exposed in `Observation`).

## Multimodal Design

Attachment-derived signals are precomputed offline using a deterministic VL-JEPA-style pipeline + curated fixtures, then stored in scenario templates (`data_generation.py`).
Runtime remains deterministic:
- No VL model calls in `step()`
- No grader-time image inference
- Agent receives only structured fields (`attachment_summary`, `attachment_signals`)
- Local PNG fixture files may be bundled for demos, but no vision model is used at runtime
- Internal-only `attachment_path` stays inside snapshots/ground truth for audit/debug

## Action Space

- `categorize`
- `set_priority`
- `draft_response`
- `escalate`
- `mark_spam`
- `request_info`
- `flag_fraud`
- `snooze`
- `consult_specialist`

`flag_fraud` requires `fraud_reason`.  
`snooze` requires `snooze_hours` and can trigger SLA penalties if it crosses the 72-hour threshold.
`consult_specialist` requires `specialist_question`.

## Reward Table

| Component | Trigger | Value | Notes |
| --- | --- | --- | --- |
| Valid action | Any schema-valid action | +0.05 first use, +0.01 repeated type | Repeated action types get reduced immediate reward |
| Policy penalty | Action contradicts active rule | -0.2 | Immediate |
| Policy history penalty | Any policy violation occurred earlier in episode | -0.08 | Applied on final step for persistent demerit |
| SLA crossed during snooze | Snooze pushes age past 72h | -0.1 | Immediate |
| Fraud missed | No `flag_fraud` in fraud scenario | -0.15 | Episode-end penalty |
| False-positive fraud flag | `flag_fraud` used in a benign scenario | -0.10 | Episode-end penalty |
| Partial progress | Correct work completed so far | 0.0-current task score | Returned each step |
| Final grader score | Episode complete | 0.0-1.0 | Full grader runs on `done` |
| Efficiency bonus | Finished in <= half allowed steps | +0.1 | Episode-end bonus |
| Cost adjustment | Stay under / exceed scenario budget | +0.08 max / -0.12 max | Episode-end tradeoff term |
| Redundancy penalty | Repeated action types | -0.05 per repeat | Episode-end penalty |
| Running over-budget signal | Cost already above budget before done | down to -0.08 | Intermediate shaping |
| Delayed fraud penalty | Fraud flagged too late in delayed-detection scenarios | up to -0.12 | Episode-end proportional penalty by lateness |
| Early misroute penalty | First categorization mismatches expected route | -0.08 | Episode-end penalty |

Shaped rewards are clamped to `[-1.0, 1.0]` (grader score remains `0.0-1.0`).  
Step details are available in `info["reward_breakdown"]`.
Cost units are normalized operational effort units (roughly comparable to a combined latency/compute/support-minute budget).

## Draft Response Rubric

`draft_response` scoring is deterministic and multi-axis (not keyword-only).  
The response rubric combines:
- Policy citation quality
- Resolution completeness (ownership + timeline + concrete next step)
- Tone quality
- Accuracy and action-grounded consistency

This rubric is blended with keyword/grounding/structure checks in the hybrid scorer to reduce paraphrase gaps and reward gaming.

## Evaluation Metrics

Each step returns interpretable metrics in `info["evaluation_metrics"]`:

```json
{
  "score": 0.78,
  "policy_score": 0.90,
  "efficiency": 0.60,
  "latency": 0.42,
  "customer_quality": 0.71,
  "risk_management": 0.83,
  "adversarial_resilience": 0.66,
  "memory_score_component": 0.64,
  "attachment_utilization": 0.75,
  "multimodal_fraud": 0.70
}
```

Failure reasons are exposed in `info["failure_modes"]` (for example: `adversarial_miss`, `risk_handling_gap`, `context_ignorance`, `high_operational_cost`).
Step info also includes `episode_id`, `total_logged_actions`, `reasoning_depth`, and `used_history` for traceability.

## API

FastAPI routes:
- `GET /health`
- `GET /tasks`
- `POST /reset`
- `POST /step`
- `GET /state`
- `GET /schema`
- `DELETE /session`

Session header:
- `X-Session-Id` (optional, defaults to `default`)

Important behavior:
- `/step` requires an existing session (call `/reset` first for that session).
- `/state` is session-scoped.
- `/state` hides ground-truth by default; use `/state?include_ground_truth=true` for evaluator/debug mode.

## Gradio Judge UI

`gradio_app.py` starts:
- FastAPI server on `7860`
- Gradio UI on `7861`

The UI supports scenario selection, reset, all action types, and live reward/component readouts.
It also includes a failure-modes dashboard with live evaluation metric breakdowns.

## Verified Rule Baseline Scores

From:
```bash
.venv/bin/python baseline.py --agent rule --seed 42
```

Current means (54 scenarios, latest local run on April 8, 2026):
- Easy: `0.91` (`std 0.1375`, min `0.70`, max `1.00`)
- Medium: `0.6982` (`std 0.1425`, min `0.49`, max `0.8732`)
- Hard: `0.5065` (`std 0.1528`, min `0.1693`, max `0.7594`)

Baseline runs are deterministic by default (fixed variation seed). Override with `--seed` when you want alternate perturbation sweeps.

## Competition Inference Script (`inference.py`)

For hackathon pre-validation, the root-level inference script is:
- `inference.py`

It runs a sequential OpenAI-client agent across all `easy`, `medium`, and `hard` scenarios and prints a JSON summary.

Required env vars:
- `API_BASE_URL`
- `MODEL_NAME`
- `HF_TOKEN`

Example:
```bash
export API_BASE_URL="https://router.huggingface.co/v1"
export MODEL_NAME="openai/gpt-4.1-mini"
export HF_TOKEN="hf_xxx"
python inference.py --seed 42
```

The `--seed` value is forwarded to the environment reset path, so HTTP-mode inference stays reproducible across fresh sessions.

## Project Layout

```text
business_policy_env/
    __init__.py
    baseline.py
    db.py
    data_generation.py
    environment.py
    models.py
    policies.py
    rewards.py
    server.py
    tasks.py
gradio_app.py
baseline.py
inference.py
openenv.yaml
pyproject.toml
tests/
    test_environment.py
scripts/
    self_check.sh
    validate_openenv_contract.py
    validate-submission.sh
    docker_smoke.sh
.github/workflows/ci.yml
Dockerfile
```

## Local Run

Install:
```bash
.venv/bin/pip install -e ".[dev]"
```
For the local Gradio judge UI:
```bash
.venv/bin/pip install -e ".[dev,ui]"
```

Optional `uv` workflow (if `uv` is installed):
```bash
uv sync
```
If you want a pinned lock locally, generate one with:
```bash
uv lock
```

Run API only:
```bash
.venv/bin/uvicorn server.app:app --host 0.0.0.0 --port 7860
```

Run Gradio + API:
```bash
.venv/bin/python gradio_app.py
```

Run inference script (HTTP mode with structured `[START]/[STEP]/[END]` logs):
```bash
export API_BASE_URL="https://router.huggingface.co/v1"
export MODEL_NAME="openai/gpt-4.1-mini"
export HF_TOKEN="hf_..."
export ENV_BASE_URL="http://127.0.0.1:7860"

.venv/bin/python inference.py --task hard --seed 42
# or
.venv/bin/python inference.py --task all --seed 42
```

Run checks:
```bash
.venv/bin/ruff check .
.venv/bin/mypy business_policy_env/
.venv/bin/python -m pytest tests/ -v
```

One-command self-check (includes OpenEnv contract validation, plus optional `openenv` CLI and Docker smoke checks when installed):
```bash
bash scripts/self_check.sh
```

Contract validation and runtime-proof helper scripts:
- `scripts/validate_openenv_contract.py`
- `scripts/docker_smoke.sh`
- `scripts/validate-submission.sh`

CI includes a dedicated `runtime-proof` job that uploads validation/runtime artifacts.

## Validation Evidence (Latest Local Run)

Pytest (50 targeted tests):
```text
..................................................                       [100%]
50 passed in 6.82s
```

OpenEnv contract validator:
```json
{
  "ok": true,
  "endpoint_keys": ["close_session", "health", "reset", "schema", "state", "step", "tasks"],
  "errors": []
}
```

Note: `openenv validate` and Docker smoke are supported by scripts in this repo; run them in your local/CI environment where `openenv` CLI and Docker are installed.

## Pre-Submission Validator

Run the provided validator locally before submitting:

```bash
chmod +x scripts/validate-submission.sh
./scripts/validate-submission.sh https://your-space.hf.space .
```

This checks:
- HF Space `/reset` responds with HTTP 200
- Dockerfile builds
- `openenv validate` passes

## Docker

The Docker image:
- Installs with `pip install -e .`
- Exposes port `7860` (API)
- Health checks `http://127.0.0.1:7860/health`
- Starts `uvicorn server.app:app --host 0.0.0.0 --port 7860`

HF deployment note:
- `app_port` is intentionally set to `7860` so automated validators can hit `/reset` on the public Space URL.
- The interactive Gradio demo is for local judge walkthroughs (`python gradio_app.py`).
