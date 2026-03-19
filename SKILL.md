---
name: fintools-agent-client
description: Run the Fintools remote agent clients from this repository with a skill-local runtime environment and persistent output export. Use when Codex needs to execute bundled Deep Research or Trading clients, choose between streaming and polling modes, validate required inputs, create or reuse a run directory, fall back to a conda environment if Python 3.10+ is unavailable, and preserve reports/results for the user.
---

# Fintools Agent Client

## Overview

Use this skill to run the repository's Deep Research or Trading client with a predictable workflow:

- Validate the required inputs
- Create or reuse a parent run directory
- Reuse a local Python environment under the skill directory
- Automatically install or update dependencies when the local runtime is missing or stale
- Use only files bundled inside this skill directory
- Execute the selected agent mode
- Preserve the outputs for the user and report where they were written

## Protected Upstream Code

The `agents_client/` directory is treated as protected upstream code in this repository.

- Do not modify `agents_client/` by default.
- Prefer making behavior, logging, runtime, packaging, and test changes in `scripts/`, `docs/`, and `tests/`.
- Only change `agents_client/` when there is an explicit requirement and a deliberate decision to modify upstream client behavior.

## Scope Boundary

This document is the contract for agent execution only.

- Agent execution targets: `trading` and `deep_research`
- Public skill archive download is handled separately by `scripts/download_skill.py`

## Quick Start

Run the agent wrapper script instead of calling the repository modules directly:

```bash
python3 fintools-agent-client/scripts/run_agent_client.py \
  --agent-type trading \
  --mode streaming \
  --stock-code 600519 \
  --agent-url http://127.0.0.1:8000/api/v1/agents/69/a2a/
```

Use a single user-facing directory concept: `--work-dir`. Treat it as the parent directory for all runs, create a dedicated run subdirectory for each execution, and keep the persistent runtime environment under the skill directory itself.
Store `FINTOOLS_ACCESS_TOKEN` in the parent directory after the first successful run so later runs can reuse it without asking again.
If you run the optional streaming probe, keep its output under the same parent directory in `probe/`.

## Required Inputs

Agent execution requires:

- `--agent-type`: `deep_research` or `trading`
- `--mode`: `streaming` or `polling`
- `--stock-code`
- `--agent-url`
- `FINTOOLS_ACCESS_TOKEN` in the environment, or `--access-token`

Optional:

- `--work-dir`: user-specified parent directory for all runs
- `--task-id`: resume an existing polling task

Fail fast when any required input is missing. Do not rely on hard-coded default stock codes or agent URLs.
User-facing prompts should say "streaming（实时模式）" and "polling（轮询模式）".

## Mode Selection

- Streaming mode: `streaming`
  Use when the user wants continuous event updates.
- Polling mode: `polling`
  Explain it as: "轮询模式：不是一直保持连接，而是隔一段时间查一次任务进度，适合长时间任务。"

Current repository support for agent execution:

- `deep_research + streaming`: supported
- `trading + streaming`: supported
- `trading + polling`: supported
- `deep_research + polling`: supported

## Execution Workflow

1. Determine the working directory.
2. If `--work-dir` is provided, use it as the parent directory for runs.
3. Otherwise use `skill_root/.runtime/runs/` as the default parent directory.
4. Create a unique run subdirectory such as `fintools-agent-client-run-trading-600519-streaming-20260312-120000`.
   If the same name already exists within the same second, append a sequence suffix such as `-002`.
5. Print both the parent directory and the current run directory immediately.
6. Check whether the current Python satisfies 3.10+.
7. Validate that the skill directory already contains bundled `agents_client/` and `requirements.txt`.
8. Fail immediately if the bundled runtime files are missing.
9. Read `FINTOOLS_ACCESS_TOKEN` from the CLI or environment; if absent, reuse the cached token stored in the parent directory.
10. Cache the token in the parent directory after the first successful lookup.
11. Check the skill-local runtime directory under `.runtime/env/`.
12. If the local runtime is missing, create it automatically.
13. If `requirements.txt` changed since the last successful install, update the local runtime automatically.
14. Record runtime metadata in `.runtime/install-state.json`.
15. Use `scripts/run_agent_client.py` for agent execution.
16. Stream intermediate results to stdout as they are produced.
17. Run the child Python process in unbuffered mode so hosts such as OpenClaw can see progress immediately.
18. Write a `summary.json` file in the current run directory.
19. Write `run.log` in the current run directory while still showing the same output in the terminal.
20. Keep reports, summary, logs, and runtime artifacts under the same run directory.
21. Keep the current run directory after the run finishes.
22. Never delete the parent directory automatically.

