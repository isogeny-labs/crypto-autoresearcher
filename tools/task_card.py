#!/usr/bin/env python3
"""Mechanical task cards: the instructions the director tier hands the
mechanical tier, checked and executed by a tool rather than trusted.

`docs/model-tiers.md` is the design. The topology is three hops:

  1. the `experiment-director` (director tier, Sonnet) compiles a decided
     experiment into a task card that names every value the mechanical
     executor needs: an approved runbook (`kind: runbook`), or a list of
     frozen commands (`kind: frozen_command`);
  2. the main session relays the card to `executor-mechanical` (Haiku) as the
     exact text `prompt` prints -- it adds nothing, so the relay cannot
     introduce a choice the director did not make;
  3. the director assesses the result, starting from `check-relay`, which
     establishes without judgment whether the executor's report is the
     tool's output or something the executor wrote itself.

A card is accepted only when it leaves the executor nothing to decide. `lint`
enforces that: every field present, every path and digest real, no
operator-facing word that hands a choice back, no unfilled placeholder, and --
for an `EXP-*` card -- a committed approval. The card adds no authority: an
approval it cites is the Coordinator's.

A frozen-command card is executed by `run`, never by the model: the tool
checks the pinned commit and every bound digest, runs each argv without a
shell under its timeout, writes stdout and stderr where the card says, and
writes a write-once receipt with every exit code and digest. The executor
runs one command and relays what it prints, exactly as a runbook executor
relays `tools/runbook.py`. So `check-relay` works for both kinds.

ONE FILE, EVERY REPOSITORY. This file is canonical in
aburan28/crypto-autoresearcher and copied byte-identical into the sibling
repositories (crypto, cryptanalysis), so whichever repository's
`executor-mechanical` answers a dispatch, the same card works. It depends only
on PyYAML; `kind: runbook` additionally needs `tools/runbook.py`, which only
crypto-autoresearcher has, and is refused elsewhere. Change it here and copy
it; never edit a copy.

    python3 tools/task_card.py lint <card.yaml>
    python3 tools/task_card.py prompt <card.yaml>
    python3 tools/task_card.py run <card.yaml>            # frozen_command only
    python3 tools/task_card.py check-relay <card.yaml> --report <executor-report.txt>
    python3 tools/task_card.py request compile --design <spec> [--bind <path>]... --out <card.yaml>
    python3 tools/task_card.py request assess <card.yaml> [--report <executor-report.txt>]
    python3 tools/task_card.py ingest <reply.md> --expect card --out <card.yaml>
    python3 tools/task_card.py ingest <reply.md> --expect assessment --card <card.yaml> --out <assessment.yaml>
    python3 tools/task_card.py lane --design <spec> [--bind <path>]... --card <card.yaml> \
        --assessment <assessment.yaml> [--via auto|conductor|delphi] [--task T-42] [--route]
        [--free local|public]

BATCH LANE. `request` prints a single-turn prompt with every fact computed
(HEAD, sha256s, the receipt, what changed on disk), for a batch API: Delphi
(`conductor delphi ask --profile director --wait --file <prompt>`) or
`python3 -m orchestration.adapter batch submit --role experiment-director`
in crypto-autoresearcher. `ingest` writes the reply only when it is
mechanically right. Between them, `run` executes the card with no model.
`lane` does all of it end to end through one backend: Conductor-hosted
Delphi (the key is in the project vault) or standalone `delphi` (the key is
ANTHROPIC_API_KEY); `--via auto` picks whichever is connected. `--route` asks
`delphi route` which model each step's task family goes to (Delphi's capability
registry) and escalates a step the tool refuses to the next model in the chain.
`--free local|public` runs standalone delphi in free mode (DELPHI_FREE): only
models that cost nothing are called (self-hosted, local, and with `public` the
free remote tiers, which may log prompts: public or synthetic designs only);
a paid model is substituted from Delphi's free map or refused.

Exit status: 0 clean / completed, 1 findings, 2 the card could not be read or
`run` refused to start, 3 `run` stopped at a failing command (a result to
report, not a problem to fix).
"""
from __future__ import annotations

import argparse
import hashlib
import json
import os
import re
import shutil
import subprocess
import sys
import time
from pathlib import Path, PurePosixPath
from typing import Any

import yaml

REPO = Path(__file__).resolve().parents[1]

SCHEMA = "crypto.autoresearch.mechanical-task-card.v1"
RECEIPT_SCHEMA = "crypto.autoresearch.task-card-receipt.v1"
KINDS = ("runbook", "frozen_command")
CARD_ID = re.compile(r"^CARD-[A-Za-z0-9][A-Za-z0-9-]{2,120}$")
SHA256 = re.compile(r"^[0-9a-f]{64}$")
COMMIT = re.compile(r"^[0-9a-f]{40}$")
OWNER = re.compile(r"^[a-z][a-z0-9-]{0,63}$")
PLACEHOLDER = re.compile(r"\{([a-z_]+)\}")
SHELL_TOKENS = {"|", "||", "&&", ";", ">", ">>", "<", "&", "2>&1", "2>", "$("}
DENIED_ENV = re.compile(r"^(LD_PRELOAD|LD_LIBRARY_PATH|DYLD_.*|RISC0_DEV_MODE|"
                        r".*(TOKEN|SECRET|PASSWORD|API_KEY|CREDENTIAL).*)$")
# The same list as tools/runbook.py: words that hand a choice back to the
# operator. Kept in step by tests/test_task_card.py where both files exist.
VAGUE = re.compile(
    r"\b(appropriate(ly)?|as needed|if needed|if necessary|when necessary|"
    r"reasonabl[ey]|sensibl[ey]|judge?ment|judge|decide|choose|pick|ideally|"
    r"roughly|approximately|maybe|perhaps|might|consider|try to|feel free|"
    r"as you see fit|use your|whatever|somehow|or similar|something like|"
    r"a few|several|etc|e\.g|tbd|todo|fixme|xxx)\b|\?", re.IGNORECASE)
# Text a mechanical executor would have to fill in itself.
UNFILLED = re.compile(r"<[^<>\n]{1,60}>")
TAIL_LINES = 20
REQUIRED = ("schema", "card_id", "experiment_id", "author_role", "executor_role",
            "kind", "bus_address", "background", "write_scope", "stop_when")


class CardError(Exception):
    """A card that cannot be read at all, or a run that cannot start."""


# ---------------------------------------------------------------------------
# Small utilities (no dependency on tools/runbook.py)
# ---------------------------------------------------------------------------

def sha256_bytes(data: bytes) -> str:
    return hashlib.sha256(data).hexdigest()


def sha256_file(path: Path) -> str:
    return sha256_bytes(path.read_bytes())


def rel(repo: Path, path: Path) -> str:
    try:
        return path.resolve().relative_to(repo.resolve()).as_posix()
    except ValueError:
        raise CardError(f"{path} is outside the repository {repo}; cards, binds and "
                        f"outputs live inside it") from None


def safe_relative(relative: str) -> str:
    pure = PurePosixPath(relative)
    if not relative or pure.is_absolute() or ".." in pure.parts:
        raise CardError(f"{relative!r} must be a repository-relative path without '..'")
    return pure.as_posix()


