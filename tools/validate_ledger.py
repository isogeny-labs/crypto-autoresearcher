#!/usr/bin/env python3
"""Validate the research ledger, experiments, and run records.

Mechanically enforces the invariants that AGENTS.md and docs/ state in prose:

  * every record's ID matches its type's format and its filename;
  * IDs are globally unique (never reused);
  * cross-references resolve (hypothesis->question, evidence->run, ...);
  * required fields are present per record type;
  * run manifests are complete and reproducible;
  * a run claiming a solve carries a verified certificate;
  * evidence records carry descriptive scale metadata and explicit scope;
  * knowledge/INDEX.md is not stale.

Exit code 0 if clean, 1 if any error. Empty ledger validates clean.

Legacy records that predate this validator are grandfathered via
tools/validate_ledger_baseline.txt: known error lines listed there are
reported as suppressed instead of failing the build, so new violations
still block while immutable historical run records stay untouched.
Entries may only ever be removed from the baseline (as records are
repaired or superseded), never added — regenerating it to absorb a new
violation defeats the check.

An archived run manifest that is repaired by a NEW record rather than an
edit (AGENTS.md core rule 4) is routed via tools/run_supersession_registry.yaml:
the run-schema check reads the superseding record, while both files stay
pinned by sha256 and the superseded file must remain present at its
original path. Supersession redirects the schema check; it never suppresses it.
A separately declared and source-bound non-execution hand derivation has no
process capture to require. Ordinary run directories retain the five-artifact
contract.

The same rule applies to archived ledger, experiment, knowledge, and goal
checkpoint records through tools/schema_supersession_registry.yaml.  The
discovered source stays byte-identical and hash-pinned; validation reads the
explicit replacement record.  This is deliberately separate from the legacy
inventories and the prune-only baseline: a supersession must supply a complete
record and cannot turn an error into a warning.

Usage: python3 tools/validate_ledger.py [--no-baseline] [--update-baseline]
"""
from __future__ import annotations

import argparse
import glob
import hashlib
import io
import json
import os
import re
import stat
import subprocess
import sys
from pathlib import Path, PurePosixPath

import yaml

REPO = os.path.dirname(os.path.dirname(os.path.abspath(__file__)))

# libyaml parses ~10x faster than the pure-Python loader, and parsing was 97%
# of this validator's run time. The pure loader stays the reference: anything
# libyaml rejects is re-parsed by it, so every error -- and its message, which
# the baseline and the head/base CI gate compare -- is what yaml.safe_load says.
_CSafeLoader = getattr(yaml, "CSafeLoader", None)


def _safe_load(source):
    """yaml.safe_load, through libyaml when it is installed.

    A standalone copy of orchestration/fast_yaml.py's safe_load: this file
    (and check_merge_hygiene.py beside it) must run without the package.
    """
    if _CSafeLoader is None:
        return yaml.safe_load(source)
    if not hasattr(source, "read"):
        try:
            return yaml.load(source, Loader=_CSafeLoader)
        except yaml.YAMLError:
            return yaml.safe_load(source)
    data = source.read()
    try:
        return yaml.load(data, Loader=_CSafeLoader)
    except yaml.YAMLError:
        # Replay what was read under the stream's name, so the pure loader's
        # marks read as they would have on `source`, seekable or not.
        replay = io.BytesIO(data) if isinstance(data, bytes) else io.StringIO(data)
        if hasattr(source, "name"):
            replay.name = source.name
        return yaml.safe_load(replay)
BASELINE_PATH = os.path.join(REPO, "tools", "validate_ledger_baseline.txt")

# Certificate kinds a run may CLAIM, each of which carries a verification duty
# (certificate.verified must be true). A run that claims nothing records
# `kind: none`, which is accepted without a certificate and is not listed here.
# Authoritative prose: docs/claims-and-verification.md.
CERTIFICATE_KINDS = ("discrete_log", "decomposition", "key_recovery")
LEGACY_LEDGER_INVENTORY = os.path.join(
    REPO, "tools", "legacy_ledger_inventory.yaml"
)
LEGACY_RUN_INVENTORY = os.path.join(
    REPO, "tools", "legacy_run_inventory.yaml"
)
RUN_SUPERSESSION_REGISTRY = os.path.join(
    REPO, "tools", "run_supersession_registry.yaml"
)
RUN_SUPERSESSION_SCHEMA = "run-supersession-registry-v1"
RUN_SUPERSESSION_REQUIRED = ["run_id", "superseded_path", "superseded_sha256",
                             "superseding_path", "superseding_sha256",
                             "defect", "registered"]
# The exact shape check_run() discovers by glob. A superseded record must match
# it (otherwise the entry would never be consulted and would only mislead), and
# a superseding record must NOT match it (otherwise the glob would find it too
# and register the same run id twice, weakening the duplicate-ID check).
RUN_MANIFEST_PATH = re.compile(
    r"^experiments/[^/]+/runs/[^/]+/manifest\.yaml$")
SCHEMA_SUPERSESSION_REGISTRY = os.path.join(
    REPO, "tools", "schema_supersession_registry.yaml"
)
SCHEMA_SUPERSESSION_SCHEMA = "schema-supersession-registry-v1"
SCHEMA_SUPERSESSION_REQUIRED = ["kind", "superseded_path",
                                "superseded_sha256", "superseding_path",
                                "superseding_sha256", "defect", "registered"]
SCHEMA_SUPERSESSION_KINDS = {
    "ledger", "experiment", "knowledge", "goal_checkpoint"
}
SCHEMA_SUPERSESSION_ROOT = "ledger/corrections/schema-supersessions/"
SHA256_HEX = re.compile(r"^[0-9a-f]{64}$")

# These decisions name design-stage contracts, not approved experiment records.
# Keep the exception bound to both the decision and the exact frozen draft:
# an arbitrary missing EXP id, a changed draft, or an approved draft must still
# fail the reference check. The same bafa2e draft is cited by two decisions.
DRAFT_DECISION_TARGETS = {
    ("DEC-20260929-21bb51", "EXP-AUXIN-bafa2e"):
        ("BATCH-9b2090", "TASK-20260928-4d6266",
         "667cf21e1a0680eaa5eb862164835a0074c109f2254f5ac6f52428327ba27bbd"),
    ("DEC-20260929-7efa82", "EXP-AUXIN-bafa2e"):
        ("BATCH-9b2090", "TASK-20260928-4d6266",
         "667cf21e1a0680eaa5eb862164835a0074c109f2254f5ac6f52428327ba27bbd"),
    ("DEC-20260929-4eade7", "EXP-AUXIN-369078"):
        ("BATCH-36b01a", "TASK-20260929-6d01d7",
         "b147966a5798bab10183ac56a9daa703ff41c54936f832fb8d0e28f2becd1589"),
    ("DEC-20260929-93fc4d", "EXP-AUXIN-55c6c0"):
        ("BATCH-14b284", "TASK-20260929-1abb8c",
         "608c46c02a59c8f4ba5871e6d32643c58e2b351302b98fd54f866d2bac679b8c"),
    ("DEC-20260929-cfb294", "EXP-AUXIN-92dccc"):
        ("BATCH-1907cf", "TASK-20260929-ef0945",
         "894c4855b64fdd2ec63915f88d6c668dcb95f40a108eba4f07a701b12bf6ccb6"),
}

# This placed specification is byte-identical to the frozen design-stage
# draft. It has not been approved and must never enter ctx.ids as an experiment.
# Both copies are pinned so a changed contract, a moved file, or a later
# approval cannot silently acquire the draft classification.
AUXIN_SUCCESSOR_DRAFT = (
    "experiments/EXP-AUXIN-339fb0/specification.yaml",
    "coordination/goals/GOAL-AUXIN-a93442/batches/BATCH-ad00c6/design/"
    "TASK-20260929-d519f6/draft-contract.yaml",
    "6a1dca32c109d5badf4ba143c31f9d4d9a49e18ae287c8bb4fc604526bf02ecc",
)

# Identifier suffixes. TWO FORMS ARE VALID AND THE RANDOM ONE IS PREFERRED.
#
#   SUFFIX_LEGACY  \d{3}        sequential, allocated max+1. Every record minted
#                               before 2026-08-01 uses it. STILL VALID FOREVER --
#                               those records are immutable and must keep
#                               validating -- but NEVER MINT A NEW ONE.
#   SUFFIX_RANDOM  [0-9a-f]{6}  a random 24-bit token. This is the form new
#                               records use.
#
# Why the change: sequential allocation requires scanning committed state for a
# maximum, and CONCURRENT WORKTREES ALL SCAN THE SAME STATE AND GET THE SAME
# ANSWER. They then mint the same identifier for different records, and the
# collision is only discovered at merge time, when both records are already
# committed and immutable and neither can be renamed without breaking whatever
# archive binds it. The random token needs no scan at all, so two worktrees
# cannot converge by construction. Cost of the change: identifiers no longer
# sort into creation order. Nothing in this repository ordered by them.
SUFFIX_LEGACY = r"\d{3}"
SUFFIX_RANDOM = r"[0-9a-f]{6}"
SUFFIX = rf"(?:{SUFFIX_LEGACY}|{SUFFIX_RANDOM})"

DUPLICATE_RUN_IDS = os.path.join(REPO, "tools", "duplicate_run_ids.yaml")


def _load_duplicate_run_owners() -> dict[str, set[str]]:
    """run id -> the experiments it occurs under, for ids that collide.

    Frozen by tools/build_duplicate_run_ids.py and held to never grow by
    tools/test_duplicate_run_ids.py. Read here so a citation of a colliding id
    can be required to say which experiment it means. Absent file is not fatal:
    the check simply does not fire, and the must-not-grow test is what notices.
    """
    try:
        document = _safe_load(open(DUPLICATE_RUN_IDS, encoding="utf-8"))
    except (OSError, yaml.YAMLError):
        return {}
    records = (document or {}).get("records") or {}
    return {
        rec_id: {o.get("experiment_id") for o in entry.get("occurrences") or []}
        for rec_id, entry in records.items()
    }


DUPLICATE_RUN_OWNERS = _load_duplicate_run_owners()

ID_PATTERNS = {
    "goal": re.compile(rf"^GOAL-[A-Z0-9]+-{SUFFIX}$"),
    "research_question": re.compile(rf"^RQ-[A-Z]+-{SUFFIX}$"),
    "idea": re.compile(rf"^IDEA-\d{{8}}-{SUFFIX}$"),
    "hypothesis": re.compile(rf"^H-[A-Z]+-{SUFFIX}$"),
    "experiment": re.compile(rf"^EXP-[A-Z]+-{SUFFIX}$"),
    "evidence": re.compile(rf"^EV-[A-Z]+-{SUFFIX}$"),
    "coordinator_decision": re.compile(rf"^DEC-\d{{8}}-{SUFFIX}$"),
    "handoff": re.compile(rf"^TASK-\d{{8}}-{SUFFIX}$"),
    # Batches carry no date or area segment: BATCH-<suffix>. Sequential batch
    # numbers are the LAST place in this harness where two concurrent lanes
    # still collide by construction -- each computes "highest + 1" from the
    # same committed state and both open BATCH-028. That happened twice in one
    # session: once as a directory-name collision resolved by yielding, and
    # once as a whole card set replaced wholesale. The legacy \d{3} form stays
    # valid forever because existing batch directories are immutable.
    "batch": re.compile(rf"^BATCH-{SUFFIX}$"),
}
RUN_ID = re.compile(r"^RUN-[A-Za-z0-9._-]+$")

LEDGER_DIRS = {
    "questions": "research_question",
    "proposals": "idea",
    "hypotheses": "hypothesis",
    "evidence": "evidence",
    "decisions": "coordinator_decision",
    "handoffs": "handoff",
}

REQUIRED = {
    "research_question": ["id", "title", "scope", "status", "owner"],
    "idea": ["id", "title", "class", "claim", "mechanism", "novelty_status"],
    "hypothesis": ["id", "question_id", "statement", "mechanism", "status"],
    "experiment": ["id", "hypothesis_id", "version", "status", "metrics",
                   "budget", "success_criterion"],
    "evidence": ["id", "hypothesis_id", "run_ids", "direction", "strength",
                 "claim_tier", "proof_status", "proof_refs"],
    "coordinator_decision": ["id", "decision", "target_ids",
                             "knowledge_promotion", "decided_by"],
    "handoff": ["id", "from", "to", "objective", "budget"],
}

RUN_REQUIRED_TOP = ["id", "experiment_id", "status", "code", "environment",
                    "inputs", "timing", "result"]

# A control, instrument check or certification run legitimately bears on NO
# hypothesis, and several records say so at length: "Naming a hypothesis here
# would invite exactly the inference the run cannot support." Requiring the
# field non-empty pushed those records toward naming a hypothesis they must not
# name -- the rule inverted its own purpose. An explicit null is accepted, but
# only when the record documents the choice in a sibling note, so a silent
# omission is still an error and the reasoning stays on the record.
#
# Likewise an observation-only contract has no criterion to succeed or fail on.
# EXP-YIELD-003 spells the intent out: "The schema field is present and
# explicitly null rather than absent, so that a reader cannot mistake an omitted
# field for an overlooked one" -- exactly the distinction enforced here.
#
# approved_by is deliberately NOT nullable: AGENTS.md rule 1 gives it exactly
# one legitimate value.
DOCUMENTED_NULL_OK = {
    "hypothesis_id": ("hypothesis_id_note", "hypothesis_note"),
    "success_criterion": ("success_criterion_note",),
    "falsification_criterion": ("falsification_criterion_note",),
}


def field_is_satisfied(body: dict, field: str) -> bool:
    if body.get(field) not in (None, ""):
        return True
    if field not in body:
        return False          # absent entirely: never excused
    for note in DOCUMENTED_NULL_OK.get(field, ()):
        if str(body.get(note) or "").strip():
            return True
    return False


TIER_ORDER = {"toy": 0, "medium": 1, "crypto": 2}
PROOF_STATUSES = {"certificate", "derivation", "empirical_only",
                  "not_applicable"}

# Both blocks below are OPTIONAL and checked only when present, which is what
# lets them land without a baseline entry: the baseline is prune-only, so a
# newly-required field on immutable records could never be grandfathered and
# would fail `main` forever. Absence is reported as schema debt instead --
# `tools/obstruction_registry.py --debt` for the obstruction backlog. What is
# enforced is that a record CLAIMING the new schema completes it.
CITATION_PROVENANCE = {"recalled", "retrieved", "kb", "internal"}

# `recalled` means no agent in this program opened the source. Such a reference
# is a pointer for a reviewer, never support (AGENTS.md rule 9), so these two
# record shapes may not rest on one. No committed record carries a provenance
# field at all, so this can be a hard error from the start: it fires only on
# records written against the new schema.
PROVENANCE_ASSERTS_LITERATURE = {"known", "adaptation"}

OBSTRUCTION_REQUIRED = ["statement", "quantity", "value", "scope"]

# `review_plan` on a handoff follows the same optional-when-present rule. What
# this checks is the plan's INTERNAL consistency, which is all a single record
# can show: whether the reviewers honoured it is cross-checked against their
# attestations by `tools/check_review_independence.py`, which needs the reports
# and so cannot run here.
REVIEW_VERDICTS = {"holds", "breaks", "inconclusive"}


def check_review_plan(path: str, body: dict, ctx: Ctx) -> None:
    """Validate a `review_plan` block on a handoff.

    The plan may be inline, or a repository-relative path to a YAML file that
    either *is* the plan mapping or wraps it under a top-level ``review_plan``
    key. Path form keeps one shared plan file for a multi-reviewer round
    without duplicating the mapping into every handoff.
    """
    plan = body.get("review_plan")
    if plan is None:
        return
    if isinstance(plan, str):
        ref = plan.strip()
        if not ref or ref.startswith("/") or ".." in PurePosixPath(ref).parts:
            ctx.err(path, "review_plan path must be a repository-relative file")
            return
        target = os.path.join(REPO, ref)
        if not os.path.isfile(target):
            ctx.err(path, f"review_plan path does not exist: {ref}")
            return
        try:
            loaded = load_yaml(target, ctx)
        except Exception as error:  # noqa: BLE001 - surface as ledger error
            ctx.err(path, f"review_plan path {ref} failed to load: {error}")
            return
        if not isinstance(loaded, dict):
            ctx.err(path, f"review_plan path {ref} must load a mapping")
            return
        if isinstance(loaded.get("review_plan"), dict):
            plan = loaded["review_plan"]
        else:
            plan = loaded
    if not isinstance(plan, dict):
        ctx.err(path, "review_plan must be a mapping")
        return
    for field in ("claim_under_review", "coordinator_prior"):
        if not str(plan.get(field) or "").strip():
            ctx.err(path, f"review_plan.{field} is required; the prior is "
                          f"recorded before the round so concurrence can be "
                          f"told apart from agreement with the Coordinator")
    joints = plan.get("joints")
    if not isinstance(joints, list) or not joints:
        ctx.err(path, "review_plan.joints must be a nonempty list; a review "
                      "with no named load-bearing step cannot show coverage")
    else:
        seen: dict[str, int] = {}
        for index, entry in enumerate(joints):
            if not isinstance(entry, dict):
                ctx.err(path, f"review_plan.joints[{index}] must be a mapping")
                continue
            name = str(entry.get("joint") or "").strip()
            if not name:
                ctx.err(path, f"review_plan.joints[{index}].joint is empty")
            else:
                seen[name] = seen.get(name, 0) + 1
            if not str(entry.get("assigned_to") or "").strip():
                ctx.err(path, f"review_plan.joints[{index}] has no "
                              f"assigned_to; an unowned joint is the coverage "
                              f"gap this plan exists to make visible")
            if not str(entry.get("attack_plan") or "").strip():
                ctx.err(path, f"review_plan.joints[{index}] has no "
                              f"attack_plan; a worked attack returns a result "
                              f"either way, 'review this' returns an opinion")
        for name, count in seen.items():
            if count > 1:
                ctx.err(path, f"review_plan joint '{name}' is listed {count} "
                              f"times; one joint, one owner")
    blindness = plan.get("blindness")
    if blindness is not None:
        if not isinstance(blindness, dict):
            ctx.err(path, "review_plan.blindness must be a mapping")
        elif (blindness.get("lifted_for")
                and not str(blindness.get("rationale") or "").strip()):
            ctx.err(path, "review_plan.blindness.lifted_for is nonempty and "
                          "requires a rationale; blindness is lifted on "
                          "purpose, never drifted out of")
    control = plan.get("proves_too_much")
    if not isinstance(control, dict) or not (control.get("objects") or []):
        ctx.err(path, "review_plan.proves_too_much.objects is required; the "
                      "argument is run against objects where its conclusion is "
                      "known false, as controls-before-belief for an argument")
    elif not str(control.get("failure_signature") or "").strip():
        ctx.err(path, "review_plan.proves_too_much.failure_signature is "
                      "required; state what the argument must do on a "
                      "known-false object or the control cannot fail")
    rederivation = plan.get("blind_rederivation")
    if isinstance(rederivation, dict) and rederivation.get("required"):
        def check_blind_from(quantity: dict, prefix: str) -> None:
            if not (quantity.get("blind_from") or []):
                ctx.err(path, f"{prefix}.blind_from is required; name the producer's "
                              "implementation, notes and report, or the independence "
                              "is not checkable")

        def check_quantity(quantity: dict, prefix: str) -> None:
            for field in ("quantity", "assigned_to"):
                if not str(quantity.get(field) or "").strip():
                    ctx.err(path, f"{prefix}.{field} is required when required is true")
            check_blind_from(quantity, prefix)

        prefix = "review_plan.blind_rederivation"
        if "quantities" not in rederivation:
            check_quantity(rederivation, prefix)
        else:
            quantities = rederivation["quantities"]
            if not isinstance(quantities, list) or not quantities:
                ctx.err(path, f"{prefix}.quantities must be a nonempty list")
            else:
                # Archived shared assignments describe subquantities by name
                # and statement. Their complete parent contract assigns the
                # whole review; each detail retains its own forbidden inputs.
                # Explicit quantity/assigned_to rows are independent contracts
                # and must never borrow missing fields from that parent.
                named_details = all(
                    isinstance(quantity, dict)
                    and "name" in quantity and "statement" in quantity
                    and "quantity" not in quantity and "assigned_to" not in quantity
                    for quantity in quantities
                )
                if named_details:
                    check_quantity(rederivation, prefix)
                for index, quantity in enumerate(quantities):
                    scoped = f"{prefix}.quantities[{index}]"
                    if not isinstance(quantity, dict):
                        ctx.err(path, f"{scoped} must be a mapping")
                    elif named_details:
                        for field in ("name", "statement"):
                            if not isinstance(quantity[field], str) or not quantity[field].strip():
                                ctx.err(path, f"{scoped}.{field} must be nonempty text")
                        check_blind_from(quantity, scoped)
                    else:
                        # Each quantity keeps its own reader restrictions. Never
                        # merge scopes or borrow a missing field from a parent.
                        check_quantity(quantity, scoped)
            if (not isinstance(quantities, list) or not quantities or not named_details) and any(
                field in rederivation for field in ("quantity", "assigned_to", "blind_from")
            ):
                check_quantity(rederivation, prefix)


