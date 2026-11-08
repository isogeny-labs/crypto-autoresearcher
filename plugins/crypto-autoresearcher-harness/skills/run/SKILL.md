---
name: run
description: Run existing experiment programs and report their outputs. Use for run, run experiments, run the harness, or execution of a named EXP-*, TASK-*, GOAL-*, or existing experiment command.
---

# Run

Execute existing experiments. Finish with actual run counts, results, failures,
output paths, and each experiment's run report. This is the single public
execution entry point.

## Find the program

Preserve a named experiment, task, goal, command, and requested stopping point.
Read only the selected experiment's launch instructions, inputs, and relevant
source. Use an existing command-based runner directly; a missing trial-plan.json
is not a reason to migrate a working experiment.

For an unqualified request, inspect the existing experiment worklist once:

```sh
python3 tools/newest_experiments.py --limit 3 --json
```

Use `--experiment <ID>` or `--goal <ID>` for named scope. The list is
decision-aware and readiness-first: committed `DEC-*` holds are already applied,
and within each priority group `ready` rows (a committed launcher or trial plan
with a valid dispatch queue entry)
sort above `needs_implementation_or_plan`, so the top rows are the ones that can
proceed to dispatcher admission and claim. Each row carries `off_main_runs`: branches not yet on `main` that
already hold run records for that experiment. A non-empty value means someone
executed it elsewhere; name it in the report and do not run the same trials
again. The `needs_implementation_or_plan` label is a preparation hint: look for
the existing documented launcher before declaring that experiment unavailable.
`needs_dispatch_queue` means a trial plan exists but its queue is a placeholder
or does not list its executor task; report that coordination impediment and
continue with `ready` rows.
Do not invent a new experiment, recover private keys, or turn this skill into an
autonomous attack workflow; mathematical experiments use public synthetic inputs.

For `$run GOAL-...`, select only that goal's experiments:

```sh
python3 tools/newest_experiments.py --goal <GOAL-ID> --limit 0 --json
```

Keep the goal filter throughout execution and in the result summary. If an older
experiment has no `goal_id` in its specification, follow the named goal's existing
experiment/queue pointers to its documented launcher; do not scan other goals or
infer membership from an identifier prefix. An empty or impeded goal-scoped list
never falls back to the whole portfolio. Report the selected goal, attempted
experiments, completed/failed trials, output paths, and any remaining impediment.

A sparse checkout (`python3 tools/sparse_checkout.py status`,
`docs/sparse-checkout.md`) keeps run archives and reference bundles off disk.
A `needs_materialization` row, or a launch the runner refuses because run
directories are off disk, needs one command: `python3 tools/sparse_checkout.py
add --experiment <EXP-ID>`. A declared input that `git ls-files` lists but the
disk lacks is outside the checkout, not missing: `add --path` it rather than
reporting an impediment.

## Execute

Run the existing program with its declared inputs, seeds, controls, and trial
count. Use a fresh output location, preserve earlier attempts, and respect live
ownership and machine resource limits. For a prepared trial plan with its existing
claim, use the process supervisor:

```sh
python3 tools/experiment_execution.py run --plan <existing-plan-path> \
  --owner <claim-owner> --epoch <claim-epoch>
```

### Runbook experiments

When `experiments/<EXP-ID>/runbook.yaml` exists, execute it through
`tools/runbook.py`, not by calling the supervisor directly: the runbook wraps
the supervisor, claim and release, and adds per-output validity checks, a
hash-chained journal, tool-computed metrics and a generated report
(`docs/runbook-execution.md`). The procedure is fixed and identical for every
model: `lint`, `run --as <address>` (rerun the same command to resume),
`verify`, `report` (`render` when no Typst was installed), `publish-paths` and
the git commands it prints, then `status --brief` as the result. The exact
commands are in `.claude/agents/executor-mechanical.md`, "Runbook execution:
the procedure"; under Claude Code, dispatch that subagent (Haiku) with the
runbook path. A runbook that does not lint is an impediment to report, never
something to repair here, and `tools/runbook.py report` writes the run report.