def git(repo: Path, *args: str) -> tuple[int, str]:
    result = subprocess.run(["git", *args], cwd=repo, capture_output=True, text=True)
    return result.returncode, result.stdout.strip()


def committed_bytes_match(repo: Path, relative: str) -> bool:
    code, blob = git(repo, "rev-parse", f"HEAD:{relative}")
    return code == 0 and git(repo, "hash-object", relative) == (0, blob)


def _runbook_module(repo: Path):
    """`tools/runbook.py`, needed only by `kind: runbook` cards."""
    if not (repo / "tools" / "runbook.py").is_file():
        return None
    sys.path.insert(0, str(repo / "tools"))
    import runbook  # noqa: PLC0415
    return runbook


def load_card(path: str | Path, repo: Path = REPO) -> tuple[str, str, dict[str, Any]]:
    full = Path(path)
    full = (full if full.is_absolute() else repo / full).resolve()
    try:
        raw = full.read_bytes()
    except OSError as exc:
        raise CardError(f"{path}: {exc.strerror}") from None
    try:
        doc = yaml.safe_load(raw)
    except yaml.YAMLError as exc:
        raise CardError(f"{path}: YAML does not parse: {exc}") from None
    if not isinstance(doc, dict):
        raise CardError(f"{path}: a task card is a mapping")
    return rel(repo, full), sha256_bytes(raw), doc


def _text(where: str, value: Any) -> list[str]:
    if not isinstance(value, str) or not value.strip():
        return [f"{where}: must be non-empty text"]
    findings = []
    hits = sorted({m.group(0) for m in VAGUE.finditer(value)})
    if hits:
        findings.append(f"{where}: leaves a choice to the operator "
                        f"({', '.join(repr(h) for h in hits)}); state exactly what happens")
    if UNFILLED.search(value):
        findings.append(f"{where}: unfilled placeholder {UNFILLED.search(value).group(0)!r}")
    return findings


def _scope_covers(scope: list[str], path: str) -> bool:
    target = PurePosixPath(path)
    for entry in scope:
        base = PurePosixPath(entry.rstrip("/"))
        if target == base or base in target.parents:
            return True
    return False


def _in_scope(at: str, scope: list[str], path: Any) -> list[str]:
    if not isinstance(path, str) or not path:
        return [f"{at}: must be a repository-relative path"]
    try:
        safe_relative(path)
    except CardError as exc:
        return [f"{at}: {exc}"]
    return [] if _scope_covers(scope, path) else [f"{at}: {path} is outside write_scope"]


# ---------------------------------------------------------------------------
# Lint
# ---------------------------------------------------------------------------

def _approval_findings(repo: Path, card: dict[str, Any]) -> list[str]:
    """A frozen-command card for an EXP-* names the decision that approved it."""
    decision = card.get("approval_decision")
    if not isinstance(decision, str):
        return ["approval_decision: an EXP-* frozen-command card names its committed approval decision"]
    path = repo / decision
    if not path.is_file() or not committed_bytes_match(repo, decision):
        return [f"approval_decision: {decision} is not a committed file"]
    record = (yaml.safe_load(path.read_text(encoding="utf-8")) or {}).get("coordinator_decision") or {}
    if record.get("decision") != "approve" or card["experiment_id"] not in (record.get("target_ids") or []):
        return [f"approval_decision: {decision} does not approve {card['experiment_id']}"]
    return []


def _runbook_findings(repo: Path, card: dict[str, Any], scope: list[str]) -> list[str]:
    rb = _runbook_module(repo)
    if rb is None:
        return ["kind: runbook cards need tools/runbook.py, which only "
                "crypto-autoresearcher has; use kind: frozen_command here"]
    findings: list[str] = []
    path = card.get("runbook")
    if not isinstance(path, str):
        return ["runbook: a runbook card names the runbook path"]
    if not SHA256.match(str(card.get("runbook_sha256", ""))):
        findings.append("runbook_sha256: must be the runbook's 64-hex sha256")
    try:
        runbook = rb.load_runbook(repo, path)
    except (OSError, rb.RunbookError) as exc:
        return findings + [f"runbook: {exc}"]
    if card.get("runbook_sha256") != runbook.sha256:
        findings.append(f"runbook_sha256: card names {card.get('runbook_sha256')}, "
                        f"the runbook on disk is {runbook.sha256}")
    lint = rb.lint(runbook)
    findings += [f"runbook: does not lint clean: {item}" for item in lint]
    if runbook.experiment_id != card.get("experiment_id"):
        findings.append(f"experiment_id: card names {card.get('experiment_id')}, "
                        f"the runbook is {runbook.experiment_id}")
    if runbook.doc.get("executor_tier") != "mechanical":
        findings.append("runbook: executor_tier must be `mechanical` for a mechanical card")
    for needed in (f"{runbook.base_dir}/runbook-sessions/", f"{runbook.base_dir}/reports/"):
        if not _scope_covers(scope, needed):
            findings.append(f"write_scope: must include {needed}")
    if str(card.get("experiment_id", "")).startswith("EXP-") and not lint:
        if not rb.find_approval(repo, runbook.experiment_id, runbook.sha256):
            findings.append("runbook: no committed approval decision names this experiment "
                            f"and runbook_sha256 {runbook.sha256}")
    return findings


