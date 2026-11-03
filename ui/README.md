# `ui/` — a read-only dashboard over the research corpus

Published to **GitHub Pages** on every push to `main`, and servable
locally against the working tree:

```sh
make ui                       # live, http://127.0.0.1:8787
make ui-build                 # static, ./site (gitignored; size reported by the build)
python3 -m http.server -d site 8080
```

Standard library plus PyYAML, which the repository already depends on. No
runtime npm dependencies, no bundler, no CDN, no new entry in `pyproject.toml`: this runs in
an offline container, which is where most of this program's sessions
actually run.

## One app, two hosts

GitHub Pages serves files; it cannot answer a query. So **nothing asks
one.** `ui/payloads.py` defines a file-shaped data contract,
`ui/build.py` writes it out and `ui/server.py` computes the same bytes on
request, and the browser does every filter, sort and search itself over
`data/index.json` (~0.8 MB gzipped). The published site and the local
server run the same `app.js` against the same paths.

Two products that disagree about their own data are one product and one
bug, so the contract lives in one module and the tests build a fixture
site and check it file by file.

Three differences remain, and they are the ones that cannot be otherwise:

| | live (`make ui`) | published snapshot |
| --- | --- | --- |
| `data/meta.json` `mode` | `live` | `static`, with commit and build time |
| record source text | loaded on demand from disk | bundled per record, loaded on demand |
| refresh | `POST api/refresh` re-reads the corpus | rebuilt by CI on the next push |
| `data/ops.json` | CloudWatch, cached ~45s; refresh forces a new sample | taken once at build time |

**The published site is a snapshot and says so.** A banner on every view
names the commit and the build time and links to it. A reader comparing
the page against their working tree has to know which commit they are
looking at; a static page that implied freshness would mislead on exactly
the point that matters.

Every record includes a `source_url` pointing to `data/sources/<id>.json`.
The Source tab loads that one file on demand and supports copying and downloading
its text. Reading a finding or searching the index does not fetch source files.
Both hosts use the same source payload, including Markdown front matter and
malformed YAML. Source reads that fail stop the build instead of publishing an
error message as content. Source bytes count toward the Pages size limit.

Knowledge entry bodies also travel in their record payload so the Entry tab
can show the full finding immediately. Long entries have a contents outline.
Record tabs support keyboard arrows, Home/End, and `?tab=source` deep links.
Loading errors offer retry and a link to the same committed source on GitHub.
Proof basis appears in plain text alongside metadata: a written derivation is
not presented as a Lean-verified theorem.

Full-text search loads per-kind excerpt shards on demand; it searches those
excerpts, rather than downloading the source corpus.

The built `index.html` references `app.js?v=<commit>` and `app.css?v=<commit>`.
Pages lets a browser keep an asset for ten minutes, and a reloaded page
pointing at a bare `app.js` ran the previous deploy's client against the
new deploy's data. With the commit in the reference, a deploy always shows
its own client.

## Publishing

`.github/workflows/pages.yml` builds and deploys on every push to `main`
that touches `ledger/`, `experiments/`, `knowledge/`, `ui/` or the ECC
policy, plus a daily run and `workflow_dispatch`. It runs the UI tests,
builds, and refuses to deploy a site with fewer than 100 records, a
missing entry file, or one over the 1 GB Pages limit — an empty build
must not replace a working page.

**One-time setup:** *Settings → Pages → Build and deployment → Source:
**GitHub Actions***. Until that is set the workflow builds and then fails
at the deploy step.

The output (`site/`) is gitignored, like `knowledge/INDEX.md` and the
dispatch plans: it is derived byte-for-byte from committed files, and
committing it would add the whole corpus to the repository a second time
in a form that changes on every merge.

## What it is for

`/research-status` answers "what is the state of the program?" once, in
prose, by spending a model's turn on it. This answers the same question
continuously, for free, and it answers the questions that follow — *which
records cite this evidence? what does this goal's next action refer to?
which identifiers are cited but do not exist?* — which prose cannot,
because they are navigation, not summary.

It reads `ledger/`, `experiments/` and `knowledge/` directly. It is not a
second source of truth and holds nothing of its own.

## On a phone

The desktop shell uses a compact horizontal navigation bar. On small screens,
the navigation scrolls in one row beneath the brand and controls. The home
page's current-work cards stack on phones, activity rows put their date above
the title, and category filters wrap. Search stays at 16px on mobile to avoid
iOS zoom. Detailed record and experiment tables retain their existing layouts.

