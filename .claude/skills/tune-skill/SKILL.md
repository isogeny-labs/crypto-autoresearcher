---
name: tune-skill
description: >-
  Propose a reward-guided revision of another skill's instructions, using its
  downstream ledger records as the reward. Writes no ledger record; every
  diff is a code change a human approves. Use to tune or improve a skill
  against its track record, e.g. `/tune-skill propose-ideas`.

---

# Tune skill

Treats a target skill's instruction file as a policy: gathers the batch of
ledger records it has produced since the last tuning round, scores that batch
on decisiveness (not on whether it was "right"), and asks an agent to propose
a minimal, citation-backed diff to the instructions. A human approves before
anything is applied. Nothing here writes to `ledger/`, changes a hypothesis
or goal status, or claims Coordinator authority — it edits files under
`.claude/skills/` and `agents/` exactly like any other code change, so normal
git/PR review is the only gate. See the conversation this came out of for the
alternative, ledger-integrated design (an `RQ-META-*` campaign) if this
prototype proves useful enough to graduate into the program's own governance
model instead of living beside it.

**Scope of applicability.** This reward chain only exists for skills whose
output is a record with a gradable downstream outcome:

| skill | output record | downstream chain |
| --- | --- | --- |
| `propose-ideas` | `IDEA-*` (`ledger/proposals/`) | → `H-*` → `EXP-*` → `EV-*` → `DEC-*` |
| `design-experiment` | `H-*` status change + `EXP-*` contract | → `EXP-*` → `EV-*` → `DEC-*` |
| `run` | run records under `experiments/EXP-*/` | → `EV-*` → `DEC-*` |
| `review-evidence` | `EV-*` + `DEC-*` | (terminal — score its own `strength`/`knowledge_promotion` choices against later corrections, if any) |
| `tune-skill` | round records | → applied round → outcome record (`tools/self_improve.py`); loop mode only |

For anything else in `.claude/skills/` (`coordinate`, `deep-research`,
`research-status`, `curate-knowledge`, `agent-bus`) there is no single graded
output record to chain from — refuse, and tell the user this prototype only
covers the skills above (`tune-skill` only in loop mode, below).

## Steps

1. **Resolve target and files in scope.** Take the skill name from the
   command args (`/tune-skill <skill-name> [--since <date-or-commit>]`).
   Confirm it's one of the skills above; if not, stop and say so. Read
   `.claude/skills/<skill-name>/SKILL.md`. If its text dispatches a
   subagent ("Dispatch the **X** subagent"), also read `agents/X.md` — both
   files are in scope for the diff, since instructions live in either place.

2. **Ground against `origin/main` and find the batch window.** `git fetch
   origin`. List `coordination/skill-tuning/<skill-name>/round-*.yaml`
   (create the directory if this is the first round for this skill); if any
   exist, sort by `round.decided_at` and read the latest's
   `round.batch_window.until` as the cutoff. Otherwise use `--since` if
   given, else no lower bound (full history). Record the resolved window
   (`since`, and `until` = `origin/main` HEAD sha) — this is what makes
   rounds composable instead of re-scoring the same records twice.