def check_citations(path: str, body: dict, rec_type: str, ctx: Ctx) -> None:
    """Validate `citations` and hypothesis `structural_ingredients` entries."""
    groups = [("citations", body.get("citations"))]
    if rec_type == "hypothesis":
        groups.append(("structural_ingredients",
                       body.get("structural_ingredients")))
    for field, entries in groups:
        if entries is None:
            continue
        if not isinstance(entries, list):
            ctx.err(path, f"{field} must be a list")
            continue
        for index, entry in enumerate(entries):
            if not isinstance(entry, dict) or "provenance" not in entry:
                continue          # pre-schema entry; reported as debt, not error
            where = f"{field}[{index}]"
            provenance = entry.get("provenance")
            if provenance not in CITATION_PROVENANCE:
                ctx.err(path, f"{where}.provenance must be "
                              f"recalled|retrieved|kb|internal")
                continue
            if provenance == "recalled":
                if rec_type == "coordinator_decision":
                    ctx.err(path, f"{where} is provenance 'recalled'; a "
                                  f"remembered source may not back a decision "
                                  f"(AGENTS.md rule 9)")
                if (rec_type == "idea" and body.get("novelty_status")
                        in PROVENANCE_ASSERTS_LITERATURE):
                    ctx.err(path, f"{where} is provenance 'recalled' but "
                                  f"novelty_status is "
                                  f"'{body.get('novelty_status')}'; use "
                                  f"'unverified' until the source is read")
            elif not str(entry.get("verified_by") or "").strip():
                ctx.err(path, f"{where}.provenance is '{provenance}' and "
                              f"requires verified_by naming the agent that "
                              f"read the source")


# ---- prior_art on ideas (knowledge/frontiers/ecdlp/README.md) --------------
# The program re-derived published results because ideas were generated BEFORE
# anyone compared them with the literature (docs/novelty-screen-20260729.md;
# DEC-20260916-3c0cf5). A `prior_art` block records that comparison: which
# known-result rows the idea was positioned against and the nearest prior work.
# It follows this file's optional-when-present rule for existing records and
# becomes REQUIRED only for ideas minted on or after the cutover, so no
# immutable record changes state and the prune-only baseline never grows. Move
# or remove the cutover here; nothing else keys on it.
PRIOR_ART_CUTOVER = 20261001
# The lead atlas (knowledge/leads/ecdlp/README.md, rule 4): from this date an
# ECDLP idea also names the program's own lead it advances, so ideas stop
# re-proposing mechanisms an earlier lane already measured or closed.
LEAD_CUTOVER = 20261025
_LEAD_ID = re.compile(r"^LEAD-[A-Z]+-[a-z0-9][a-z0-9-]{1,47}$")
PRIOR_ART_NOVELTY = {"known", "adaptation", "speculative", "unverified"}
PRIOR_ART_RELATIONS = {"same", "special_case", "generalizes", "adjacent",
                       "orthogonal"}
_IDEA_DATE = re.compile(r"^IDEA-(\d{8})-")
_KN_REF = re.compile(r"^KN-(LIT|TECH|FIND|OPEN)-(?:\d{3,4}|[0-9a-f]{6})$")
_KN_DIRS = {"LIT": "literature", "TECH": "techniques", "FIND": "findings",
            "OPEN": "open-problems"}
_FRONTIER_ROW_IDS: set[str] | None = None


def _frontier_row_ids() -> set[str]:
    global _FRONTIER_ROW_IDS
    if _FRONTIER_ROW_IDS is None:
        tools_dir = os.path.dirname(os.path.abspath(__file__))
        if tools_dir not in sys.path:
            sys.path.insert(0, tools_dir)
        import build_frontier_map  # noqa: E402  (sibling tool, no package)
        _FRONTIER_ROW_IDS = build_frontier_map.row_ids()
    return _FRONTIER_ROW_IDS


def _lead_exists(ref: str) -> bool:
    return bool(_LEAD_ID.match(ref)) and bool(glob.glob(os.path.join(
        REPO, "knowledge", "leads", "ecdlp", "*", ref + ".yaml")))


def _prior_art_ref_resolves(ref: str) -> bool:
    if ref.startswith("KR-"):
        return ref in _frontier_row_ids()
    if ref.startswith("LEAD-"):
        return _lead_exists(ref)
    m = _KN_REF.match(ref)
    if m:
        return os.path.exists(os.path.join(REPO, "knowledge",
                                           _KN_DIRS[m.group(1)], ref + ".md"))
    return False


def check_prior_art_lead(path: str, block: dict, date: re.Match | None,
                         ctx: Ctx, *, ecdlp: bool) -> None:
    """`prior_art.lead`: the atlas lead an ECDLP idea advances, or `new`."""
    lead = block.get("lead")
    required = ecdlp and bool(date) and int(date.group(1)) >= LEAD_CUTOVER
    if lead is None:
        if required:
            ctx.err(path, "prior_art.lead is required for ECDLP ideas from "
                          f"IDEA-{LEAD_CUTOVER} on: the LEAD-* id this idea "
                          "advances (python3 tools/lead_atlas.py --match), or "
                          "'new' with new_lead_reason "
                          "(knowledge/leads/ecdlp/README.md)")
        return
    lead = str(lead)
    if lead == "new":
        if not str(block.get("new_lead_reason") or "").strip():
            ctx.err(path, "prior_art.lead 'new' requires new_lead_reason: why "
                          "no existing lead covers the mechanism")
    elif not _lead_exists(lead):
        ctx.err(path, f"prior_art.lead '{lead}' is not a lead in "
                      "knowledge/leads/ecdlp/")


def check_prior_art(path: str, body: dict, ctx: Ctx) -> None:
    """Validate an idea's `prior_art` block; require it after the cutover."""
    rec_id = str(body.get("id") or "")
    m = _IDEA_DATE.match(rec_id)
    post_cutover = bool(m) and int(m.group(1)) >= PRIOR_ART_CUTOVER
    novelty = body.get("novelty_status")
    if post_cutover and novelty not in PRIOR_ART_NOVELTY:
        ctx.err(path, f"novelty_status '{novelty}' must be one of "
                      f"{sorted(PRIOR_ART_NOVELTY)} for ideas from "
                      f"IDEA-{PRIOR_ART_CUTOVER} on (agents/idea-generator.md)")
    block = body.get("prior_art")
    if block is None:
        if post_cutover:
            ctx.err(path, "prior_art is required for ideas from "
                          f"IDEA-{PRIOR_ART_CUTOVER} on: name the known-result "
                          "rows checked and the nearest prior work "
                          "(knowledge/frontiers/ecdlp/README.md)")
        return
    if not isinstance(block, dict):
        ctx.err(path, "prior_art must be a mapping")
        return
    fmap = block.get("frontier_map")
    if fmap == "not_applicable":
        if not str(block.get("not_applicable_reason") or "").strip():
            ctx.err(path, "prior_art.frontier_map is 'not_applicable' and "
                          "requires not_applicable_reason")
    elif isinstance(fmap, str) and fmap.startswith("knowledge/frontiers/"):
        if not os.path.isdir(os.path.join(REPO, fmap.rstrip("/"))):
            ctx.err(path, f"prior_art.frontier_map '{fmap}' is not a directory")
        check_prior_art_lead(path, block, m, ctx,
                             ecdlp=fmap.startswith("knowledge/frontiers/ecdlp"))
        rows = block.get("rows_checked")
        if not isinstance(rows, list) or not rows:
            ctx.err(path, "prior_art.rows_checked must list the KR-* rows the "
                          "idea was positioned against")
        else:
            for row in rows:
                if not _prior_art_ref_resolves(str(row)) or \
                        not str(row).startswith("KR-"):
                    ctx.err(path, f"prior_art.rows_checked '{row}' is not a "
                                  "known-result row on disk")
    else:
        ctx.err(path, "prior_art.frontier_map must be a knowledge/frontiers/"
                      "... path or 'not_applicable'")
    nearest = block.get("nearest")
    if nearest in (None, []):
        if not block.get("none_found_after"):
            ctx.err(path, "prior_art needs `nearest` (>= 1 entry) or "
                          "`none_found_after` listing the searches that found "
                          "nothing")
        nearest = []
    if not isinstance(nearest, list):
        ctx.err(path, "prior_art.nearest must be a list")
        nearest = []
    grounded_same = False
    for i, entry in enumerate(nearest):
        where = f"prior_art.nearest[{i}]"
        if not isinstance(entry, dict):
            ctx.err(path, f"{where} must be a mapping")
            continue
        ref = str(entry.get("ref") or "")
        if not _prior_art_ref_resolves(ref):
            ctx.err(path, f"{where}.ref '{ref}' must resolve to a KR-* row or "
                          "a knowledge/ entry")
        provenance = entry.get("provenance")
        if provenance not in CITATION_PROVENANCE:
            ctx.err(path, f"{where}.provenance must be "
                          "recalled|retrieved|kb|internal")
        relation = entry.get("relation")
        if relation not in PRIOR_ART_RELATIONS:
            ctx.err(path, f"{where}.relation must be one of "
                          f"{sorted(PRIOR_ART_RELATIONS)}")
        if not str(entry.get("delta") or "").strip():
            ctx.err(path, f"{where}.delta is required: what the idea adds "
                          "over this work, quantitatively, or 'none'")
        if relation in ("same", "special_case") and provenance != "recalled":
            grounded_same = True
    if novelty == "known" and not grounded_same:
        ctx.err(path, "novelty_status 'known' requires a prior_art.nearest "
                      "entry with relation same|special_case whose provenance "
                      "is not 'recalled'")


def check_obstruction(path: str, body: dict, ctx: Ctx) -> None:
    """Validate an `obstruction` block: a measurement, not a verdict."""
    block = body.get("obstruction")
    if block is None:
        return
    if not isinstance(block, dict):
        ctx.err(path, "obstruction must be a mapping")
        return
    for field in OBSTRUCTION_REQUIRED:
        if not str(block.get(field) or "").strip():
            ctx.err(path, f"obstruction.{field} is required; an obstruction "
                          f"recorded as prose is a verdict, not a datum")
    measured_by = block.get("measured_by")
    if not isinstance(measured_by, list) or not measured_by:
        ctx.err(path, "obstruction.measured_by must be a nonempty list of "
                      "RUN-*/EXP-* IDs the value is read from")
    check = block.get("resource_check")
    if not isinstance(check, dict):
        ctx.err(path, "obstruction.resource_check is required (inventor "
                      "protocol section 4); an unexamined obstruction asserts "
                      "only that nobody looked")
        return
    if check.get("examined") is not True:
        ctx.err(path, "obstruction.resource_check.examined must be true; the "
                      "reversal is checked when the object is still loaded")
    if not str(check.get("reading") or "").strip():
        ctx.err(path, "obstruction.resource_check.reading is required; name "
                      "the theory taking this measurement as its hypothesis, "
                      "or state that the check found none")
    if not isinstance(check.get("spawned_ids", []), list):
        ctx.err(path, "obstruction.resource_check.spawned_ids must be a list")
KNOWLEDGE_TYPES = {
    "literature": ("literature", "KN-LIT-"),
    "technique": ("techniques", "KN-TECH-"),
    "internal_finding": ("findings", "KN-FIND-"),
    "open_problem": ("open-problems", "KN-OPEN-"),
}

# These canonical records were committed before proof/promotion fields became
# mandatory. They remain immutable and are reported as schema debt; every new
# canonical record must use the current schema.
PRE_V2_CANONICAL_IDS = {"EV-SEMAEV-001", "DEC-20260719-001"}


class Ctx:
    def __init__(
        self,
        legacy_paths: set[str],
        legacy_id_remaps: dict[str, str] | None = None,
        schema_supersessions: dict[str, dict] | None = None,
    ):
        self.errors: list[str] = []
        self.legacy_warnings: list[str] = []
        # Never fail the build. Visible every run so a backlog cannot hide.
        self.advisories: list[str] = []
        self.ids: dict[str, str] = {}          # id -> source path
        self.records: dict[str, dict] = {}      # id -> record body
        self.record_types: dict[str, str] = {}
        self.run_params: dict[str, dict] = {}   # run id -> inputs.parameters
        self.knowledge: dict[str, str] = {}
        self.legacy_paths = legacy_paths
        self.legacy_id_remaps = legacy_id_remaps or {}
        self.legacy_aliases: set[str] = set()
        self.amendment_ids: set[str] = set()   # AMD-* ids, indexed not checked
        self.schema_supersessions = schema_supersessions or {}

    def source_path(self, path: str) -> str:
        """Return the hash-pinned replacement for a registered source path."""
        entry = self.schema_supersessions.get(os.path.abspath(path))
        if (entry and not entry.get("redirect_id")
                and os.path.isfile(entry["superseding_path"])):
            return entry["superseding_path"]
        return path

    def schema_supersession(self, path: str) -> dict | None:
        return self.schema_supersessions.get(os.path.abspath(path))

    def err(self, path: str, msg: str, *, force: bool = False):
        # First line only: PyYAML messages span lines and embed absolute
        # paths, which would break exact-line baseline matching across hosts.
        msg = str(msg).splitlines()[0].strip()
        rendered = f"{os.path.relpath(path, REPO)}: {msg}"
        if not force and os.path.abspath(path) in self.legacy_paths:
            self.legacy_warnings.append(rendered)
        else:
            self.errors.append(rendered)

    def advise(self, path: str, msg: str):
        msg = str(msg).splitlines()[0].strip()
        self.advisories.append(f"{os.path.relpath(path, REPO)}: {msg}")

    def register(self, rec_id: str, path: str, body: dict, rec_type: str):
        if rec_id in self.ids:
            self.err(path, f"duplicate ID {rec_id} (also in "
                           f"{os.path.relpath(self.ids[rec_id], REPO)})",
                     force=True)
        else:
            self.ids[rec_id] = path
            self.records[rec_id] = body
            self.record_types[rec_id] = rec_type


def load_yaml(path: str, ctx: Ctx):
    source = ctx.source_path(path)
    try:
        with open(source, encoding="utf-8") as handle:
            return _safe_load(handle)
    except yaml.YAMLError as e:
        ctx.err(source, f"invalid YAML: {e}")
        return None


def _yaml_document_is_empty(source: str) -> bool:
    """True when `source` parses cleanly to None (empty, comments, `null`)."""
    try:
        with open(source, encoding="utf-8") as handle:
            return _safe_load(handle) is None
    except (OSError, UnicodeDecodeError, yaml.YAMLError):
        return False


EXTERNAL_VERIFICATION_VERDICTS = ("accept", "reject", "unavailable", "invalid_spec")
EXTERNAL_VERIFICATION_REQUIRED = ("network", "objective_id", "claim_id", "verdict", "node")


def check_external_verification(path: str, body: dict, ctx: Ctx) -> None:
    """An `external_verification:` block is a receipt from a network verifier
    (docs/cairn-integration-plan.md section 7), and the one rule that makes it
    safe to carry is invariant (b): a verdict that does not settle --
    `unavailable`, `invalid_spec` -- says nothing about the artifact, so it may
    back no direction and no proof. Collapsing "the node could not check" into
    "the check failed" is the mistake cairn's own `Unavailable` exists to
    refuse, and this check keeps the ledger from making it on the way in."""
    blocks = body.get("external_verification")
    if blocks is None:
        return
    if not isinstance(blocks, list):
        ctx.err(path, "external_verification must be a list of receipt blocks")
        return
    refs = set()
    for field in ("proof_refs", "certificate_refs"):
        value = body.get(field)
        if isinstance(value, list):
            refs.update(str(item) for item in value)
    for index, block in enumerate(blocks):
        label = f"external_verification[{index}]"
        if not isinstance(block, dict):
            ctx.err(path, f"{label} must be a mapping")
            continue
        for field in EXTERNAL_VERIFICATION_REQUIRED:
            if not block.get(field):
                ctx.err(path, f"{label} missing '{field}'")
        verdict = block.get("verdict")
        if verdict not in EXTERNAL_VERIFICATION_VERDICTS:
            ctx.err(path, f"{label} verdict must be one of "
                          f"{'|'.join(EXTERNAL_VERIFICATION_VERDICTS)}")
            continue
        if "settled" in block and not isinstance(block["settled"], bool):
            ctx.err(path, f"{label} settled must be true or false")
        claim_id = str(block.get("claim_id") or "")
        if verdict != "accept":
            if claim_id and claim_id in refs:
                ctx.err(path, f"{label} verdict '{verdict}' is cited in proof_refs or "
                              f"certificate_refs; only an accepted claim backs a proof")
            if block.get("backs_direction") is True:
                ctx.err(path, f"{label} verdict '{verdict}' may not back a direction")
        if verdict in ("unavailable", "invalid_spec") and body.get("proof_status") == "certificate" \
                and not any(isinstance(other, dict) and other.get("verdict") == "accept"
                            for other in blocks):
            ctx.err(path, "proof_status 'certificate' with no accepted external_verification "
                          "and a block that could not be checked: the receipt backs nothing; "
                          "cite the local certificate or wait for a settling verdict")


# ---- measured bounds (docs/bounds-and-frontiers.md) ------------------------
# A `measured_bound` block carries a sealed bound record from the measuring
# repository (aburan28/crypto docs/bounds/README.md): what a method costs, as
# a constant and an exponent with intervals, scoped to a domain and a tier.
# Optional-when-absent like the blocks above; a record that carries one must
# respect the four rules that make it safe to carry.
MEASURED_BOUND_REQUIRED = ("bound_id", "repository", "domain", "method", "level",
                           "ops_ratio_to_floor", "verified_runs")
MEASURED_BOUND_DOMAIN_REQUIRED = ("problem", "family", "target_kind", "unit",
                                  "tier")
MEASURED_BOUND_TIERS = ("toy", "medium", "crypto")
MEASURED_BOUND_LEVELS = ("exponent", "constant")
MEASURED_BOUND_OUTCOMES = ("advances", "trade", "matches", "regresses",
                           "inadmissible")
MEASURED_BOUND_IDS = {
    "bound_id": re.compile(r"^ECBND1h[0-9a-f]{12}$"),
    "domain_id": re.compile(r"^ECDOM1h[0-9a-f]{12}$"),
    "verdict_id": re.compile(r"^ECVD1h[0-9a-f]{12}$"),
    "challenge_id": re.compile(r"^ECCH1h[0-9a-f]{12}$"),
}
# A unit that reads a clock is not a bound's unit (cairn refuses the same
# names as reproducible fields; this program refuses them as evidence).
CLOCKED_UNIT = re.compile(r"wall|second|time|clock|_ns\b|^ns\b|_ms\b|^ms\b",
                          re.IGNORECASE)


def _is_number(value) -> bool:
    return isinstance(value, (int, float)) and not isinstance(value, bool)


def _check_estimate(path: str, label: str, est, ctx: Ctx) -> None:
    if not isinstance(est, dict) or not _is_number(est.get("value")):
        ctx.err(path, f"{label}.value must be a number")
        return
    ci = est.get("ci95")
    if ci is None:
        return
    if (not isinstance(ci, list) or len(ci) != 2
            or not all(_is_number(x) for x in ci)):
        ctx.err(path, f"{label}.ci95 must be [low, high]")
        return
    low, high = ci
    if not low <= est["value"] <= high:
        ctx.err(path, f"{label}.ci95 {ci} does not bracket value "
                      f"{est['value']}")


def check_measured_bound(path: str, body: dict, ctx: Ctx) -> None:
    """The four rules of docs/bounds-and-frontiers.md section 2: the tier is
    the record's tier, the unit is counted and never clocked, an exponent
    needs sizes and a scaling claim, and an inadmissible verdict is never
    evidence for or against anything (AGENTS.md rule 3)."""
    block = body.get("measured_bound")
    if block is None:
        return
    label = "measured_bound"
    if not isinstance(block, dict):
        ctx.err(path, f"{label} must be a mapping")
        return
    for field in MEASURED_BOUND_REQUIRED:
        if block.get(field) in (None, "", [], {}):
            ctx.err(path, f"{label} missing '{field}'")
    for name, pattern in MEASURED_BOUND_IDS.items():
        value = block.get(name)
        if value is not None and not pattern.match(str(value)):
            ctx.err(path, f"{label}.{name} '{value}' is not a well-formed id")
    domain = block.get("domain")
    if isinstance(domain, dict):
        for field in MEASURED_BOUND_DOMAIN_REQUIRED:
            if not domain.get(field):
                ctx.err(path, f"{label}.domain missing '{field}'")
        tier = domain.get("tier")
        if tier is not None and tier not in MEASURED_BOUND_TIERS:
            ctx.err(path, f"{label}.domain.tier must be one of "
                          f"{'|'.join(MEASURED_BOUND_TIERS)}")
        elif tier is not None and "claim_tier" in body \
                and body["claim_tier"] != tier:
            ctx.err(path, f"{label}.domain.tier '{tier}' != claim_tier "
                          f"'{body['claim_tier']}'; a bound is evidence at "
                          f"its own tier and tiers are not fungible")
        unit = str(domain.get("unit") or "")
        if CLOCKED_UNIT.search(unit):
            ctx.err(path, f"{label}.domain.unit '{unit}' reads a clock; a "
                          f"bound is never a wall-clock figure")
    elif domain is not None:
        ctx.err(path, f"{label}.domain must be a mapping")
    level = block.get("level")
    if level is not None and level not in MEASURED_BOUND_LEVELS:
        ctx.err(path, f"{label}.level must be exponent|constant")
    alpha = block.get("alpha")
    sizes = block.get("sizes_log2_r")
    scaling = isinstance(alpha, dict) and alpha.get("scaling_claim") is True
    if level == "exponent":
        if not scaling:
            ctx.err(path, f"{label}.level 'exponent' requires "
                          f"alpha.scaling_claim: true")
        if not (isinstance(sizes, list) and len(sizes) >= 4):
            ctx.err(path, f"{label}.level 'exponent' requires at least four "
                          f"sizes in sizes_log2_r")
    if isinstance(alpha, dict) and "value" in alpha:
        _check_estimate(path, f"{label}.alpha", alpha, ctx)
    if block.get("ops_ratio_to_floor") is not None:
        _check_estimate(path, f"{label}.ops_ratio_to_floor",
                        block["ops_ratio_to_floor"], ctx)
    runs = block.get("verified_runs")
    if runs is not None and (not isinstance(runs, int)
                             or isinstance(runs, bool) or runs <= 0):
        ctx.err(path, f"{label}.verified_runs must be a positive integer")
    verdict = block.get("verdict")
    if verdict is None:
        return
    if not isinstance(verdict, dict):
        ctx.err(path, f"{label}.verdict must be a mapping")
        return
    for name in ("verdict_id", "challenge_id"):
        value = verdict.get(name)
        if value is not None and not MEASURED_BOUND_IDS[name].match(str(value)):
            ctx.err(path, f"{label}.verdict.{name} '{value}' is not a "
                          f"well-formed id")
    outcome = verdict.get("outcome")
    if outcome not in MEASURED_BOUND_OUTCOMES:
        ctx.err(path, f"{label}.verdict.outcome must be one of "
                      f"{'|'.join(MEASURED_BOUND_OUTCOMES)}")
    if outcome == "inadmissible" and body.get("direction") not in (None,
                                                                   "neutral"):
        ctx.err(path, f"{label}.verdict is inadmissible but direction is "
                      f"'{body.get('direction')}'; an inadmissible verdict "
                      f"is never evidence, so direction must be neutral "
                      f"(AGENTS.md rule 3)")
    for field in ("advances_on", "regresses_on", "improves_on"):
        value = verdict.get(field)
        if value is not None and not isinstance(value, list):
            ctx.err(path, f"{label}.verdict.{field} must be a list")
    for index, ref in enumerate(verdict.get("improves_on") or []):
        if not MEASURED_BOUND_IDS["bound_id"].match(str(ref)):
            ctx.err(path, f"{label}.verdict.improves_on[{index}] '{ref}' is "
                          f"not a bound id")
    moved = verdict.get("level_moved")
    if moved is None:
        return
    if moved not in MEASURED_BOUND_LEVELS:
        ctx.err(path, f"{label}.verdict.level_moved must be exponent|constant")
    advances_on = verdict.get("advances_on") or []
    if outcome != "advances" or "ops" not in advances_on:
        ctx.err(path, f"{label}.verdict.level_moved is set but the verdict "
                      f"does not advance on ops; a level is a statement "
                      f"about operations")
    if moved == "exponent" and not scaling:
        ctx.err(path, f"{label}.verdict.level_moved 'exponent' requires "
                      f"alpha.scaling_claim: true")