def _command_findings(repo: Path, card: dict[str, Any], scope: list[str]) -> list[str]:
    findings: list[str] = []
    commit = card.get("commit")
    if commit is not None:
        if not COMMIT.match(str(commit)):
            findings.append("commit: must be a full 40-hex commit id")
        elif git(repo, "cat-file", "-e", f"{commit}^{{commit}}")[0] != 0:
            findings.append(f"commit: {commit} is not a commit in this repository")
    findings += _in_scope("receipt", scope, card.get("receipt"))
    fresh = card.get("must_not_exist") or []
    if not isinstance(fresh, list):
        findings.append("must_not_exist: must list repository paths")
        fresh = []
    for index, path in enumerate(fresh):
        findings += _in_scope(f"must_not_exist[{index}]", scope, path)
    binds = card.get("binds") or []
    bound: set[str] = set()
    if not isinstance(binds, list):
        findings.append("binds: must be a list of {path, sha256}")
        binds = []
    for index, item in enumerate(binds):
        at = f"binds[{index}]"
        if not isinstance(item, dict) or not isinstance(item.get("path"), str):
            findings.append(f"{at}: needs path and sha256")
            continue
        file = repo / item["path"]
        if not file.is_file():
            findings.append(f"{at}: {item['path']} does not exist")
        elif sha256_file(file) != item.get("sha256"):
            findings.append(f"{at}: {item['path']} does not match its sha256")
        bound.add(item["path"])
    commands = card.get("commands")
    if not isinstance(commands, list) or not commands:
        return findings + ["commands: a frozen-command card lists at least one command"]
    for index, command in enumerate(commands):
        at = f"commands[{index}]"
        if not isinstance(command, dict):
            findings.append(f"{at}: must be a mapping")
            continue
        argv = command.get("argv")
        if not (isinstance(argv, list) and argv and all(isinstance(a, str) and a for a in argv)):
            findings.append(f"{at}.argv: must be a non-empty list of strings (no shell string)")
            continue
        shell = sorted(set(argv) & SHELL_TOKENS)
        if shell:
            findings.append(f"{at}.argv: shell syntax {shell}; the command runs without a shell")
        for token in argv:
            if UNFILLED.search(token) or PLACEHOLDER.search(token):
                findings.append(f"{at}.argv: unfilled placeholder in {token!r}")
            if (repo / token).is_file() and token not in bound:
                findings.append(f"{at}.argv: names repository file {token} that binds does not pin")
        timeout = command.get("timeout_seconds")
        if not isinstance(timeout, int) or isinstance(timeout, bool) or timeout <= 0:
            findings.append(f"{at}.timeout_seconds: must be a positive integer")
        codes = command.get("success_exit_codes")
        if not (isinstance(codes, list) and codes and all(isinstance(c, int) for c in codes)):
            findings.append(f"{at}.success_exit_codes: must list the exit codes that mean success")
        retry = command.get("retry")
        if retry is not None:
            codes_ok = (isinstance(retry, dict) and isinstance(retry.get("exit_codes"), list)
                        and retry["exit_codes"] and all(isinstance(c, int) for c in retry["exit_codes"]))
            attempts = retry.get("max_attempts") if isinstance(retry, dict) else None
            if not codes_ok or not isinstance(attempts, int) or isinstance(attempts, bool) \
                    or not 2 <= attempts <= 3:
                findings.append(f"{at}.retry: needs exit_codes (the infrastructure failures to retry) "
                                f"and max_attempts of 2 or 3")
        if command.get("id") is not None and not OWNER.match(str(command["id"])):
            findings.append(f"{at}.id: lowercase letters, digits and hyphens")
        if command.get("cwd") is not None:
            try:
                cwd = safe_relative(str(command["cwd"]))
            except CardError as exc:
                findings.append(f"{at}.cwd: {exc}")
            else:
                if not (repo / cwd).is_dir():
                    findings.append(f"{at}.cwd: {cwd} is not a directory in the repository")
        for stream in ("stdout", "stderr"):
            if command.get(stream) is not None:
                findings += _in_scope(f"{at}.{stream}", scope, command[stream])
        for output in command.get("outputs") or []:
            findings += _in_scope(f"{at}.outputs", scope, output)
        env = command.get("env") or {}
        if not isinstance(env, dict) or not all(isinstance(k, str) and isinstance(v, str)
                                                for k, v in env.items()):
            findings.append(f"{at}.env: must map names to string values")
        else:
            denied = sorted(k for k in env if DENIED_ENV.match(k))
            if denied:
                findings.append(f"{at}.env: may not set {denied}")
    if str(card.get("experiment_id", "")).startswith("EXP-"):
        findings += _approval_findings(repo, card)
    return findings


def lint(card: dict[str, Any], repo: Path = REPO) -> list[str]:
    """Every way this card could leave the mechanical executor a choice."""
    findings = [f"{key}: required" for key in REQUIRED if key not in card]
    if findings:
        return findings
    if card["schema"] != SCHEMA:
        findings.append(f"schema: must be {SCHEMA}")
    if not CARD_ID.match(str(card["card_id"])):
        findings.append("card_id: must look like CARD-<experiment>-<n>")
    if card["author_role"] != "experiment-director":
        findings.append("author_role: cards are written by experiment-director")
    if card["executor_role"] != "executor-mechanical":
        findings.append("executor_role: cards are executed by executor-mechanical")
    if card["kind"] not in KINDS:
        findings.append(f"kind: must be one of {list(KINDS)}")
    if not OWNER.match(str(card["bus_address"])):
        findings.append("bus_address: lowercase letters, digits and hyphens")
    if not isinstance(card["background"], bool):
        findings.append("background: true when the budget exceeds ten minutes, else false")
    scope = card["write_scope"]
    if not (isinstance(scope, list) and scope and all(isinstance(s, str) and s for s in scope)):
        findings.append("write_scope: must list at least one path")
        scope = []
    for entry in scope:
        try:
            safe_relative(entry.rstrip("/"))
        except CardError as exc:
            findings.append(f"write_scope: {exc}")
    stops = card["stop_when"]
    if not (isinstance(stops, list) and stops):
        findings.append("stop_when: list each condition on which the executor stops and returns `refused`")
        stops = []
    for index, text in enumerate(stops):
        findings += _text(f"stop_when[{index}]", text)
    if card.get("notes") is not None:
        findings += _text("notes", card["notes"])
    if card["kind"] == "runbook":
        findings += _runbook_findings(repo, card, scope)
    elif card["kind"] == "frozen_command":
        findings += _command_findings(repo, card, scope)
    return findings


# ---------------------------------------------------------------------------
# Prompt: the exact dispatch text
# ---------------------------------------------------------------------------

def render_prompt(card_path: str, card_sha: str, card: dict[str, Any], repo: Path = REPO) -> str:
    """Deterministic: same card, same bytes."""
    lines = [
        f"You are executor-mechanical. This is task card {card['card_id']} "
        f"({card_path}, sha256 {card_sha}); tools/task_card.py lint accepted it.",
        "Every value you need is below. Use no other value, run nothing else, and "
        "compute nothing: every number you report is copied from tool output.",
        "",
    ]
    if card["kind"] == "runbook":
        runbook = _runbook_module(repo).load_runbook(repo, card["runbook"])
        lines += [
            'Follow ".claude/agents/executor-mechanical.md", section "Runbook '
            'execution: the procedure", steps 1 to 8, with exactly these values:',
            f"  <runbook> = {card['runbook']}",
            f"  <your bus address> = {card['bus_address']}",
            f"  <session_dir> = {runbook.session_dir}",
            f"  <session id> = {runbook.doc['session_id']}",
            f"  step 2 in the background: {'yes' if card['background'] else 'no'}",
        ]
    else:
        lines += [
            "Run exactly this one command from the repository root, and nothing else:",
            f"  python3 tools/task_card.py run {card_path}",
            f"Run it in the background: {'yes' if card['background'] else 'no'}. "
            "The tool checks the card, runs every command on it and writes the receipt; "
            "you run none of the card's commands yourself.",
            "Exit 0: completed. Exit 3: stopped at a failing command, which is a result "
            "to report. Exit 2: refused to start; return `refused` with the IMPEDIMENT line.",
        ]
    lines += ["", "Write only inside:"] + [f"  - {entry}" for entry in card["write_scope"]]
    lines += ["", "Stop and return `refused`, naming the condition, when:"]
    lines += [f"  - {text}" for text in card["stop_when"]]
    if card.get("notes"):
        lines += ["", f"Note from the director: {card['notes']}"]
    if card["kind"] == "runbook":
        lines += ["", "Return the output of step 7 (`status --brief`) verbatim, and nothing you "
                  "composed yourself."]
    else:
        lines += ["", "Return everything the command printed, verbatim, and nothing you "
                  "composed yourself."]
    return "\n".join(lines) + "\n"


