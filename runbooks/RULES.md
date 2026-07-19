# E2E Runbook Rules

Read this before running any scenario in `runbooks/`. Each runbook links here and does
**not** repeat these rules — it only adds its scenario-specific purpose, golden rules,
phases, and scorecard.

`runbooks/` has **two layers**. Scripted deterministic harnesses
(`runbooks/restate-postgres-workers/`, driven by `just restate-postgres-workers-e2e` and the
`scripts/*-e2e.sh` runners) are gate **evidence**: they boot real infrastructure and assert
exact outcomes, and they stay scripts. Browser runbooks are the **agent-judged semantic
layer** on top: you (the agent) drive the example apps through browser automation and judge
the result with your own reasoning, gating on what the browser surface actually renders.
Keep the layers separate — a runbook never re-implements a scripted harness, and a
scripted harness never asks for judgement.

CLI operator runbooks live in the lash-cli repository's `runbooks/` directory.

These are **agent-driven runbooks**, not scripts. Use judgement freely — but never skip a
scenario's verification gates or the Abort rule below.

## What you're testing

You are testing the **example app's browser surface**, not the model and not your own
browser automation. The scenario is only valid if the rendered page, app API, and durable
state produce the observed result. When those surfaces disagree, the run is void.

## The browser surface (example apps)

Scenarios drive an **example web app** (`examples/agent-service`,
`examples/agent-workbench`). There is no scripted driver for these — browser automation
*is* the driver. Use whatever your harness provides: a browser MCP/plugin, Playwright, or
similar. If nothing is pre-wired, the known-good zero-install path is a PEP 723 Playwright
script run with `uv`:

```python
# /// script
# requires-python = ">=3.10"
# dependencies = ["playwright"]
# ///
from playwright.sync_api import sync_playwright
```

`uv run script.py` resolves Playwright into a cached venv and launches the shared
`~/.cache/ms-playwright` Chromium (run `playwright install chromium` once if the launch
reports a missing browser build).

Apply every rule below to the browser surface:

- **Poll, don't sleep** → gate on a waiting assertion with an explicit timeout
  (`expect(locator).to_be_visible(timeout=...)`, or polling an app API until a condition
  holds) — never a fixed sleep to decide async work finished.
- **Gate objectively**, in order of authority: (1) the **rendered page** — text/elements a
  user actually sees, captured as a **named-checkpoint screenshot**; (2) the app's **HTTP
  API** — the runbook names the endpoints that are backend truth; (3) **on-disk artifacts**
  — the example's data dir (SQLite session stores, `trace.jsonl`). The UI and the backend
  must agree: a rendered board the board endpoint contradicts, or an inbox card that
  disagrees with the inbox API, is a **contract violation** → Abort/RCA.
- **Screenshots are evidence, not decoration.** Take one at every checkpoint the runbook
  names, save it under the run's artifact directory, and cite the filename in the
  scorecard. A screenshot alone never passes a gate — pair it with the text or API
  assertion that proves what it shows. Scroll containers hide evidence: scroll the
  transcript/timeline to the newest entry before capturing, or the checkpoint reply sits
  below the fold.
- **Selectors are yours to discover.** Runbooks name UI affordances (the board grid, the
  compose form), not CSS selectors — inspect the served page and pick stable selectors
  yourself; a UI change that breaks an affordance the runbook names is a finding, not a
  reason to guess.

**Real tokens, deliberate runs.** The examples have no deterministic test provider: they
call OpenRouter (and Tavily for web tools) with keys from the environment / repo `.env`.
Every browser scenario is deliberate, token-spending, and model-nondeterministic. Gate on
**structural outcomes** (a terminal game state, a message present in an inbox), never on
exact model prose. A missing required key is a harness gap → Abort, do not stub around it.

**Boot and teardown are part of the run.** Phase 0 boots the example (`cargo run -p
agent-service`, `just agent-workbench <port>`) and gates on its readiness signal
(`/healthz`, the listening line). Boot via `cargo run` / the `just` recipe **only** —
never launch a `target/debug/*` path directly: this repo redirects builds through
`CARGO_TARGET_DIR`, so a stale in-repo `target/` binary can predate the endpoints a
runbook gates on and fake a contract violation. You own everything you started: end the run — success
or Abort — with the example stopped and any Docker containers it launched torn down
(`just agent-workbench-down <port>`).

For an Abort/RCA, use the app's pipeline — UI event handling / HTTP API / turn or trigger
execution / durable process / store persistence / render — and name the stage the failure
lives in.

## Poll, don't sleep

Turns, triggers, and process work are async and render over several updates. Gate on a
waiting assertion with an explicit timeout (`expect(locator).to_be_visible(timeout=...)`,
or polling an app API until a condition holds) — never a fixed sleep to decide async work
finished. A timeout at a gate is a hard failure → Abort/RCA.

## Gate objectively before you judge

Prefer an objective signal over eyeballing. In order of authority:

1. **Rendered page** — text/elements a user actually sees, captured as a named-checkpoint
   screenshot.
2. **App HTTP API** — the runbook names the endpoints that are backend truth.
3. **On-disk artifacts** — the example's data dir, including SQLite session stores and
   `trace.jsonl`.

Run the structural gate **before** judging behavior. If the objective signal is missing,
the failure is upstream of anything you would judge — Abort/RCA, don't score the vibe. The
UI and backend must agree; a rendered board the board endpoint contradicts, or an inbox
card that disagrees with the inbox API, is a contract violation → Abort/RCA.

## When to STOP (Abort triggers)

Stop immediately on **any** of:

- a browser automation command error or non-zero driver exit;
- a waiting assertion or API-poll timeout at a gate;
- the example app exiting unexpectedly before a gate;
- a **contract violation** — the rendered page, app API, and on-disk state disagree;
- an assertion that contradicts the scenario's answer key.

Do not push through, do not paper over, do not attempt a fix as part of the run.

## How to REPORT

**On abort — RCA, then stop:**
1. **Stop.** Do not continue the scenario.
2. **Capture evidence** — the failing automation command and its error; the last rendered
   page and named-checkpoint screenshot; app status; relevant API response and on-disk
   artifacts; and the exact gate that failed.
3. **RCA** — symptom → the app stage it broke at (UI event handling / HTTP API / turn or
   trigger execution / durable process / store persistence / render) → root cause → the
   evidence that proves it. Never stop at "the assertion timed out."
4. **Report and stop.** This is a diagnosis, not a repair. A divergence between an observed
   behavior and CONTEXT.md or the docs is reported as a finding — **do not** edit the doc
   or the code to make the run pass.

**On success — score, don't vibe:** for each scored item, name the **specific rendered
text or element** (or API / on-disk fact) the gate matched — no credit for vibes. Mark the
objective gate (page / API / disk) separately from any judged behavior. Fill the
scenario's scorecard verbatim.