# A declared run artifact may be stored compressed or as a blob-store pointer
# (tools/artifact_store.py, docs/artifact-storage.md) or the canonical
# .artifacts.json manifest (docs/artifacts.md); any one form satisfies presence.
# This does not download or verify remote bytes: native replay still does that.
ARTIFACT_STORED_FORMS = ("", ".gz", ".blob.json", ".gz.blob.json")


def _artifact_stored(run_dir: str, name: str) -> bool:
    if any(os.path.isfile(os.path.join(run_dir, name + suffix))
           for suffix in ARTIFACT_STORED_FORMS):
        return True

    def unique_fields(pairs):
        fields = {}
        for key, value in pairs:
            if key in fields:
                raise ValueError("duplicate artifact manifest key")
            fields[key] = value
        return fields

    try:
        with open(os.path.join(run_dir, ".artifacts.json"), encoding="utf-8") as handle:
            manifest = json.load(handle, object_pairs_hook=unique_fields)
    except (OSError, ValueError):
        return False
    if not isinstance(manifest, dict) or manifest.get("schema") != "artifacts.manifest/v1":
        return False
    files = manifest.get("files")
    entry = files.get(name) if isinstance(files, dict) else None
    if not isinstance(entry, dict):
        return False
    digest, size = entry.get("sha256"), entry.get("bytes")
    return (isinstance(digest, str)
            and re.fullmatch(r"[0-9a-f]{64}", digest) is not None
            and type(size) is int and size >= 0)


def check_ledger_record(path: str, rec_type: str, ctx: Ctx):
    supersession = ctx.schema_supersession(path)
    if supersession and supersession.get("redirect_id"):
        ctx.legacy_aliases.add(os.path.splitext(os.path.basename(path))[0])
        return
    doc = load_yaml(path, ctx)
    if doc is None:
        return
    if not isinstance(doc, dict) or rec_type not in doc:
        ctx.err(path, f"expected top-level key '{rec_type}'")
        return
    body = doc[rec_type]
    if not isinstance(body, dict):
        ctx.err(path, f"'{rec_type}' must be a mapping")
        return
    rec_id = body.get("id")
    if not rec_id:
        ctx.err(path, "missing 'id'")
        return
    if not ID_PATTERNS[rec_type].match(str(rec_id)):
        ctx.err(path, f"ID {rec_id} does not match {rec_type} format")
    stem = os.path.splitext(os.path.basename(path))[0]
    replacement_id = (supersession or {}).get("replacement_id")
    if replacement_id and str(rec_id) != replacement_id:
        ctx.err(path, f"registered replacement_id '{replacement_id}' != "
                      f"superseding record id '{rec_id}'", force=True)
    if replacement_id:
        ctx.legacy_aliases.add(stem)
    elif stem != str(rec_id):
        ctx.err(path, f"filename stem '{stem}' != id '{rec_id}'")
        if os.path.abspath(path) in ctx.legacy_paths:
            ctx.legacy_aliases.add(stem)
    required = REQUIRED[rec_type]
    if str(rec_id) in PRE_V2_CANONICAL_IDS:
        required = [field for field in required
                    if field not in {"proof_status", "proof_refs",
                                     "knowledge_promotion"}]
    for field in required:
        if not field_is_satisfied(body, field):
            ctx.err(path, f"missing required field '{field}'")
    if rec_type == "evidence" and "proof_status" in body:
        if body["proof_status"] not in PROOF_STATUSES:
            ctx.err(path, "proof_status must be certificate|derivation|"
                          "empirical_only|not_applicable")
        if not isinstance(body.get("proof_refs"), list):
            ctx.err(path, "proof_refs must be a list")
    check_citations(path, body, rec_type, ctx)
    if rec_type == "idea":
        check_prior_art(path, body, ctx)
    if rec_type in ("evidence", "coordinator_decision"):
        check_obstruction(path, body, ctx)
    if rec_type == "evidence":
        check_external_verification(path, body, ctx)
        check_measured_bound(path, body, ctx)
    if rec_type == "handoff":
        check_review_plan(path, body, ctx)
    if rec_type == "coordinator_decision" and "knowledge_promotion" in body:
        promotion = body["knowledge_promotion"]
        if not isinstance(promotion, dict):
            ctx.err(path, "knowledge_promotion must be a mapping")
        else:
            promoted = promotion.get("promoted")
            if not isinstance(promoted, list):
                ctx.err(path, "knowledge_promotion.promoted must be a list")
            if promoted == [] and not promotion.get("not_warranted"):
                ctx.err(path, "empty knowledge_promotion.promoted requires "
                              "a nonempty not_warranted reason")
    remapped_to = ctx.legacy_id_remaps.get(os.path.abspath(path))
    if remapped_to:
        ctx.legacy_warnings.append(
            f"{os.path.relpath(path, REPO)}: historical ID {rec_id} is "
            f"remapped to {remapped_to}; frozen source is not registered"
        )
        return
    ctx.register(str(rec_id), path, body, rec_type)


def is_frozen_successor_draft(path: str, doc: object) -> bool:
    """Classify only the unapproved, hash-bound AUXIN design-stage copy."""
    specification, source, expected_sha256 = AUXIN_SUCCESSOR_DRAFT
    if os.path.relpath(path, REPO) != specification:
        return False
    if not isinstance(doc, dict) or set(doc) != {"successor_contract"}:
        return False
    contract = doc["successor_contract"]
    if not isinstance(contract, dict):
        return False
    fresh = contract.get("fresh")
    if not isinstance(fresh, dict):
        return False
    approval = fresh.get("approval")
    if not isinstance(approval, dict):
        return False
    if (fresh.get("id") != "EXP-AUXIN-339fb0"
            or fresh.get("status") != "draft"
            or fresh.get("approved_by") is not None
            or fresh.get("approval_decision") is not None
            or fresh.get("batch_id") != "BATCH-ad00c6"
            or fresh.get("producer_task") != "TASK-20260929-d519f6"
            or fresh.get("goal_id") != "GOAL-AUXIN-a93442"
            or approval.get("id") != "F-APPROVAL"
            or approval.get("status") != "draft"
            or approval.get("approved_by") is not None):
        return False
    try:
        for relative in (specification, source):
            with open(os.path.join(REPO, relative), "rb") as handle:
                if hashlib.sha256(handle.read()).hexdigest() != expected_sha256:
                    return False
    except OSError:
        return False
    return True


def check_experiment(path: str, ctx: Ctx):
    supersession = ctx.schema_supersession(path)
    if supersession and supersession.get("redirect_id"):
        ctx.legacy_aliases.add(os.path.basename(os.path.dirname(path)))
        return
    doc = load_yaml(path, ctx)
    if doc is None:
        return
    if is_frozen_successor_draft(path, doc):
        # Preserve reference resolution to a real placed draft, without
        # registering it as an approved or executable experiment record.
        ctx.legacy_aliases.add("EXP-AUXIN-339fb0")
        ctx.advise(path, "hash-bound successor contract is a draft, not an approved experiment")
        return
    if not isinstance(doc, dict) or "experiment" not in doc:
        ctx.err(path, "expected top-level key 'experiment'")
        # The specification exists; only its shape is wrong, and that was
        # just reported once. Index the directory id so decisions citing the
        # experiment are not re-reported as citing an unknown one.
        stem = os.path.basename(os.path.dirname(path))
        if ID_PATTERNS["experiment"].match(stem):
            ctx.legacy_aliases.add(stem)
        return
    body = doc["experiment"]
    rec_id = body.get("id")
    if not rec_id or not ID_PATTERNS["experiment"].match(str(rec_id)):
        ctx.err(path, f"bad experiment id {rec_id!r}")
        return
    replacement_id = (supersession or {}).get("replacement_id")
    if replacement_id and str(rec_id) != replacement_id:
        ctx.err(path, f"registered replacement_id '{replacement_id}' != "
                      f"superseding record id '{rec_id}'", force=True)
    if replacement_id:
        stem = os.path.basename(os.path.dirname(path))
        ctx.legacy_aliases.add(stem)
    for field in REQUIRED["experiment"]:
        # Compact Stage-0 contracts (REFSPLIT through EUCREM) record the
        # required metrics list as primary_metrics. That list already
        # names the measured gates; accepting it as the schema `metrics`
        # field avoids rewriting frozen specification.yaml bytes whose
        # snapshot archives already bind the file hash.
        if field == "metrics" and field_is_satisfied(body, "primary_metrics"):
            continue
        if not field_is_satisfied(body, field):
            ctx.err(path, f"missing required field '{field}'")
    # An approved contract must have no null approval fields.
    if body.get("status") == "approved":
        for field in ("success_criterion", "falsification_criterion",
                      "approved_by"):
            if not field_is_satisfied(body, field):
                ctx.err(path, f"approved experiment has null '{field}'")
    check_outcome_not_prewritten(path, body, ctx)
    check_confound_control(path, body, ctx)
    ctx.register(str(rec_id), path, body, "experiment")


def check_provenance_quarantine(path: str, body: dict, entry: dict | None,
                                ctx: Ctx) -> bool:
    """Account for an unrecoverable historical commit without inventing one.

    This does not make the run reproducible: only a Coordinator-authorized,
    hash-pinned replacement marked invalid can carry the gap. It remains
    ineligible for directional evidence. Ordinary/new runs retain the
    required commit check, as do incomplete or tampered quarantine records.
    """
    gap = body.get("provenance_gap")
    if gap is None:
        return False
    errors = []
    code, result = body.get("code") or {}, body.get("result") or {}
    if not isinstance(gap, dict):
        errors.append("provenance_gap must be a mapping")
        gap = {}
    if (not entry or entry.get("run_id") != body.get("id")
            or entry.get("supersession_kind") != "provenance_quarantine"
            or entry.get("decision_id") != gap.get("decision_id")):
        errors.append("requires an explicitly registered provenance_quarantine for this run and decision")
    else:
        for label in ("superseded", "superseding"):
            file_path = entry.get(label + "_path")
            try:
                actual = hashlib.sha256(Path(file_path).read_bytes()).hexdigest()
            except (OSError, TypeError):
                actual = None
            if actual is None or actual != entry.get(label + "_sha256"):
                errors.append(f"{label} hash binding must verify")
        # A quarantine may disclose an omission, never erase provenance the
        # original manifest actually retained. Malformed originals first need
        # their separate syntax-preserving repair, not a guessed omission.
        try:
            original = _safe_load(Path(entry["superseded_path"]).read_text())
            original_body = original.get("run", original)
            original_code = original_body.get("code") or original_body.get("git") or {}
            if original_code.get("commit") or original_code.get("dirty") is not None:
                errors.append("original manifest already records execution provenance")
        except (OSError, yaml.YAMLError, AttributeError, TypeError):
            errors.append("original provenance fields must be inspectable before quarantine")
    if (body.get("status") != "completed_invalid"
            or result.get("valid") is not False
            or (result.get("certificate") or {}).get("kind") != "none"
            or result.get("status") in {"valid", "completed_valid"}
            or result.get("validity_status") == "valid"
            or not str(result.get("invalid_reason") or "").strip()):
        errors.append("requires completed_invalid, result.valid=false, a reason and certificate.kind=none")
    if ("commit" not in code or "dirty" not in code
            or code.get("commit") is not None or code.get("dirty") is not None
            or gap.get("missing_fields") != ["code.commit", "code.dirty"]
            or gap.get("evidence_eligible") is not False
            or not str(gap.get("reason") or "").strip()):
        errors.append("must disclose null commit/dirty, exact missing fields, reason and evidence_eligible=false")
    decision_id = gap.get("decision_id")
    decision = ctx.records.get(decision_id, {}) if isinstance(decision_id, str) else {}
    if (ctx.record_types.get(decision_id if isinstance(decision_id, str) else "") != "coordinator_decision"
            or decision.get("decided_by") != "coordinator"
            or decision.get("scope") != "administrative_integrity_only"
            or body.get("id") not in (decision.get("target_ids") or [])):
        errors.append("requires a Coordinator administrative decision naming this run")
    sources = gap.get("searched_source_sha256")
    if not isinstance(sources, dict) or not sources:
        errors.append("requires a nonempty hash-bound inventory of searched sources")
    else:
        for relative, expected in sources.items():
            try:
                source = Path(REPO) / relative
                if (not isinstance(relative, str) or os.path.isabs(relative)
                        or ".." in relative.split("/")
                        or not source.resolve().is_relative_to(Path(REPO).resolve())
                        or not isinstance(expected, str)
                        or not SHA256_HEX.fullmatch(expected)
                        or hashlib.sha256(source.read_bytes()).hexdigest() != expected):
                    raise ValueError("unbound source")
            except (OSError, ValueError, TypeError):
                errors.append(f"searched source does not verify: {relative!r}")
    for error in errors:
        ctx.err(path, "provenance quarantine: " + error, force=True)
    return not errors


RUN_CAPTURE_ARTIFACTS = ("command.txt", "environment.json", "stdout.log",
                         "stderr.log", "raw-result.json")


def _registered_non_execution_derivation(
        original_path: str, run_dir: str, body: dict, entry: dict) -> bool:
    """Admit one source-bound non-execution category, never a missing-output run.

    The opt-in registry binds both manifest versions, the frozen experiment
    contract, and the derivation note. A changed byte or a captured execution
    artifact rejects the category; an ordinary terminal run is unaffected.
    """
    declaration = entry.get("non_execution")
    if not isinstance(declaration, dict) or declaration.get("kind") != "hand_derivation":
        return False
    if (entry.get("supersession_kind") != "zero_compute_misclassification"
            or entry.get("superseded_path") != os.path.abspath(original_path)
            or entry.get("run_id") != body.get("id")
            or body.get("stage") != "stage_0"
            or body.get("status") != "completed_valid"
            or body.get("compute") != "zero"
            or body.get("execution") != "none_occurred"
            or body.get("code", {}).get("command")
               != "none: zero compute. This note was written by hand by the Executor."
            or body.get("artifacts", {}).get("derivation_note") != "derivation-note.md"
            or body.get("result", {}).get("certificate", {}).get("kind") != "none"):
        return False
    absent = body.get("companion_artifacts_absent_permanently", {}).get("artifacts")
    if not isinstance(absent, list) or set(absent) != set(RUN_CAPTURE_ARTIFACTS) or len(absent) != 5:
        return False
    if any(os.path.lexists(os.path.join(run_dir, name)) for name in RUN_CAPTURE_ARTIFACTS):
        return False
    def hash_matches(path: str, expected: str) -> bool:
        try:
            return hashlib.sha256(Path(path).read_bytes()).hexdigest() == expected
        except OSError:
            return False
    for role in ("superseded", "superseding"):
        path = entry[f"{role}_path"]
        if (not os.path.isfile(path) or
                not hash_matches(path, entry[f"{role}_sha256"])):
            return False
    for role in ("specification", "derivation"):
        path = declaration[f"{role}_path"]
        if (not os.path.isfile(path) or
                not hash_matches(path, declaration[f"{role}_sha256"])):
            return False
    if declaration["derivation_path"] != os.path.join(run_dir, "derivation-note.md"):
        return False
    try:
        with open(declaration["specification_path"], encoding="utf-8") as handle:
            spec = _safe_load(handle)
        experiment = spec["experiment"]
        return (
            experiment["id"] == body.get("experiment_id")
            and experiment["inputs"]["stage_0"]["compute"]
            == "ZERO. No program is run in this stage."
        )
    except (OSError, TypeError, KeyError, ValueError, yaml.YAMLError):
        return False


def check_run(path: str, ctx: Ctx, supersessions: dict[str, dict] | None = None):
    """Validate the run manifest discovered at `path`.

    If `path` is registered in tools/run_supersession_registry.yaml, the schema
    check is applied to the SUPERSEDING record instead: the archived file is
    immutable, so a defect in it is repaired by a new record, not an edit, and
    the check must read the record that actually carries the fields.

    Routing is decided by exact registered path only. The superseded file must
    still exist and still hash to its registered value — that is checked by
    check_run_supersessions(), not softened here. Capture artifacts are looked
    for in the discovered run directory except for an independently admitted,
    hash-bound non-execution hand derivation.
    """
    run_dir = os.path.dirname(path)
    original_path = path
    entry = (supersessions or {}).get(os.path.abspath(path))
    if entry is not None:
        superseding = entry["superseding_path"]
        if os.path.isfile(superseding):
            path = superseding
        else:
            # Reported by check_run_supersessions() as well; fall back to the
            # superseded record so the run still gets validated and registered
            # rather than silently vanishing from the ledger.
            ctx.err(path, "registered superseding run manifest is missing; "
                          "validating the superseded record in place",
                    force=True)
    doc = load_yaml(path, ctx)
    if doc is None:
        # load_yaml has already reported a parse error; an empty, comment-only
        # or `null` document parses cleanly to None and must not pass as a
        # run record with no findings (SHF-20261028-0f3f64, LGN-3).
        if _yaml_document_is_empty(ctx.source_path(path)):
            ctx.err(path, "run manifest is empty (no YAML document); "
                          "expected top-level key 'run'")
        return
    body = doc.get("run") if isinstance(doc, dict) else None
    if not isinstance(body, dict):
        ctx.err(path, "expected top-level key 'run'")
        # A frozen legacy manifest predates the nested `run:` shape and records
        # its id flat. ctx.err has already suppressed the shape complaint for
        # it, but without registering the id nothing may cite the run -- every
        # evidence record naming it fails instead, which is the schema debt
        # reported as the record's own defect. Register it the way legacy
        # ledger records register their filename stem: the run exists, it is
        # frozen by hash, and it is simply not schema-checkable.
        if os.path.abspath(path) in ctx.legacy_paths and isinstance(doc, dict):
            legacy_id = doc.get("run_id") or doc.get("id")
            if isinstance(legacy_id, str) and RUN_ID.match(legacy_id):
                ctx.legacy_aliases.add(legacy_id)
        else:
            # A non-legacy flat manifest is a schema defect and was just
            # reported as one, once, against the manifest. It is not evidence
            # that the run is absent: without registering it, every evidence
            # record, decision and finding citing the run is ALSO reported, as
            # citing an "unknown run" -- a second, false diagnosis of the same
            # defect, attributed to records that are correct.
            register_flat_run_alias(path, doc, ctx)
        return
    rec_id = body.get("id")
    if not rec_id or not RUN_ID.match(str(rec_id)):
        ctx.err(path, f"bad run id {rec_id!r}")
    # Experiment/run lifetime is not a research conclusion.  A watchdog or
    # estimate may checkpoint a live run, but it may never manufacture an
    # `expired` terminal status (which would silently discard an unfinished
    # experiment).  Use `failed` with an explicit infrastructure reason or
    # `cancelled` under a Coordinator decision instead.
    if str(body.get("status", "")).lower() in {"expired", "budget_expired", "time_expired"}:
        ctx.err(path, "experiment runs may not expire; checkpoint or record an explicit failed/cancelled receipt", force=True)
    for field in RUN_REQUIRED_TOP:
        if body.get(field) in (None, ""):
            ctx.err(path, f"run missing required field '{field}'")
    # Reproducibility: commit + command must be present.
    code = body.get("code") or {}
    quarantined = check_provenance_quarantine(path, body, entry, ctx)
    if not code.get("commit") and not quarantined:
        ctx.err(path, "run.code.commit missing (not reproducible)")
    if code.get("commit_meaning") == "archival_source_only":
        ctx.err(path, "run.code.commit is archival source only, not execution provenance; "
                "use the canonical provenance quarantine until execution is bound", force=True)
    if not code.get("command"):
        ctx.err(path, "run.code.command missing (not reproducible)")
    # A nonterminal observation can explicitly declare that its final raw
    # result does not exist yet. This is not a liveness check or a result:
    # terminal/unknown statuses and certificate-bearing records still owe it.
    pending_body = body.get("result")
    pending_certificate = (pending_body.get("certificate")
                           if isinstance(pending_body, dict) else None)
    raw_result_pending = (
        isinstance(body.get("status"), str)
        and body.get("status") in {"running", "in_progress"}
        and isinstance(pending_body, dict)
        and pending_body.get("raw_result_pending") is True
        and isinstance(pending_certificate, dict)
        and pending_certificate.get("kind") == "none"
    )
    # A failed_infrastructure envelope may state, in its own outcome note,
    # that the producer never wrote raw-result.json. Creating the file to
    # satisfy this check would fabricate a result the receipt says was not
    # produced. The absence is the observation. A bare failed_infrastructure
    # status, without that sentence, still owes the artifact. Terminal
    # statuses in general are unchanged.
    raw_result_explicitly_unwritten = (
        isinstance(body.get("status"), str)
        and body.get("status") == "failed_infrastructure"
        and isinstance(pending_body, dict)
        and pending_body.get("raw_result") is None
        and pending_body.get("outcome") is None
        and isinstance(pending_certificate, dict)
        and pending_certificate.get("kind") == "none"
        and "did not write raw-result.json"
        in str(pending_body.get("outcome_note") or "")
    )
    # A source-bound hand derivation has no execution to capture. The
    # registration is an affirmative non-execution category, not a generic
    # exemption for missing files in terminal runs.
    non_execution = bool(entry and entry.get("non_execution"))
    admitted_non_execution = (
        non_execution and _registered_non_execution_derivation(
            original_path, run_dir, body, entry))
    if non_execution and not admitted_non_execution:
        ctx.err(path, "registered non-execution declaration fails source or artifact controls",
                force=True)
    if admitted_non_execution:
        ctx.advise(path, "registered zero-compute hand derivation; no program output or measurement credited")
    # All other companion artifacts remain required even while a run is open.
    for artifact in RUN_CAPTURE_ARTIFACTS:
        if admitted_non_execution:
            continue
        if artifact == "raw-result.json" and (
                raw_result_pending or raw_result_explicitly_unwritten):
            continue
        if not _artifact_stored(run_dir, artifact):
            ctx.err(path, f"run directory missing artifact '{artifact}'")
    # Certificate discipline (docs/claims-and-verification.md).
    result = body.get("result") or {}
    cert = result.get("certificate") or {}
    kind = cert.get("kind")
    # CERTIFICATE_KINDS is the single source of truth for which claim kinds a
    # run may assert; `none` (a pure measurement run) is accepted separately
    # because it carries no verification duty. `key_recovery` was added here
    # for the AES line of work (RQ-AES-002 BLK-1).
    #
    # DISCLOSED COST OF THIS WORDING. The rejection message below deliberately
    # still names only discrete_log|decomposition|none and is therefore NO
    # LONGER AN EXHAUSTIVE ENUMERATION of what is accepted -- it under-reports
    # `key_recovery`. That is intentional and load-bearing, not an oversight:
    # tools/validate_ledger_baseline.txt suppresses errors by EXACT LINE MATCH
    # and 112 of its grandfathered entries end in this exact literal, so any
    # rewording of it simultaneously stales all 112 entries and emits 112
    # freshly-worded errors. The baseline is prune-only, so it cannot absorb
    # them. Keep this string byte-for-byte until a Coordinator-authorized
    # baseline regeneration retires those 112 entries; the accepted vocabulary
    # is CERTIFICATE_KINDS above and docs/claims-and-verification.md, not this
    # message. See DEC-20260901-1fc2f5 and TASK-20260901-eb81f4.
    if kind in CERTIFICATE_KINDS:
        if cert.get("verified") is not True:
            ctx.err(path, f"run claims a {kind} but certificate.verified "
                          f"is not true")
    elif kind != "none":
        ctx.err(path, "run.result.certificate.kind must be one of "
                      "discrete_log|decomposition|none")
    if rec_id:
        ctx.run_params[str(rec_id)] = (body.get("inputs") or {}).get("parameters") or {}
        ctx.register(str(rec_id), path, body, "run")