When the experiment has a task card (`experiments/<EXP-ID>/task-cards/`),
the dispatch is the card (`docs/model-tiers.md`): `python3
tools/task_card.py lint <card>` must print `CARD OK` (otherwise report the
findings as the impediment), and the prompt to `executor-mechanical` is
exactly what `python3 tools/task_card.py prompt <card>` prints, with nothing
added. Save the executor's returned text to a file and dispatch
`experiment-director` in `assess` mode with the card and that file; its
execution assessment is the result this skill reports. It is a relay check,
not a review: it decides nothing about the hypothesis and blocks nothing.

Keep the runner's built-in admission, resource, and output-correctness checks.
Do not duplicate them in an agent-led validation phase or disable them to force
a launch. Routine trials are processes; they do not need a new agent per seed.
Show real progress while they run.

Do not run preflight, whole-ledger/schema validation, portfolio-health sweeps,
protocol review, or merge-hygiene checks as prerequisites to this skill. Do not
author protocols, approval records, migrations, repair queues, or review plans
just to satisfy a run request. Do not fetch/merge branches or start independent
review as an automatic part of execution. Those are separate tasks.

## Report each experiment

After an experiment's trials finish (completed, failed, or timed out), write
its run report as `research-visuals` describes under "Every experiment run"
(`.claude/skills/research-visuals/SKILL.md`): a write-once directory
`experiments/<EXP-ID>/reports/run-<YYYYMMDDTHHMMZ>/` holding a report of what
ran and what it measured, at least one graph of the recorded data (or a
diagram of what ran when there is nothing to compare), and `report.pdf`
rendered from them and inspected. One report per experiment per session,
covering every run directory this session wrote for it. Never write into a run
directory or edit an earlier report.

The report describes outputs; it is not a review. It states no verdict,
support, weakening, or significance, plots recorded values only, and computes
nothing new beyond labeled arithmetic on recorded values. It does not delay
the run records: commit and push those first (below), then the report. If no
renderer can be installed, commit the report source and graphs and state the
blocker; do not skip the report.

When `experiments/<EXP-ID>/protocol.json` exists, also write the unified
export beside the run records: `python3 tools/experiment_protocol.py
from-rows|from-taskq ... --protocol experiments/<EXP-ID>/protocol.json --out
experiments/<EXP-ID>/export.json`, then `check-export --verify-files` until it
passes (`docs/experiment-protocol.md`). The export carries rows and hashes
only; its `notes` are observations.

## Publish the run records

Run records left only in a working tree are not evidence and are invisible to
the next session, which then runs the same trials again. When trials finish,
commit the run directories this session wrote (`experiments/<EXP-ID>/runs/...`,
plus `experiments/<EXP-ID>/runbook-sessions/<id>/` for a runbook, and nothing
else) on the session's own branch and push it, so the selector's
`off_main_runs` column shows them to every later `run` session. Commit and push
each experiment's report directory (`experiments/<EXP-ID>/reports/run-*/`)
next, on the same branch. Open or refresh
a PR for that branch with the runtime's PR tool when one is available; this is
publication of observations, not review, archival, or a research-state change.
Never amend or rewrite a pushed run commit, and never commit ledger records,
specification edits, generated indexes, or anything outside those run and report
directories from this skill.

If a launcher, necessary input, ownership, or runtime admission is unavailable,
report the exact impediment once. For an unqualified run, continue other runnable
experiments; for a named run, retain its scope. Do not replace execution with
paperwork or repeatedly poll unchanged state. A needed implementation or protocol
change is reported separately, not silently made during this skill.

## Return the results

Retain commands, parameters/seeds, code and environment identity, logs, raw
outputs, elapsed time, and failed attempts using the runner's existing output
format. Report what actually completed, where its outputs are, and where each
experiment's run report and PDF are. State any missing data without
fabricating receipts. A failed process is not a mathematical
refutation, and a successful run alone does not promote a scientific claim.

Continue existing runnable work within the user's requested scope. Stop at the
named boundary, user stop, or when no selected work can execute. Reporting results
does not require ledger repair or completion of a review cycle; it does include
the branch the run records were pushed to. End with a session receipt
(`python3 tools/session_receipt.py --skill run ...`, see `docs/session-receipts.md`).

## Curvesmash challenge context

For challenge-linked execution, retain the selected track and existing experiment/task scope. A catalog entry or generated task draft is not a launcher. Use the existing declared program and preserve its track metadata in outputs; do not initiate claim review or a submission from an experiment run.

See [the shared challenge workflow](../../../../docs/research-challenges.md).