3. **Collect the batch.** For `propose-ideas` and `design-experiment` the
   walk below is a tool, so a second session reproduces the first one's
   batch instead of re-deriving it by hand:

   ```sh
   python3 tools/tune_skill_batch.py propose-ideas [--since DATE] [--until DATE]
   python3 tools/tune_skill_batch.py design-experiment --json
   ```

   It reads the generated indexes (`python3 tools/build_ledger_index.py`
   writes `ledger/.index/{proposals,hypotheses,experiments}.jsonl`), parses
   `ledger/evidence/` and `ledger/decisions/` as the terminal records, runs
   the structured pass then the free-text pass described below, applies
   step 4's reward table, and reports coverage, the thin-data test, and the
   receipts (`tools/session_receipt.py`) that cover the window, including
   the summed `bounced` counts. Where no receipts exist for the window it
   says so and the round record carries that caveat; nothing is estimated.
   Round 1 (`coordination/skill-tuning/*/round-*.yaml`, window closed 2026-10-07) is the
   reference run: full history, both skills above the thin threshold, and
   for `propose-ideas` three terminal items in four found only by free
   text. For `run` and `review-evidence` the walk is still manual, in the
   same two passes. Open a YAML file only to verify a hit.
   **Structured fields alone under-count badly** — a dry run against
   `propose-ideas`'s full history (799 ideas) found only 2 terminal outcomes
   via fields alone, versus at least 5 once free-text matching was added
   below, and every free-text match checked was hand-verified as genuine
   provenance, not an incidental mention. Do both passes, in this order:
   - **Structured pass.** `IDEA-*` → `H-*`: grep `ledger/hypotheses/*.yaml`
     for `proposal_id: <id>`, `source_idea_id: <id>`, **and** `idea_id:
     <id>` — the corpus uses all three field names inconsistently, and
     checking fewer silently drops records. `IDEA-*` → `EXP-*` directly:
     grep `experiments/EXP-*/specification.yaml` for `derived_from_idea:
     <id>` — many experiments carry this even when `hypothesis_id: null`,
     i.e. they skip the hypothesis link entirely; missing this path alone
     was the largest single source of undercount in the dry run. `H-*` →
     `EXP-*`: grep for `hypothesis_id: <id>`. `H-*`/`EXP-*` → `EV-*`: grep
     `ledger/evidence/*.yaml` for matching `hypothesis_id` and
     `experiment_ids`. `EV-*` → `DEC-*`: grep `ledger/decisions/*.yaml` for
     the `EV-*` id in `evidence_refs` (more reliable than `target_ids`,
     which mixes record types).
   - **Free-text fallback pass.** For every idea not yet resolved to a
     terminal `EV-*` by the structured pass, grep its literal ID
     (`IDEA-YYYYMMDD-<tok>`) across `ledger/hypotheses/`, `experiments/`,
     `ledger/evidence/`, and `ledger/decisions/`. A hit in an `EV-*` or
     `DEC-*` file is a candidate terminal outcome — read the surrounding
     text before trusting it, since a mention can be a comparison or
     cross-reference (e.g. "dominated_by IDEA-X") rather than provenance.
     Tag which pass found each match (`structured` vs `free_text`) in the
     batch table; free-text matches carry more review burden and should
     stay visibly distinguishable, never silently merged with structured
     ones.
   Every batch item ends in one of: a terminal `EV-*` (has `strength`), still
   in-flight (reached `H-*`/`EXP-*` but no `EV-*` yet — exclude from scoring,
   count separately as coverage), or never picked up at all (no downstream
   record by either pass — same treatment). Do this gathering directly; it's
   grep and read, no agent needed.

4. **Score the batch — decisiveness, not correctness.** For each item with a
   terminal `EV-*`, map `strength` to a reward:

   <!-- frozen:reward -->
   | `strength` | reward | why |
   | --- | --- | --- |
   | `strong`, `replicated` | +2 | minimal test actually discriminated |
   | `preliminary`, `anecdotal` | +1 | discriminated, weakly |
   | `inconclusive`, `contradictory` | 0 | test failed to resolve, or wasn't reproducible |
   <!-- /frozen:reward -->

   **Any `strength` value outside this table is `unscored`, not `0`.** The
   dry run against `propose-ideas` found live evidence records using `n/a`
   (the majority of the free-text-matched sample) and `moderate` (a whole
   MLKEM chain), neither of which appears in `templates/research-records.md`'s
   documented six-value enum. Do not silently drop these and do not fold
   them into the histogram at any score — list each in its own `unscored`
   bucket with the literal value seen, so schema drift in the corpus stays
   visible instead of quietly shrinking the batch. An item with only
   `unscored` evidence counts toward coverage but never toward the
   thin-data threshold in step 5.

   **Explicitly ignore `direction`** (`supports`/`weakens`/`contradicts`/
   `neutral`) in the score. Rewarding `supports` outcomes would train the
   generator toward safe, easily-confirmed proposals and away from genuinely
   uncertain high-value ones — the premature-closure failure mode
   `AGENTS.md` rule 9 already names. A decisive falsification scores the same
   as a decisive confirmation. Also tabulate, as diagnostics only and never
   as reward inputs: coverage (fraction of the batch that ever reached
   `EXP-*`), and any `DEC-*` `rationale`/`limitations` text in the chain that
   flags an overclaim, undisclosed `dominated_by`, or missing
   `heuristic_assumptions` — these are evidence for the diff, not points
   against the score.

   **Bounces.** Whether an idea was sent back for schema incompleteness
   (`propose-ideas` step 4) leaves no ledger trace, so for batches before
   2026-10-07 this signal cannot be reconstructed. From that date the
   skill's session receipt carries `--bounced <n>`, and
   `tune_skill_batch.py` sums it per window as a diagnostic (never a reward
   input): a rising bounce rate with flat decisiveness says the schema
   check is doing the generator's work.