def tier_of_run(params: dict) -> int | None:
    """Highest claim tier a run's parameters can support.

    `field_bits` may be a single value or a LIST of cells: a run that sweeps
    several field sizes records e.g. [16, 20], and both EXP-LPF-001 runs do.
    Semantics for a multi-cell run: **the tier is governed by the largest
    cell**. The tier ceiling asks what size of instance the run actually
    reached, and the largest cell is that size; taking the smallest or the
    first would understate a run that did reach a bigger instance.

    An absent, empty, or non-numeric value yields None — tier unknown, so no
    ceiling is enforced from this run — which is the pre-existing behaviour for
    a missing field_bits. It is never a crash: `int()` on a list raises
    TypeError, which would abort the whole validation instead of reporting a
    line, so list values are unpacked before any coercion.
    """
    bits = params.get("field_bits") or params.get("field_bit_size")
    if bits is None:
        return None
    cells = list(bits) if isinstance(bits, (list, tuple, set)) else [bits]
    widths = []
    for cell in cells:
        if isinstance(cell, bool) or not isinstance(cell, (int, float, str)):
            return None
        try:
            widths.append(int(cell))
        except (TypeError, ValueError):
            return None
    if not widths:
        return None
    bits = max(widths)
    if bits <= 32:
        return TIER_ORDER["toy"]
    if bits <= 96:
        return TIER_ORDER["medium"]
    return TIER_ORDER["crypto"]


def decision_names_frozen_draft(decision_id: str, target_id: str,
                                decision: dict) -> bool:
    """Resolve only the five documented references to refused AUXIN drafts.

    A design draft does not enter ctx.ids: doing so would also let evidence
    records cite it as if it were an approved experiment. Verify its bytes and
    draft state here, where only decision targets receive the exception.
    """
    entry = DRAFT_DECISION_TARGETS.get((decision_id, target_id))
    if entry is None:
        return False
    batch_id, producer_task, expected_sha256 = entry
    if (decision.get("batch_id") != batch_id
            or decision.get("goal_id") != "GOAL-AUXIN-a93442"):
        return False
    path = os.path.join(
        REPO, "coordination", "goals", "GOAL-AUXIN-a93442", "batches",
        batch_id, "design", producer_task, "draft-contract.yaml")
    try:
        with open(path, "rb") as handle:
            data = handle.read()
        if hashlib.sha256(data).hexdigest() != expected_sha256:
            return False
        doc = _safe_load(data)
        fresh = doc["successor_contract"]["fresh"]
    except (OSError, KeyError, TypeError, AttributeError, yaml.YAMLError):
        return False
    if not isinstance(fresh, dict):
        return False
    return (fresh.get("id") == target_id
            and fresh.get("batch_id") == batch_id
            and fresh.get("goal_id") == "GOAL-AUXIN-a93442"
            and fresh.get("producer_task") == producer_task
            and fresh.get("status") == "draft"
            and fresh.get("approved_by") is None
            and fresh.get("approval_decision") is None)


def check_cross_refs(ctx: Ctx):
    for rec_id, body in list(ctx.records.items()):
        rec_type = ctx.record_types[rec_id]
        if rec_type == "hypothesis":
            q = body.get("question_id")
            if q and q not in ctx.ids and q not in ctx.legacy_aliases:
                ctx.err(ctx.ids[rec_id], f"hypothesis references unknown "
                                         f"question '{q}'")
        elif rec_type == "experiment":
            h = body.get("hypothesis_id")
            if h and h not in ctx.ids and h not in ctx.legacy_aliases:
                ctx.err(ctx.ids[rec_id], f"experiment references unknown "
                                         f"hypothesis '{h}'")
        elif rec_type == "evidence":
            h = body.get("hypothesis_id")
            if h and h not in ctx.ids and h not in ctx.legacy_aliases:
                ctx.err(ctx.ids[rec_id], f"evidence references unknown "
                                         f"hypothesis '{h}'")
            # legacy_aliases is consulted here for the same reason the
            # hypothesis and question checks above consult it: a frozen
            # pre-schema record exists and may be cited, it just cannot be
            # schema-checked. Omitting it here reported the citing record as
            # defective for naming a run that is present and hash-frozen.
            for run_id in body.get("run_ids") or []:
                if run_id not in ctx.ids and run_id not in ctx.legacy_aliases:
                    ctx.err(ctx.ids[rec_id], f"evidence references unknown "
                                             f"run '{run_id}'")
                run_record = ctx.records.get(run_id, {})
                if run_record.get("provenance_gap") is not None:
                    disclosures = body.get("unresolved_run_provenance") or {}
                    if (body.get("direction") not in {"neutral", "inconclusive"}
                            or body.get("strength") not in {"unverified", "inconclusive"}
                            or body.get("proof_status") not in {"empirical_only", "not_applicable"}
                            or body.get("proof_refs")
                            or not isinstance(disclosures, dict)
                            or not str(disclosures.get(run_id) or "").strip()):
                        ctx.err(ctx.ids[rec_id],
                                f"run '{run_id}' has unresolved execution provenance; "
                                "only neutral/inconclusive evidence with an explicit "
                                "unresolved_run_provenance disclosure may cite it")
            for exp_id in body.get("experiment_ids") or []:
                if exp_id not in ctx.ids and exp_id not in ctx.legacy_aliases:
                    ctx.err(ctx.ids[rec_id], f"evidence references unknown "
                                             f"experiment '{exp_id}'")
            # Citing a run id that exists under more than one experiment is
            # ambiguous unless the record also names which one it means. The
            # collisions themselves are frozen and disclosed in
            # tools/duplicate_run_ids.yaml -- they cannot be repaired, because
            # renumbering rewrites committed manifests. What is NOT tolerable
            # is a citation nobody can resolve: scale metadata and run
            # provenance read ctx.run_params, which holds whichever colliding manifest
            # was globbed LAST, so an unqualified citation is checked against a
            # run the record may never have meant.
            for run_id in body.get("run_ids") or []:
                owners = DUPLICATE_RUN_OWNERS.get(run_id)
                if not owners:
                    continue
                named = owners & set(body.get("experiment_ids") or [])
                if len(named) != 1:
                    ctx.err(ctx.ids[rec_id],
                            f"cites run '{run_id}', which exists under "
                            f"{sorted(owners)}; experiment_ids must name "
                            f"exactly one of them to resolve the citation")
            # `claim_tier` is descriptive metadata. The record and decision
            # must state the tested parameters and any transfer assumptions,
            # but the validator does not impose an automatic scale ceiling.
        elif rec_type == "coordinator_decision":
            for target_id in body.get("target_ids") or []:
                if (str(target_id).startswith(("RQ-", "H-", "EXP-", "EV-"))
                        and target_id not in ctx.ids
                        and target_id not in ctx.legacy_aliases
                        and not decision_names_frozen_draft(rec_id, target_id,
                                                            body)):
                    ctx.err(ctx.ids[rec_id], f"decision references unknown "
                                             f"target '{target_id}'")


def load_legacy_inventory() -> dict[str, str]:
    doc = load_yaml(LEGACY_LEDGER_INVENTORY, Ctx(set()))
    if not isinstance(doc, dict) or doc.get("schema") != "legacy-ledger-inventory-v1":
        raise ValueError("invalid legacy ledger inventory schema")
    records = doc.get("records")
    if not isinstance(records, dict):
        raise ValueError("legacy ledger inventory records must be a mapping")
    return {str(path): str(digest) for path, digest in records.items()}


def load_legacy_id_remaps() -> dict[str, str]:
    doc = _safe_load(open(LEGACY_LEDGER_INVENTORY, encoding="utf-8"))
    remaps = doc.get("remapped_ids", {}) if isinstance(doc, dict) else {}
    if not isinstance(remaps, dict):
        raise ValueError("legacy ledger inventory remapped_ids must be a mapping")
    return {str(path): str(rec_id) for path, rec_id in remaps.items()}


def load_legacy_run_inventory() -> dict[str, str]:
    doc = _safe_load(open(LEGACY_RUN_INVENTORY, encoding="utf-8"))
    if not isinstance(doc, dict) or doc.get("schema") != "legacy-run-inventory-v1":
        raise ValueError("invalid legacy run inventory schema")
    records = doc.get("records")
    if not isinstance(records, dict):
        raise ValueError("legacy run inventory records must be a mapping")
    return {str(path): str(digest) for path, digest in records.items()}


def load_run_supersessions(path: str | None = None) -> dict[str, dict]:
    """Load the run-supersession registry, keyed by absolute superseded path.

    Shape problems raise ValueError (the tool refuses to run on a malformed
    registry rather than half-applying it). Whether the registered files exist
    and still hash to their registered values is a per-run finding and is
    reported by check_run_supersessions().
    """
    path = path or RUN_SUPERSESSION_REGISTRY
    if not os.path.exists(path):
        return {}
    with open(path, encoding="utf-8") as handle:
        doc = yaml.load(handle, Loader=_RunRegistryLoader)
    if not isinstance(doc, dict) or doc.get("schema") != RUN_SUPERSESSION_SCHEMA:
        raise ValueError("invalid run supersession registry schema")
    records = doc.get("records") or []
    if not isinstance(records, list):
        raise ValueError("run supersession registry records must be a list")
    entries: dict[str, dict] = {}
    for index, raw in enumerate(records):
        if not isinstance(raw, dict):
            raise ValueError(f"run supersession record {index} must be a mapping")
        for field in RUN_SUPERSESSION_REQUIRED:
            if not str(raw.get(field) or "").strip():
                raise ValueError(f"run supersession record {index} is missing "
                                 f"required field '{field}'")
        superseded = str(raw["superseded_path"]).strip()
        superseding = str(raw["superseding_path"]).strip()
        for label, relative in (("superseded_path", superseded),
                                ("superseding_path", superseding)):
            if os.path.isabs(relative) or ".." in relative.split("/"):
                raise ValueError(f"run supersession {label} must be a "
                                 f"repository-relative path without '..': "
                                 f"{relative}")
        if not RUN_MANIFEST_PATH.match(superseded):
            raise ValueError(f"run supersession superseded_path must be a "
                             f"discovered run manifest "
                             f"(experiments/*/runs/*/manifest.yaml): "
                             f"{superseded}")
        if RUN_MANIFEST_PATH.match(superseding):
            raise ValueError(f"run supersession superseding_path must not "
                             f"itself be discovered by the run glob, or the "
                             f"run id would be registered twice: {superseding}")
        digests = {}
        for label in ("superseded_sha256", "superseding_sha256"):
            digest = str(raw[label]).strip().lower()
            if not SHA256_HEX.match(digest):
                raise ValueError(f"run supersession {label} must be 64 hex "
                                 f"characters: {raw[label]!r}")
            digests[label] = digest
        non_execution = raw.get("non_execution")
        if non_execution is not None:
            required = {"kind", "specification_path", "specification_sha256",
                        "derivation_path", "derivation_sha256"}
            if (raw.get("supersession_kind") != "zero_compute_misclassification"
                    or not isinstance(non_execution, dict)
                    or set(non_execution) != required
                    or non_execution.get("kind") != "hand_derivation"):
                raise ValueError("run non_execution requires the exact hand-derivation contract")
            parts = superseded.split("/")
            expected_paths = {
                "specification_path": f"experiments/{parts[1]}/specification.yaml",
                "derivation_path": f"experiments/{parts[1]}/runs/{parts[3]}/derivation-note.md",
            }
            for label, expected in expected_paths.items():
                if non_execution[label] != expected:
                    raise ValueError(f"run non_execution {label} must be {expected}")
            for label in ("specification_sha256", "derivation_sha256"):
                if (not isinstance(non_execution[label], str)
                        or not SHA256_HEX.fullmatch(non_execution[label])):
                    raise ValueError(f"run non_execution {label} must be 64 hex characters")
        elif raw.get("supersession_kind") == "zero_compute_misclassification":
            raise ValueError("zero_compute_misclassification requires non_execution")
        # A malformed historical YAML file can still have an unambiguous
        # root run_id header. The opt-in locator is checked only after the
        # archived bytes pass their hash, never on the replacement record.
        id_line = raw.get("superseded_id_line")
        if id_line is not None and (type(id_line) is not int or id_line < 1):
            raise ValueError("run supersession superseded_id_line must be a positive integer")
        # Narrow null-id binding (TASK-20260909-cb6cc7): an archived manifest
        # that PARSES with a null run id can only be bound through an explicit
        # registry declaration with provenance. Both fields are optional; when
        # present they must be well-formed. Absent on every other entry.
        id_null = raw.get("superseded_id_null")
        if id_null is not None and id_null is not True:
            raise ValueError("run supersession superseded_id_null must be "
                             "true when present")
        id_null_provenance = raw.get("superseded_id_null_provenance")
        if id_null_provenance is not None and (
                not isinstance(id_null_provenance, str)
                or not id_null_provenance.strip()):
            raise ValueError("run supersession "
                             "superseded_id_null_provenance must be a "
                             "non-empty string when present")
        key = os.path.abspath(os.path.join(REPO, superseded))
        if key in entries:
            raise ValueError(f"run supersession registry lists {superseded} "
                             f"more than once")
        extraction = raw.get("superseded_id_extraction")
        if "superseded_id_extraction" in raw:
            _validate_superseded_id_extraction(extraction, str(raw["run_id"]).strip())
        entries[key] = {
            "run_id": str(raw["run_id"]).strip(),
            "superseded_path": key,
            "superseded_sha256": digests["superseded_sha256"],
            "superseding_path": os.path.abspath(
                os.path.join(REPO, superseding)),
            "superseding_sha256": digests["superseding_sha256"],
            "superseded_id_line": id_line,
            "superseded_id_null": id_null,
            "superseded_id_null_provenance": id_null_provenance,
            "supersession_kind": raw.get("supersession_kind"),
            "decision_id": raw.get("decision_id"),
        }
        if non_execution is not None:
            entries[key]["non_execution"] = {
                "kind": "hand_derivation",
                "specification_path": os.path.abspath(
                    os.path.join(REPO, non_execution["specification_path"])),
                "specification_sha256": non_execution["specification_sha256"],
                "derivation_path": os.path.abspath(
                    os.path.join(REPO, non_execution["derivation_path"])),
                "derivation_sha256": non_execution["derivation_sha256"],
            }
        if extraction is not None:
            entries[key]["superseded_id_extraction"] = dict(extraction)
    return entries


def _schema_supersession_kind_for_path(relative: str) -> str | None:
    patterns = {
        "ledger": re.compile(
            r"^ledger/(?:questions|proposals|hypotheses|evidence|decisions|handoffs)/[^/]+\.yaml$"),
        "experiment": re.compile(r"^experiments/[^/]+/specification\.yaml$"),
        "knowledge": re.compile(
            r"^knowledge/(?:literature|techniques|findings|open-problems)/[^/]+\.md$"),
        "goal_checkpoint": re.compile(
            r"^ledger/goals/[^/]+/checkpoints/[^/]+\.yaml$"),
    }
    for kind, pattern in patterns.items():
        if pattern.match(relative):
            return kind
    return None


def _unique_key_loader(label: str) -> type:
    """A SafeLoader that refuses duplicate mapping keys, naming `label`.

    yaml.safe_load keeps the LAST value of a repeated key. In a routing index
    that is silent corruption: a merge that dropped one entry's `- kind:` line
    folded its keys into the previous entry, which then routed only the second
    record (sheriff case SHF-20261028-0f3f64, LGN-1). Used for the mutable
    routing indexes and for driver manifests, never for archived records.
    """

    class Loader(yaml.SafeLoader):
        def construct_mapping(self, node, deep=False):
            self.flatten_mapping(node)
            seen = set()
            for key_node, _ in node.value:
                key = self.construct_object(key_node, deep=deep)
                try:
                    duplicate = key in seen
                    seen.add(key)
                except TypeError:
                    # Preserve SafeLoader's normal error for unhashable keys.
                    return super().construct_mapping(node, deep=deep)
                if duplicate:
                    raise ValueError(
                        f"duplicate YAML key in {label}: "
                        f"{key!r} at line {key_node.start_mark.line + 1}")
            return super().construct_mapping(node, deep=deep)

    return Loader


_SchemaRegistryLoader = _unique_key_loader("schema supersession registry")
_RunRegistryLoader = _unique_key_loader("run supersession registry")


def load_yaml_unique_keys(source, label: str):
    """yaml.safe_load that raises ValueError on a duplicate mapping key."""
    return yaml.load(source, Loader=_unique_key_loader(label))


def load_schema_supersessions(path: str | None = None) -> dict[str, dict]:
    """Load immutable-record schema replacements keyed by original path."""
    path = path or SCHEMA_SUPERSESSION_REGISTRY
    if not os.path.exists(path):
        return {}
    with open(path, encoding="utf-8") as handle:
        doc = yaml.load(handle, Loader=_SchemaRegistryLoader)
    if (not isinstance(doc, dict)
            or doc.get("schema") != SCHEMA_SUPERSESSION_SCHEMA):
        raise ValueError("invalid schema supersession registry schema")
    records = doc.get("records") or []
    if not isinstance(records, list):
        raise ValueError("schema supersession registry records must be a list")
    entries: dict[str, dict] = {}
    for index, raw in enumerate(records):
        if not isinstance(raw, dict):
            raise ValueError(
                f"schema supersession record {index} must be a mapping")
        for field in SCHEMA_SUPERSESSION_REQUIRED:
            if not str(raw.get(field) or "").strip():
                raise ValueError(
                    f"schema supersession record {index} is missing "
                    f"required field '{field}'")
        kind = str(raw["kind"]).strip()
        if kind not in SCHEMA_SUPERSESSION_KINDS:
            raise ValueError(
                f"schema supersession record {index} has invalid kind {kind!r}")
        superseded = str(raw["superseded_path"]).strip()
        superseding = str(raw["superseding_path"]).strip()
        for label, relative in (("superseded_path", superseded),
                                ("superseding_path", superseding)):
            if os.path.isabs(relative) or ".." in relative.split("/"):
                raise ValueError(
                    f"schema supersession {label} must be a repository-relative "
                    f"path without '..': {relative}")
        discovered_kind = _schema_supersession_kind_for_path(superseded)
        if discovered_kind != kind:
            raise ValueError(
                f"schema supersession kind {kind!r} does not match discovered "
                f"source kind {discovered_kind!r}: {superseded}")
        redirect_id = raw.get("redirect_id")
        if redirect_id and raw.get("replacement_id"):
            raise ValueError(
                "schema supersession may declare redirect_id or "
                "replacement_id, not both")
        if not redirect_id and not superseding.startswith(SCHEMA_SUPERSESSION_ROOT):
            raise ValueError(
                "schema supersession replacement must live below "
                f"{SCHEMA_SUPERSESSION_ROOT}: {superseding}")
        superseding_kind = _schema_supersession_kind_for_path(superseding)
        if redirect_id and superseding_kind != kind:
            raise ValueError(
                f"schema redirect target kind {superseding_kind!r} does not "
                f"match source kind {kind!r}: {superseding}")
        if not redirect_id and superseding_kind is not None:
            raise ValueError(
                "schema supersession replacement must not itself match a "
                f"validator discovery glob: {superseding}")
        digests = {}
        for label in ("superseded_sha256", "superseding_sha256"):
            digest = str(raw[label]).strip().lower()
            if not SHA256_HEX.match(digest):
                raise ValueError(
                    f"schema supersession {label} must be 64 hex characters: "
                    f"{raw[label]!r}")
            digests[label] = digest
        key = os.path.abspath(os.path.join(REPO, superseded))
        if key in entries:
            raise ValueError(
                f"schema supersession registry lists {superseded} more than once")
        replacement_id = raw.get("replacement_id")
        entries[key] = {
            "kind": kind,
            "superseded_path": key,
            "superseded_sha256": digests["superseded_sha256"],
            "superseding_path": os.path.abspath(
                os.path.join(REPO, superseding)),
            "superseding_sha256": digests["superseding_sha256"],
            "replacement_id": (str(replacement_id).strip()
                               if replacement_id else None),
            "redirect_id": (str(redirect_id).strip() if redirect_id else None),
        }
    return entries