Below 560px the record table drops the columns an identifier already carries
(kind, area) plus date and citation count, keeping identifier, status and
title, and takes a fixed layout so it fits any width down to a 320px SE
rather than nearly fitting one. Key/value pairs on detail pages stack.

**Tables stay tables.** A run's status, tier and dates are read against each
other, and turning each row into a card loses exactly that; the wide ones
scroll inside their panel, which is what `.scroll-x` is for.

## The views, in the order a reader asks

- **Home** — current research, recent work, and recent findings. The
  distinguished-point database panel (writes/s, reads, storage) sits under
  the snapshot metrics when CloudWatch credentials were present at build
  or on the live server. Three active
  goals show their objective and recorded next action, with ECC first and
  recent updates first within each group. An active goal is not a claim that
  an experiment is running. Flags and impediments display as “Needs attention”.
  The recent-work feed filters findings, experiments, ideas, decisions,
  evidence, and corrections from the latest 60 dated records, showing six
  at a time. Highlights select the two newest entries per type; All work
  shows the complete feed in date order. Task traffic and literature imports are excluded. Dates use the
  last commit touching the record when available (labelled “Committed”);
  otherwise the declared record date is labelled “Recorded”. Unknown dates
  are omitted from the feed. Goal recency also includes sharded checkpoints.
  The research pipeline and links to open questions, areas, and integrity
  live in an expandable section. All summaries are clipped source text.
- **Findings** — the promoted findings (`knowledge/findings/`), grouped
  under the research area they are filed in with that area's goals beside
  the heading, each with its proof status, claim tier, the statement
  excerpted from its own body and what it says it does *not* claim; a
  **By area** table of every research area (goals, findings, hypothesis
  verdicts, evidence polarity, open problems, latest finding); the
  hypotheses that reached a verdict; every evidence record with a
  direction; the obstructions recorded as measurements; and the open
  problems. This is the board for "what did it find?".
- **Research** — the goals board and a goal page with its record trail: every finding, evidence
  record, decision, hypothesis and experiment that cites the goal, grouped.
- **Experiments**, with run tallies by terminal status, the date each
  contract declares (under the field name that carried it), the date git
  first saw it, the latest run activity and the total measured wall-clock.
  Click a contract to expand its runs, each with its declared start, finish
  and duration. Sortable by activity, run count, measured time, contract
  date or identifier.
- **Records** — a faceted browser over everything, by kind, area, knowledge
  family and status, with opt-in full-text search.
- **Integrity** — what is broken, flagged and never fixed.

A record page leads with an *at a glance* block — the fields that say what
the record is (an evidence record's direction, strength, tier and proof
status; a decision's verdict, targets and knowledge promotion; a hypothesis'
statement and status) — above the full parsed tree. A knowledge entry page
renders the entry itself.

### Findings, exactly

`knowledge/findings/` and `knowledge/open-problems/` are parsed exactly, like
goals: ~130 small markdown files whose front matter a reader will act on.
The statement shown on a card is excerpted from the entry's own body — the
section its author labelled as the finding, and within it a blockquote if
there is one, which is the corpus convention for "the finding, in one
sentence" — clipped, never paraphrased. A finding names its goal in about
half the corpus; the rest are attributed through the evidence or decision
that promoted them, and the board says "goals named", not "owner". Each
finding and open problem is *filed* under one area — its goal's, or the
first record it cites — so the By-area table counts nothing twice, while
`areas` keeps every area its citations reach for filtering.

