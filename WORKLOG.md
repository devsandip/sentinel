# Sentinel Worklog

Append-only session handoff log. Newest entries at the bottom.

## 2026-07-12 — P1 ML core + P2 model card

**Did:**
- Scaffolded the Python-only project (uv, pyproject, ruff, pytest) and pulled the real UCI Statlog German Credit data.
- Built the real ML core: `sentinel/ml/data.py`, `pipeline.py` (live logistic regression), `fairness.py` (direct group metrics + four-fifths disparity ratio), and `cli.py`.
- Built the model card generator (P2): SR 11-7-style document to Markdown + PDF.
- 13+ tests passing, ruff clean.

**State now:**
- P1 done: AUC 0.80, age-band disparity 0.569 (FLAGs naturally), sex disparity 0.82 (passes). Metrics move with seed, reproducible within seed.
- P2 in progress: model card module + sample PDF.

**Next:**
- P3 — governance harness (audit, rbac, pii, guardrails, eval_gate, cost) with tests proving a blocked RBAC access and a redaction are logged.

**Decisions:**
- Stack: Streamlit fallback (Python-only) instead of Next.js + FastAPI, for faster ship. Same backend logic.
- Fairness implemented directly (no fairlearn) so every number is auditable in a few lines.
- Protected attribute is excluded from model features (configurable: age_band default, sex, foreign_worker).

## 2026-07-12 (later) — P3 harness through P7 polish; full app shipped

**Did:**
- P3 harness: audit (append-only, immutable), rbac, pii, guardrails, eval_gate, cost, plus config YAMLs. Tests prove a blocked RBAC access and a PII redaction are logged.
- P4 agents + orchestrator: Profiler, EDA, Modeler, Validator + plain-Python orchestrator with the human approval pause. Model gateway (templated default, lazy anthropic/openai live providers, cost cap + fallback).
- P6 UI: six-tab Streamlit app (Pipeline, Results, Audit Log, Fairness, Model Card, Cost & KPIs), Governance badge, narration toggle, inline Approve/Reject gate, model-card PDF download. Verified end to end in the browser.
- P7: PRODUCT_BRIEF.md (controls -> bank KRAs, metric tree, prototype->platform), README, .env.example, Procfile, render.yaml, requirements.txt, .claude/launch.json.

**State now:**
- 36 tests passing, ruff clean. Full governed pipeline runs in scripted mode at zero cost, pauses at the human gate, and completes with a real fairness FLAG and eval gate 6/6.
- App runs locally via `uv run streamlit run app.py`. Not deployed yet.

**Next:**
- Deploy to Render + attach a custom domain (P7 deploy step). Optionally P8 live-LLM exercise with a real key.
- Capture a demo GIF/Loom for the README.

**Decisions:**
- Orchestration is a plain Python state machine, not LangGraph — fully owned, and the audit log makes it inspectable anyway.
- BLAS threading segfault (sklearn from Streamlit's worker thread on macOS) fixed with `threadpoolctl.threadpool_limits(1)` around the sklearn calls, so it is host-independent (no launch-time env var needed).
- Synthetic PII columns (applicant_email/ssn) injected at load, RBAC-restricted globally, to make the redaction control fire on every run.

## 2026-07-13 — Stabilize the Streamlit crash; strip the OpenMP cruft

**Did:**
- Chased a recurring Streamlit SIGSEGV (no Python traceback) that killed the app seconds after a DataFrame-heavy tab rendered. Read the actual macOS crash report (`~/Library/Logs/DiagnosticReports/python3.12-*.ips`) and found the real cause: pyarrow's bundled mimalloc allocator faulting in `mi_thread_init` when Streamlit serializes a DataFrame to Arrow on its worker thread.
- Fixed it with a single env var, `ARROW_DEFAULT_MEMORY_POOL=system`, set at launch (before pyarrow imports) in `run.sh`, `.claude/launch.json`, and `render.yaml`. Added a `run.sh` stable launcher and disabled Streamlit's file watcher.
- Empirically disproved my earlier OpenMP/BLAS-threading theory: a standalone harness ran sklearn + pyarrow on worker threads 25x fully unpinned with no crash, and the real app ran the full flow with zero OpenMP pins. Removed all of it: the OMP env vars, the in-code `threadpool_limits(1)` wraps in `pipeline.py` / `fairness.py`, and the explicit `threadpoolctl` dependency.
- Fixed the `use_container_width` deprecation (past its removal date) -> `width="stretch"`.
- Verified the minimal config end to end in the browser: Run -> Approve -> Fairness/Audit/Cost/Model Card tabs -> sustained polling, stable. 36 tests pass, ruff clean.

**State now:**
- App is stable on the minimal config. The ONLY launch mitigation is `ARROW_DEFAULT_MEMORY_POOL=system`. Run locally with `./run.sh` (a bare `streamlit run app.py` on macOS will still crash because it won't set that env var).
- Nothing is committed to git yet (only `git init` ran). Branch is `master`.
- Streamlit is not currently running (last background instance was killed).

**Next:**
- Make clean per-phase git commits (P1 -> P7) so history reads well, then a remote.
- Deploy to Render via `render.yaml` and attach a custom domain (CNAME).
- Optional: P8 live-LLM exercise with a real key; capture a demo GIF for the README.

**Decisions:**
- Root cause of the crash was pyarrow/mimalloc, not sklearn/OpenMP. The OpenMP pinning was cruft chasing a wrong diagnosis and was removed entirely.
- Keep exactly one mitigation, `ARROW_DEFAULT_MEMORY_POOL=system`, because it has a crash report proving it is load-bearing. It must be set before pyarrow imports, so it lives in the launcher, not in code.