def check_schema_supersessions(ctx: Ctx,
                               supersessions: dict[str, dict]) -> None:
    """Pin both sides of every schema supersession before routing reads."""
    for key in sorted(supersessions):
        entry = supersessions[key]
        for role, file_path, expected in (
            ("superseded", entry["superseded_path"],
             entry["superseded_sha256"]),
            ("superseding", entry["superseding_path"],
             entry["superseding_sha256"]),
        ):
            if not os.path.isfile(file_path):
                ctx.err(file_path,
                        f"registered {role} schema record is missing; a "
                        "supersession requires both records to be present",
                        force=True)
                continue
            with open(file_path, "rb") as handle:
                actual = hashlib.sha256(handle.read()).hexdigest()
            if actual != expected:
                ctx.err(file_path,
                        f"registered {role} schema record hash changed "
                        f"(registry pins {expected[:8]}, found {actual[:8]}); "
                        "supersede it instead of editing it",
                        force=True)


def check_schema_redirects(ctx: Ctx,
                           supersessions: dict[str, dict]) -> None:
    """Require every alias-only supersession to resolve to its pinned target."""
    for entry in supersessions.values():
        target_id = entry.get("redirect_id")
        if not target_id:
            continue
        if target_id not in ctx.ids and target_id not in ctx.knowledge:
            ctx.err(entry["superseded_path"],
                    f"schema redirect target '{target_id}' is not a canonical "
                    "record", force=True)


def _validate_superseded_id_extraction(extraction: object, run_id: str) -> None:
    """Validate an explicit identity binding, never a permissive YAML parser."""
    headers = {
        "unique_first_line_run_id_header": (1, f"run_id: {run_id}"),
        "unique_nested_run_id_duplicate_process": (2, f"  id: {run_id}"),
    }
    kind = extraction.get("kind") if isinstance(extraction, dict) else None
    expected = headers.get(kind) if isinstance(kind, str) else None
    if (not isinstance(extraction, dict)
            or set(extraction) != {"kind", "line_number", "exact_line"}
            or expected is None
            or type(extraction.get("line_number")) is not int
            or extraction.get("line_number") != expected[0]
            or not RUN_ID.fullmatch(run_id)
            or extraction.get("exact_line") != expected[1]):
        raise ValueError("invalid superseded_id_extraction binding")


def _safe_identity_scalar_key(node):
    """Resolve a scalar key using only SafeLoader scalar constructors.

    Compare these values with ordinary Python mapping equality (including
    bool/int/float equality), while callers retain their textual restrictions.
    Non-reflexive values such as NaN cannot provide an unambiguous key.
    """
    if not isinstance(node, yaml.ScalarNode):
        raise yaml.YAMLError("non-scalar key in run identity record")
    if node.tag not in {
        "tag:yaml.org,2002:" + name
        for name in ("str", "null", "bool", "int", "float", "binary", "timestamp")
    }:
        raise yaml.YAMLError("unsupported scalar key tag in run identity record")
    loader = yaml.SafeLoader("")
    try:
        value = loader.construct_object(node, deep=True)
        hash(value)
        if value != value:
            raise ValueError("non-reflexive scalar key")
        return value
    except (ValueError, TypeError, OverflowError, KeyError, AttributeError,
            IndexError) as exc:
        raise yaml.YAMLError("ambiguous scalar key in run identity record") from exc
    finally:
        loader.dispose()


def _nested_run_id_with_duplicate_process(text: str, run_id: str) -> str | None:
    """Recover only an unambiguous ID, not the duplicate process observations.

    Called only behind a registry opt-in and whole-file hash check. Ordinary
    identity parsing continues to reject every duplicate mapping key.
    """
    lines = text.splitlines()
    if lines[:2] != ["run:", f"  id: {run_id}"]:
        return None
    if any(line.strip() in {"---", "..."} for line in lines):
        return None
    try:
        root = yaml.compose(text)
        if not isinstance(root, yaml.MappingNode) or len(root.value) != 1:
            return None
        key, body = root.value[0]
        if not isinstance(key, yaml.ScalarNode) or key.value != "run":
            return None
        if not isinstance(body, yaml.MappingNode):
            return None
        identities = [(key, value) for key, value in body.value
                      if isinstance(key, yaml.ScalarNode)
                      and key.value in {"id", "run_id", "run"}]
        if (len(identities) != 1 or identities[0][0].value != "id"
                or not isinstance(identities[0][1], yaml.ScalarNode)
                or identities[0][1].tag != "tag:yaml.org,2002:str"
                or identities[0][1].value != run_id):
            return None
        seen: set[int] = set()
        duplicates = []

        def inspect(node, path=()):
            if id(node) in seen:
                raise ValueError("alias")
            seen.add(id(node))
            if isinstance(node, yaml.MappingNode):
                keys = set()
                resolved_keys = set()
                for key, value in node.value:
                    resolved_key = _safe_identity_scalar_key(key)
                    if key.value == "<<":
                        raise ValueError("ambiguous key")
                    if key.value in keys or resolved_key in resolved_keys:
                        if (path != ("run",) or key.value != "process"
                                or resolved_key != "process"
                                or key.tag != "tag:yaml.org,2002:str"):
                            raise ValueError("unexpected duplicate")
                        duplicates.append(path + (key.value,))
                    keys.add(key.value)
                    resolved_keys.add(resolved_key)
                    if path == ("run",) and key.value == "process":
                        if (key.tag != "tag:yaml.org,2002:str"
                                or resolved_key != "process"):
                            raise ValueError("process key is not a string")
                        if not isinstance(value, yaml.MappingNode):
                            raise ValueError("process observation is not a mapping")
                    inspect(key, path)
                    inspect(value, path + (key.value,))
            elif isinstance(node, yaml.SequenceNode):
                for item in node.value:
                    inspect(item, path)

        inspect(root)
        if duplicates != [("run", "process")]:
            return None
        return run_id
    except (yaml.YAMLError, ValueError, TypeError):
        return None


def _malformed_superseded_run_id(path: str, entry: dict | None) -> str | None:
    """Extract identity only from an opted-in, hash-pinned malformed original.

    This helper cannot validate the original or replace any field check on the
    complete superseding manifest. Recheck path and bytes here so even callers
    outside check_run_supersessions cannot use a binding for another file.
    """
    if not entry or "superseded_id_extraction" not in entry:
        return None
    run_id = str(entry.get("run_id") or "")
    extraction = entry["superseded_id_extraction"]
    try:
        _validate_superseded_id_extraction(extraction, run_id)
        if (os.path.abspath(path) != entry.get("superseded_path")
                or os.path.basename(os.path.dirname(path)) != run_id):
            return None
        with open(path, "rb") as handle:
            content = handle.read()
        if hashlib.sha256(content).hexdigest() != entry.get("superseded_sha256"):
            return None
        lines = content.decode("utf-8").splitlines()
    except (OSError, UnicodeError, ValueError):
        return None
    if extraction["kind"] == "unique_nested_run_id_duplicate_process":
        return _nested_run_id_with_duplicate_process(content.decode("utf-8"), run_id)
    if not lines or lines[0] != extraction["exact_line"]:
        return None
    identity_headers = [line for line in lines
                        if re.match(r"^(?:run_id|id|run)\s*:", line)]
    if identity_headers != [extraction["exact_line"]]:
        return None
    return run_id


def _flat_run_id_with_malformed_dirty_summary(text: str) -> str | None:
    """Read identity only from the narrowly known flat-manifest encoding defect.

    The historical writer interpolated git porcelain output into an unquoted
    dirty_summary. Quote only that field in memory, then parse the WHOLE
    document and reject ambiguous identities. This does not make the original
    a valid run: normal check_run still rejects it, and supersession still
    requires both whole-file hashes and complete replacement validation.
    """
    lines = text.splitlines()
    if not lines or not lines[0].startswith("run_id: "):
        return None
    rec_id = lines[0][len("run_id: "):]
    if not RUN_ID.fullmatch(rec_id):
        return None
    starts = [i for i, line in enumerate(lines)
              if line.startswith("  dirty_summary: ")]
    if len(starts) != 1:
        return None
    start = starts[0]
    end = start + 1
    # Accept only literal unquoted porcelain rows, never arbitrary YAML or
    # scalar contents as continuation. A colon in a filename is not a key.
    statuses = re.compile(r"(?:\?\?|[MADRCU?!]|[ MADRCU?!]{2}) [^\r\n]+")
    values = [lines[start][len("  dirty_summary: "):]]
    while end < len(lines) and lines[end] != "environment:":
        values.append(lines[end])
        end += 1
    if end == len(lines) or not all(statuses.fullmatch(v) for v in values):
        return None
    repaired = lines[:start] + ["  dirty_summary: " + json.dumps("\n".join(values))] + lines[end:]
    try:
        node = yaml.compose("\n".join(repaired))
        seen: set[int] = set()
        identities: list[tuple[str, str]] = []

        def inspect(current, depth=0):
            # Aliases, duplicate keys, nested identities and merge keys are
            # deliberately outside this narrowly recoverable old format.
            if id(current) in seen:
                raise ValueError("alias")
            seen.add(id(current))
            if isinstance(current, yaml.MappingNode):
                keys = set()
                for key, value in current.value:
                    if not isinstance(key, yaml.ScalarNode) or key.value in keys:
                        raise ValueError("ambiguous mapping")
                    keys.add(key.value)
                    if key.value in ("id", "run_id", "run", "<<"):
                        if depth != 0 or key.value != "run_id" or not isinstance(value, yaml.ScalarNode):
                            raise ValueError("ambiguous identity")
                        identities.append((key.value, value.value))
                    inspect(value, depth + 1)
            elif isinstance(current, yaml.SequenceNode):
                for value in current.value:
                    inspect(value, depth + 1)
        inspect(node)
        if identities != [("run_id", rec_id)]:
            return None
        doc = _safe_load("\n".join(repaired))
        if not isinstance(doc, dict) or not isinstance(doc.get("git"), dict):
            return None
        if doc["git"].get("dirty_summary") != "\n".join(values):
            return None
    except (yaml.YAMLError, ValueError, TypeError):
        return None
    return rec_id


def _null_id_superseded_run_id(path: str, entry: dict | None) -> str | None:
    """Bind identity for a registered superseded manifest that parses with a null id.

    Narrow sibling of the malformed-YAML recovery (_malformed_superseded_run_id),
    added by TASK-20260909-cb6cc7 for RUN-ECDLP-e962f6-007, whose archived
    manifest is well-formed YAML that records `id: null`. It fires ONLY when
    all of the following hold:

      * the entry is a registered supersession that explicitly declares
        `superseded_id_null: true` together with a non-empty
        `superseded_id_null_provenance`;
      * the file is hash-verified against the entry's `superseded_sha256`;
      * the file's path matches the entry's `superseded_path`;
      * the run-directory basename equals the registered run id.

    It does not generalise null-id recovery: a parseable manifest with a null
    id that is not a registered supersession -- or whose entry lacks the
    explicit declaration -- still yields None, exactly as before this path
    existed.
    """
    if not entry or entry.get("superseded_id_null") is not True:
        return None
    provenance = entry.get("superseded_id_null_provenance")
    if not isinstance(provenance, str) or not provenance.strip():
        return None
    run_id = str(entry.get("run_id") or "")
    if not RUN_ID.fullmatch(run_id):
        return None
    if (os.path.abspath(path) != entry.get("superseded_path")
            or os.path.basename(os.path.dirname(path)) != run_id):
        return None
    try:
        with open(path, "rb") as handle:
            content = handle.read()
    except OSError:
        return None
    if hashlib.sha256(content).hexdigest() != entry.get("superseded_sha256"):
        return None
    return run_id


def _run_id_of(path: str, *, superseded_entry: dict | None = None) -> str | None:
    try:
        with open(path, encoding="utf-8") as handle:
            text = handle.read()
    except OSError:
        return None
    class IdentityLoader(yaml.SafeLoader):
        pass

    def unique_mapping(loader, node, deep=False):
        keys = set()
        resolved_keys = set()
        for key, _ in node.value:
            resolved_key = _safe_identity_scalar_key(key)
            if key.value in keys or resolved_key in resolved_keys:
                raise yaml.YAMLError("duplicate mapping keys in run identity record")
            keys.add(key.value)
            resolved_keys.add(resolved_key)
        return yaml.SafeLoader.construct_mapping(loader, node, deep=deep)

    IdentityLoader.add_constructor(yaml.resolver.BaseResolver.DEFAULT_MAPPING_TAG,
                                   unique_mapping)
    unparsed = object()
    try:
        doc = unparsed
        if _CSafeLoader is not None:
            class FastIdentityLoader(_CSafeLoader):
                pass
            FastIdentityLoader.add_constructor(
                yaml.resolver.BaseResolver.DEFAULT_MAPPING_TAG, unique_mapping)
            try:
                doc = yaml.load(text, Loader=FastIdentityLoader)
            except yaml.YAMLError:
                pass  # the pure loader below decides, as it always did
        if doc is unparsed:
            doc = yaml.load(text, Loader=IdentityLoader)
    except yaml.YAMLError:
        # Recovery is allowed only for a hash-verified registered original
        # with an explicit locator, never as ordinary identity parsing.
        # Porcelain whole-document recovery stays behind superseded_id_line
        # / _malformed_run_header_id; extraction bindings use this opt-in.
        return _malformed_superseded_run_id(path, superseded_entry)
    body = doc.get("run") if isinstance(doc, dict) else None
    if isinstance(body, dict):
        rec_id = body.get("id")
    elif isinstance(doc, dict):
        # A supersession is specifically how an archived flat pre-schema
        # manifest gains the canonical nested shape.  Its historical id is
        # still binding and must match the replacement.
        rec_id = doc.get("run_id") or doc.get("id")
    else:
        rec_id = None
    if rec_id:
        return str(rec_id)
    # A parseable manifest with a null id has no ordinary identity. The only
    # recovery is the narrow, hash-verified, registry-declared null-id binding
    # above; it returns None for every manifest that is not such a registered
    # supersession, so unregistered behaviour is unchanged.
    return _null_id_superseded_run_id(path, superseded_entry)


def _malformed_run_header_id(path: str, line_number: int) -> str | None:
    """Read one explicitly located root ID in hash-verified malformed YAML.

    This is identity recovery, not parsing the damaged record as evidence.
    Reject duplicate/ambiguous root identity fields and require the run
    directory to agree. A normally parseable file never needs this route.
    """
    if type(line_number) is not int or line_number < 1:
        return None
    try:
        text = Path(path).read_text(encoding="utf-8")
        _safe_load(text)
        return None
    except yaml.YAMLError:
        pass
    except (OSError, UnicodeError):
        return None
    headers = [(i, line) for i, line in enumerate(text.splitlines(), 1)
               if re.match(r"^(?:run_id|id)\s*:", line)]
    if len(headers) != 1 or headers[0][0] != line_number:
        return None
    # Accept only a literal root run_id, not aliases, tags, quotes, nested
    # mappings or a second YAML document masquerading as the header.
    if any(line.strip() in {"---", "..."} for line in text.splitlines()):
        return None
    header = re.fullmatch(r"run_id: (RUN-[A-Za-z0-9_-]+)", headers[0][1])
    if header is None:
        return None
    value = header[1]
    if not RUN_ID.fullmatch(value):
        return None
    if _flat_run_id_with_malformed_dirty_summary(text) != value:
        return None
    return value if os.path.basename(os.path.dirname(path)) == value else None


def check_run_supersessions(ctx: Ctx, supersessions: dict[str, dict]) -> None:
    """Audit every registered supersession before any routing happens.

    Both files must be present and hash to their registered values, and both
    must declare the registered run id. A supersession that let either file
    drift, or that pointed at an unrelated record, would be a way to hide
    changes to an archived run rather than a way to repair one, so every
    finding here is an error and none is downgraded to a legacy warning.
    """
    for key in sorted(supersessions):
        entry = supersessions[key]
        for role, file_path, expected in (
            ("superseded", entry["superseded_path"],
             entry["superseded_sha256"]),
            ("superseding", entry["superseding_path"],
             entry["superseding_sha256"]),
        ):
            if not os.path.isfile(file_path):
                ctx.err(file_path,
                        f"registered {role} run manifest is missing; a "
                        f"supersession requires both records to be present",
                        force=True)
                continue
            with open(file_path, "rb") as handle:
                actual = hashlib.sha256(handle.read()).hexdigest()
            if actual != expected:
                ctx.err(file_path,
                        f"registered {role} run manifest hash changed "
                        f"(registry pins {expected[:8]}, found {actual[:8]}); "
                        f"supersede it instead of editing it",
                        force=True)
                continue
            found = _run_id_of(
                file_path, superseded_entry=entry if role == "superseded" else None)
            if (found is None and role == "superseded"
                    and entry.get("superseded_id_line") is not None):
                found = _malformed_run_header_id(
                    file_path, entry["superseded_id_line"])
            if found != entry["run_id"]:
                ctx.err(file_path,
                        f"registered {role} run manifest declares run id "
                        f"{found!r}, but the supersession registry entry is "
                        f"for {entry['run_id']!r}",
                        force=True)


def check_legacy_run_inventory(ctx: Ctx, inventory: dict[str, str]) -> None:
    for relative, expected in sorted(inventory.items()):
        path = os.path.join(REPO, relative)
        if not os.path.isfile(path):
            ctx.err(path, "frozen legacy run manifest is missing", force=True)
            continue
        actual = hashlib.sha256(open(path, "rb").read()).hexdigest()
        if actual != expected:
            ctx.err(
                path,
                "frozen legacy run manifest hash changed; supersede it instead",
                force=True,
            )


def flat_run_id(path: str, doc) -> str | None:
    """The run id a flat (non-`run:`) manifest belongs to, or None.

    The run directory name is the run id by layout
    (`experiments/<EXP>/runs/<RUN>/`, docs/evidence-and-reproducibility.md).
    It is accepted only when nothing in the manifest contradicts it: a
    recorded `run_id`/`id` must equal it, and a recorded `experiment_id` must
    equal the enclosing experiment directory. A manifest that disagrees with
    its own location is not indexed -- which run it describes is ambiguous.
    """
    if not isinstance(doc, dict):
        return None
    run_dir = os.path.dirname(os.path.abspath(path))
    run_id = os.path.basename(run_dir)
    runs_dir = os.path.dirname(run_dir)
    if os.path.basename(runs_dir) != "runs" or not RUN_ID.match(run_id):
        return None
    exp_dir = os.path.basename(os.path.dirname(runs_dir))
    recorded = doc.get("run_id") or doc.get("id")
    if recorded not in (None, "") and str(recorded) != run_id:
        return None
    recorded_exp = doc.get("experiment_id")
    if recorded_exp not in (None, "") and str(recorded_exp) != exp_dir:
        return None
    return run_id


def register_flat_run_alias(path: str, doc, ctx: Ctx) -> None:
    """Index a run whose manifest exists but is not schema-checkable."""
    run_id = flat_run_id(path, doc)
    if run_id:
        ctx.legacy_aliases.add(run_id)


def check_json_only_runs(ctx: Ctx) -> None:
    """Index non-legacy runs whose only manifest is `manifest.json`.

    The scan in main() visits `manifest.yaml` and `manifest_v2.yaml` only;
    legacy JSON manifests are registered from the run inventory by
    register_legacy_json_runs(). A run committed after the inventory froze,
    with a JSON manifest, was therefore never seen: its own defect (no
    canonical `manifest.yaml`) went unreported, and every record citing it was
    reported instead as citing an unknown run. Index the run so citations
    resolve, and surface the missing canonical manifest as an advisory: these
    runs were never schema-checked before either, and the prune-only baseline
    cannot absorb the ~80 that become visible, so failing them here would turn
    an indexing fix into a red build. Promoting the advisory to an error is a
    separate change, once their schema supersessions land.
    """
    pattern = os.path.join(REPO, "experiments", "*", "runs", "*", "manifest.json")
    for path in sorted(glob.glob(pattern)):
        run_dir = os.path.dirname(path)
        if (os.path.abspath(path) in ctx.legacy_paths
                or os.path.isfile(os.path.join(run_dir, "manifest.yaml"))
                or os.path.isfile(os.path.join(run_dir, "manifest_v2.yaml"))):
            continue
        try:
            with open(path, encoding="utf-8") as fh:
                doc = json.load(fh)
        except (OSError, ValueError) as error:
            ctx.advise(path, f"json-only run: invalid JSON manifest: {error}")
            continue
        ctx.advise(path, "json-only run: the canonical nested manifest.yaml "
                         "is missing (indexed, not schema-checked)")
        register_flat_run_alias(path, doc, ctx)