5. **Build the tuner prompt.** Assemble: the full current text of the
   skill file (and agent contract, if applicable); the scored batch as a
   table of record IDs with short excerpts (`claim`/`mechanism` snippet,
   terminal `strength`+`direction`, any flagged `DEC-*` rationale); the
   window and coverage stats; and these hard constraints for the agent:
   <!-- frozen:constraints -->
   - Propose a **minimal, targeted diff** — specific sentences or bullets
     added/changed/removed, not a rewrite.
   - **Cite the specific record IDs** from this batch that motivate each
     change. A proposed change with no citation is not eligible to include.
   - **Do not optimize toward `support` decisions** or toward any specific
     target/area being proposed more or less often — if a change would shift
     *which* questions get proposed against rather than *how clearly* a
     proposal is specified, it must independently justify itself against the
     `docs/inventor-protocol.md` §4 premature-closure standard, not against
     the decisiveness score alone.
   - **State if the batch is too thin to act on** (rule of thumb: fewer than
     5 *scored* terminal items — `unscored` items from step 4 don't count
     toward this — or concentrated in a single `RQ-*`/area) and recommend no
     change rather than a confident-sounding diff on noise.
   <!-- /frozen:constraints -->

6. **Dispatch a general-purpose agent** with that prompt, read-only against
   the repo (instruct it explicitly not to edit or write any file — it
   returns a diff as text plus a short rationale, it does not apply one).
   `run_in_background: false` — the next step needs its output immediately.

7. **Present to the user.** Show the proposed diff, its rationale with
   citations, the batch table, and the reward summary. This is the approval
   gate — do not apply anything automatically, and do not treat a prior
   approval of a different round as standing approval for this one.

8. **On approval, apply and record.** Edit the skill/agent file(s) with the
   approved diff. Write the round record with the same tool that built the
   batch, so the record and the batch cannot disagree:

   ```sh
   python3 tools/tune_skill_batch.py <skill-name> --write-round coordination/skill-tuning \
       --decision proposed|applied|rejected|deferred --rationale "..." --caveat "..."
   ```

   It mints `round-<6hex>` with `secrets.token_hex(3)` — a minted token,
   not a scanned "next free number" (`AGENTS.md`, "Concurrency"): two
   worktrees tuning the same skill must not collide. Then add
   `files_changed` and `diff_summary` by hand (the only two fields the tool
   cannot know). The record at
   `coordination/skill-tuning/<skill-name>/<round-id>.yaml` has this shape:

   ```yaml
   round:
     id: <round-id>
     skill: <skill-name>
     files_changed: []
     batch_window: {since: null, until: null, origin_main_sha: null}
     batch_items: []          # record IDs considered, with terminal status
                              # and match_method: structured | free_text
     reward_summary: {terminal_n: 0, in_flight_n: 0, uncovered_n: 0,
                       unscored_n: 0, unscored_values: [],
                       histogram: {plus2: 0, plus1: 0, zero: 0}}
     diff_summary: null       # prose summary; the diff itself lives in the commit
     decision: applied | rejected | deferred
     rationale: []
     caveats: []              # e.g. "batch below thin-data threshold"
     decided_by: user
     decided_at: null
   ```

   If the user rejects or defers, still write the round record with
   `decision: rejected` / `deferred` and no `files_changed` — a null result
   is still a result, and the next round's window should start after it
   either way.