# ---------------------------------------------------------------------------
# Run: a frozen-command card, executed and recorded by the tool
# ---------------------------------------------------------------------------

def _tail(data: bytes) -> list[str]:
    return data.decode("utf-8", errors="replace").splitlines()[-TAIL_LINES:]


def _write(repo: Path, relative: str, data: bytes) -> None:
    path = repo / safe_relative(relative)
    path.parent.mkdir(parents=True, exist_ok=True)
    path.write_bytes(data)


def _execute(repo: Path, command: dict[str, Any], env: dict[str, str]):
    started = time.monotonic()
    try:
        proc = subprocess.run(command["argv"], cwd=repo / safe_relative(str(command.get("cwd") or ".")),
                              env=env, capture_output=True, timeout=command["timeout_seconds"])
        result = proc.returncode, proc.stdout, proc.stderr, False
    except subprocess.TimeoutExpired as exc:
        result = None, exc.stdout or b"", exc.stderr or b"", True
    except OSError as exc:
        result = None, b"", str(exc).encode(), False
    return (*result, round(time.monotonic() - started, 3))


def run_card(card_path: str, card_sha: str, card: dict[str, Any], repo: Path = REPO) -> dict[str, Any]:
    """Execute a linted frozen-command card and write its write-once receipt.

    Raises CardError (an impediment: nothing ran, nothing was written) when
    the card is not a frozen-command card, does not lint, names a commit that
    is not HEAD, already has a receipt, or names a `must_not_exist` path that
    exists. A command succeeds only with a success exit code and every
    declared output written; `retry` reruns it, up to its `max_attempts`,
    only on the exit codes it names.
    """
    if card.get("kind") != "frozen_command":
        raise CardError("run executes frozen_command cards; a runbook card runs through tools/runbook.py")
    findings = lint(card, repo)
    if findings:
        raise CardError("card does not lint: " + "; ".join(findings))
    receipt_path = repo / safe_relative(card["receipt"])
    if receipt_path.exists():
        raise CardError(f"receipt {card['receipt']} already exists; receipts are write-once")
    present = [path for path in card.get("must_not_exist") or [] if (repo / path).exists()]
    if present:
        raise CardError(f"must_not_exist paths already exist: {present}")
    head = git(repo, "rev-parse", "HEAD")[1]
    if card.get("commit") and card["commit"] != head:
        raise CardError(f"card pins commit {card['commit']}, HEAD is {head}")
    dirty_before = _dirty_paths(repo)

    results, status = [], "completed"
    for index, command in enumerate(card["commands"], 1):
        env = dict(os.environ, **(command.get("env") or {}))
        retry = command.get("retry") or {}
        attempts = []
        for _attempt in range(retry.get("max_attempts", 1)):
            code, out, err, timed_out, elapsed = _execute(repo, command, env)
            attempts.append({"exit_code": code, "timed_out": timed_out, "seconds": elapsed})
            if timed_out or code not in (retry.get("exit_codes") or []):
                break
        for stream, data in (("stdout", out), ("stderr", err)):
            if command.get(stream):
                _write(repo, command[stream], data)
        outputs = {path: (sha256_file(repo / path) if (repo / path).is_file() else None)
                   for path in command.get("outputs") or []}
        # A declared output the command did not write is a failure: the card
        # said the command writes it.
        ok = (not timed_out) and code in command["success_exit_codes"] and None not in outputs.values()
        results.append({"index": index, "id": command.get("id"), "cwd": command.get("cwd") or ".",
                        "argv": command["argv"], "exit_code": code, "attempts": len(attempts),
                        "attempt_log": attempts,
                        "timed_out": timed_out, "seconds": elapsed, "succeeded": ok,
                        "stdout_sha256": sha256_bytes(out), "stderr_sha256": sha256_bytes(err),
                        "stdout_tail": _tail(out), "stderr_tail": _tail(err), "outputs": outputs})
        if not ok:
            status = f"stopped at command {index}"
            break
    receipt = {"schema": RECEIPT_SCHEMA, "card_id": card["card_id"], "card_path": card_path,
               "card_sha256": card_sha, "commit": head, "status": status,
               "dirty_before": dirty_before, "dirty_after": _dirty_paths(repo),
               "commands_total": len(card["commands"]), "commands": results}
    receipt_path.parent.mkdir(parents=True, exist_ok=True)
    receipt_path.write_text(json.dumps(receipt, indent=2, sort_keys=True) + "\n", encoding="utf-8")
    return receipt


def brief(receipt: dict[str, Any], receipt_rel: str, receipt_sha: str) -> str:
    """What `run` prints, derived from the receipt alone, so it can be re-derived."""
    lines = [f"card: {receipt['card_id']} (sha256 {receipt['card_sha256']})",
             f"commit: {receipt['commit']}",
             f"receipt: {receipt_rel} sha256 {receipt_sha}",
             f"status: {receipt['status']}"]
    for item in receipt["commands"]:
        exit_text = "timed out" if item["timed_out"] else f"exit {item['exit_code']}"
        label = f"{item['index']}" + (f" ({item['id']})" if item.get("id") else "")
        where = f" in {item['cwd']}" if item.get("cwd", ".") != "." else ""
        if item.get("attempts", 1) > 1:
            exit_text += f" after {item['attempts']} attempts"
        lines.append(f"command {label}: {json.dumps(item['argv'])}{where} {exit_text} "
                     f"({item['seconds']} s) {'succeeded' if item['succeeded'] else 'FAILED'}")
        lines.append(f"  stdout sha256 {item['stdout_sha256']}; last {len(item['stdout_tail'])} lines:")
        lines += [f"    {line}" for line in item["stdout_tail"]]
        if item["stderr_tail"]:
            lines.append(f"  stderr last {len(item['stderr_tail'])} lines:")
            lines += [f"    {line}" for line in item["stderr_tail"]]
        for path, digest in item["outputs"].items():
            lines.append(f"  output {path}: {digest or 'MISSING'}")
    not_run = receipt["commands_total"] - len(receipt["commands"])
    if not_run:
        lines.append(f"not run: {not_run} command(s) after the stop")
    return "\n".join(lines)


# ---------------------------------------------------------------------------
# Check-relay
# ---------------------------------------------------------------------------

def _normalized(text: str) -> list[str]:
    return [" ".join(line.split()) for line in text.splitlines() if line.strip()]


def _missing(expected: list[str], reported: list[str]) -> list[str]:
    position, missing = 0, []
    for line in expected:
        try:
            position = reported.index(line, position) + 1
        except ValueError:
            missing.append(line)
    return missing