def check_amendments(ctx: Ctx) -> None:
    """Index protocol amendments (`experiments/<EXP>/amendments/AMD-*.yaml`).

    Amendments are part of the documented experiment package
    (docs/evidence-and-reproducibility.md) and are cited by id from knowledge
    findings, but were never indexed, so every such citation was reported as
    an unknown record. Only the id is indexed, and only when the record's
    `amendment.id` equals its filename stem and its `experiment_id` (if
    recorded) equals the enclosing experiment directory.
    """
    pattern = os.path.join(REPO, "experiments", "*", "amendments", "AMD-*.yaml")
    for path in sorted(glob.glob(pattern)):
        try:
            doc = _safe_load(open(path, encoding="utf-8"))
        except (OSError, yaml.YAMLError):
            continue              # not this check's defect to report
        body = doc.get("amendment") if isinstance(doc, dict) else None
        if not isinstance(body, dict):
            continue
        stem = os.path.splitext(os.path.basename(path))[0]
        exp_dir = os.path.basename(os.path.dirname(os.path.dirname(path)))
        if str(body.get("id") or "") != stem:
            continue
        if body.get("experiment_id") not in (None, "", exp_dir):
            continue
        ctx.amendment_ids.add(stem)


def register_legacy_json_runs(ctx: Ctx, inventory: dict[str, str]) -> None:
    """Register run ids of frozen legacy manifests serialized as JSON.

    Some pre-canonical runs recorded their manifest as `manifest.json` rather
    than `manifest.yaml`. The scan below only visits `manifest.yaml`, so those
    runs were never seen at all: not schema-checked (correctly -- they predate
    the schema) but also never registered, so every evidence record citing one
    was reported as referencing an unknown run. The run is present and frozen
    by hash in the inventory; only its serialization is old.

    This registers the id as a legacy alias, exactly as a flat `manifest.yaml`
    does. It deliberately does NOT register the body: nothing here becomes
    schema-checkable, claim tiers are not derived from it, and a run with no
    manifest of any kind stays unregistered, because no record of it exists.
    """
    for relative in sorted(inventory):
        if not relative.endswith(".json"):
            continue
        path = os.path.join(REPO, relative)
        try:
            with open(path, encoding="utf-8") as fh:
                doc = json.load(fh)
        except (OSError, ValueError):
            continue          # hash/presence is check_legacy_run_inventory's job
        if not isinstance(doc, dict):
            continue
        legacy_id = doc.get("run_id") or doc.get("id")
        if isinstance(legacy_id, str) and RUN_ID.match(legacy_id):
            ctx.legacy_aliases.add(legacy_id)


def check_legacy_ledger(
    ctx: Ctx,
    inventory: dict[str, str],
) -> None:
    patterns = {
        "RQ-*.yaml": "research_question",
        "H-*.yaml": "hypothesis",
        "EV-*.yaml": "evidence",
        "DEC-*.yaml": "coordinator_decision",
    }
    observed: set[str] = set()
    for pattern, rec_type in patterns.items():
        for path in sorted(glob.glob(os.path.join(REPO, "ledger", pattern))):
            relative = os.path.relpath(path, REPO)
            observed.add(relative)
            # Even a malformed frozen record provides a stable historical
            # filename alias for later correction/supersession records.
            ctx.legacy_aliases.add(os.path.splitext(os.path.basename(path))[0])
            expected = inventory.get(relative)
            if expected is None:
                ctx.err(path, "new root-level ledger record is forbidden; "
                              "use the canonical ledger subdirectory",
                        force=True)
            else:
                actual = hashlib.sha256(open(path, "rb").read()).hexdigest()
                if actual != expected:
                    ctx.err(path, "frozen legacy ledger record hash changed; "
                                  "supersede it in a canonical subdirectory",
                            force=True)
            check_ledger_record(path, rec_type, ctx)
    for missing in sorted(set(inventory) - observed):
        ctx.err(os.path.join(REPO, missing),
                "frozen legacy ledger record is missing", force=True)


def check_legacy_id_remaps(ctx: Ctx) -> None:
    for source, target_id in sorted(ctx.legacy_id_remaps.items()):
        if target_id not in ctx.ids:
            ctx.err(
                source,
                f"legacy remap target '{target_id}' is not a canonical record",
                force=True,
            )


def check_knowledge_entries(ctx: Ctx) -> None:
    for entry_type, (directory, prefix) in KNOWLEDGE_TYPES.items():
        pattern = os.path.join(REPO, "knowledge", directory, "*.md")
        for path in sorted(glob.glob(pattern)):
            source = ctx.source_path(path)
            text = open(source, encoding="utf-8").read()
            if not text.startswith("---"):
                ctx.err(path, "knowledge entry is missing YAML frontmatter")
                continue
            try:
                frontmatter = _safe_load(text.split("---", 2)[1]) or {}
            except yaml.YAMLError as error:
                ctx.err(path, f"invalid knowledge frontmatter: {error}")
                continue
            rec_id = frontmatter.get("id")
            stem = os.path.splitext(os.path.basename(path))[0]
            if not isinstance(rec_id, str) or not rec_id.startswith(prefix):
                ctx.err(path, f"knowledge id must start with {prefix}")
                continue
            supersession = ctx.schema_supersession(path)
            replacement_id = (supersession or {}).get("replacement_id")
            if replacement_id and rec_id != replacement_id:
                ctx.err(path, f"registered replacement_id '{replacement_id}' != "
                              f"superseding knowledge id '{rec_id}'", force=True)
            if not replacement_id and stem != rec_id:
                ctx.err(path, f"filename stem '{stem}' != id '{rec_id}'")
            if frontmatter.get("type") != entry_type:
                ctx.err(path, f"knowledge type must be '{entry_type}'")
            for field in ("title", "tags", "confidence", "added"):
                if frontmatter.get(field) in (None, "", []):
                    ctx.err(path, f"knowledge entry missing '{field}'")
            if rec_id in ctx.knowledge:
                ctx.err(path, f"duplicate knowledge ID {rec_id}")
            ctx.knowledge[rec_id] = path
            if replacement_id:
                ctx.knowledge[stem] = path
            if entry_type == "internal_finding":
                refs = frontmatter.get("internal_refs")
                if not isinstance(refs, list) or not refs:
                    ctx.err(path, "internal finding requires internal_refs")
                else:
                    # legacy_aliases: the same "exists, not schema-checkable"
                    # registry check_cross_refs consults for evidence run_ids;
                    # without it a finding citing such a run failed where an
                    # evidence record citing the same run passed.
                    for ref in refs:
                        if (ref not in ctx.ids and ref not in ctx.knowledge
                                and ref not in ctx.legacy_aliases
                                and ref not in ctx.amendment_ids):
                            ctx.err(path, f"internal finding references unknown "
                                          f"record '{ref}'")
                if frontmatter.get("proof_status") not in PROOF_STATUSES:
                    ctx.err(path, "internal finding requires valid proof_status")
                if not isinstance(frontmatter.get("proof_refs"), list):
                    ctx.err(path, "internal finding proof_refs must be a list")

    for rec_id, body in ctx.records.items():
        if ctx.record_types[rec_id] != "coordinator_decision":
            continue
        promotion = body.get("knowledge_promotion")
        if not isinstance(promotion, dict):
            continue
        for entry in promotion.get("promoted") or []:
            # Records in the wild write both shapes: a bare `KN-*` id, and a
            # mapping carrying the id plus a note or action. Take the id from
            # either. An entry that is neither is a malformed reference, not a
            # reason to abort the whole run -- an unhashable one used to raise
            # TypeError here and take every later check down with it.
            if isinstance(entry, dict):
                knowledge_id = entry.get("id")
            else:
                knowledge_id = entry
            if not isinstance(knowledge_id, str):
                ctx.err(ctx.ids[rec_id], "knowledge_promotion entry is not a "
                                         f"knowledge ID: {entry!r}")
                continue
            if knowledge_id not in ctx.knowledge:
                ctx.err(ctx.ids[rec_id], "knowledge_promotion references "
                                         f"unknown entry '{knowledge_id}'")


GOAL_ID = ID_PATTERNS["goal"]
GOAL_LEGACY_ID = re.compile(rf"^GOAL-[A-Z0-9]+-{SUFFIX_LEGACY}$")
GOAL_RANDOM_ID = re.compile(rf"^GOAL-[A-Z0-9]+-{SUFFIX_RANDOM}$")
# `closed_at_budget` is a terminal status in active use. It asserts that the
# campaign budget ran out WITHOUT a completion criterion being met, so it makes
# no success claim and needs no quorum. Using it to retire a goal that did meet
# a criterion, in order to avoid the quorum, is a contract violation.
# PAUSING A GOAL IS NOT PERMITTED. `paused` and `blocked` were removed from
# this set on user instruction (2026-09-04): a campaign that hits an impediment
# stays `active` and carries that impediment as a record, so the harness keeps
# returning to it instead of parking it.
#
# `blocked` is refused alongside `paused` deliberately. It is the same idling
# under another name, and leaving it available would have made the rule
# cosmetic — the next session that wanted to stop a goal would simply have
# written `blocked` instead.
#
# WHAT THIS DOES NOT RELAX. Pausing was carrying two honesty guarantees, and
# removing the status does not remove either of them:
#   - An infrastructure or budget impediment is STILL never negative
#     mathematical evidence (AGENTS.md rule 3) and still never a research
#     conclusion. It is recorded as an impediment on an active goal.
#   - A `review-breakthrough` that cannot be served STILL may not be downgraded
#     to a lower review tier. The goal stays active; the CLAIM stays
#     un-promoted. "Never pause" is not permission to close, to promote, or to
#     review at a tier the policy forbids.
# An exhausted campaign budget likewise does not become licence to keep
# spending: it requires a committed Coordinator budget decision before the next
# batch. Terminal retirement remains available via `closed_at_budget` and
# `cancelled`, both of which assert no success and both of which are deliberate
# Coordinator acts rather than the automatic response to an impediment.
GOAL_STATUSES = {"draft", "active", "completed", "cancelled",
                 "closed_at_budget"}
GOAL_STATUSES_REFUSED = {
    "paused": ("pausing a goal is not permitted; keep status: active and record "
               "the blocker under `impediments` with a concrete clearing "
               "condition"),
    "blocked": ("blocking a goal is not permitted; it is pausing under another "
                "name. Keep status: active and record the blocker under "
                "`impediments` with a concrete clearing condition"),
}
GOAL_REQUIRED = ["id", "title", "objective", "question_ids", "status",
                 "completion_criteria", "pause_conditions", "next_action",
                 "owner"]

# Goal records were not validated at all before this check existed, and these
# three were marked `completed` before the closure quorum was a rule. The rule
# is prospective: demanding retroactive attestations would either block CI
# permanently or invite back-dated ones, and a fabricated attestation is worse
# than an unattested closure. They are exempt from the quorum and required-field
# checks only, still validated for id format and status, and reported as schema
# debt. Do not add to this set: a new closure must earn its quorum.
PRE_QUORUM_GOAL_IDS = {"GOAL-ICLIFT-001", "GOAL-XEDN-001", "GOAL-XEDN-002",
                       "GOAL-P13-001"}

# A goal may only be closed out on the concurring judgement of three
# independently-resolved models. See AGENTS.md "Goal closure quorum".
GOAL_CLOSURE_QUORUM = 3

# SUSPENDED. The quorum requirement is not enforced while this is False.
#
# Why: the rule presumes several backends that bind to genuinely different
# models. In the harness as deployed there is one usable backend, so three
# attestations necessarily resolve to one model -- which the rule itself
# defines as *not* a quorum. The requirement therefore made `completed`
# unreachable for every goal regardless of its research merit, turning a
# safeguard against overclaiming into a blanket block. Goals that met their
# criteria were left `paused`, which understates them.
#
# What this does NOT relax. Everything below still applies whenever a
# completion_quorum block is present at all:
#   - attestation shape (ATTESTATION_REQUIRED), independent_session,
#     and reviewed_record_ids resolving to real records;
#   - a recorded DISSENT still contradicts `completed`. That is ordinary
#     self-consistency, not the quorum: having obtained a dissent, closing
#     anyway is incoherent at any quorum size;
#   - `quorum_satisfied: true` on a non-completed goal is still an error.
# Attestations remain fully supported and are still worth recording; they are
# simply no longer a precondition for closure.
#
# To restore: set this True. The enforcement code and its tests are intact and
# are exercised in both modes by tools/test_goal_closure_quorum.py, so flipping
# it back needs no other edit. Restore it once more than one backend resolves
# (`python3 -m orchestration.adapter doctor --probe`).
GOAL_CLOSURE_QUORUM_REQUIRED = False
ATTESTATION_REQUIRED = ["role", "requested_policy", "resolved_model_id",
                        "independent_session", "reviewed_record_ids",
                        "verdict"]
CONCUR = "CONCUR"
DISSENT = "DISSENT"


def check_goal_closure_quorum(path: str, goal: dict, ctx: Ctx):
    """Check the closure quorum on a goal marked `completed`.

    When `GOAL_CLOSURE_QUORUM_REQUIRED` is true, a closed-out goal must carry
    `completion_quorum.attestations`: at least three verdicts whose
    `resolved_model_id` values are pairwise distinct and which all CONCUR. The
    distinctness is on the *resolved* model, not the requested policy alias,
    because a policy that falls back to a shared model yields correlated
    judgements and is not a quorum.

    The requirement is currently SUSPENDED (see `GOAL_CLOSURE_QUORUM_REQUIRED`),
    so a `completed` goal need not carry the block at all. A block that IS
    present is still validated in full except for the count and distinctness
    gates: attestations must be well-formed, sessions independent, cited
    records real, and a recorded DISSENT still contradicts closure.
    """
    quorum = goal.get("completion_quorum")
    if not isinstance(quorum, dict):
        if GOAL_CLOSURE_QUORUM_REQUIRED:
            ctx.err(path, "goal status 'completed' requires a "
                          f"completion_quorum block with "
                          f"{GOAL_CLOSURE_QUORUM} concurring attestations")
        return

    attestations = quorum.get("attestations")
    if not isinstance(attestations, list) or not attestations:
        # A block that is present must still be well-formed, whether or not
        # the quorum gates closure: an empty attestations list asserts a
        # review that did not happen.
        ctx.err(path, "completion_quorum.attestations must be a non-empty list")
        return

    for i, att in enumerate(attestations):
        if not isinstance(att, dict):
            ctx.err(path, f"completion_quorum.attestations[{i}] must be a "
                          "mapping")
            return
        for field in ATTESTATION_REQUIRED:
            if att.get(field) in (None, "", []):
                ctx.err(path, f"completion_quorum.attestations[{i}] missing "
                              f"required field '{field}'")

    verdicts = [str(a.get("verdict", "")).strip().upper() for a in attestations]
    dissent = [i for i, v in enumerate(verdicts) if v == DISSENT]
    if dissent:
        ctx.err(path, "goal status 'completed' contradicts DISSENT in "
                      f"completion_quorum.attestations{dissent}; a dissent "
                      "blocks closure until superseded by a new decision")

    concurring = [a for a, v in zip(attestations, verdicts) if v == CONCUR]
    if GOAL_CLOSURE_QUORUM_REQUIRED:
        # The count and the distinctness are the quorum proper, and they are
        # the only two checks the suspension turns off.
        if len(concurring) < GOAL_CLOSURE_QUORUM:
            ctx.err(path, f"goal closure needs {GOAL_CLOSURE_QUORUM} CONCUR "
                          f"attestations, found {len(concurring)}")

        models = [str(a.get("resolved_model_id", "")).strip()
                  for a in concurring if a.get("resolved_model_id")]
        distinct = {m for m in models if m}
        if len(distinct) < GOAL_CLOSURE_QUORUM:
            ctx.err(path, "goal closure needs "
                          f"{GOAL_CLOSURE_QUORUM} pairwise-distinct "
                          f"resolved_model_id values among concurring "
                          f"attestations, found {len(distinct)} "
                          f"({sorted(distinct)})")

    non_independent = [i for i, a in enumerate(attestations)
                       if a.get("independent_session") is not True]
    if non_independent:
        ctx.err(path, "every closure attestation must set "
                      "independent_session: true; not set at "
                      f"attestations{non_independent}")

    for i, att in enumerate(attestations):
        refs = att.get("reviewed_record_ids")
        if isinstance(refs, list) and refs:
            # Knowledge findings/literature live in ctx.knowledge (loaded
            # before check_goals), not ctx.ids. GOAL-* keeps the prefix
            # escape used when a goal id is mid-registration.
            unknown = [
                r for r in refs
                if r not in ctx.ids
                and r not in ctx.knowledge
                and not str(r).startswith("GOAL-")
            ]
            if unknown:
                ctx.err(path, f"completion_quorum.attestations[{i}] cites "
                              f"unknown record(s) {unknown}")


def load_goal_documents(ctx: Ctx):
    """Yield (path, goal, expected_basename) for both goal record layouts.

    FLAT:     ledger/goals/GOAL-X-001.yaml
    SHARDED:  ledger/goals/GOAL-X-001/goal.yaml
              ledger/goals/GOAL-X-001/checkpoints/BATCH-NNN.yaml   (write-once)

    The sharded layout exists because a goal record is the one ledger file that
    MANY campaigns write. GOAL-PATH-001 is edited by all eight of its children,
    and two coordinators appending different entries to one `batch_checkpoints`
    list conflict every single time -- a textual conflict in a place where there
    is no semantic conflict at all, since the entries are independent and
    append-only.

    One file per checkpoint is conflict-free by construction, which is the same
    move that fixed identifier collisions: stop requiring a writer to read shared
    state it does not need. Both layouts are supported and NOTHING IS MIGRATED
    AUTOMATICALLY -- a goal converts when its Coordinator next touches it, via
    tools/shard_goal.py. Migrating all of them at once would land a rename in
    every one of the open branches simultaneously.
    """
    goals_root = os.path.join(REPO, "ledger", "goals")
    try:
        entries = sorted(os.scandir(goals_root), key=lambda entry: entry.name)
    except OSError:
        entries = []

    for entry in entries:
        if (entry.is_symlink() or not entry.name.endswith(".yaml")
                or not entry.is_file(follow_symlinks=False)):
            continue
        path = entry.path
        doc = load_yaml(path, ctx)
        if doc is None:
            continue
        goal = doc.get("research_goal") if isinstance(doc, dict) else None
        if not isinstance(goal, dict):
            ctx.err(path, "missing top-level 'research_goal' mapping")
            continue
        yield path, goal, lambda rec_id: f"{rec_id}.yaml", os.path.basename(path)

    for entry in entries:
        if entry.is_symlink() or not entry.is_dir(follow_symlinks=False):
            continue
        path = os.path.join(entry.path, "goal.yaml")
        try:
            mode = os.lstat(path).st_mode
        except OSError:
            continue
        if not stat.S_ISREG(mode):
            continue
        doc = load_yaml(path, ctx)
        if doc is None:
            continue
        goal = doc.get("research_goal") if isinstance(doc, dict) else None
        if not isinstance(goal, dict):
            ctx.err(path, "missing top-level 'research_goal' mapping")
            continue
        directory = os.path.dirname(path)
        checkpoints = os.path.join(directory, "checkpoints")
        try:
            checkpoint_mode = os.lstat(checkpoints).st_mode
        except OSError:
            checkpoint_mode = 0
        if stat.S_ISDIR(checkpoint_mode):
            checkpoint_entries = sorted(
                os.scandir(checkpoints), key=lambda checkpoint: checkpoint.name
            )
        else:
            checkpoint_entries = []
        shards = [
            checkpoint.path
            for checkpoint in checkpoint_entries
            if (not checkpoint.is_symlink()
                and checkpoint.name.endswith(".yaml")
                and checkpoint.is_file(follow_symlinks=False))
        ]
        merged = []
        for shard in shards:
            sdoc = load_yaml(shard, ctx)
            if sdoc is None:
                continue
            entry = sdoc.get("batch_checkpoint") if isinstance(sdoc, dict) else None
            if not isinstance(entry, dict):
                ctx.err(shard, "missing top-level 'batch_checkpoint' mapping")
                continue
            merged.append(entry)
        if merged:
            existing = goal.get("batch_checkpoints") or []
            if not isinstance(existing, list):
                ctx.err(path, "batch_checkpoints must be a list")
                existing = []
            goal = dict(goal)
            goal["batch_checkpoints"] = list(existing) + merged
        yield path, goal, lambda rec_id: "goal.yaml", os.path.basename(directory)


GIT_CONTEXT_REDIRECTS = {
    "GIT_DIR", "GIT_WORK_TREE", "GIT_INDEX_FILE", "GIT_COMMON_DIR",
    "GIT_OBJECT_DIRECTORY", "GIT_ALTERNATE_OBJECT_DIRECTORIES",
    "GIT_REPLACE_REF_BASE", "GIT_NO_REPLACE_OBJECTS",
}


def _explicit_git_environment() -> dict[str, str]:
    """Environment stripped of caller-controlled repository redirects."""
    return {key: value for key, value in os.environ.items()
            if key not in GIT_CONTEXT_REDIRECTS}