## Output Contract

Always tell the user:

- Which runtime was used: `venv` or `conda`
- Which working directory was used
- The exact report file path when a report was downloaded
- The exact report directory path, usually `<run-dir>/downloaded_reports/`
- Whether it was user-specified or auto-created
- Whether reports were downloaded
- Whether outputs were persisted elsewhere

The final user-facing result must explicitly include `report_path` when present. Reporting only the run directory is not sufficient.

The working directory should contain at least:

- `summary.json`
- `run.log`
- `downloaded_reports/` when a report was downloaded

Use `--work-dir` as the only user-facing directory parameter. Do not make the user choose separate runtime and output locations.
Default auto-created parent directories should use `skill_root/.runtime/runs/`, with each run stored under its own `fintools-agent-client-run-*` subdirectory.
Keep the persistent runtime under `skill_root/.runtime/env/` and write runtime metadata into `skill_root/.runtime/install-state.json`.
Keep optional probe output under `probe/` in the same parent directory instead of creating unrelated temp directories.
Cache the access token in the parent directory so the user normally provides it only once per parent directory.
This skill must remain runnable even if the original `agent-client-template/` repository is removed, so all runtime code and `requirements.txt` stay bundled inside `fintools-agent-client/`.

## Host Agent Suggestion

If the host agent cannot display subprocess stdout in real time, suggest reading the current run directory's `run.log`.

Recommended behavior for OpenClaw or similar hosts:

- Before each major step starts, forward the skill's `[status] ...` line to the user instead of waiting for the step to finish.
- During execution, keep forwarding new `[status] ...` lines so the user knows what is happening now, for example environment checks, dependency installation, agent startup, polling, and report download.
- At the end, always show the final `[result] Report path: ...` line to the user together with the run directory and log path.
- If a report was downloaded, explicitly surface both the report file path and the `downloaded_reports/` directory path in the final answer.
- Do not replace the report path with only the run directory or a generic "results saved" summary.
- Start the skill normally.
- Read the printed run directory path.
- Optionally poll `<run-dir>/run.log` for new content and show appended lines to the user.
- Still treat terminal stdout as the primary output when the host supports live streaming.

This is only a compatibility suggestion for hosts with buffered subprocess output. It is not required for hosts that already support live stdout/stderr streaming.

## Resources

- Agent runner: [scripts/run_agent_client.py](./scripts/run_agent_client.py)
- Streaming probe: [scripts/stream_probe.py](./scripts/stream_probe.py)
- Runtime details and current limitations: [references/runtime-contract.md](./references/runtime-contract.md)

## Examples

Trading, streaming mode:

```bash
python3 fintools-agent-client/scripts/run_agent_client.py \
  --agent-type trading \
  --mode streaming \
  --stock-code 600519 \
  --agent-url http://127.0.0.1:8000/api/v1/agents/69/a2a/ \
  --work-dir /Users/example/fintools-agent-client-runs
```

Trading, polling mode with an explicit working directory:

```bash
python3 fintools-agent-client/scripts/run_agent_client.py \
  --agent-type trading \
  --mode polling \
  --stock-code 600519 \
  --agent-url http://127.0.0.1:8000/api/v1/agents/69/a2a/ \
  --work-dir /tmp/my-agent-runs
```

Deep Research, polling mode:

```bash
python3 fintools-agent-client/scripts/run_agent_client.py \
  --agent-type deep_research \
  --mode polling \
  --stock-code 600519 \
  --agent-url http://127.0.0.1:8000/api/v1/agents/82/a2a/ \
  --work-dir /tmp/my-agent-runs
```