def check_relay(card: dict[str, Any], report_text: str, repo: Path = REPO) -> dict[str, Any]:
    """Whether the executor's report carries the tool's own output, unedited.

    The reference is recomputed from the record, never taken from the
    executor: `tools/runbook.py status --brief` of the session for a runbook
    card, `brief` of the receipt for a frozen-command card. Every reference
    line must appear, in order, in the report; a paraphrased, rounded or
    reordered report is not a relay, whatever it says.
    """
    reported = _normalized(report_text)
    if card["kind"] == "frozen_command":
        receipt_rel = card["receipt"]
        path = repo / safe_relative(receipt_rel)
        result: dict[str, Any] = {"applicable": True, "receipt": receipt_rel}
        if not path.is_file():
            result.update(relay_verbatim=False, missing_lines=[], verify_findings=["no receipt: the card never ran"])
            return result
        receipt = json.loads(path.read_text(encoding="utf-8"))
        missing = _missing(_normalized(brief(receipt, receipt_rel, sha256_file(path))), reported)
        findings = [] if receipt.get("card_id") == card["card_id"] else ["receipt belongs to another card"]
        result.update(relay_verbatim=not missing, missing_lines=missing, verify_findings=findings,
                      status=receipt.get("status"))
        return result
    rb = _runbook_module(repo)
    runbook = rb.load_runbook(repo, card["runbook"])
    session = runbook.session_dir
    result = {"applicable": True, "session_dir": session}
    try:
        expected = _normalized(rb.brief(repo, session))
    except (OSError, rb.RunbookError, IndexError, KeyError, ValueError) as exc:
        result.update(relay_verbatim=False, verify_findings=[f"session unreadable: {exc}"], missing_lines=[])
        return result
    missing = _missing(expected, reported)
    result["relay_verbatim"] = not missing
    result["missing_lines"] = missing
    result["verify_findings"] = rb.verify(repo, session)
    return result


# ---------------------------------------------------------------------------
# Batch lane: self-contained director requests, mechanically ingested replies
# ---------------------------------------------------------------------------
#
# A batch request (Delphi through Conductor, or `orchestration.adapter batch`
# in crypto-autoresearcher) is one turn: the model reads no file and runs no
# command. So `request` puts every fact in the prompt, computed by this tool
# (HEAD, every sha256, the receipt, what changed on disk), and `ingest` accepts
# a reply only when it is mechanically right: the card lints, the assessment's
# outcome is the one the facts determine. The mechanical tier needs no model
# here at all: `run` executes the card.

YAML_BLOCK = re.compile(r"```ya?ml[ \t]*\n(.*?)\n```", re.DOTALL)
OUTCOMES = ("executed_as_specified", "stopped", "impeded", "executor_deviated")
RECOMMENDATIONS = ("proceed_to_analysis", "rerun_after_infrastructure_fix", "respecify", "escalate")
ALLOWED = {"executed_as_specified": ("proceed_to_analysis",),
           "executor_deviated": ("escalate",),
           "stopped": ("rerun_after_infrastructure_fix", "respecify", "escalate"),
           "impeded": ("rerun_after_infrastructure_fix", "respecify", "escalate")}


def _dirty_paths(repo: Path) -> list[str]:
    code, out = git(repo, "status", "--porcelain", "--untracked-files=all")
    if code != 0:
        return []
    return sorted(line[3:].split(" -> ")[-1].strip('"') for line in out.splitlines() if line)


def _contract(repo: Path) -> str:
    """The director's full contract: `agents/` in crypto-autoresearcher, where the
    `.claude/agents/` file is a generated pointer to it; `.claude/agents/` elsewhere."""
    for path in (repo / "agents" / "experiment-director.md",
                 repo / ".claude" / "agents" / "experiment-director.md"):
        if path.is_file():
            text = path.read_text(encoding="utf-8")
            break
    else:
        raise CardError("no experiment-director contract in this repository")
    if text.startswith("---"):
        text = text.split("---", 2)[2]
    return text.strip()


def _fenced(label: str, text: str, lang: str = "") -> list[str]:
    return [f"### {label}", "", f"````{lang}", text.rstrip("\n"), "````", ""]


def compile_request(designs: list[str], binds: list[str], card_out: str, repo: Path = REPO) -> str:
    """The prompt for a director compile in one turn, deterministic in the repository state."""
    card_out = safe_relative(card_out)
    head = git(repo, "rev-parse", "HEAD")[1]
    facts = [f"repository HEAD: {head}", f"card path: {card_out}"]
    for relative in binds:
        relative = safe_relative(relative)
        file = repo / relative
        facts.append(f"bind {relative}: " + (f"sha256 {sha256_file(file)}" if file.is_file() else "DOES NOT EXIST"))
    lines = [
        "You are experiment-director in compile mode, answering in a single turn through a batch API.",
        "You cannot read files or run commands. Every fact you may use is in this message; the facts "
        "under 'Computed facts' were computed by tools/task_card.py and are copied, never recomputed. "
        "A value the design does not give is a specification error, never a default.",
        "",
        "Write a `kind: frozen_command` card. Reply with exactly two fenced yaml blocks and nothing "
        "else: first the card, then `specification_errors: [...]` (an empty list only when every value "
        "came from the design or the facts). `tools/task_card.py ingest` writes the card only when it "
        "lints clean and the error list is empty.",
        "",
    ]
    lines += _fenced("Your role contract (this repository's experiment-director)", _contract(repo), "markdown")
    template = repo / "templates" / "mechanical-task-card.yaml"
    if template.is_file():
        lines += _fenced("Card template", template.read_text(encoding="utf-8"), "yaml")
    lines += _fenced("Computed facts", "\n".join(facts))
    for relative in designs:
        relative = safe_relative(relative)
        file = repo / relative
        try:
            data = file.read_bytes()
        except OSError:
            raise CardError(f"design {relative} cannot be read") from None
        lines += _fenced(f"Decided design: {relative} (sha256 {sha256_bytes(data)})",
                         data.decode("utf-8", errors="replace"))
    return "\n".join(lines)


def assessment_facts(card: dict[str, Any], report_text: str | None = None, repo: Path = REPO) -> dict[str, Any]:
    """Everything an assessment rests on, and the outcome those facts determine."""
    facts: dict[str, Any] = {"card_id": card["card_id"], "receipt": card.get("receipt")}
    path = repo / safe_relative(str(card.get("receipt") or ""))
    if card.get("kind") != "frozen_command" or not path.is_file():
        facts.update(receipt_present=False, outcome="impeded")
        return facts
    receipt = json.loads(path.read_text(encoding="utf-8"))
    mismatched = []
    for item in receipt.get("commands", []):
        for output, digest in (item.get("outputs") or {}).items():
            now = sha256_file(repo / output) if (repo / output).is_file() else None
            if digest is not None and now != digest:
                mismatched.append(output)
    scope = card["write_scope"]
    # What the run changed is read from the receipt (dirty right after the run, not before
    # it), so the director's own later files -- prompts, replies, this assessment -- are
    # never mistaken for executor writes.
    before = set(receipt.get("dirty_before") or [])
    after = receipt.get("dirty_after")
    outside = [p for p in (after if after is not None else _dirty_paths(repo))
               if p not in before and not _scope_covers(scope, p)]
    facts.update(receipt_present=True, receipt_sha256=sha256_file(path), status=receipt["status"],
                 summary=brief(receipt, card["receipt"], sha256_file(path)),
                 outputs_changed_since_run=mismatched, writes_outside_scope=outside)
    deviated = bool(mismatched or outside)
    if report_text is not None:
        relay = check_relay(card, report_text, repo)
        facts["relay_verbatim"] = relay["relay_verbatim"]
        deviated = deviated or not relay["relay_verbatim"]
    else:
        facts["relay"] = "none: tools/task_card.py run was invoked directly, no executor relayed"
    if deviated:
        facts["outcome"] = "executor_deviated"
    else:
        facts["outcome"] = "executed_as_specified" if receipt["status"] == "completed" else "stopped"
    return facts