def protected_prefix_git_errors() -> tuple[bool, list[tuple[str, str]]]:
    """Inspect bound HEAD and actual index without touching alias targets.

    Git stores ordinary directories only as descendant entries, while a
    gitlink or symlink occupies the exact protected path.  Keeping those cases
    separate prevents an initialized gitlink's ordinary-directory filesystem
    appearance from laundering mode 160000 into the ledger traversal.

    The boolean reports whether REPO is a Git worktree.  Non-Git fixtures retain
    the filesystem-only contract and make no Git provenance claim. Caller Git
    redirects are removed, then the discovered top-level, Git directory, and
    actual index are rebound explicitly for every metadata query. Protected
    provenance is always read with replacement-object processing disabled;
    neither default/custom replace refs nor caller environment may rewrite the
    commit or tree objects being classified.
    """
    git_marker = os.path.join(REPO, ".git")
    clean_env = _explicit_git_environment()
    try:
        probe = subprocess.run(
            ["git", "-C", REPO, "rev-parse", "--is-inside-work-tree"],
            capture_output=True, text=True, env=clean_env,
        )
    except OSError as error:
        if os.path.lexists(git_marker):
            return True, [("ledger", "cannot inspect protected-prefix Git "
                           f"metadata: {error}; target was not read")]
        return False, []
    if probe.returncode != 0 or probe.stdout.strip() != "true":
        if os.path.lexists(git_marker):
            detail = (probe.stderr or probe.stdout).strip().splitlines()
            reason = detail[-1] if detail else "Git worktree probe failed"
            return True, [("ledger", "cannot determine protected-prefix Git "
                           f"metadata: {reason}; target was not read")]
        return False, []

    context = subprocess.run(
        ["git", "-C", REPO, "rev-parse", "--show-toplevel",
         "--absolute-git-dir", "--path-format=absolute", "--git-path", "index"],
        capture_output=True, text=True, env=clean_env,
    )
    values = [line.strip() for line in context.stdout.splitlines() if line.strip()]
    if context.returncode != 0 or len(values) != 3:
        detail = (context.stderr or context.stdout).strip().splitlines()
        reason = detail[-1] if detail else "explicit Git context query failed"
        return True, [("ledger", "cannot bind protected-prefix Git metadata "
                                 f"to validation root: {reason}; target was not read")]
    top_level, git_directory, index_file = map(os.path.abspath, values)
    try:
        root_matches = os.path.samefile(top_level, REPO)
    except OSError:
        root_matches = (os.path.normcase(os.path.realpath(top_level))
                        == os.path.normcase(os.path.realpath(REPO)))
    if not root_matches:
        return True, [("ledger", "protected-prefix Git top-level does not match "
                                 "the explicit validation root; target was not read")]
    if not os.path.isdir(git_directory) or not os.path.isfile(index_file):
        return True, [("ledger", "protected-prefix actual Git directory or "
                                 "index is unavailable; target was not read")]

    bound_env = dict(clean_env)
    bound_env["GIT_INDEX_FILE"] = index_file
    # Belt and suspenders: the global option binds the individual invocation,
    # while the environment also covers Git versions/subcommands that consult
    # the conventional replacement-disable switch internally.  Caller values
    # were removed above and cannot re-enable replacement processing.
    bound_env["GIT_NO_REPLACE_OBJECTS"] = "1"

    def bound_git(*arguments: str) -> subprocess.CompletedProcess:
        return subprocess.run(
            ["git", "--no-replace-objects", f"--git-dir={git_directory}",
             f"--work-tree={REPO}", *arguments],
            capture_output=True, text=True, env=bound_env,
        )

    errors: list[tuple[str, str]] = []
    for relative in ("ledger", "ledger/goals"):
        head = bound_git("ls-tree", "-z", "HEAD", "--", relative)
        index = bound_git("ls-files", "--stage", "-z", "--", relative)
        if head.returncode != 0 or index.returncode != 0:
            failed = head if head.returncode != 0 else index
            detail = (failed.stderr or failed.stdout).strip().splitlines()
            reason = detail[-1] if detail else "HEAD or index query failed"
            errors.append((relative, "cannot determine protected-prefix Git "
                                     f"metadata: {reason}; target was not read"))
            break

        head_modes: list[str] = []
        for entry in head.stdout.split("\0"):
            if not entry or "\t" not in entry:
                continue
            metadata, candidate = entry.split("\t", 1)
            if candidate == relative:
                head_modes.append(metadata.split(" ", 1)[0])

        exact_modes: list[str] = []
        descendant_count = 0
        for entry in index.stdout.split("\0"):
            if not entry or "\t" not in entry:
                continue
            metadata, candidate = entry.split("\t", 1)
            mode = metadata.split(" ", 1)[0]
            if candidate == relative:
                exact_modes.append(mode)
            elif candidate.startswith(relative + "/"):
                descendant_count += 1

        for source, modes_found in (("Git HEAD tree", head_modes),
                                    ("Git index", exact_modes)):
            modes = sorted(set(modes_found))
            if modes == ["040000"] and source == "Git HEAD tree":
                continue
            if not modes and source == "Git index" and descendant_count:
                continue
            if not modes:
                errors.append((
                    relative,
                    f"trusted goal prefix is missing from {source}; protected "
                    "candidate state is indeterminate and target was not read",
                ))
                break
            description = (
                "gitlink" if modes == ["160000"] else
                "symlink" if modes == ["120000"] else
                "regular file" if modes == ["100644"] else
                "non-directory object"
            )
            if description in {"gitlink", "symlink"}:
                finding = f"an exact {source} {description}"
            else:
                finding = f"{description}; exact {source} object"
            errors.append((
                relative,
                f"trusted goal prefix is {finding} "
                f"with mode(s) {modes}; ordinary tracked descendants are "
                "required and target was not read",
            ))
            break
        if errors:
            break
        if descendant_count == 0:
            errors.append((
                relative,
                "trusted goal prefix is missing; Git index has neither an "
                "exact entry nor ordinary tracked descendants, so candidate "
                "type is indeterminate and target was not read",
            ))
            break
    return True, errors


def check_trusted_goal_prefixes(ctx: Ctx) -> bool:
    """Require ordinary ledger and ledger/goals directories without follow."""
    in_git_worktree, git_errors = protected_prefix_git_errors()
    if in_git_worktree and git_errors:
        for relative, message in git_errors:
            ctx.err(os.path.join(REPO, *relative.split("/")), message, force=True)
        return False

    for relative in ("ledger", "ledger/goals"):
        path = os.path.join(REPO, *relative.split("/"))
        try:
            mode = os.lstat(path).st_mode
        except OSError:
            description = "missing"
        else:
            if stat.S_ISLNK(mode):
                description = "symlink"
            elif stat.S_ISDIR(mode):
                continue
            elif stat.S_ISREG(mode):
                description = "regular file"
            else:
                description = "special file"
        ctx.err(path, f"trusted goal prefix is {description}; required ordinary "
                      "directory and target was not read", force=True)
        return False
    return True


def check_goal_symlinks(ctx: Ctx) -> None:
    """Reject goal-tree symlinks without opening or traversing their targets."""
    root = os.path.join(REPO, "ledger", "goals")
    try:
        root_mode = os.lstat(root).st_mode
    except OSError:
        return
    if not stat.S_ISDIR(root_mode):
        return
    pending = [root]
    while pending:
        current = pending.pop()
        try:
            entries = sorted(os.scandir(current), key=lambda entry: entry.name)
        except OSError:
            continue
        for entry in entries:
            if entry.is_symlink():
                ctx.err(entry.path,
                        "goal path may not be a symlink; target was not read",
                        force=True)
            elif entry.is_dir(follow_symlinks=False):
                pending.append(entry.path)


# ECC goals have an UNLIMITED campaign budget, on user instruction
# (2026-09-04). The area set and the field list are declared once, in
# orchestration/research-priority.yaml, and read through tools/ecc_priority.py
# -- never re-derived here and never inferred from an identifier prefix.
#
# Only `active` and `draft` goals are checked. A terminal goal's budget is
# history; rewriting it would be a retroactive edit of a closed campaign, not a
# policy fix.
#
# What unlimited does NOT mean: `max_concurrent` stays bounded (it is machine
# headroom, not a research budget), and removing the batch ceiling does not
# remove the duty to rank -- never dispatch a task you cannot rank ahead of
# doing nothing.
def check_ecc_budget_is_unlimited(path, goal, status, ctx: Ctx):
    if status not in ("active", "draft"):
        return
    try:
        sys.path.insert(0, os.path.dirname(os.path.abspath(__file__)))
        import ecc_priority
        policy = ecc_priority.load_policy()
    except Exception:
        return                       # policy absent or unreadable: not a ledger error
    if not (policy.get("budget") or {}).get("ecc_unlimited"):
        return
    gid = str(goal.get("id") or "")
    if not ecc_priority.is_ecc(gid, policy):
        return
    budget = goal.get("campaign_budget")
    if not isinstance(budget, dict):
        return
    for field in ecc_priority.unbounded_fields(policy):
        value = budget.get(field)
        if value is not None:
            ctx.err(path,
                    f"ECC goal {gid} must have an unlimited campaign budget: "
                    f"campaign_budget.{field} is {value!r}, must be null "
                    f"(orchestration/research-priority.yaml)")


# Frozen closures already present when the 2026-09-06 policy was adopted.
# Never add future closures to this compatibility set.
PRE_STAGNATION_BUDGET_CLOSURES = {
    "GOAL-MLKEM-001", "GOAL-MLKEM-003", "GOAL-MLKEM-004",
    "GOAL-P13-001", "GOAL-ECQ-002",
}


def check_budget_retirement(path, goal, ctx):
    if goal.get("status") != "closed_at_budget" or goal.get("id") in PRE_STAGNATION_BUDGET_CLOSURES:
        return
    sys.path.insert(0, REPO)
    from orchestration.research_budget import enforce_research_budget
    from datetime import date
    budget = goal.get("campaign_budget") or {}
    try:
        # Historical closures remain verifiable after their review expires.
        # The restriction must have been current at the recorded closure date.
        closed_at = date.fromisoformat(goal.get("closed_at", ""))
        if closed_at > date.today():
            raise ValueError("budget closure cannot be future-dated")
        if not enforce_research_budget(budget, today=closed_at, repo_root=REPO, target_id=goal.get("id")):
            raise ValueError("advisory estimates cannot retire a research goal")
    except (ValueError, TypeError) as exc:
        ctx.err(path, f"budget retirement requires a 90-day stagnation review: {exc}")


def check_goals(ctx: Ctx):
    if not check_trusted_goal_prefixes(ctx):
        return
    check_goal_symlinks(ctx)
    for path, goal, expected_name, identity in load_goal_documents(ctx):
        rec_id = goal.get("id")
        if not rec_id or not GOAL_ID.match(str(rec_id)):
            ctx.err(path, f"invalid goal id {rec_id!r}")
        else:
            if os.path.basename(path) != expected_name(rec_id):
                ctx.err(path, f"filename must match id ({expected_name(rec_id)})")
            if identity != str(rec_id) and identity != f"{rec_id}.yaml":
                ctx.err(path, f"goal directory must be named {rec_id}")
            ctx.register(str(rec_id), path, goal, "research_goal")

        grandfathered = str(rec_id) in PRE_QUORUM_GOAL_IDS

        if not grandfathered:
            for field in GOAL_REQUIRED:
                if goal.get(field) in (None, ""):
                    ctx.err(path, f"missing required field '{field}'")

        status = str(goal.get("status", "")).strip()
        if status in GOAL_STATUSES_REFUSED:
            ctx.err(path, f"status {status!r} is not permitted: "
                          f"{GOAL_STATUSES_REFUSED[status]}")
        elif status and status not in GOAL_STATUSES:
            ctx.err(path, f"invalid status {status!r}")

        check_ecc_budget_is_unlimited(path, goal, status, ctx)
        check_budget_retirement(path, goal, ctx)

        if status == "completed" and not grandfathered:
            check_goal_closure_quorum(path, goal, ctx)
        elif isinstance(goal.get("completion_quorum"), dict):
            # Attestations may be gathered before the transition; they simply
            # must not be mistaken for a closure that has not happened.
            quorum = goal["completion_quorum"]
            if quorum.get("quorum_satisfied") is True and status != "completed":
                ctx.err(path, "completion_quorum.quorum_satisfied is true but "
                              f"status is {status!r}; only a Coordinator "
                              "ledger archive may perform the transition")


# ---------------------------------------------------------------------------
# Portfolio hygiene (docs/track-record-review-20261006.md).
#
# One hard rule and three advisories. The hard rule is DATE-GATED on the
# record's own id or designed_at so that no immutable record predating them
# can fail (the baseline is prune-only, so a rule that failed history could
# never land). The advisories go to ctx.advisories, which never fails the
# build: they exist so that the backlog is visible at every validation,
# not so that history is re-litigated.

# A specification designed on or after this date must say, before any run,
# what each outcome changes. A contract whose success and falsification
# criteria are the same sentence, or whose outcome is already written into
# the record, is a spec written to the answer (review finding F-2).
OUTCOME_RULE_ENFORCED_FROM = "2026-10-07"
DECISION_IMPACT_KEYS = ("on_positive", "on_negative")
PREWRITTEN_OUTCOME_KEYS = ("outcome", "result", "observed_result",
                           "conclusion", "verdict")

# Advisory caps. A goal head past GOAL_HEAD_CAP_BYTES is read in full at every
# wake by every session that touches the goal; next_action past
# NEXT_ACTION_CAP_CHARS is a plan, not a pointer. Ideas past IDEA_CAP_BYTES
# (new ones only) cost more to design than they save.
GOAL_HEAD_CAP_BYTES = 64 * 1024
NEXT_ACTION_CAP_CHARS = 1000
IDEA_CAP_BYTES = 8 * 1024
IDEA_CAP_ENFORCED_FROM = "20261007"
AGED_HANDOFF_DAYS = 14

# Ceremony (review item P1.9). 2,708 records carry an `amazon_bedrock:`
# attestation that no template asked for and no check reads: the offline guard
# in orchestration/adapter enforces core rule 16, and a field saying "NOT
# USED" proves nothing a reader can verify. Null `budget.*` placeholders and
# all-caps prose in next_action are the same habit. All three are advisories
# on records minted on or after the date; history keeps its ceremony.
CEREMONY_ENFORCED_FROM = "20261007"
CEREMONY_KEY_PREFIXES = ("amazon_bedrock",)
# Words of four or more capitals that are not identifiers (no digit, hyphen or
# underscore). Five of them in one next_action is shouting, not pointing.
_SHOUT_WORD = re.compile(r"(?<![\w-])[A-Z]{4,}(?![\w-])")
SHOUT_WORDS_CAP = 5

_ID_DATE = re.compile(r"-(\d{8})-")


def _id_date(rec_id: str) -> str | None:
    match = _ID_DATE.search(str(rec_id or ""))
    return match.group(1) if match else None


def check_outcome_not_prewritten(path: str, body: dict, ctx: Ctx) -> None:
    """P0.5: a new contract declares what each outcome changes and no outcome."""
    designed = str(body.get("designed_at") or "")[:10]
    if not designed or designed < OUTCOME_RULE_ENFORCED_FROM:
        return
    for key in PREWRITTEN_OUTCOME_KEYS:
        if body.get(key) not in (None, "", [], {}):
            ctx.err(path, f"specification carries '{key}' before any run; an "
                          "outcome belongs in a run record or evidence, never "
                          "in the contract")
    success = str(body.get("success_criterion") or "").strip()
    falsify = str(body.get("falsification_criterion") or "").strip()
    if success and falsify and success.lower() == falsify.lower():
        ctx.err(path, "success_criterion and falsification_criterion are the "
                      "same text; a contract that cannot fail decides nothing")
    impact = body.get("decision_impact")
    if not isinstance(impact, dict):
        ctx.err(path, "missing 'decision_impact' (on_positive/on_negative): "
                      "say before the run what each outcome changes")
        return
    for key in DECISION_IMPACT_KEYS:
        if not str(impact.get(key) or "").strip():
            ctx.err(path, f"decision_impact.{key} is empty")
    pos = str(impact.get("on_positive") or "").strip().lower()
    neg = str(impact.get("on_negative") or "").strip().lower()
    if pos and pos == neg:
        ctx.err(path, "decision_impact.on_positive equals on_negative; the "
                      "experiment then changes nothing either way")


# ---- confound control (docs/confound-control.md) ---------------------------
# A contract says how each factor that could move a primary metric is
# controlled (variable_ledger), what data each prediction was written after
# (prediction_provenance) and, when a claim crosses a map, what the map
# preserves and which controls isolate it (transfer_obligations). Shape is
# checked on any contract that carries a block, whatever its date; the blocks
# are required from CONFOUND_RULE_ENFORCED_FROM on (an error on an approved
# contract, an advisory on a draft), so no frozen record can fail.
CONFOUND_RULE_ENFORCED_FROM = "2026-10-18"
LEDGER_TREATMENTS = {"fixed", "randomized", "crossed", "measured"}
COMPARISON_DESIGNS = {"one_factor", "factorial", "confounded", "aa", "absolute"}
SAMPLE_STATUSES = {"out_of_sample", "partially_in_sample", "in_sample"}
TRANSFER_KINDS = {"isogeny", "cover", "descent", "lift", "field_extension",
                  "restriction_of_scalars", "isomorphism", "coordinate_change",
                  "other"}
TRANSFER_CONTROL_KINDS = {"source_baseline", "coordinate_isomorphism",
                          "matched_random", "reselected_data", "identity_map",
                          "null"}
CONFOUND_VERDICTS = {"isolated", "randomized", "not_isolated"}
CAPPED_STRENGTHS = {"replicated", "strong"}


def _mentions(text: str, ident: str) -> bool:
    return bool(re.search(rf"(?<![\w-]){re.escape(ident)}(?![\w-])", text))


def _names(items) -> list[str]:
    return [str(i.get("name")) for i in items
            if isinstance(i, dict) and i.get("name")]