The **not claimed** line on a card is the entry's own boundary section
("Not claimed", "Non-claims", "Limits", "What this says, and what it does
NOT say"), because a claim shown without its boundary is the overclaim the
program's rules exist to prevent.

Evidence `direction` has four values in the schema and about forty spellings
in the records (`supports_with_caveat`, `weakening_scoped`,
`refutes_own_prior_reading`). The board folds them into four for grouping
and colour — *supports*, *weakens*, *mixed*, *neutral* — and always shows the
author's exact word beside the colour. Most evidence is neutral and most
hypotheses never reach a verdict; the counts say so.

An **obstruction** is a negative result recorded as a measurement
(`evidence.obstruction` in `templates/research-records.md`): what blocks an
approach, as a quantity over a stated scope. It lives nested inside an
evidence record, below what the shallow scan can see, so the few dozen
records that carry one are parsed exactly and listed with whether the
reversal — the block read as a resource — was examined.

## What it will not do

**It writes nothing.** Not a ledger record, not coordination state, not a
derived index on disk, not a `__pycache__` entry. `tests/test_ui_index.py`
asserts this by stat'ing every file in a fixture repository before and
after a full build, deep scan, record read and search.

That is a design constraint, not a missing feature. Only the Coordinator
changes hypothesis status or approves experiments (AGENTS.md rule 1);
records are immutable and corrections supersede rather than overwrite
(rule 2). A dashboard that could edit them would be a second, unauditable
path into state that the whole program is built to keep auditable. So the
integrity page **flags and never fixes**, and there is no POST endpoint
except `/api/refresh`, which re-reads the corpus.

## Dates, and which kind each one is

Two kinds of time appear, and the distinction is load-bearing:

- **Declared** — a date the record asserts about itself (`approved_at`,
  `recorded_at`, `started_at`). Always shown under the field name that
  carried it, because a contract *approved* on a day and one merely
  *recorded* on it are different facts.
- **Observed** — the commit time from git history, via `ui/gitdates.py`,
  shown as *committed*. One `git log` pass over `ledger/`, `experiments/`
  and `knowledge/` costs under a second and fills in the ~90% of this
  corpus that declares no date at all: 1,002 of 1,151 experiment contracts
  and 2,434 of 2,531 runs have no timestamp of their own.

They are never merged. A page that showed a commit time under "approved"
would assert something no record says. Hover any date for the exact instant
in UTC and its relative age.

**A shallow clone yields no dates rather than identical ones.**
`actions/checkout` clones depth 1 by default, and a single-commit history
reports every file as added by that commit — 15,000 records all "committed"
at the same instant, which is a *wrong* value rather than a missing one and
looks entirely plausible on a page. `gitdates.load` detects it, reports why,
and the UI shows no commit dates at all; `pages.yml` sets `fetch-depth: 0`
so that path is not taken in CI.

## Two tiers, and why

The ledger is ~5,600 YAML records and ~82 MB. PyYAML's pure-Python loader
parses all of it in **about 55 seconds**; reading the same bytes takes
**about 0.6**. A dashboard that paid 55 s before showing anything, and
re-paid it on refresh, would not get used. So:

| tier | what | cost | what it drives |
| --- | --- | --- | --- |
| 1 | `ui/scan.py` shallow header scan of every file | ~10 s | lists, boards, search, the link graph |
| 2 | `yaml.safe_load` of one record, cached | instant | every detail view |

Tier 1 is line-oriented and therefore approximate. It is not assumed to be
correct — `tests/test_ui_index.py::test_shallow_reading_agrees_with_the_exact_parse`
parses a sample of the real ledger both ways and asserts the agreement rate,
so a record shape the scanner cannot read shows up as a failing test rather
than as blank rows in the browser. A value the shallow parser cannot
represent is reported as *structured*, never guessed at.

A record detail view carries a **`parsed`** badge when its body came from
tier 2. A record that does not parse says so, in red, and links to its
source.

Two things are deliberately exempt from tier 1:

- **Goals** are fully parsed at startup. There are ~100, they carry the
  numbers a reader acts on (budget, completion criteria, impediments), and
  the portfolio board is the view most likely to be trusted without opening
  the record.
- **The unparseable sweep** is an exact parse of the whole ledger and runs
  in a background thread after the server is already answering. Until it
  finishes the integrity page says *not yet measured* rather than showing
  zero — reporting a clean sweep that has not happened is the failure
  AGENTS.md rule 5 names.

## What it knows about the program's rules

The dashboard reads three rules out of `CLAUDE.md` and shows them, rather
than leaving a reader to check by hand:

- **Rule 11, ECC comes first.** ECC goals sort ahead of everything else on
  every board, and are tagged. The area set is read from
  `orchestration/research-priority.yaml` through `tools/ecc_priority.py` —
  it is **never** inferred from an identifier prefix. If that module cannot
  be loaded, ECC ordering is switched off and the integrity page says so,
  rather than the UI guessing a set.
- **Rule 11, ECC budgets are unlimited.** An active ECC goal with a bounded
  `maximum_batches` or `total_wall_clock_seconds` is flagged.
- **Rule 10, goals are never paused.** A goal whose status is `paused` or
  `blocked` is flagged by name. Impediments are shown as impediments — a
  campaign carrying one is still active.

## Identifier linking

Every program identifier in free text becomes a link **if a record with
that identifier exists**. One that resolves to nothing stays plain text,
which is how a dangling reference makes itself visible while you are
reading rather than only in a report.

Both identifier forms link: the random-token form (`GOAL-AUXIN-a93442`)
and the legacy three-digit form (`GOAL-ECDLP-001`). Legacy records are
immutable, must never be renamed, and are most of this program's history.

## Which file a duplicated identifier resolves to

The same identifier can appear in more than one file: a superseding copy
lives under `ledger/corrections/schema-supersessions/` beside the live
record. Keeping the first sighting meant 31 records displayed the v2 body,
and linked "source" at the correction, purely because that path sorts before
`ledger/evidence/`. Resolution now prefers the **canonical** file — the one
whose filename *is* the identifier, outside an archive — and the collision
is still reported under integrity. A record that exists only as a correction
copy is still reachable at that path.

When a canonical YAML record has a registered, hash-matched schema copy, its
detail page shows the copy in a separate **parsed correction** tab, including
when the original parses but fails the current ledger schema. The original
record, source text, parse state, and identifier remain canonical. The reader
does not treat a hash match as a review of the correction's scientific meaning.

An experiment is likewise not always announced by `specification.yaml`:
nineteen directories carry `specification.json` or only prose, and between
them 218 runs. A directory with runs is an experiment whatever shape its
contract takes, and the table says which shape.

The second segment of an identifier is an area token for most kinds but a
**date** for `DEC-`, `IDEA-`, `TASK-` and `CORR-`, and a bare token for
`BATCH-`. Both `ui/scan.py:RECORD_ID_RE` and `ui/static/app.js:ID_RE`
encode that; they must stay in step. For `KN-` it is the entry's **family**
(`FIND`, `OPEN`, `TECH`, `LIT`): families are not research areas and get
their own facet, so 7,900 literature entries no longer sit in the area
filter under an area called `LIT`.

## The data contract

Everything the page renders is a plain JSON file, at the same path in
both hosts. Programmatic consumers can read them the same way the
browser does.

| path | contains |
| --- | --- |
| `data/meta.json` | mode, commit, build time, counts, ECC area set, facets |
| `data/index.json` | every record as a positional row — see `meta.columns` |
| `data/overview.json` | portfolio summary, ECC-first goals, recent records |
| `data/ops.json` | CloudWatch snapshot of the rho distinguished-point database (`rho-dp`): write/read IOPS, throughput, storage. `available: false` when the build has no AWS credentials — the page omits the panel instead of showing a naked 0 |
| `data/goals.json` | the goal board |
| `data/goals/<id>.json` | one goal: checkpoints, criteria, impediments, bound records |
| `data/records/<id>.json` | parsed body, link ids, source URL; a knowledge entry also carries `markdown` |
| `data/sources/<id>.json` | full UTF-8 source text and its repository path; fetched only from the Source tab |
| `data/experiments.json` | contracts with run tallies by terminal status |
| `data/findings.json` | findings with excerpts and attribution, hypothesis verdicts, evidence rows with direction and polarity, obstructions, open problems |
| `data/integrity.json` | unparseable records, duplicate ids, dangling refs, goal flags |
| `data/search/<KIND>.json` | body excerpts for full-text search, per kind |
| `POST api/refresh` | live server only: re-read the corpus from disk |

Rows in `data/index.json` are positional rather than objects because at
14.6k records the repeated key names cost more than the values: 2.6 MB as
objects, 1.4 MB as rows. `meta.columns` names them.

The local server binds to loopback by default. There is no
authentication because there is nothing to authenticate: every handler
reads.

## Database load (`rho-dp`)

The home page shows write IOPS, read IOPS, throughput and storage for the
rho distinguished-point Postgres instance (`rho-dp` in `us-west-2`).
Those numbers come from CloudWatch, not from ledger record counts.

`ui/ops.py` is stdlib-only (no boto3). It:

- prefers the wall-clock last hour when the newest sample is in it;
- otherwise reports the hour *ending at the latest sample*, labelled as
  such, instead of painting LAST HOUR as 0 because the series is stale;
- never invents a rate of zero for an empty window (`null` → em dash);
- names the instance, never the hostname.

Locally, put `AWS_ACCESS_KEY_ID` and `AWS_SECRET_ACCESS_KEY` in `.env`
(gitignored) or the shell. Temporary role credentials also require
`AWS_SESSION_TOKEN`; the client sends and signs it with each RDS and CloudWatch
request. Then:

```sh
set -a && source .env && set +a
python3 -m ui.ops          # JSON snapshot; exit 1 if unavailable
make ui                   # live panel, refresh re-queries CloudWatch
```

The Pages build takes the same snapshot when those names are set as
repository Actions secrets (`Settings → Secrets and variables → Actions`).
Without them the site still publishes; the panel is omitted.

IAM needs `cloudwatch:GetMetricStatistics` (CloudWatch does not support
resource-level ARNs for that call) and `rds:DescribeDBInstances` on
`rho-dp`. S3 bucket-size metrics are tried in `us-west-2` (this bucket's
region) then `us-east-1`.

## Layout

```
ui/
  scan.py      shallow header scanner; the identifier grammar
  index.py     the in-memory index: records, links, goals, experiments, integrity
  payloads.py  the data contract, shared by the server and the builder
  ops.py       CloudWatch snapshot of rho-dp (optional; silent without keys)
  server.py    stdlib HTTP server; computes the contract live
  build.py     writes the same contract out as a static site
  static/      index.html, app.css, app.js — vanilla, no dependencies
tests/test_ui_index.py
tests/test_ui_ops.py
.github/workflows/pages.yml
```

### Reader regression checks

```sh
python3 -m pytest tests/test_ui_index.py tests/test_ui_ops.py -q
npm ci --prefix ui --ignore-scripts
npm test --prefix ui
```

jsdom is a development-only dependency for testing lazy source loading,
project-Pages base paths, safe text rendering, source copy, keyboard tabs,
deep links, retry after failed requests, and the database-load panel. It is
not shipped in the site.

## Progress and receipt comparisons

Home includes a **Research progress** panel for an explicitly supplied,
sanitized supervisor-report snapshot. It shows the observed 24-hour window,
actions, validated-output change, handoff latency, measured cost and coverage.
Unavailable and stale data stay explicit; discoveries and relation counts are
not inferred from action traffic. Use `--progress-snapshot FILE` with either
`python -m ui` or `python -m ui.build`; the default is `ui/progress.json`.

**Compare** reads hash-pinned, archived `groebner_compare` summaries selected in
`ui/receipts.json`. Choose two receipts to inspect scope, accounting, outcomes,
attempt failures/timeouts (when journals are supplied), source hashes and
verification state. The initial catalog is empty pending real archived inputs.
No solver runs or automatic winner claims occur in the reader.

Both hosts serve `data/progress.json` and `data/comparisons.json`. See
[`docs/ui-research-readers.md`](../docs/ui-research-readers.md) for the exporter,
catalog contract, deployment inputs, evidence boundaries and regression checks.

Compare also includes a pinned, offline curve benchmark archive with exact EC1 /
global identities and recorded IC/rho timings. See [the cross-repository contract](../docs/curve-identities.md).


## Curve catalog, research trails and real comparison receipts

`#/curves` reads `data/curves.json`: four source-reported binary curve records
(degrees 13 and 19), 96 trait slots (12 core metadata fields, 51 DiSSECT output
fields and 33 crypto curve_traits fields), full EC1 identity preimages, per-trait
source links, search and a shareable two-curve comparison. Unknown traits stay
unknown. Hash checks establish metadata identity, not mathematical certification.
Integers larger than JavaScript’s exact range are emitted as decimal display
strings after identity validation, preserving all digits.
Factor-base and isogeny configurations remain candidate metadata in Compare.

`ui/curves/dissect-traits.json` snapshots all 22 registered DiSSECT trait
families and their 51 named outputs at upstream commit
[`8edc3030fb91411a55aa6c07d050507d840c5e55`](https://github.com/crocs-muni/DiSSECT/blob/8edc3030fb91411a55aa6c07d050507d840c5e55/dissect/traits/__init__.py).
It preserves output types, default parameter lists, descriptions and per-module
source hashes. Every curve exposes an explicit Unknown slot for each output.
Use **Filter traits** to search names, families, descriptions and parameters;
expand **Definition and parameters** for the pinned definition. Definition
links are separate from result provenance. No DiSSECT tests are run or imported.
Unknown means no sourced result is loaded; applicability is not established.
Parameterized fields describe a family of measurements, not a scalar result.
Future ingestion must retain exact parameter values and measurement provenance;
it must not fold several parameter combinations into one scalar. Similar labels
are deliberately not aliased: class-number bounds are not an exact class number,
extension conductor ratios are not endomorphism-order conductors, and binary
model coefficients are not short-Weierstrass coefficients.

`ui/curves/catalog.json` allowlists local `curve-capsule/1` JSON files by exact
file SHA-256. A capsule contains `field`, `curve`, optional `endomorphism`,
`curve_uid`, and an immutable upstream `source` (repository, commit, path,
SHA-256). Preserve the source's field/curve hash preimage exactly; do not add
computed traits to it. Supplementary traits belong outside that identity.
Each value is labelled source-reported and linked to its source. Identity,
pin, path or supplementary-trait conflicts fail closed. Browsing fetches no
upstream data and performs no mathematical computation.

`ui/curves/crypto-traits.json` (adapter `crypto-curve-traits/1`, pinned under
`supplementary_traits` in the catalog) snapshots aburan28/crypto's computed
`docs/curves/traits.json` (`curve-traits/1`) with its `registry.json` and
`TRAITS.md` pins at one commit; it holds only records whose registry
representations include a catalogued `curve_uid`. The two `crypto-EC1….json`
capsules are crypto registry representations whose `curve_uid` the shared
identity helper reproduces. Joins are by exact `curve_uid` only:
`binary13.json` is the same Koblitz equation under another modulus and
generator, so it receives no crypto traits. Each value keeps crypto's status
(`proved`, `probable`, `bounded`, `unknown`, `not_evaluated`,
`not_applicable`) in the **crypto curve_traits** section. A DiSSECT or core
slot is filled only when its definition is the same quantity and the status is
`proved` or `probable`: `cofactor.order`/`cofactor` (registry generator order
and cofactor), `embedding.complement_bit_length` (bit length of (r−1)/ord_r(q)),
`discriminant.cm_disc`, `max_conductor` (v in t²−4q = v²·d_K) and
`factorization` (primes with multiplicity, as DiSSECT unpacks them), plus core
order, trace, CM discriminant and End(E) conductor (1 when End(E) = O_K is
established). Capsule-reported values that disagree fail closed. Exact class
numbers, Frobenius conductors, twists and volcano depths stay supplementary;
parameterized DiSSECT families and values that would need arithmetic, such as
`embedding_degree_complement`, stay Unknown. Refresh with
`python3 tools/export_crypto_curve_traits.py --crypto ../crypto --commit <sha>`
(`--check` re-derives the committed files).

`#/provenance` reads `data/provenance.json`. It follows an experiment and its
run IDs through at most three inbound citation steps to evidence, decisions,
corrections and findings. It never follows a shared hypothesis into unrelated
experiments. Timelines use declared record dates, leaving missing dates unknown.
Home summarizes visible gaps; experiment records and run tables link to trails.
`declared_archived` means only that the experiment contract says `archived`.
Coordination archive receipts, live PR state and worker telemetry are not inferred.
A citation is not an endorsement; a missing link is a coverage gap, not evidence
that review or archival never happened. The local server reads its working tree;
static exports reflect the chosen source tree, including any uncommitted edits.

The Compare selectors now include all nine rows of the existing pinned primary
benchmark snapshot, registered in `ui/receipts.json` with
`adapter: benchmark-snapshot/1`. This is a new reader adapter, not a new run.
The 2026-10-20 snapshot pins `cryptanalysis` main commit
`5ab7d5bc5a16ff4d87a5ef8bed45cf9543f47c14`. It refreshes candidate IDs
and recorded timings from the committed primary archive, while its coverage
remains exactly those nine N13 toy rows; see the
[validation report](../docs/reports/2026-10-20-formal-validation/report.md).
Its normalized `comparison-package/1` projection preserves curve/candidate/workload
IDs, source pins, target counts, verification/status, online and total times,
operation units, calibration/resource IDs and failures. No arbitrary package
JSON is accepted as evidence. Add source-specific adapters with validation before
registering other experiment families. The original Groebner summary reader
remains supported.

Curve/workload filters and both selected receipts are URL parameters. Missing
host details, exclusions or incompatible accounting retain a warning and never
produce a winner. Paired rho timings remain explicitly source-reported, not
independently archived rho candidates. Both HTTP serving and static generation
use `ui.payloads` for these new payloads. Source links require network; viewing
local/static payloads does not.

Focused validation:

```sh
python3 -m pytest tests/test_ui_research_views.py tests/test_ui_benchmarks.py tests/test_ui_index.py
cd ui && npm ci && npm test
```

Optional real-browser layout smoke test: install development-only Playwright
in `ui/` (`npm install --no-save playwright`, then `npx playwright install chromium`),
serve the built snapshot or start `python3 -m ui`, and from the repository root run
`UI_TEST_URL=http://127.0.0.1:8787 node tests/test_ui_research_browser.cjs`.
`PLAYWRIGHT_MODULE` may name an existing Playwright installation. The test checks
the new routes at mobile and desktop widths without executing experiments.