def assess_request(card_path: str, card_sha: str, card: dict[str, Any], report_text: str | None = None,
                   repo: Path = REPO) -> str:
    facts = assessment_facts(card, report_text, repo)
    allowed = ALLOWED[facts["outcome"]]
    summary = facts.pop("summary", None)
    lines = [
        "You are experiment-director in assess mode, answering in a single turn through a batch API.",
        "You cannot read files or run commands. The facts below were computed by tools/task_card.py "
        f"from the receipt and the checkout. They determine the outcome: `{facts['outcome']}`. Your "
        f"part is the recommendation, one of {list(allowed)}, and one reason per line citing the fact "
        "or summary line it rests on. Never interpret the result.",
        "",
        "Reply with exactly one fenced yaml block and nothing else:",
        "",
        "```yaml",
        "execution_assessment:",
        f"  card_id: {card['card_id']}",
        f"  card_sha256: {card_sha}",
        f"  outcome: {facts['outcome']}",
        f"  recommendation: <one of {' | '.join(allowed)}>",
        "  reasons: [<one line each>]",
        "  interpretation: not_assessed",
        "```",
        "",
    ]
    lines += _fenced("Your role contract (this repository's experiment-director)", _contract(repo), "markdown")
    lines += _fenced(f"Card {card_path} (sha256 {card_sha})", yaml.safe_dump(card, sort_keys=False), "yaml")
    lines += _fenced("Computed facts", yaml.safe_dump(facts, sort_keys=True), "yaml")
    if summary:
        lines += _fenced("Run summary (tools/task_card.py, derived from the receipt)", summary)
    return "\n".join(lines)


def _blocks(text: str) -> list[Any]:
    out = []
    for body in YAML_BLOCK.findall(text):
        try:
            out.append(yaml.safe_load(body))
        except yaml.YAMLError:
            out.append(None)
    return out


def ingest(reply: str, out: str, expect: str, card: dict[str, Any] | None = None,
           repo: Path = REPO) -> list[str]:
    """Validate a model's reply and write it write-once; findings mean nothing was written."""
    out = safe_relative(out)
    target = repo / out
    if target.exists():
        return [f"{out} already exists; cards and assessments are write-once"]
    blocks = [b for b in _blocks(reply) if isinstance(b, dict)]
    if expect == "card":
        cards = [b for b in blocks if "schema" in b]
        errors = [b for b in blocks if "specification_errors" in b]
        if len(cards) != 1:
            return [f"reply must hold exactly one card block, found {len(cards)}"]
        if not errors:
            return ["reply has no specification_errors block"]
        listed = errors[0]["specification_errors"] or []
        if listed:
            return [f"specification_error: {item}" for item in listed]
        findings = lint(cards[0], repo)
        if findings:
            return findings
        document = cards[0]
    else:
        assessments = [b["execution_assessment"] for b in blocks
                       if isinstance(b.get("execution_assessment"), dict)]
        if len(assessments) != 1:
            return [f"reply must hold exactly one execution_assessment block, found {len(assessments)}"]
        record = assessments[0]
        facts = assessment_facts(card, None, repo)
        findings = []
        if record.get("card_id") != card["card_id"]:
            findings.append(f"card_id: {record.get('card_id')} is not {card['card_id']}")
        if record.get("outcome") != facts["outcome"]:
            findings.append(f"outcome: {record.get('outcome')}; the facts determine {facts['outcome']}")
        if record.get("recommendation") not in ALLOWED[facts["outcome"]]:
            findings.append(f"recommendation: {record.get('recommendation')} is not one of "
                            f"{list(ALLOWED[facts['outcome']])} for {facts['outcome']}")
        if record.get("interpretation") != "not_assessed":
            findings.append("interpretation: must be not_assessed")
        reasons = record.get("reasons")
        if not (isinstance(reasons, list) and reasons and all(isinstance(r, str) and r for r in reasons)):
            findings.append("reasons: list at least one reason")
        if findings:
            return findings
        record["facts"] = {k: v for k, v in facts.items() if k != "summary"}
        document = {"execution_assessment": record}
    target.parent.mkdir(parents=True, exist_ok=True)
    target.write_text(yaml.safe_dump(document, sort_keys=False), encoding="utf-8")
    return []


# ---------------------------------------------------------------------------
# Lane: compile -> run -> assess end to end through one batch backend
# ---------------------------------------------------------------------------
#
# The two director calls go to a batch API; everything else is this tool.
# `conductor` is Conductor-hosted Delphi (`conductor delphi ask --profile
# director`, the key in the project vault, the delegation linked to a task);
# `delphi` is the standalone binary (`delphi run`, the key in the environment).
# Neither ever sees a file: each call is the prompt `request` printed.

DIRECTOR_MODEL = "claude-sonnet-5-5"   # director-runbook's anthropic binding
DIRECTOR_PROFILE = "director"          # Conductor's delphi director profile


def _conductor_connected(binary: str) -> bool:
    if not shutil.which(binary):
        return False
    try:
        probe = subprocess.run([binary, "delphi", "profiles"], capture_output=True, text=True, timeout=60)
    except (OSError, subprocess.TimeoutExpired):
        return False
    return probe.returncode == 0 and DIRECTOR_PROFILE in probe.stdout


def pick_backend(via: str, conductor: str, delphi: str) -> str:
    if via != "auto":
        return via
    if _conductor_connected(conductor):
        return "conductor"
    if shutil.which(delphi) and os.environ.get("ANTHROPIC_API_KEY"):
        return "delphi"
    raise CardError("no batch backend: `conductor delphi profiles` does not list a director profile "
                    "(connect Conductor to a control plane whose vault holds the key), and standalone "
                    "delphi needs ANTHROPIC_API_KEY")


# The task family of each director step, as Delphi's calibration suites name it.
FAMILY = {"compile": "card-compile", "assess": "assess"}


class _Refused(CardError):
    """The model declined to answer (delphi status refused): worth escalating, unlike an
    infrastructure error, which a stronger model would not fix."""


def _target(spec: str) -> dict[str, str]:
    provider, _, rest = spec.partition(":")
    model, effort = rest, ""
    if "@" in rest[1:]:
        model, effort = rest[:rest.rindex("@")], rest[rest.rindex("@") + 1:]
    return {"provider": provider, "model": model, "effort": effort}


FREE_MODES = ("local", "public")