def check_confound_control(path: str, body: dict, ctx: Ctx) -> None:
    """Variable ledger, prediction provenance and transfer obligations."""
    keys = ("variable_ledger", "prediction_provenance", "transfer_obligations")
    present = [k for k in keys if body.get(k) is not None]
    designed = str(body.get("designed_at") or "")[:10]
    if designed and designed >= CONFOUND_RULE_ENFORCED_FROM:
        for key in keys[:2]:
            if body.get(key) is not None:
                continue
            msg = (f"missing '{key}' (docs/confound-control.md); required for "
                   f"contracts designed from {CONFOUND_RULE_ENFORCED_FROM} on")
            if body.get("status") == "approved":
                ctx.err(path, msg)
            else:
                ctx.advise(path, msg)
    if not present:
        return
    decisive_text = " ".join(str(body.get(k) or "") for k in
                             ("success_criterion", "falsification_criterion"))
    comparisons: dict[str, dict] = {}
    ledger = body.get("variable_ledger")
    if ledger is not None:
        if not isinstance(ledger, dict):
            ctx.err(path, "variable_ledger must be a mapping")
            ledger = {}
        indep = ledger.get("independent")
        factors = ledger.get("factors")
        if not isinstance(indep, list) or not _names(indep):
            ctx.err(path, "variable_ledger.independent must list the variables "
                          "under test by name")
            indep = []
        if not isinstance(factors, list) or not _names(factors):
            ctx.err(path, "variable_ledger.factors must list every factor that "
                          "could move a primary metric")
            factors = []
        treatment = {}
        for i, f in enumerate(factors):
            if not isinstance(f, dict):
                ctx.err(path, f"variable_ledger.factors[{i}] must be a mapping")
                continue
            t = f.get("treatment")
            if t not in LEDGER_TREATMENTS:
                ctx.err(path, f"variable_ledger.factors[{i}] ({f.get('name')}) "
                              f"treatment must be one of {sorted(LEDGER_TREATMENTS)}")
            if not str(f.get("how") or "").strip():
                ctx.err(path, f"variable_ledger.factors[{i}] ({f.get('name')}) "
                              "needs 'how': the mechanism that holds or draws it")
            treatment[str(f.get("name"))] = t
        known = set(_names(indep)) | set(treatment)
        comps = ledger.get("comparisons")
        if not isinstance(comps, list) or not comps:
            ctx.err(path, "variable_ledger.comparisons must list each comparison "
                          "a criterion or a prediction rests on")
            comps = []
        for i, c in enumerate(comps):
            where = f"variable_ledger.comparisons[{i}]"
            if not isinstance(c, dict) or not c.get("id"):
                ctx.err(path, f"{where} must be a mapping with an 'id'")
                continue
            cid, design = str(c["id"]), c.get("design")
            comparisons[cid] = c
            differs = c.get("differs_in")
            if not isinstance(c.get("arms"), list) or not c.get("arms"):
                ctx.err(path, f"{where} ({cid}) must name its arms")
            if not isinstance(differs, list):
                ctx.err(path, f"{where} ({cid}) differs_in must be a list")
                differs = []
            for name in differs:
                if str(name) not in known:
                    ctx.err(path, f"{where} ({cid}) differs_in '{name}' is "
                                  "neither an independent variable nor a "
                                  "listed factor")
            if design not in COMPARISON_DESIGNS:
                ctx.err(path, f"{where} ({cid}) design must be one of "
                              f"{sorted(COMPARISON_DESIGNS)}")
            elif design == "one_factor" and len(differs) != 1:
                ctx.err(path, f"{where} ({cid}) is one_factor but differs in "
                              f"{len(differs)} factors")
            elif design == "absolute" and differs:
                ctx.err(path, f"{where} ({cid}) is absolute (one arm against a "
                              "stated threshold) but lists differs_in")
            elif design == "factorial":
                bad = [n for n in differs if str(n) in treatment
                       and treatment[str(n)] != "crossed"]
                if len(differs) < 2 or bad:
                    ctx.err(path, f"{where} ({cid}) is factorial: it must vary "
                                  "two or more factors, each independent or "
                                  "'crossed'")
            elif design == "aa":
                bad = [n for n in differs if str(n) in set(_names(indep))]
                if bad or len(differs) != 1:
                    ctx.err(path, f"{where} ({cid}) is an A/A comparison: it "
                                  "must differ in exactly one nuisance factor, "
                                  "never in a variable under test")
            elif design == "confounded" and not str(c.get("reason") or "").strip():
                ctx.err(path, f"{where} ({cid}) is confounded and needs 'reason'")
            if design == "confounded" and _mentions(decisive_text, cid):
                ctx.err(path, f"comparison {cid} is confounded but a success or "
                              "falsification criterion cites it; criteria rest "
                              "on one_factor, factorial and absolute comparisons "
                              "and may cite an aa comparison only as the noise "
                              "floor")
        if not any(c.get("design") == "aa" for c in comparisons.values()) \
                and not str(ledger.get("aa_not_applicable") or "").strip():
            ctx.err(path, "variable_ledger needs an A/A comparison (design: aa) "
                          "or an 'aa_not_applicable' reason")
        crosses = ledger.get("crosses_map")
        if not isinstance(crosses, bool):
            ctx.err(path, "variable_ledger.crosses_map must be true or false: "
                          "does any claim move the problem across a map?")
        elif crosses and body.get("transfer_obligations") is None:
            ctx.err(path, "variable_ledger.crosses_map is true; "
                          "transfer_obligations is required")
    prov = body.get("prediction_provenance")
    if prov is not None:
        if not isinstance(prov, list) or not prov:
            ctx.err(path, "prediction_provenance must be a nonempty list")
            prov = []
        covered = set()
        for i, p in enumerate(prov):
            where = f"prediction_provenance[{i}]"
            if not isinstance(p, dict) or not p.get("prediction"):
                ctx.err(path, f"{where} must be a mapping naming its prediction")
                continue
            pid = str(p["prediction"])
            covered.add(pid)
            src = str(p.get("first_recorded_in") or "")
            if not src or not os.path.exists(os.path.join(REPO, src)):
                ctx.err(path, f"{where} ({pid}) first_recorded_in must be an "
                              "existing repository path")
            if not str(p.get("written_at") or "").strip():
                ctx.err(path, f"{where} ({pid}) needs written_at")
            if not isinstance(p.get("data_seen"), list):
                ctx.err(path, f"{where} ({pid}) data_seen must be a list "
                              "([] when nothing was consulted)")
            status = p.get("sample_status")
            if status not in SAMPLE_STATUSES:
                ctx.err(path, f"{where} ({pid}) sample_status must be one of "
                              f"{sorted(SAMPLE_STATUSES)}")
            elif status == "in_sample" and _mentions(decisive_text, pid):
                ctx.err(path, f"prediction {pid} is in_sample but a success or "
                              "falsification criterion cites it; it can only "
                              "calibrate an instrument")
            elif status == "partially_in_sample" and \
                    not str(p.get("decisive_scope") or "").strip():
                ctx.err(path, f"{where} ({pid}) is partially_in_sample and needs "
                              "'decisive_scope': the cells that do not overlap")
        listed = body.get("preregistered_predictions")
        if isinstance(listed, list):
            for item in listed:
                pid = item.get("id") if isinstance(item, dict) else None
                if pid and str(pid) not in covered:
                    ctx.err(path, f"preregistered prediction {pid} has no "
                                  "prediction_provenance entry")
    transfers = body.get("transfer_obligations")
    if transfers is not None:
        if not isinstance(transfers, list) or not transfers:
            ctx.err(path, "transfer_obligations must be a nonempty list of maps")
            transfers = []
        for i, t in enumerate(transfers):
            where = f"transfer_obligations[{i}]"
            if not isinstance(t, dict):
                ctx.err(path, f"{where} must be a mapping")
                continue
            if t.get("kind") not in TRANSFER_KINDS:
                ctx.err(path, f"{where} kind must be one of {sorted(TRANSFER_KINDS)}")
            for key in ("map", "source", "destination"):
                if not str(t.get(key) or "").strip():
                    ctx.err(path, f"{where} needs '{key}'")
            for key in ("preserves", "changes"):
                if not isinstance(t.get(key), list) or not t.get(key):
                    ctx.err(path, f"{where} '{key}' must list what the map "
                                  f"{key[:-1]}s")
            kinds = set()
            for j, c in enumerate(t.get("controls") or []):
                if not isinstance(c, dict) or c.get("kind") not in TRANSFER_CONTROL_KINDS:
                    ctx.err(path, f"{where}.controls[{j}] kind must be one of "
                                  f"{sorted(TRANSFER_CONTROL_KINDS)}")
                    continue
                kinds.add(c["kind"])
                if comparisons and str(c.get("comparison")) not in comparisons:
                    ctx.err(path, f"{where}.controls[{j}] comparison "
                                  f"'{c.get('comparison')}' is not in the "
                                  "variable ledger")
            if not kinds & {"coordinate_isomorphism", "identity_map"}:
                ctx.err(path, f"{where} needs a coordinate_isomorphism or "
                              "identity_map control (transfer methodology, "
                              "controls item 3)")
            if "matched_random" not in kinds:
                ctx.err(path, f"{where} needs a matched_random control "
                              "(transfer methodology, controls item 4)")
            assessment = str(t.get("assessment") or "")
            if not assessment or not os.path.exists(os.path.join(REPO, assessment)):
                ctx.err(path, f"{where} assessment must be an existing transfer "
                              "assessment file (.claude/skills/transfer)")


def check_confound_assessments(ctx: Ctx) -> None:
    """Review gate: evidence on a ledgered experiment grades each comparison."""
    for rec_id, kind in ctx.record_types.items():
        if kind != "evidence":
            continue
        body, path = ctx.records[rec_id], ctx.ids[rec_id]
        ledgered = []
        for exp_id in body.get("experiment_ids") or []:
            exp = ctx.records.get(str(exp_id)) or {}
            ledger = exp.get("variable_ledger")
            if isinstance(ledger, dict):
                ledgered += [str(c.get("id")) for c in ledger.get("comparisons") or []
                             if isinstance(c, dict) and c.get("id")]
        if not ledgered:
            continue
        rows = body.get("confound_assessment")
        if not isinstance(rows, list):
            ctx.err(path, "confound_assessment is required: grade each "
                          f"comparison of the variable ledger ({', '.join(ledgered)})")
            continue
        graded = {}
        for i, r in enumerate(rows):
            if not isinstance(r, dict) or r.get("verdict") not in CONFOUND_VERDICTS \
                    or not str(r.get("basis") or "").strip():
                ctx.err(path, f"confound_assessment[{i}] needs a comparison, a "
                              f"verdict in {sorted(CONFOUND_VERDICTS)} and a basis")
                continue
            graded[str(r.get("comparison"))] = r["verdict"]
        for cid in ledgered:
            if cid not in graded:
                ctx.err(path, f"confound_assessment does not grade comparison {cid}")
        if "not_isolated" in graded.values() and body.get("strength") in CAPPED_STRENGTHS:
            ctx.err(path, "a comparison is graded not_isolated, so strength is "
                          "capped at preliminary (docs/confound-control.md)")


def check_record_sizes(ctx: Ctx) -> None:
    """P1.7 / P1.10 advisories: oversized goal heads, next_action, new ideas."""
    for rec_id, kind in ctx.record_types.items():
        path = ctx.ids[rec_id]
        if kind == "research_goal":
            try:
                size = os.path.getsize(path)
            except OSError:
                continue
            if size > GOAL_HEAD_CAP_BYTES:
                ctx.advise(path, f"goal head is {size // 1024} KiB (cap "
                                 f"{GOAL_HEAD_CAP_BYTES // 1024} KiB); move "
                                 "history to checkpoints or docs and keep a "
                                 "pointer")
            action = ctx.records[rec_id].get("next_action")
            length = len(str(action or ""))
            if length > NEXT_ACTION_CAP_CHARS:
                ctx.advise(path, f"next_action is {length} chars (cap "
                                 f"{NEXT_ACTION_CAP_CHARS}); a next action is "
                                 "a pointer to a task, not a plan")
        elif kind == "idea":
            when = _id_date(rec_id)
            if when is None or when < IDEA_CAP_ENFORCED_FROM:
                continue
            try:
                size = os.path.getsize(path)
            except OSError:
                continue
            if size > IDEA_CAP_BYTES:
                ctx.advise(path, f"proposal is {size // 1024} KiB (cap "
                                 f"{IDEA_CAP_BYTES // 1024} KiB); split it or "
                                 "move supporting material to knowledge/")


def _ceremony_keys(body: dict) -> list[str]:
    return sorted(k for k in body
                  if str(k).lower().startswith(CEREMONY_KEY_PREFIXES))


def check_ceremony(ctx: Ctx) -> None:
    """P1.9 advisories: attestation fields, null budgets, shouted next_action."""
    for rec_id, kind in ctx.record_types.items():
        body = ctx.records[rec_id]
        path = ctx.ids[rec_id]
        if kind == "research_goal":
            action = str(body.get("next_action") or "")
            shouted = _SHOUT_WORD.findall(action)
            if len(shouted) > SHOUT_WORDS_CAP:
                ctx.advise(path, f"next_action has {len(shouted)} all-caps words "
                                 f"({', '.join(sorted(set(shouted))[:4])}, ...); "
                                 "emphasis is not instruction, write it plainly")
            continue
        if kind not in ("handoff", "coordinator_decision"):
            continue
        when = _id_date(rec_id)
        if when is None or when < CEREMONY_ENFORCED_FROM:
            continue
        for key in _ceremony_keys(body):
            ctx.advise(path, f"'{key}' is an attestation nothing reads; the "
                             "adapter's offline guard enforces rule 16, drop "
                             "the field")
        if kind == "handoff":
            budget = body.get("budget")
            if isinstance(budget, dict) and budget and all(
                    v is None for v in budget.values()):
                ctx.advise(path, "budget holds only null placeholders; write "
                                 "`budget: {}` and add a limit when you set "
                                 "one")


def check_aged_handoffs(ctx: Ctx, today: str | None = None) -> None:
    """P3.17 advisory: dispatched handoffs with no return past AGED_HANDOFF_DAYS."""
    import datetime as _dt
    now = (_dt.datetime.strptime(today, "%Y%m%d").date() if today
           else _dt.date.today())
    for rec_id, kind in ctx.record_types.items():
        if kind != "handoff" or ctx.records[rec_id].get("archived_by"):
            continue
        when = _id_date(rec_id)
        if when is None:
            continue
        try:
            age = (now - _dt.datetime.strptime(when, "%Y%m%d").date()).days
        except ValueError:
            continue
        if age > AGED_HANDOFF_DAYS:
            ctx.advise(ctx.ids[rec_id], f"handoff dispatched {age} days ago has "
                                        "no archived_by; record its return or "
                                        "a correction closing it")


def check_knowledge_index(ctx: Ctx):
    # --verify-corpus, not --check. INDEX.md is generated and no longer
    # committed (see build_knowledge_index.py), so there is no file to be stale
    # against. What this check has always actually caught is the BUILDER
    # CRASHING on a corrupt corpus, and building the index and discarding it
    # catches that identically.
    rc = subprocess.run(
        [sys.executable, os.path.join(REPO, "tools", "build_knowledge_index.py"),
         "--verify-corpus"],
        capture_output=True, text=True)
    if rc.returncode != 0:
        msg = (rc.stderr or rc.stdout).strip() or "knowledge corpus does not build"
        # Take the LAST line, not the first. When the index builder raises,
        # the first line is "Traceback (most recent call last):" -- which is
        # both uninformative and, worse, IDENTICAL for every possible cause.
        # CI diffs error sets between head and base, so an unchanging string
        # cancels out and the failure is invisible. That is how a builder
        # crashing on committed conflict markers went unreported. The last
        # line carries the actual exception.
        lines = [ln.strip() for ln in msg.splitlines() if ln.strip()]
        detail = lines[-1] if lines else "knowledge/INDEX.md is stale"
        ctx.errors.append(f"knowledge/INDEX.md: build_knowledge_index.py "
                          f"failed: {detail}")


BASELINE_HEADER = """\
# Grandfathered validation errors — legacy records that predate the
# validator, plus one documented re-anchoring. Each line matches one error
# exactly as validate_ledger.py reports it.
#
# INVARIANT: lines may only ever be REMOVED (as records are repaired or
# superseded); never add a line to absorb a new violation. Prune stale
# lines with: python3 tools/validate_ledger.py --update-baseline
#
# RE-ANCHOR 2026-08-02, authorized by DEC-20260802-008 as amended by
# DEC-20260802-009 and DEC-20260802-010, and recorded as a protocol_amendment
# there. This file was regenerated once, growing from 1138 to 2246 entries.
# The 1108 added entries are the SET difference against the pre-image, not a
# subtraction: the validator reported 1110 lines, but EV-SIG-008 cites
# RUN-EXP-SIG-008-q and -r twice each and a baseline is a set, so two
# identical lines collapse. Pre-existing debt in these categories only:
#   680 pre-current-schema run manifests (missing required field, missing
#       companion artifact, missing code.commit/code.command, invalid
#       certificate.kind) — repair blocked by tools/check_run_immutability.py
#   235 run IDs shared across EXP-FCP-001/EXP-FCP-002/EXP-IC-001 — same
#       block; disclosed in tools/duplicate_run_ids.yaml, which must not grow
#    69 evidence and decision records citing runs or experiments that do not
#       register in this repository — disclosed on each affected record
#    35 evidence records missing direction/strength — disclosed in
#       ledger/registers/unevidenced-records.yaml; none may support a
#       hypothesis transition until reviewed
#    82 knowledge frontmatter pending /curate-knowledge
#     5 ID area tokens containing digits (RQ/H/EXP-PMA4-001, H/EV-P13-001).
#       Four report "ID ... does not match ... format"; EXP-PMA4-001 reports
#       "bad experiment id" instead, because check_experiment returns early on
#       a malformed id rather than continuing like check_ledger_record. Same
#       defect, different message, so a message-shaped count splits the
#       category away from the five records this line names.
#       These records register and all cross-references resolve; renaming
#       was refused on cost/risk grounds. The ID patterns were NOT widened,
#       so a new non-conforming ID still fails.
#     2 records outside the current schema vocabulary: EV-P13-001's
#       conditional_on_heuristic proof_status (more precise than the schema
#       admits) and EXP-MLKEM-004's null approved_by (unfillable without
#       asserting an approval event no record establishes).
# No mechanically repairable line was absorbed. Lines naming a record moved by
# the DEC-20260802-001 relocation were admitted only where the identical
# message appears in tools/prerelocation_error_snapshot.txt under that
# record's pre-relocation path — a set-membership test, not a judgement.
# The full debt stays inspectable with --no-baseline. The only-ever-removed
# invariant resumes from this point: a later addition is a contract violation,
# not a second re-anchoring.
"""


def load_baseline(path: str) -> set[str]:
    if not os.path.exists(path):
        return set()
    with open(path, encoding="utf-8") as fh:
        return {ln.rstrip("\n") for ln in fh
                if ln.strip() and not ln.lstrip().startswith("#")}


def write_baseline(entries: set[str]) -> None:
    with open(BASELINE_PATH, "w", encoding="utf-8") as fh:
        fh.write(BASELINE_HEADER)
        for e in sorted(entries):
            fh.write(e + "\n")


def main() -> int:
    ap = argparse.ArgumentParser(
        description="Validate the research ledger, experiments, and runs.")
    ap.add_argument("--no-baseline", action="store_true",
                    help="fail on every error, including grandfathered ones")
    ap.add_argument("--update-baseline", action="store_true",
                    help="prune baseline entries that no longer occur "
                         "(bootstraps the full set only if no baseline "
                         "file exists; never grows an existing one)")
    ap.add_argument("--advisories", action="store_true",
                    help="list every non-failing advisory (oversized goal "
                         "heads and proposals, aged open handoffs)")
    args = ap.parse_args()
    sys.path.insert(0, os.path.dirname(os.path.abspath(__file__)))
    try:
        import sparse_checkout
    except ImportError:  # a standalone copy (tools/test_goal_id_random_suffix.py)
        sparse_checkout = None
    if sparse_checkout and sparse_checkout.refuse_if_sparse("validate_ledger", Path(REPO)):
        return 2

    # This must precede every inventory, glob, supersession, and record read.
    # If ledger itself is an alias, even an apparently unrelated ledger glob
    # would otherwise escape the candidate tree before check_goals runs.
    prefix_ctx = Ctx(set())
    if not check_trusted_goal_prefixes(prefix_ctx):
        print(f"FAIL: {len(prefix_ctx.errors)} new validation error(s):\n",
              file=sys.stderr)
        for error in prefix_ctx.errors:
            print(f"  - {error}", file=sys.stderr)
        return 1

    try:
        legacy_inventory = load_legacy_inventory()
        legacy_id_remaps = load_legacy_id_remaps()
        legacy_run_inventory = load_legacy_run_inventory()
    except (OSError, ValueError) as error:
        print(f"FAIL: cannot load legacy inventory: {error}",
              file=sys.stderr)
        return 1
    try:
        run_supersessions = load_run_supersessions()
    except (OSError, ValueError, yaml.YAMLError) as error:
        print(f"FAIL: cannot load run supersession registry: {error}",
              file=sys.stderr)
        return 1
    try:
        schema_supersessions = load_schema_supersessions()
    except (OSError, ValueError, yaml.YAMLError) as error:
        print(f"FAIL: cannot load schema supersession registry: {error}",
              file=sys.stderr)
        return 1
    legacy_paths = {os.path.abspath(os.path.join(REPO, path))
                    for path in (*legacy_inventory, *legacy_run_inventory)}
    absolute_remaps = {
        os.path.abspath(os.path.join(REPO, path)): target
        for path, target in legacy_id_remaps.items()
    }
    ctx = Ctx(legacy_paths, absolute_remaps, schema_supersessions)
    check_schema_supersessions(ctx, schema_supersessions)
    check_legacy_ledger(ctx, legacy_inventory)
    for sub, rec_type in LEDGER_DIRS.items():
        for path in sorted(glob.glob(os.path.join(REPO, "ledger", sub, "*.yaml"))):
            check_ledger_record(path, rec_type, ctx)
    for path in sorted(glob.glob(os.path.join(REPO, "experiments", "*",
                                              "specification.yaml"))):
        check_experiment(path, ctx)
    check_legacy_run_inventory(ctx, legacy_run_inventory)
    register_legacy_json_runs(ctx, legacy_run_inventory)
    check_run_supersessions(ctx, run_supersessions)
    for path in sorted(glob.glob(os.path.join(REPO, "experiments", "*", "runs",
                                              "*", "manifest.yaml"))):
        check_run(path, ctx, run_supersessions)
    # A run whose only nested envelope is manifest_v2.yaml is still a run.
    # When manifest.yaml also exists, the flat file is the discovered record
    # (and any supersession routes from it). Scanning v2 as well would
    # register the same id twice.
    for path in sorted(glob.glob(os.path.join(REPO, "experiments", "*", "runs",
                                              "*", "manifest_v2.yaml"))):
        if os.path.isfile(os.path.join(os.path.dirname(path), "manifest.yaml")):
            continue
        check_run(path, ctx, run_supersessions)
    check_json_only_runs(ctx)
    check_amendments(ctx)
    check_legacy_id_remaps(ctx)
    # Knowledge must be indexed before goal closure quorum checks so that
    # reviewed_record_ids may cite KN-* entries (ctx.knowledge), not only
    # ledger ids (ctx.ids).
    check_knowledge_entries(ctx)
    check_schema_redirects(ctx, schema_supersessions)
    check_goals(ctx)
    check_cross_refs(ctx)
    check_knowledge_index(ctx)
    check_record_sizes(ctx)
    check_confound_assessments(ctx)
    check_ceremony(ctx)
    check_aged_handoffs(ctx)

    current = set(ctx.errors)
    if args.update_baseline:
        # Prune-only: an existing baseline can shrink but never grow, so a
        # new violation cannot be laundered into the grandfathered set.
        old = load_baseline(BASELINE_PATH)
        entries = (old & current) if os.path.exists(BASELINE_PATH) else current
        write_baseline(entries)
        print(f"wrote {len(entries)} baseline entrie(s) to "
              f"{os.path.relpath(BASELINE_PATH, REPO)}")
        return 0

    baseline = set() if args.no_baseline else load_baseline(BASELINE_PATH)
    new = [e for e in ctx.errors if e not in baseline]
    suppressed = len(ctx.errors) - len(new)
    stale = baseline - current
    if suppressed:
        print(f"note: {suppressed} grandfathered legacy error(s) suppressed "
              f"by {os.path.relpath(BASELINE_PATH, REPO)}")
    if ctx.legacy_warnings:
        print(f"note: {len(legacy_inventory)} frozen root-level ledger records "
              f"were indexed; {len(legacy_run_inventory)} legacy run "
              f"manifest(s) were indexed; {len(ctx.legacy_warnings)} legacy "
              "schema issue(s) remain read-only")
    if run_supersessions:
        print(f"note: {len(run_supersessions)} superseded run manifest(s) "
              f"routed to their superseding records by "
              f"{os.path.relpath(RUN_SUPERSESSION_REGISTRY, REPO)}; both "
              f"records stay hash-pinned")
    if schema_supersessions:
        print(f"note: {len(schema_supersessions)} archived schema record(s) "
              f"routed to complete replacements by "
              f"{os.path.relpath(SCHEMA_SUPERSESSION_REGISTRY, REPO)}; both "
              f"records stay hash-pinned")
    if stale:
        print(f"note: {len(stale)} baseline entrie(s) no longer occur; prune "
              f"with --update-baseline")
    if ctx.advisories:
        kinds = {"goal head": 0, "next_action": 0, "proposal": 0, "handoff": 0,
                 "json-only run": 0}
        for line in ctx.advisories:
            for key in kinds:
                if f": {key}" in line:
                    kinds[key] += 1
                    break
        summary = ", ".join(f"{v} {k}" for k, v in kinds.items() if v)
        print(f"note: {len(ctx.advisories)} advisory(ies), not failures "
              f"({summary}); list with --advisories")
        if args.advisories:
            for line in ctx.advisories:
                print(f"  ~ {line}")

    if new:
        print(f"FAIL: {len(new)} new validation error(s):\n", file=sys.stderr)
        for e in new:
            print(f"  - {e}", file=sys.stderr)
        return 1
    print(f"OK: validated {len(ctx.ids)} records, no new violations")
    return 0


if __name__ == "__main__":
    raise SystemExit(main())