9. **Commit and push as a normal code change.** One commit covering the
   skill/agent file edit(s) and the round record, message referencing the
   round id. No ledger snapshot/archive step applies — this isn't a ledger
   record — but open or refresh a PR with the runtime's PR tool as usual and
   enable auto-merge (`gh pr merge <n> --auto --merge`) so the diff gets the
   same review any other instruction change would.

10. **Receipt.** `python3 tools/session_receipt.py --skill tune-skill
    --role <role> --outcome <published|no_change|impeded> --files-read <n>`
    (`docs/session-receipts.md`). A round with a thin batch is
    `no_change`; it is still a round.

## Loop mode: `/tune-skill next`

The loop (`tools/self_improve.py`; design, calibration and limits in
`docs/self-improvement-loop.md`) picks the target, measures what an applied
round did, and makes `tune-skill` a target of itself. Run `python3
tools/self_improve.py plan` and act on its `next` line only:

- **`tune <skill>`**: steps 1–7 for that skill (write scope: `TARGETS` in the
  tool, which leaves out `agents/coordinator.md`), with the PR as step 7's
  approval gate. Branch `skill-tuning/<skill>-<round-id>`; write the round
  with `--decision proposed`; run `python3 tools/self_improve.py guard
  --target <skill>` and stop if it fails; if it lists `eval_required`, run
  `python3 -m orchestration.eval run --suite evals/suites/discipline.yaml
  --trials 10 --baseline evals/baselines/current.json` and stop on a
  discipline regression, or say in the PR that it was not run. Then step 9
  and the PR. The round is applied when a human merges it.
- **`measure <round>`**: `python3 tools/self_improve.py measure <round>
  --write`, commit the outcome record in a PR.
- **`revert <round>`**: a round whose outcome is `regressed`. Open a PR
  restoring its `files_changed` from the commit before it merged, with a new
  round record carrying `reverts: <round>` and `--decision proposed`.
- **`wait_*` / `idle`**: no change. Report the plan and stop.

<!-- frozen:loop-gates -->
Loop gates, outside every round's write scope:

- One live round per target: no new round while a `skill-tuning/<skill>-*`
  branch is open or an applied round is unmeasured, so outcomes stay
  attributable to one change.
- Never merge a tuning PR yourself, and never re-run `measure` to get a
  different verdict: an outcome record is written once.
- `guard` failing, or a discipline-eval regression, ends the round; a
  capability gain never pays for a discipline loss.
- For target `tune-skill` the batch is the outcome records
  (`improved` +2, `no_change_detectable` 0, `regressed` −2) and the diff may
  touch neither these gates, the `reward` and `constraints` regions, nor the
  scoring code.
<!-- /frozen:loop-gates -->

## If this proves out

A round record's reward trend across several rounds is the "learning curve."
If it's actually moving decisiveness and the team wants this to carry real
authority (gate on Coordinator approval, cite as evidence, survive audit),
graduate it into the ledger as an `RQ-META-*` campaign over the skill file
instead of extending this prototype — that gets citation discipline,
immutability, and Coordinator sign-off for free instead of reimplementing
them here.

## Default challenge research loop

Research goals use [the default challenge research loop](../../../docs/challenge-research-loop.md). Preserve the frozen problem, candidate, evidence and review pointers relevant to this skill. Work within its existing role; findings guide the next attempt, and a worker completion alone is not scientific acceptance.

For goal-level boundary work, `autoresearch campaign frontier --goal <GOAL-ID>`
shows the fixed comparison domain, reviewed points, remaining gap and next test.
Carry those references; keep measured, modeled and unresolved claims distinct.