def _delphi_env(opts: dict[str, Any]) -> dict[str, str] | None:
    """The environment for standalone delphi: free mode is DELPHI_FREE, set from opts so the
    lane's record says what actually ran (lane takes an inherited DELPHI_FREE as its default)."""
    env = dict(os.environ)
    env.pop("DELPHI_FREE", None)
    if opts.get("free"):
        env["DELPHI_FREE"] = opts["free"]
    return env


def route_for(family: str, opts: dict[str, Any]) -> dict[str, Any]:
    """`delphi route -family F -json`: the chosen model, its escalation chain and the basis."""
    proc = subprocess.run([opts["delphi"], "route", "-family", family, "-json"], capture_output=True, text=True,
                          env=_delphi_env(opts))
    try:
        data = json.loads(proc.stdout)
    except ValueError:
        raise CardError(f"delphi route -family {family} failed ({proc.returncode}): "
                        f"{proc.stderr.strip()[-400:]}") from None
    if data.get("error"):
        raise CardError(f"no routed model for {family}: {data['error']}")
    r = data["route"]
    return {"family": family, "choice": r["choice"], "escalation": r.get("escalation") or [], "basis": r["basis"]}


def _ask(backend: str, prompt: Path, workdir: Path, name: str, opts: dict[str, Any]) -> tuple[str, dict]:
    """One batch call; returns the answer text and what the backend reported."""
    if backend == "conductor":
        argv = [opts["conductor"], "delphi", "ask", "--profile", DIRECTOR_PROFILE, "--wait",
                "--file", str(prompt)] + (["--task", opts["task"]] if opts.get("task") else [])
        proc = subprocess.run(argv, capture_output=True, text=True)
        if proc.returncode != 0:
            raise CardError(f"conductor delphi ask failed ({proc.returncode}): {proc.stderr.strip()[-400:]}")
        return proc.stdout, {"profile": DIRECTOR_PROFILE, "stderr_tail": _tail(proc.stderr.encode())}
    out = workdir / name
    target = opts.get("target") or {"provider": "anthropic", "model": opts["model"], "effort": "high"}
    argv = [opts["delphi"], "run", "-provider", target["provider"], "-model", target["model"]]
    if target.get("effort"):
        argv += ["-effort", target["effort"]]
    argv += ["-every", "30s", "-out", str(out), "-prompt", prompt.read_text(encoding="utf-8")]
    proc = subprocess.run(argv, capture_output=True, text=True, env=_delphi_env(opts))
    results = out / "results.jsonl"
    if proc.returncode != 0 or not results.is_file():
        raise CardError(f"delphi run failed ({proc.returncode}): {proc.stderr.strip()[-400:]}")
    rows = [json.loads(line) for line in results.read_text(encoding="utf-8").splitlines() if line.strip()]
    result = rows[-1]
    meta = {k: result.get(k) for k in ("status", "model", "batch_id", "usage", "stop_reason", "truncated")}
    if result.get("status") == "refused":
        raise _Refused(f"the model declined: {json.dumps(result.get('refusal'))}")
    if result.get("status") != "succeeded":
        raise CardError(f"delphi returned status {result.get('status')}: "
                        f"{json.dumps(result.get('refusal') or result.get('error'))}")
    return result["text"], meta


def lane(designs: list[str], binds: list[str], card_out: str, assessment_out: str, via: str = "auto",
         opts: dict[str, Any] | None = None, repo: Path = REPO, say=print) -> int:
    """Exit status: 0 ran and assessed; 1 a reply was refused (nothing written for it);
    2 impediment (no backend, a call failed, a path already exists); 3 the run stopped at a
    failing command and was assessed."""
    opts = {"conductor": os.environ.get("CONDUCTOR", "conductor"),
            "delphi": os.environ.get("DELPHI", "delphi"), "model": DIRECTOR_MODEL, **(opts or {})}
    opts["free"] = opts.get("free") or os.environ.get("DELPHI_FREE") or None
    card_out, assessment_out = safe_relative(card_out), safe_relative(assessment_out)
    workdir = repo / (card_out.rsplit(".", 1)[0] + ".lane")
    record: dict[str, Any] = {"card": card_out, "assessment": assessment_out, "calls": {}}
    try:
        for path in (card_out, assessment_out):
            if (repo / path).exists():
                raise CardError(f"{path} already exists; cards and assessments are write-once")
        if workdir.exists():
            raise CardError(f"{rel(repo, workdir)} already exists; every lane gets a fresh record")
        if opts.get("free") and opts["free"] not in FREE_MODES:
            raise CardError(f"--free must be one of {', '.join(FREE_MODES)}, not {opts['free']!r}")
        # Routing is Delphi's capability registry and free mode is DELPHI_FREE; both are
        # standalone delphi's, and Conductor-hosted Delphi uses its fixed, paid director profile.
        needs = [flag for flag, on in (("--route", opts.get("route")), ("--free (DELPHI_FREE)", opts.get("free")))
                 if on]
        if needs:
            if via == "conductor":
                raise CardError(f"{' and '.join(needs)} needs standalone delphi; Conductor-hosted Delphi "
                                "uses its fixed director profile")
            if not shutil.which(opts["delphi"]):
                raise CardError(f"{' and '.join(needs)} needs the delphi binary ({opts['delphi']} not found)")
            backend = "delphi"
        else:
            backend = pick_backend(via, opts["conductor"], opts["delphi"])
        record["backend"] = backend
        if opts.get("free"):
            record["free"] = opts["free"]
        say(f"LANE backend {backend}" + (f", free mode ({opts['free']})" if opts.get("free") else ""))
        workdir.mkdir(parents=True)

        def call(stage: str, text: str, accept) -> list[str]:
            """Ask, and let accept (ingest) judge the reply; with --route a refused reply goes to
            the next model in the escalation chain, except a compile reply whose findings are all
            specification errors: that is the design's gap, not the model's."""
            prompt = workdir / f"{stage}.prompt.md"
            prompt.write_text(text, encoding="utf-8")
            targets: list[dict[str, str] | None] = [None]
            if opts.get("route"):
                plan = route_for(FAMILY[stage], opts)
                record.setdefault("routes", {})[stage] = plan
                say(f"LANE {stage}: routed to {plan['choice']} ({plan['basis']})")
                targets = [_target(t) for t in [plan["choice"], *plan["escalation"]]]
            findings: list[str] = []
            for attempt, target in enumerate(targets):
                name = stage if attempt == 0 else f"{stage}-escalation-{attempt}"
                say(f"LANE {name}: submitted" + (f" to {target['provider']}:{target['model']}" if target else "")
                    + ", waiting for the batch")
                try:
                    answer, meta = _ask(backend, prompt, workdir, name, dict(opts, target=target))
                except _Refused as exc:
                    record["calls"][name] = {"prompt_sha256": sha256_bytes(text.encode()), "target": target,
                                             "refused": str(exc)}
                    findings = [str(exc)]
                    say(f"LANE {name}: {exc}")
                    continue
                (workdir / f"{name}.reply.md").write_text(answer, encoding="utf-8")
                findings = accept(answer)
                record["calls"][name] = {"prompt_sha256": sha256_bytes(text.encode()),
                                         "reply_sha256": sha256_bytes(answer.encode()), "target": target,
                                         "accepted": not findings, **meta}
                say(f"LANE {name}: answered" + (f" (batch {meta['batch_id']}, usage {json.dumps(meta['usage'])})"
                                                if meta.get("batch_id") else ""))
                if not findings or all(f.startswith("specification_error:") for f in findings):
                    return findings
                if attempt + 1 < len(targets):
                    say(f"LANE {name}: refused by the tool ({findings[0]}); escalating")
            return findings

        findings = call("compile", compile_request(designs, binds, card_out, repo),
                        lambda reply: ingest(reply, card_out, "card", None, repo))
        if findings:
            record["outcome"] = "card_refused"
            for item in findings:
                say(f"INGEST: {item}")
            say(f"LANE FAIL card refused; replies kept in {rel(repo, workdir)}")
            return 1
        card_path, card_sha, card = load_card(card_out, repo)
        say(f"CARD OK {card_path} sha256 {card_sha}")
        receipt = run_card(card_path, card_sha, card, repo)
        say(brief(receipt, card["receipt"], sha256_file(repo / card["receipt"])))
        findings = call("assess", assess_request(card_path, card_sha, card, None, repo),
                        lambda reply: ingest(reply, assessment_out, "assessment", card, repo))
        if findings:
            record["outcome"] = "assessment_refused"
            for item in findings:
                say(f"INGEST: {item}")
            say(f"LANE FAIL assessment refused; replies kept in {rel(repo, workdir)}")
            return 1
        verdict = yaml.safe_load((repo / assessment_out).read_text(encoding="utf-8"))["execution_assessment"]
        record.update(outcome=verdict["outcome"], recommendation=verdict["recommendation"],
                      card_sha256=card_sha, receipt=card["receipt"])
        say(f"LANE OK {verdict['outcome']} -> {verdict['recommendation']}; assessment {assessment_out}")
        return 0 if receipt["status"] == "completed" else 3
    except CardError as exc:
        record["outcome"] = "impeded"
        record["impediment"] = str(exc)
        say(f"IMPEDIMENT {exc}")
        return 2
    finally:
        if workdir.is_dir():
            (workdir / "lane.json").write_text(json.dumps(record, indent=2, sort_keys=True) + "\n",
                                               encoding="utf-8")


def _main_batch(args) -> int:
    try:
        if args.command == "request" and args.mode == "compile":
            sys.stdout.write(compile_request(args.design, args.bind or [], args.out) + "\n")
            return 0
        card = None
        if args.card:
            card_path, card_sha, card = load_card(args.card)
        if args.command == "request":
            report = Path(args.report).read_text(encoding="utf-8") if args.report else None
            sys.stdout.write(assess_request(card_path, card_sha, card, report) + "\n")
            return 0
        if args.expect == "assessment" and card is None:
            raise CardError("ingest --expect assessment needs --card")
        reply = Path(args.reply).read_text(encoding="utf-8")
        findings = ingest(reply, args.out, args.expect, card)
    except CardError as exc:
        print(f"CARD ERROR {exc}")
        return 2
    for item in findings:
        print(f"INGEST: {item}")
    print(f"INGEST {'FAIL' if findings else 'OK'} {args.out}")
    return 1 if findings else 0


def main(argv: list[str] | None = None) -> int:
    parser = argparse.ArgumentParser(description=__doc__.split("\n\n")[0])
    sub = parser.add_subparsers(dest="command", required=True)
    for name in ("lint", "prompt", "run"):
        sub.add_parser(name).add_argument("card")
    relay = sub.add_parser("check-relay")
    relay.add_argument("card")
    relay.add_argument("--report", required=True, help="the executor's returned text, saved to a file")
    request = sub.add_parser("request", help="a self-contained director prompt for a batch API")
    request.add_argument("mode", choices=("compile", "assess"))
    request.add_argument("card", nargs="?", help="assess: the card")
    request.add_argument("--design", action="append", help="compile: a decided design file (repeatable)")
    request.add_argument("--bind", action="append", help="compile: a file whose sha256 the card binds")
    request.add_argument("--out", help="compile: where the card will be written")
    request.add_argument("--report", help="assess: an executor's relayed text, when one relayed")
    take = sub.add_parser("ingest", help="validate a batch reply and write it write-once")
    take.add_argument("reply")
    take.add_argument("--expect", choices=("card", "assessment"), required=True)
    take.add_argument("--out", required=True)
    take.add_argument("--card", help="assessment: the card it assesses")
    run_lane = sub.add_parser("lane", help="compile, run and assess end to end through a batch backend")
    run_lane.add_argument("--design", action="append", required=True, help="a decided design file (repeatable)")
    run_lane.add_argument("--bind", action="append", help="a file whose sha256 the card binds")
    run_lane.add_argument("--card", required=True, help="where the card is written")
    run_lane.add_argument("--assessment", required=True, help="where the assessment is written")
    run_lane.add_argument("--via", choices=("auto", "conductor", "delphi"), default="auto")
    run_lane.add_argument("--task", help="conductor: link each delegation to this Conductor task")
    run_lane.add_argument("--model", default=DIRECTOR_MODEL, help="delphi: the director model")
    run_lane.add_argument("--route", action="store_true",
                          help="let `delphi route` choose each step's model and escalate refused replies")
    run_lane.add_argument("--free", choices=FREE_MODES,
                          help="delphi free mode: only models that cost nothing (public: free remote tiers too, "
                               "for public or synthetic designs only)")
    args = parser.parse_args(argv)
    if args.command == "lane":
        return lane(args.design, args.bind or [], args.card, args.assessment, args.via,
                    {"task": args.task, "model": args.model, "route": args.route, "free": args.free})
    if args.command in ("request", "ingest"):
        if args.command == "request" and args.mode == "compile" and not (args.design and args.out):
            parser.error("request compile needs --design and --out")
        if args.command == "request" and args.mode == "assess" and not args.card:
            parser.error("request assess needs the card")
        return _main_batch(args)

    try:
        card_path, card_sha, card = load_card(args.card)
    except CardError as exc:
        print(f"CARD ERROR {exc}")
        return 2
    if args.command == "run":
        try:
            receipt = run_card(card_path, card_sha, card)
        except CardError as exc:
            print(f"IMPEDIMENT {exc}")
            return 2
        receipt_path = REPO / card["receipt"]
        print(brief(receipt, card["receipt"], sha256_file(receipt_path)))
        return 0 if receipt["status"] == "completed" else 3
    findings = lint(card)
    if args.command == "lint" or findings:
        for item in findings:
            print(f"CARD: {item}")
        print(f"CARD {'FAIL' if findings else 'OK'} {card_path} sha256 {card_sha}")
        return 1 if findings else 0
    if args.command == "prompt":
        sys.stdout.write(render_prompt(card_path, card_sha, card))
        return 0
    report = Path(args.report).read_text(encoding="utf-8")
    result = check_relay(card, report)
    print(json.dumps(result, indent=2, sort_keys=True))
    clean = result["relay_verbatim"] and not result["verify_findings"]
    return 0 if clean else 1


if __name__ == "__main__":
    sys.exit(main())
