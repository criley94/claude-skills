#!/usr/bin/env python3
"""Open-work substrate for the turn-boundary completion lock — v3.56.0.

The reported failure: an Agent Teams session ends its turn with work still
open, and fills the turn boundary with a summary. Every previous remedy put the
stopping condition somewhere the AGENT controls — an instruction it reads, a
promise string it types, a summary it decides is complete enough. This module
puts the stopping condition in files the HARNESS writes:

  * the harness task list at ``~/.claude/tasks/session-<first-8>/<taskId>.json``
    (``status`` in ``pending`` / ``in_progress`` / ``completed``, plus an
    ``owner``), and
  * the session transcript, from which the user's directives are DERIVED into
    an accumulating ask-ledger — so an agent cannot decline to register an ask
    it would rather not do.

``hooks/pipeline-completion-audit.py`` calls :func:`evaluate_completion_lock`
from ``main()``; everything here is pure computation plus bounded reads/writes.

KILL-SWITCHES (the only release; the agent can never decide to stop, the user
always can). Each is the usual ``CT6_*_DISABLED`` truthy-env shape, matching
``run_continuity.continuity_disabled()``:

  * ``CT6_COMPLETION_LOCK_DISABLED``  — master; disables the whole lock.
  * ``CT6_TASK_LIST_GATE_DISABLED``   — the harness-task-list source only.
  * ``CT6_ASK_LEDGER_GATE_DISABLED``  — stops the ask-ledger recording at all.
  * ``CT6_TURN_OUTPUT_GATE_DISABLED`` — the one-line-of-state rule only.
  * ``CT6_ASK_LEDGER_BLOCKING``       — OPT-IN; lets the ledger refuse a stop.

Per-source switches matter: disabling a noisy ledger must not disable the
task-list gate that works.

WHICH SOURCES MAY REFUSE A STOP — only two, and the split is the point:

  * The task list MAY block: the HARNESS writes ``status``, so "done" is a fact
    this gate reads rather than a claim it is told.
  * The turn-output rule MAY block: whether a turn is a narrative is decidable
    from the text itself.
  * The ask-ledger is ADVISORY. It knows a directive was GIVEN; it cannot know
    it was MET. Shipped as a blocking source it made an ordinary session — one
    request, no tasks — unexitable forever, because nothing ever closed an
    entry. A source that cannot verify its own release condition must not hold a
    session hostage, and the reliable half of a gate must not be taken down by
    the half that cannot tell done from not-done. Recording stays involuntary
    and the asks are surfaced whenever something else blocks; they are simply
    not the thing refusing the stop unless ``CT6_ASK_LEDGER_BLOCKING`` is set.

TWO FAILURE MODES, DELIBERATELY DIFFERENT (REQ-6):

  * This module's own code raising is handled by ``main()``'s fail-open wrapper
    — a bug here must never wedge a session.
  * A source that could NOT BE READ is unknown state, and unknown state is not
    "empty". Read failures are returned as DATA (``unreadable[]``), so the
    caller BLOCKS and names the file. A blanket fail-open there would let one
    malformed task JSON reproduce the exact bug this exists to fix.

Stdlib-only. No import-time side effects, no I/O at import.
"""
from __future__ import annotations

import hashlib
import json
import os
import re
import sys
import time
from pathlib import Path
from typing import Any

# --- reuse (dual-form import per house convention) ---------------------------
# RD-4/RD-5/RD-7: the transcript readers, the teammate token, and the atomic
# write all come from run_continuity. Building a second transcript reader or a
# second write path would drift from the one the engagement detector uses.
try:  # package shape (repo root on sys.path)
    from hooks import run_continuity as _rc
except ImportError:  # pragma: no cover - bare-module shape (hooks/ on sys.path)
    import run_continuity as _rc  # type: ignore[no-redef]

try:
    from hooks.shared_util import _utc_now_iso
except ImportError:  # pragma: no cover - bare-module shape
    from shared_util import _utc_now_iso  # type: ignore[no-redef]


# --- kill-switches -----------------------------------------------------------

DISABLE_ENV = "CT6_COMPLETION_LOCK_DISABLED"        # master
DISABLE_TASKS_ENV = "CT6_TASK_LIST_GATE_DISABLED"   # harness task-list source
DISABLE_LEDGER_ENV = "CT6_ASK_LEDGER_GATE_DISABLED"  # ask-ledger source
DISABLE_OUTPUT_ENV = "CT6_TURN_OUTPUT_GATE_DISABLED"  # turn-output rule

#: The injected task-root override. This is the TEST SEAM — the suite points it
#: at a tmp_path so no test can reach the developer's real ``~/.claude/tasks``.
TASKS_ROOT_ENV = "CT6_TASKS_ROOT"

#: The task-abandonment window (v3.64.0, D1). Harness task lists OUTLIVE
#: sessions — resume / continue / compact keeps the same store, teams keep the
#: team store, and the harness carries lists across session forks — so an open
#: task is not, by itself, evidence that THIS session has work to close. A
#: field-reported wedge held every turn of a live workspace on four tasks whose
#: owning sessions had been terminated days earlier, with no release except an
#: env kill-switch. An open task whose FILE has gone untouched longer than this
#: window is therefore INHERITED DEBT: surfaced in the block, never blocking.
#: (Precedents: the run-marker staleness window — "an abandoned run's marker
#: must not tax the workspace forever", review remediation #3 — and the
#: v3.55.0 frontend-E2E pre-existing-debt split.)
#:
#: The mtime is the discriminator because it is the only HARNESS-WRITTEN time
#: signal a task carries (the JSON has no timestamps, and the harness rewrites
#: the file on every TaskUpdate — so working an inherited task revives it).
#: Backdating an mtime through Bash remains the same NAMED residual every
#: filesystem gate in this plugin carries.
#:
#: Defaults to the RESOLVED run-marker window (``CT6_RUN_MARKER_STALE_HOURS``,
#: 72h): one abandonment lever unless the operator says otherwise. The
#: dedicated override below is floored exactly like the marker's (the S-3
#: lesson): a window that can be collapsed to nothing is a kill-switch that
#: does not look like one.
TASK_STALE_HOURS_ENV = "CT6_TASK_STALE_HOURS"
MIN_TASK_STALE_HOURS = 1.0
DEFAULT_TASK_STALE_HOURS = 72.0

#: Statuses the harness writes for work that is NOT finished.
OPEN_STATUSES = frozenset({"pending", "in_progress"})

#: The only status that means "done". Everything else — missing, empty, or a
#: value this version does not recognize — counts as OPEN. The asymmetry is
#: deliberate: unknown state is not "done".
TERMINAL_STATUSES = frozenset({"completed"})

#: Sidecar files the harness keeps beside the task JSONs. Skipped BY NAME, never
#: via a silent parse failure — anything else unparseable must surface.
TASK_SIDECARS = frozenset({".lock", ".highwatermark"})

#: The ask-ledger, under ``<workspace>/.architect-team/``.
LEDGER_FILENAME = "ask-ledger.json"

#: A turn is a narrative at or above this many REPORT-LENGTH lines (see
#: NARRATIVE_MIN_LINE_CHARS).
#:
#: RAISED 3 -> 6 (H1). At 3 this fired on ordinary inter-tool narration: natural
#: sentences run 45-60 chars, so an agent saying what it is about to do three
#: times measured as a 3-line report and was refused. G3 was reported as "six
#: one-line narration blocks" and fixed by raising the CEILING, which only ever
#: reached the short-line arm — the class was never fixed and this constant was
#: the unfixed half. Six report-length lines in one turn is more report than
#: narration; G3's original short lines are unaffected because
#: `report_length_lines` ignores anything under NARRATIVE_MIN_LINE_CHARS.
NARRATIVE_LINE_THRESHOLD = 6

#: A turn under this many non-whitespace chars is a state line even on one line.
#: Above it, an unbroken paragraph is a report that merely lacks newlines.
#: Measured on the RAW turn text (``len(text.strip())``), so the number means
#: what it says — it used to be measured after whitespace removal, which put the
#: real threshold near 715 raw characters (F5).
NARRATIVE_PROSE_CHARS = 600

#: Markers become decisive at this many non-empty lines. Below it the one-line
#: floor is absolute: a single marked line is state, not a report (F4).
NARRATIVE_MARKER_LINES = 2

#: A markerless line shorter than this is terse state and does not count toward
#: the line threshold (F6). See the measured basis in ``classify_turn_output``.
NARRATIVE_MIN_LINE_CHARS = 24

#: The ceiling above NARRATIVE_MIN_LINE_CHARS (T2). Counting only report-length
#: lines left the line arm with no upper bound, so a report made ENTIRELY of
#: short lines never reached it — 30 lines at 19 chars is 569 characters, under
#: the prose arm too.
#:
#: RAISED 6 -> 12 (G3). At 6 this fired on the ordinary shape of an agent
#: narrating between tool calls — six one-line blocks ("Running step 1." …
#: "Running step 6.") concatenate to six lines with no report anywhere in them.
#: That was live. 12 clears a normal 6-10 line working turn and still catches
#: T2's 30-line case with margin.
NARRATIVE_ABSOLUTE_LINES = 12

#: The ask-ledger is ADVISORY by default and does not block on its own.
#:
#: It records a directive but cannot tell DONE from NOT-DONE without semantics,
#: and a gate that cannot verify its own release condition is not a gate — the
#: first cut blocked an ordinary session forever after a single request, because
#: nothing ever closed an entry. Recording stays involuntary and useful: open
#: asks are surfaced whenever something else blocks, so the agent sees every
#: outstanding directive. Set this to a truthy value to make the source block on
#: its own, which is only sane once a resolution path is wired.
LEDGER_BLOCKING_ENV = "CT6_ASK_LEDGER_BLOCKING"


def _env_truthy(name: str) -> bool:
    """The ``run_continuity.continuity_disabled()`` truthy-env shape."""
    v = os.environ.get(name, "").strip().lower()
    return v not in ("", "0", "false", "no")


def lock_disabled() -> bool:
    """True when the master kill-switch is set truthy."""
    return _env_truthy(DISABLE_ENV)


def tasks_disabled() -> bool:
    """True when the harness-task-list source is switched off."""
    return _env_truthy(DISABLE_TASKS_ENV)


def ledger_disabled() -> bool:
    """True when the ask-ledger source is switched off entirely (no recording)."""
    return _env_truthy(DISABLE_LEDGER_ENV)


def ledger_blocking() -> bool:
    """True when the ask-ledger may refuse a stop ON ITS OWN. Default: False.

    The harness-task-list source can block because the harness writes `status`,
    so "done" is a fact the gate reads. The ledger has no such signal — it knows
    a directive was GIVEN, never that it was MET. Blocking on it made an
    ordinary session unexitable after one request, which is the failure mode
    that gets the whole gate switched off. Advisory by default; opt in only once
    something can genuinely close an entry.
    """
    return _env_truthy(LEDGER_BLOCKING_ENV)


def output_disabled() -> bool:
    """True when the one-line-of-state turn-output rule is switched off."""
    return _env_truthy(DISABLE_OUTPUT_ENV)


# --- the harness task list ---------------------------------------------------


def tasks_root(explicit: str | Path | None = None) -> Path:
    """The harness task store root.

    Precedence, highest first: an ``explicit`` argument, the ``CT6_TASKS_ROOT``
    override, then the real ``~/.claude/tasks``. The explicit argument is what
    makes every reader testable without touching the user's real store.
    """
    if explicit:
        return Path(explicit)
    env = os.environ.get(TASKS_ROOT_ENV, "").strip()
    if env:
        return Path(env)
    return Path.home() / ".claude" / "tasks"


def _read_failure_reason(exc: BaseException) -> str:
    """A short, human-readable reason for a source-read failure."""
    if isinstance(exc, json.JSONDecodeError):
        return f"invalid JSON at line {exc.lineno} column {exc.colno}"
    if isinstance(exc, UnicodeDecodeError):
        return "not valid UTF-8"
    if isinstance(exc, OSError):
        return f"unreadable ({exc.strerror or exc.__class__.__name__})"
    return f"unreadable ({exc.__class__.__name__})"


def read_harness_tasks(
    session_id: str | None,
    root: str | Path | None = None,
) -> dict[str, Any]:
    """Read one session's harness task files.

    Returns ``{"items": [...], "unreadable": [...], "dir": <str|None>}`` where
    each item is the parsed task JSON plus a ``_path`` key, and each unreadable
    entry is ``{"path": ..., "reason": ...}``.

    **This never raises for a bad file.** Read failures are DATA, which is what
    lets the caller block-and-name a corrupt store (REQ-6) instead of reading it
    as empty. A missing session dir is genuinely empty and yields no unreadable
    entry — a session that never registered a task must not be blocked.
    """
    result: dict[str, Any] = {"items": [], "unreadable": [], "dir": None}
    sid = session_id.strip() if isinstance(session_id, str) else ""
    if not sid:
        return result

    resolved_root = tasks_root(root)
    session_dir = resolved_root / f"session-{sid[:8]}"
    result["dir"] = str(session_dir)
    # v3.60.0 (F13) — a missing ROOT is unknown; a missing SESSION DIR is empty.
    # These were collapsed, and the difference is the whole contract: this
    # module blocks on an unreadable source because "unknown is not empty", yet
    # pointing CT6_TASKS_ROOT at a path that does not exist read as a clean
    # pass and released the stop. Measured — an open task blocked, the same
    # session with the root redirected to a nonexistent path exited 0.
    #
    # The session dir stays the honest empty case: a session that has simply
    # registered nothing is the ordinary state and must never wedge.
    try:
        if not resolved_root.is_dir():
            result["unreadable"].append({
                "path": str(resolved_root),
                "reason": "the harness task root does not exist, so whether "
                          "work is registered cannot be determined",
            })
            return result
    except Exception as exc:
        result["unreadable"].append({
            "path": str(resolved_root),
            "reason": f"the harness task root could not be examined: "
                      f"{type(exc).__name__}",
        })
        return result
    try:
        if not session_dir.is_dir():
            return result
        entries = sorted(session_dir.iterdir())
    except Exception as exc:
        # F2: NOT (OSError, ValueError) — a RecursionError from a nested-JSON
        # bomb escaped that tuple and broke the property all of REQ-6 rests on.
        # "Read failures are DATA" must hold for every malformed input, not the
        # two shapes that were anticipated.
        result["unreadable"].append(
            {"path": str(session_dir), "reason": _read_failure_reason(exc)}
        )
        return result

    for path in entries:
        if path.name in TASK_SIDECARS:
            continue
        try:
            if not path.is_file():
                result["unreadable"].append(
                    {"path": str(path), "reason": "not a regular file"}
                )
                continue
            data = json.loads(path.read_text(encoding="utf-8"))
        except Exception as exc:  # F2 — see the sibling note above
            result["unreadable"].append(
                {"path": str(path), "reason": _read_failure_reason(exc)}
            )
            continue
        if not isinstance(data, dict):
            result["unreadable"].append(
                {"path": str(path), "reason": "not a JSON object"}
            )
            continue
        item = dict(data)
        item["_path"] = str(path)
        try:
            # The harness rewrites the file on every TaskUpdate, so this is the
            # last time the HARNESS moved the task — the abandonment signal D1
            # reads. A stat failure leaves the key absent and the task LIVE:
            # unknown is not abandoned, matching the lock's unknown-is-not-done
            # asymmetry everywhere else.
            item["_mtime"] = path.stat().st_mtime
        except OSError:
            pass
        result["items"].append(item)
    return result


def _status_is_open(item: dict[str, Any]) -> bool:
    raw = item.get("status")
    status = raw.strip().lower() if isinstance(raw, str) else ""
    if status in OPEN_STATUSES:
        return True
    return status not in TERMINAL_STATUSES  # missing / unknown -> OPEN


def open_task_items(
    items: list[dict[str, Any]],
    owner: str | None = None,
) -> list[dict[str, Any]]:
    """The still-open tasks, optionally scoped to one ``owner``.

    Owner-scoping is what keeps a pipeline teammate honest without wedging it:
    it is held for its own lanes and never for lanes it has no power to close.
    """
    out: list[dict[str, Any]] = []
    for item in items or []:
        if not isinstance(item, dict) or not _status_is_open(item):
            continue
        if owner is not None and item.get("owner") != owner:
            continue
        out.append(item)
    return out


def task_stale_hours() -> float:
    """The resolved task-abandonment window in hours.

    ``CT6_TASK_STALE_HOURS`` when set to a positive number (floored at
    :data:`MIN_TASK_STALE_HOURS`, the S-3 rule); otherwise the RESOLVED
    run-marker window, so by default the two abandonment levers are one lever.
    """
    raw = os.environ.get(TASK_STALE_HOURS_ENV, "").strip()
    try:
        h = float(raw)
    except ValueError:
        h = 0.0
    if h > 0:
        return max(h, MIN_TASK_STALE_HOURS)
    try:
        return max(float(_rc.marker_stale_hours()), MIN_TASK_STALE_HOURS)
    except Exception:
        return DEFAULT_TASK_STALE_HOURS


def partition_stale_tasks(
    items: list[dict[str, Any]],
    now: float | None = None,
) -> tuple[list[dict[str, Any]], list[dict[str, Any]]]:
    """Split open tasks into ``(live, stale)`` by file age.

    Stale = the harness has not touched the task file for longer than
    :func:`task_stale_hours`. An item with no readable ``_mtime`` is LIVE —
    unknown is not abandoned, and the conservative direction on this gate is
    the blocking one. A future-dated mtime is trivially fresh.
    """
    ts = time.time() if now is None else float(now)
    window = task_stale_hours() * 3600.0
    live: list[dict[str, Any]] = []
    stale: list[dict[str, Any]] = []
    for item in items or []:
        mtime = item.get("_mtime") if isinstance(item, dict) else None
        if isinstance(mtime, (int, float)) and (ts - float(mtime)) > window:
            stale.append(item)
        else:
            live.append(item)
    return live, stale


# --- the turn-output classifier ----------------------------------------------
#
# Both directions are pinned by tests. A rule that never fires is decoration; a
# rule that fires on a legitimate terse status update gets disabled by the user,
# which is the same as not shipping it. The <= 3-space indent allowances are
# CommonMark's: at 4+ spaces the line is a code block, not a heading or a list.

_FENCE_RE = re.compile(r"^ {0,3}(?:```|~~~)")
_HEADING_RE = re.compile(r"^ {0,3}#{1,6}(?:\s|$)")
# H4 — the bullet vocabulary was ASCII-only (`-`, `*`, `+`), and in the 2-line
# band the marker arm is the ONLY arm that can fire: `too_many_lines` needs 12
# and the prose arm needs 600 chars. So the spec's named catch — "a two-line
# summary carrying a heading, bullet list, bold-label block, or table" — rested
# on three exact ASCII characters, and a one-character substitution defeated it.
# Measured: `• built it / • tests green` and an en-dash list both
# evaded while the ASCII spelling tripped. Widened to the glyphs a model
# actually emits: bullet, white bullet, hyphen-bullet, triangular bullet,
# en/em dash, and the arrow forms.
_BULLET_RE = re.compile("^ {0,3}[-*+•◦⁃‣·–—→➤▪●▸]\\s")
_NUMBERED_RE = re.compile(r"^ {0,3}\d{1,9}[.)]\s")
# Both spellings of a bold label opening a line: ``**Label:**`` and ``**Label**:``.
_BOLD_LABEL_RE = re.compile(r"^ {0,3}\*\*[^*]+?(?::\*\*|\*\*\s*:)")

_MARKER_RULES = (
    ("heading", _HEADING_RE),
    ("bullet", _BULLET_RE),
    ("numbered", _NUMBERED_RE),
    ("bold-label", _BOLD_LABEL_RE),
)


def _is_table_row(stripped: str) -> bool:
    """A pipe in TABLE position — the line opens with ``|`` and closes a cell.

    Requiring the leading pipe is what keeps prose like ``pipe a | b to sort``
    from reading as a table.
    """
    return stripped.startswith("|") and stripped.count("|") >= 2


def classify_turn_output(text: str) -> dict[str, Any]:
    """Classify a turn's assistant text. Pure function, no I/O.

    The caller passes ALL assistant text in the turn (every block since the last
    genuine user prompt) via :func:`_turn_assistant_text` — not the last block.
    That is load-bearing: it is what closes the "write the summary, then end
    with `Working.`" sign-off evasion.

    Returns ``{"narrative": bool, "reason": str, "lines": int, "markers": [...]}``.

    Narrative when ANY of:
      * a structural marker at ``>= NARRATIVE_MARKER_LINES`` lines — heading,
        bullet (ASCII or Unicode), numbered item, bold-label block, table row;
      * ``>= NARRATIVE_ABSOLUTE_LINES`` non-empty lines, whatever their length;
      * more than ``NARRATIVE_PROSE_CHARS`` raw chars of unbroken prose.

    NEVER narrative on a ONE-LINE turn, whatever markers it carries.

    The ``>= 3 report-length lines`` arm is RETIRED (H1) — it fired on three
    ordinary narration sentences. STRUCTURE identifies a report; markerless
    prose of 3..11 lines under the prose threshold is deliberately allowed.
    """
    if not isinstance(text, str) or not text.strip():
        return {"narrative": False, "reason": "empty turn output",
                "lines": 0, "markers": []}

    raw_lines = text.splitlines()
    # An UNTERMINATED fence opens nothing. Otherwise an agent could write a bare
    # ``` and every marker after it would be invisible to the marker arm — a
    # bulleted summary hidden behind one line. Only BALANCED delimiters suppress,
    # so a dangling one is dropped before the scan begins.
    fence_lines = [i for i, ln in enumerate(raw_lines) if _FENCE_RE.match(ln)]
    toggles = set(fence_lines[:-1] if len(fence_lines) % 2 else fence_lines)
    fence_delimiters = set(fence_lines)

    # THREE counters, THREE different arms, and they are NOT interchangeable.
    # Each name states exactly what it counts, because the last time this
    # distinction lived in a comment instead of the names, an arm was written
    # against the wrong counter and shipped (T4). They nest strictly:
    #
    #   all_nonempty_lines >= unfenced_lines >= report_length_lines
    #
    #   all_nonempty_lines   every non-empty line, FENCED CONTENT INCLUDED.
    #                        Feeds `too_many_lines` (G1 — a summary hidden in a
    #                        fence has to register somewhere) and the reported
    #                        `lines` total. NOT a cosmetic counter.
    #   unfenced_lines       non-empty lines OUTSIDE fences, any length. Feeds
    #                        `marked_report` — markers can only be found out
    #                        here, so this is the count that matches them.
    #   report_length_lines  unfenced lines of >= NARRATIVE_MIN_LINE_CHARS.
    #                        Feeds `long_enough`; the length floor is what keeps
    #                        terse state lines out of the report arm (F6).
    #
    # Adding an arm? Pick by what the arm MEANS, not by which name is nearest.
    # Measured on the classifier's own corpus test: 10 of 40 inputs separate
    # all_nonempty from unfenced, and 25 of 40 separate unfenced from
    # report-length. Substituting one for another is a behaviour change.
    all_nonempty_lines = 0
    unfenced_lines = 0
    report_length_lines = 0
    markers: list[str] = []
    in_fence = False
    for index, raw_line in enumerate(raw_lines):
        stripped = raw_line.strip()
        if not stripped:
            continue
        all_nonempty_lines += 1
        if index in toggles:
            in_fence = not in_fence
            continue
        if in_fence or index in fence_delimiters:
            # T4: code is not report prose. Fenced lines are excluded from
            # `unfenced_lines` and `report_length_lines` — counting them made a
            # perfectly ordinary status update carrying a three-line snippet
            # measure 6 lines and trip.
            #
            # They are deliberately still IN `all_nonempty_lines`, which is
            # incremented above this branch: G1 put the ceiling arm back on the
            # full count, because excluding fences everywhere left a summary
            # wrapped in a fence invisible to every arm but the 600-char one.
            continue
        for name, pattern in _MARKER_RULES:
            if pattern.match(raw_line) and name not in markers:
                markers.append(name)
        if _is_table_row(stripped) and "table-row" not in markers:
            markers.append("table-row")
        # F6: a SHORT line is state, not report prose, and must not push a terse
        # status update over the line-count threshold.
        # `task 2 in progress / task 3 pending / no blockers` is 3 lines and 37
        # characters — the shape the block message ASKS for. Measured basis for
        # the constant: that report's longest line is 18 chars, while the
        # shortest line of a genuine multi-line report measured here is 25, so
        # the boundary sits between them with margin on both sides. (The
        # reviewer suggested ~40; that would have excluded real report lines.)
        #
        # This rule deliberately does NOT exempt marked lines. The first cut did
        # ("a bullet is a summary however short"), and the mutation harness
        # showed the clause was DEAD: `marked_report` below already fires on any
        # marker at >= 2 lines, while this arm needs >= 3, so a marked line can
        # never be the deciding count. A short bullet list is still a narrative
        # — via markers, which is the honest route.
        unfenced_lines += 1
        if len(stripped) >= NARRATIVE_MIN_LINE_CHARS:
            report_length_lines += 1

    # Three arms, each catching a shape the others miss.
    #
    # F4 — markers decide again at >= 2 lines. Making the length floor dominate
    # removed the unbreakable loop and most of the enforcement with it: a 2-line
    # bullet summary, `## Summary` plus a line, a 2-row table and a
    # `**Done:** / **Remaining:**` pair all slipped, and every one of them is
    # unmistakably the "I fill it with a summary" shape this rule exists to
    # catch. The ONE-LINE FLOOR IS ABSOLUTE and is what the loop fix really
    # needed: `**Status:** still on task 1 of 9.` is a single line, so markers
    # never make it a narrative. A marker cannot indicate report STRUCTURE in a
    # turn too short to have any.
    #
    # F5 — the prose arm measures RAW text. It used to measure after
    # `"".join(text.split())`, so the real threshold was ~715 raw characters and
    # a 700-char paragraph slipped at 560 measured. The constant now means what
    # it says.
    #
    # Each arm below names the counter it means; see the counter contract at the
    # top of the loop. This comment previously read "every arm counts PROSE
    # lines, `line_count` is just for reporting" — TRUE at T4, made FALSE by G1
    # when the ceiling went back on the full count, and left uncorrected. A
    # reader who trusted it would conclude one counter was cosmetic and be free
    # to substitute the other, which is T4 exactly. The names now carry this so
    # a stale comment cannot mislead the same way twice.
    body = text.strip()
    # H1 — the `long_enough` arm is RETIRED, and this is the sixth revision of
    # this rule, so the reasoning is recorded rather than the change alone.
    #
    # It fired at `report_length_lines >= 3`, which counts unfenced lines of
    # >= NARRATIVE_MIN_LINE_CHARS (24). G3 was reported as "six one-line
    # narration blocks" and fixed by raising the CEILING 6 -> 12 — which only
    # ever reached the `too_many_lines` arm. The class was never fixed: ordinary
    # inter-tool narration at natural sentence length runs 45-60 chars, so the
    # identical scenario tripped at THREE sentences. Measured on the shipped
    # module: three narration sentences of 59 / 62 / 56 chars -> narrative=True.
    # Narrating between tool calls is the single most common thing an agent
    # does, and with work open every such turn was refused with an instruction
    # it had already satisfied.
    #
    # There is no threshold that separates "three narration sentences" from
    # "a three-line markerless report" — they are the same shape. Rather than
    # tune a seventh time, markerless prose is now caught only where the signal
    # is unambiguous: sheer volume (the 12-line ceiling) or sheer length (the
    # 600-char prose arm). STRUCTURE is what identifies a report, and the marker
    # arm carries that at >= 2 lines — which is the reported failure ("I fill it
    # with a summary"), not unstructured narration.
    #
    # The first cut of this fix RETIRED the arm outright (`long_enough = False`).
    # The independent review was right to push back: that is a policy change, not
    # a bug fix, and it let a markerless plain-prose report of ANY length under
    # 600 chars through — measured, 8 markerless report lines at 473 chars were
    # allowed. A marker-only rule cannot see a report that simply does not use
    # markdown.
    #
    # So the arm is RAISED rather than retired: `NARRATIVE_LINE_THRESHOLD` 3 -> 6.
    # Three narration sentences clear it; six report-length lines in one turn are
    # more report than narration. G3's original six SHORT lines are unaffected,
    # because `report_length_lines` only counts lines of
    # >= NARRATIVE_MIN_LINE_CHARS.
    #
    # HONEST RESIDUAL, recorded not hidden: a markerless prose report of 3..5
    # report-length lines under 600 chars is allowed. That is the narrowed
    # accepted cost of not blocking ordinary narration — the two shapes genuinely
    # overlap in that band and no threshold separates them.
    long_enough = report_length_lines >= NARRATIVE_LINE_THRESHOLD
    # T2 — the ceiling the F6 short-line allowance was missing.
    # G1: the ceiling counts EVERY non-empty line, fenced content included —
    # `all_nonempty_lines`, and this is the ONE arm for which that is correct.
    # Excluding fenced lines from all three arms (T4) left a summary wrapped in
    # a fence invisible to everything but the 600-char arm. Keeping them out of
    # `report_length_lines` is what T4 actually needed; the ceiling is where
    # they still have to register. HONEST RESIDUAL: with the ceiling raised to
    # 12 for G3, a fence only reaches it at 12 total lines, so a SHORT fenced
    # summary still evades. Narrowed, not closed — pinned as such.
    too_many_lines = all_nonempty_lines >= NARRATIVE_ABSOLUTE_LINES
    long_prose = (not long_enough and not too_many_lines
                  and len(body) > NARRATIVE_PROSE_CHARS)
    # `unfenced_lines`, NOT `all_nonempty_lines`: a marker can only be matched
    # outside a fence, so the count that gates it must be the same population.
    # One unfenced bullet above a four-line snippet is a status update, and
    # reading 5 here instead of 1 would refuse it.
    marked_report = bool(markers) and unfenced_lines >= NARRATIVE_MARKER_LINES
    narrative = bool(long_enough or too_many_lines or long_prose or marked_report)
    if narrative:
        bits = []
        if long_enough:
            bits.append(f"{report_length_lines} report-length lines "
                        f"(>= {NARRATIVE_LINE_THRESHOLD})")
        if too_many_lines:
            bits.append(f"{all_nonempty_lines} lines "
                        f"(>= {NARRATIVE_ABSOLUTE_LINES}, whatever their length)")
        if long_prose:
            bits.append(f"{len(body)} chars of unbroken prose "
                        f"(> {NARRATIVE_PROSE_CHARS})")
        if marked_report:
            # Reports the honest TOTAL, not the `unfenced_lines` that decided
            # the arm — a reason string, not a threshold. Kept verbatim so this
            # rename stays a pure clarity change; noted rather than silently
            # "improved".
            bits.append(f"{all_nonempty_lines} lines carrying structural "
                        "markers: " + ", ".join(markers))
        elif markers:
            bits.append("structural markers: " + ", ".join(markers))
        reason = "; ".join(bits)
    else:
        reason = (f"{all_nonempty_lines} non-empty line(s), {len(body)} chars - "
                  "short enough to be a state line"
                  + (f" (markers present but not decisive at "
                     f"{all_nonempty_lines} "
                     f"line(s): {', '.join(markers)})" if markers else ""))
    # `lines` is the honest total, fenced content included — the same counter the
    # ceiling arm uses, not a separate reporting-only number.
    return {"narrative": narrative, "reason": reason,
            "lines": all_nonempty_lines, "markers": markers}


# --- the ask-ledger ----------------------------------------------------------
#
# The harness task list defeats a lying agent because the HARNESS writes it. A
# ledger the MODEL writes would inherit the unreliability this exists to remove,
# so entries are DERIVED from the transcript — which the harness also writes.
#
# But `run_continuity.load_transcript_slices` is tail-capped. Re-deriving the
# whole ledger from a truncated window on a long session would drop the earliest
# directives — precisely the ones most likely still unfinished — and silently
# allow the stop. So derivation is strictly ADDITIVE against the stored file: a
# stored entry is never removed, reopened, or downgraded by a pass that simply
# could not see its originating turn.

LEDGER_SCHEMA = 1

#: Injected blocks the harness appends to user prompts. Their content churns
#: between turns, so hashing them would mint a new id for the same directive on
#: every pass and no entry could ever be resolved.
_INJECTED_BLOCK_RE = re.compile(r"<system-reminder>.*?</system-reminder>",
                                re.DOTALL | re.IGNORECASE)

#: The marker the harness puts on a slash-command prompt.
#:
#: F1 (independent review): dropping the whole prompt because it carries this
#: marker drops the user's DIRECTIVE with it — measured at 25 of 51
#: command-carrying prompts in the user's own history, including the prompt that
#: commissioned this feature. So the INVOCATION is stripped and the PROSE is
#: kept: `<command-name>` and `<command-message>` are the command's identity and
#: come out whole, while `<command-args>` is where the user's words live, so only
#: its tags come off. A bare invocation with no prose derives nothing.
_COMMAND_MARKER = "<command-name>"
_COMMAND_BLOCK_RE = re.compile(
    r"<command-(?:name|message)>.*?</command-(?:name|message)>",
    re.DOTALL | re.IGNORECASE,
)
_COMMAND_ARGS_TAG_RE = re.compile(r"</?command-args>", re.IGNORECASE)

#: Bare acknowledgements carry no new ask. Registering one opens an entry that
#: can never be honestly resolved — noise that gets the whole gate disabled.
#: "continue" / "proceed" belong here too: they instruct the agent to keep going
#: on the EXISTING asks rather than adding one.
_ACKNOWLEDGEMENTS = frozenset({
    "ok", "okay", "k", "kk", "sure", "yes", "yep", "yeah", "yup", "y",
    "no", "nope", "n", "thanks", "thank you", "ty", "thx", "cheers",
    "great", "nice", "cool", "perfect", "awesome", "excellent", "good",
    "got it", "gotcha", "sounds good", "makes sense", "understood", "right",
    "correct", "agreed", "fine", "done", "continue", "carry on", "go on",
    "go ahead", "proceed", "keep going", "next", "go",
})


class LedgerUnreadable(Exception):
    """The stored ask-ledger exists but could not be read.

    Raised ONLY by :func:`read_ledger`, so the caller can turn a corrupt store
    into a NAMED blocking violation (REQ-6) instead of a silent empty ledger.
    """


def ledger_path(root: str | Path) -> Path:
    """``<root>/.architect-team/ask-ledger.json``."""
    return Path(root) / _rc.STATE_DIRNAME / LEDGER_FILENAME


def read_ledger(root: str | Path) -> dict[str, Any]:
    """The stored ledger. Absent is genuinely empty; corrupt raises.

    Raises :class:`LedgerUnreadable` when the file exists but cannot be parsed
    or is not an ask-ledger document — unknown state is not "empty".
    """
    path = ledger_path(root)
    try:
        if not path.exists():
            return {"schema": LEDGER_SCHEMA, "entries": []}
        data = json.loads(path.read_text(encoding="utf-8"))
    except Exception as exc:  # F2 — every malformed input, not just the two
        raise LedgerUnreadable(f"{path}: {_read_failure_reason(exc)}") from exc
    if not isinstance(data, dict) or not isinstance(data.get("entries"), list):
        raise LedgerUnreadable(f"{path}: not an ask-ledger document")
    return data


def _normalize_directive(text: str) -> str:
    """The user's words, with harness-injected and command envelopes removed."""
    out = _INJECTED_BLOCK_RE.sub("", text or "")
    out = _COMMAND_BLOCK_RE.sub("", out)
    out = _COMMAND_ARGS_TAG_RE.sub("", out)
    return out.strip()


def _is_prose(text: str) -> bool:
    """True when what survived a command envelope reads as an ASK.

    Two ways it does not: a single bare token (that command's argument), and a
    remainder that is nothing but flags. A flag mixed WITH words is still an ask
    — the guard must not eat a real directive that happens to carry an option.
    """
    tokens = text.split()
    if len(tokens) < 2:
        return False
    return not all(t.startswith("-") for t in tokens)


def _is_acknowledgement(text: str) -> bool:
    collapsed = " ".join(text.lower().split()).strip(" .!,?;:")
    return collapsed in _ACKNOWLEDGEMENTS


def derive_ledger_entries(records: list[dict[str, Any]]) -> list[dict[str, Any]]:
    """Derive ledger entries from the HARNESS-written transcript.

    Reuses ``run_continuity``'s genuine-prompt handling, so the injected records
    the harness also stores as ``role: user`` (meta body-echoes, system-injected
    notifications, sidechains, peer messages) never become directives. Because
    the source is the transcript rather than a model-initiated registration
    call, an agent cannot decline to register an ask it would rather not do.
    """
    entries: list[dict[str, Any]] = []
    seen: set[str] = set()
    gate = getattr(_rc, "_gate", None)
    for rec in _rc._genuine_prompts(list(records or [])):
        try:
            raw = gate._text(rec) if gate is not None else ""
        except Exception:  # pragma: no cover - defensive; gate helpers are pure
            continue
        text = _normalize_directive(raw)
        if not text or _is_acknowledgement(text):
            continue
        if _COMMAND_MARKER in (raw or "").lower() and not _is_prose(text):
            # What survives a command envelope is only an ASK when it is prose.
            # A lone token is that command's argument (`/model opus` must not
            # register "opus"), and an all-flags remainder is options rather
            # than a directive (`/setup --external-llm --yes`, N3). A ledger
            # full of flag noise is how a user learns to disable the gate.
            continue
        entry_id = hashlib.sha256(text.encode("utf-8", "replace")).hexdigest()[:16]
        if entry_id in seen:
            continue
        seen.add(entry_id)
        first_seen = None
        if gate is not None:
            try:
                first_seen = gate._timestamp(rec)
            except Exception:  # pragma: no cover - defensive
                first_seen = None
        entries.append({
            "id": entry_id,
            "text": text,
            "first_seen": first_seen or _utc_now_iso(),
            "status": "open",
            "resolved_at": None,
            "evidence": None,
        })
    return entries


def _ledger_should_persist(root: str | Path) -> bool:
    """True when writing the ledger to disk can actually matter (F-F).

    Persistence exists for ONE reason: ``load_transcript_slices`` is tail-capped,
    so a blocking ledger must accumulate or it silently under-reports on long
    sessions. Two conditions make that worth a file, and nothing else does:

    * the blocking opt-in is set — the ledger can refuse a stop, so accumulation
      is load-bearing again; or
    * ``.architect-team/`` already exists — a CT6-touched workspace, where the
      directory is not new pollution.

    Otherwise typing one request into an unrelated repo wrote CT6 state into it.
    That was arguable while the ledger blocked; once it is advisory the file buys
    nothing and just litters the filesystem. Note this is also what keeps
    ``run_continuity._atomic_write_json``'s ``parent.mkdir(parents=True)`` from
    creating the directory as a side effect — the write is never reached rather
    than the shared writer being special-cased.
    """
    if ledger_blocking():
        return True
    return (Path(root) / _rc.STATE_DIRNAME).is_dir()


def _write_ledger(root: str | Path, ledger: dict[str, Any]) -> bool:
    # RD-7: the run_continuity tmp-then-replace path, not a second write path.
    return _rc._atomic_write_json(ledger_path(root), ledger)


def accumulate_ledger(
    root: str | Path,
    derived: list[dict[str, Any]],
) -> dict[str, Any]:
    """Read -> union by id -> write. **Purely additive.**

    A stored entry is never removed, reopened, or downgraded by a pass whose
    transcript slice does not contain its originating turn. The stored side wins
    every collision, so an already-resolved directive stays resolved and the
    original ``first_seen`` survives.

    The file is written ONLY when the union actually changed. That is not just
    an optimization: ``run_continuity``'s progress fingerprint hashes
    ``.architect-team/**`` stat data and does not exclude this file, so
    rewriting it on every Stop would register as progress and defeat the
    pre-existing no-progress wedge detector. Writing nothing when nothing is
    derived also keeps the lock from creating ``.architect-team/`` in every
    unrelated project it runs in.

    Propagates :class:`LedgerUnreadable` from :func:`read_ledger` — a corrupt
    store must not be silently overwritten with a fresh one.
    """
    ledger = read_ledger(root)
    entries = list(ledger.get("entries") or [])
    seen = {e.get("id") for e in entries if isinstance(e, dict)}
    added = False
    for entry in derived or []:
        if not isinstance(entry, dict):
            continue
        entry_id = entry.get("id")
        if not entry_id or entry_id in seen:
            continue
        entries.append(dict(entry))
        seen.add(entry_id)
        added = True
    ledger = {"schema": LEDGER_SCHEMA, "entries": entries}
    if added:
        _write_ledger(root, ledger)
    return ledger


def _entry_is_open(entry: dict[str, Any]) -> bool:
    status = entry.get("status")
    status = status.strip().lower() if isinstance(status, str) else ""
    return status != "resolved"  # missing / unknown -> OPEN


def open_ledger_entries(root: str | Path) -> list[dict[str, Any]]:
    """Every unresolved entry. Unknown status counts as open."""
    entries = read_ledger(root).get("entries") or []
    return [e for e in entries if isinstance(e, dict) and _entry_is_open(e)]


def resolve_ledger_entry(
    root: str | Path,
    entry_id: str,
    evidence: str,
) -> dict[str, Any]:
    """Mark one entry resolved. Conservative — ambiguous stays open.

    A resolve with no evidence, or for an id that is not stored, changes
    nothing: over-blocking fails safe, under-blocking is the reported bug.
    """
    ledger = read_ledger(root)
    ev = evidence.strip() if isinstance(evidence, str) else ""
    if not entry_id or not ev:
        return ledger
    changed = False
    for entry in ledger.get("entries") or []:
        if not isinstance(entry, dict) or entry.get("id") != entry_id:
            continue
        if not _entry_is_open(entry):
            continue
        entry["status"] = "resolved"
        entry["resolved_at"] = _utc_now_iso()
        entry["evidence"] = ev
        changed = True
    if changed:
        _write_ledger(root, ledger)
    return ledger


# --- teammate identity -------------------------------------------------------

# The mandated spawn-brief first line is
# ``[CT6-TEAMMATE <teammate-name> RUN <run-id-or-slug>]``; briefs are also
# written without the brackets or the RUN tail, so both are accepted. The
# negative lookahead keeps ``[CT6-TEAMMATE RUN slug]`` (no name) from resolving
# the literal "RUN" as the teammate's name.
_TEAMMATE_NAME_RE = re.compile(
    r"\[?\s*" + re.escape(_rc.TEAMMATE_TOKEN)
    + r"\s+(?!RUN\b)([A-Za-z0-9][A-Za-z0-9._-]*)"
)


def _identity_records(
    records: list[dict[str, Any]],
    head_records: list[dict[str, Any]] | None = None,
) -> list[dict[str, Any]]:
    """The records that may legitimately carry this session's spawn brief.

    **Position is the discriminator**, and both halves are load-bearing:

    * The FIRST inbound (``role: user``) record, with a ``<teammate-message>``
      envelope ALLOWED. A teams-mode brief arrives inside that envelope, which
      ``_is_user_prompt`` deliberately excludes — so a genuine-prompts-only scan
      resolved nothing for a teams-mode teammate and classified the worker as an
      orchestrator, held on every lane including ones it cannot close (N1). That
      violates REQ-4's "never wedged on lanes it has no power to close".
    * Every genuine user prompt thereafter, envelopes EXCLUDED. This is what
      keeps ADV-9 closed: a Lead's own first prompt occupies position one, so a
      peer message arriving MID-SESSION can never rename it.

    An envelope is the brief only where the brief actually appears. Anywhere
    else it is an inbound peer message, and the two are told apart by where they
    sit rather than by what they contain.
    """
    gate = getattr(_rc, "_gate", None)
    if gate is None:  # pragma: no cover - helpers unavailable
        return []
    ordered = list(head_records or []) + list(records or [])
    out: list[dict[str, Any]] = []
    for rec in ordered:
        if not isinstance(rec, dict):
            continue
        try:
            role = gate._role(rec)
        except Exception:  # pragma: no cover - defensive
            continue
        if role == "user":
            out.append(rec)  # position one: the brief, envelope allowed
            break
    seen = {id(r) for r in out}
    for rec in _rc._genuine_prompts(ordered):
        if id(rec) not in seen:
            out.append(rec)
            seen.add(id(rec))
    return out


def teammate_name(
    records: list[dict[str, Any]],
    head_records: list[dict[str, Any]] | None = None,
    truncated: bool = False,
) -> str | None:
    """The teammate's name from its ``CT6-TEAMMATE`` spawn brief, or None.

    Searched: the FIRST inbound record (a peer envelope is honoured there), plus
    every genuine user prompt. See :func:`_identity_records` for why position is
    the discriminator.

    The head slice is searched first because the brief lives at the transcript
    head; ``truncated`` is accepted for signature symmetry with
    ``run_continuity.is_teammate_transcript``, but the head slice is honoured
    whenever it is supplied.

    Returns None when no name is resolvable. Per ADV-8 the caller then stands
    down ONLY if a genuine token is present — never on the heuristic alone.
    """
    gate = getattr(_rc, "_gate", None)
    if gate is None:  # pragma: no cover - helpers unavailable -> stand down
        return None
    for rec in _identity_records(records, head_records):
        try:
            text = gate._text(rec)
        except Exception:  # pragma: no cover - defensive
            continue
        match = _TEAMMATE_NAME_RE.search(text or "")
        if match:
            return match.group(1)
    return None


def _has_teammate_token(
    records: list[dict[str, Any]],
    head_records: list[dict[str, Any]] | None = None,
) -> bool:
    """True when this session's spawn brief carries the ``CT6-TEAMMATE`` token.

    ADV-8: this — not ``run_continuity.is_teammate_transcript`` — is what
    authorizes a standdown. That detector also classifies on a >= 1500-char
    first prompt mentioning ``.architect-team``, a shape the USER's own long
    prompts hit; standing down on it let a long prompt silently disable the
    whole gate. Shares :func:`_identity_records` with :func:`teammate_name`, so
    a teams-mode brief is recognized in position one while a mid-session peer
    envelope can forge neither the token nor a name.
    """
    gate = getattr(_rc, "_gate", None)
    if gate is None:  # pragma: no cover - helpers unavailable
        return False
    for rec in _identity_records(records, head_records):
        try:
            text = gate._text(rec)
        except Exception:  # pragma: no cover - defensive
            continue
        if _rc.TEAMMATE_TOKEN in (text or ""):
            return True
    return False


def first_inbound_is_peer_envelope(
    records: list[dict[str, Any]],
    head_records: list[dict[str, Any]] | None = None,
) -> bool:
    """True when this session's FIRST inbound record is a peer envelope.

    THE RECOGNISER THE TOKEN MISSES. Every teammate path above keys on
    ``CT6-TEAMMATE``, and a real CT6 brief does not carry it — it arrives as a
    ``<teammate-message>`` envelope with prose, which is the shape the Lead
    dispatches. With no token and no parseable name the ownership site below
    classified a genuine worker as an ORCHESTRATOR and held it on its PEERS'
    lanes: a condition a worker structurally cannot clear, since it can neither
    close another teammate's task nor mark the run complete. Measured, guard
    disabled so the exit code is attributable: tokenless teammate with a peer's
    open task -> exit 2 from the lock proper; the tokened control -> exit 0.

    POSITION is the discriminator, and it is the same one
    :func:`_identity_records` already uses:

    * a WORKER's transcript opens with the brief its Lead sent, stored as a
      ``role: user`` record wrapped in ``<teammate-message …>``;
    * an ORCHESTRATOR's opens with a genuine human prompt.

    Position ONE only. A peer message arriving mid-session must never
    reclassify a Lead (ADV-9) — otherwise any teammate could disarm the Lead's
    gate by sending it a message. The Lead's own first prompt occupies position
    one and cannot be displaced. The head slice is searched first, so a Lead
    whose visible TAIL happens to open with a peer message is still held.

    Deliberately NOT ``run_continuity.is_teammate_transcript``, for the reason
    recorded at the ownership site: that detector also classifies on a
    >= 1500-char first prompt mentioning ``.architect-team``, a shape the USER's
    own long prompts hit. This keys on position-one STRUCTURE, not on length,
    so it cannot be tripped by a long human prompt.

    Envelope detection is `pretool_skill_gate`'s, reached through
    ``run_continuity._gate`` — the same reuse rule as every other helper here.
    """
    gate = getattr(_rc, "_gate", None)
    if gate is None:  # pragma: no cover - helpers unavailable
        return False
    for rec in list(head_records or []) + list(records or []):
        if not isinstance(rec, dict):
            continue
        try:
            if gate._role(rec) != "user":
                continue
            return bool(gate._is_teammate_message(rec))
        except Exception:  # pragma: no cover - defensive; helpers are pure
            return False
    return False


#: Every kill-switch this module can name in a block message. A block always
#: names exactly one, so their presence in a harness-injected record identifies
#: it as this hook's own feedback rather than anything the user or agent wrote.
_BLOCK_SWITCH_NAMES = (DISABLE_ENV, DISABLE_TASKS_ENV,
                       DISABLE_LEDGER_ENV, DISABLE_OUTPUT_ENV)


def _is_lock_block_record(rec: dict[str, Any], gate: Any) -> bool:
    """True for a harness-injected record carrying this hook's own block (G2).

    Deliberately narrow: an INJECTED ``role: user`` record (a genuine prompt is
    the user talking, and an assistant record is the agent, so neither may move
    the boundary) whose text names one of this module's kill-switches.
    """
    try:
        if gate._role(rec) != "user" or gate._is_user_prompt(rec):
            return False
        text = gate._text(rec) or ""
    except Exception:  # pragma: no cover - defensive
        return False
    return any(name in text for name in _BLOCK_SWITCH_NAMES)


def _turn_assistant_text(records: list[dict[str, Any]]) -> str:
    """Every assistant text block THIS turn produced, joined.

    T1 — this used to return the LAST non-empty assistant block, which was a
    complete evasion in one direction and a false positive in the other:

    * Write the summary, then end with ``Working.`` and the selector returned
      only ``Working.`` — the narrative was never measured. That is the natural
      shape of the reported failure (a report, then a sign-off), and no amount
      of threshold tuning could reach it, because the defect is in the INPUT
      rather than in the predicate.
    * A turn that ends in tool calls produces no assistant text at all, so the
      backwards scan walked PAST the user prompt into the previous turn and
      re-measured an old narrative — firing on text this turn never produced.

    The turn boundary is the last genuine user prompt, taken from
    ``run_continuity._genuine_prompts`` rather than from a second notion of
    "this turn" invented here. Identity comparison is deliberate: the helper
    returns the same record objects, and two turns can carry byte-identical
    prompts.
    """
    gate = getattr(_rc, "_gate", None)
    if gate is None:  # pragma: no cover - helpers unavailable
        return ""
    recs = [r for r in (records or []) if isinstance(r, dict)]
    start = 0
    prompts = _rc._genuine_prompts(recs)
    if prompts:
        last_prompt = prompts[-1]
        for i in range(len(recs) - 1, -1, -1):
            if recs[i] is last_prompt:
                start = i + 1
                break
    # G2 — the boundary also advances past THIS HOOK'S OWN last block.
    #
    # Concatenating since the user prompt is cumulative, so once a turn produced
    # a narrative every later Stop re-measured it: the agent replied with
    # exactly the one line of state the block demanded and the arm fired anyway,
    # `lines` climbing. No reply could clear it, because the text was already in
    # the transcript — the unbreakable loop again in a new form.
    #
    # The harness feeds a blocked Stop's reason back as a non-genuine
    # ``role: user`` record, which makes it an in-transcript marker of the
    # previous Stop and needs no new persistence (the guard state is written
    # only for engaged CT6 runs, and writing state here would reintroduce the
    # F-F pollution). Detection keys on this module's OWN kill-switch names,
    # which every block message must carry, rather than on the emitter's prose.
    for i in range(len(recs) - 1, start - 1, -1):
        if _is_lock_block_record(recs[i], gate):
            start = i + 1
            break
    parts: list[str] = []
    for rec in recs[start:]:
        try:
            if gate._role(rec) != "assistant":
                continue
            text = gate._text(rec)
        except Exception:  # pragma: no cover - defensive
            continue
        if text and text.strip():
            parts.append(text)
    return "\n".join(parts)


# --- the single entry point main() calls -------------------------------------


def _task_label(task: dict[str, Any]) -> str:
    ident = task.get("id") or Path(str(task.get("_path") or "?")).stem
    status = task.get("status") or "no status"
    subject = str(task.get("subject") or "").strip()
    label = f"{ident} ({status})"
    return f"{label} {subject}" if subject else label


def _ask_label(entry: dict[str, Any]) -> str:
    text = " ".join(str(entry.get("text") or "").split())
    if len(text) > 120:
        text = text[:117] + "..."
    return f"{entry.get('id')} \"{text}\""


def _block_reasons(result: dict[str, Any], owner: str | None) -> list[str]:
    reasons: list[str] = []
    tasks = result["open_tasks"]
    if tasks:
        scope = f" owned by {owner}" if owner else ""
        listed = "; ".join(_task_label(t) for t in tasks[:10])
        more = "" if len(tasks) <= 10 else f" (+{len(tasks) - 10} more)"
        reasons.append(
            f"{len(tasks)} open task(s){scope} in the harness task list: "
            f"{listed}{more}"
        )
    asks = result["open_asks"]
    if asks:
        listed = "; ".join(_ask_label(a) for a in asks[:10])
        more = "" if len(asks) <= 10 else f" (+{len(asks) - 10} more)"
        reasons.append(
            f"{len(asks)} unresolved ask(s) in the ask-ledger: {listed}{more}"
        )
    for entry in result["unreadable"]:
        reasons.append(
            f"unreadable source: {entry['path']} ({entry['reason']}) — an "
            f"unreadable source is unknown state, not an empty one"
        )
    turn = result["turn_output"]
    if turn:
        reasons.append(
            f"the turn ended in a narrative ({turn['reason']}) — while work is "
            f"open the turn output is one line of state, not a narrative"
        )
    return reasons


def evaluate_completion_lock(
    root: str | Path,
    session_id: str | None,
    records: list[dict[str, Any]],
    head_records: list[dict[str, Any]] | None = None,
    truncated: bool = False,
    tasks_root: str | Path | None = None,
) -> dict[str, Any]:
    """Decide whether this session's Stop must be refused.

    Returns ``{"blocked", "open_tasks", "stale_tasks", "tasks_dir",
    "open_asks", "unreadable", "turn_output", "reasons", "killswitch"}``.
    ``open_tasks`` holds only LIVE open work; ``stale_tasks`` holds open tasks
    aged past the abandonment window (inherited debt — surfaced, never
    blocking). Source problems are REPORTED in ``unreadable`` (and block); only
    genuinely unexpected errors propagate to ``main()``'s fail-open wrapper.

    ``root`` is the workspace (the ask-ledger lives under it); ``tasks_root``
    injects the harness task store for tests.
    """
    result: dict[str, Any] = {
        "blocked": False, "open_tasks": [], "open_asks": [], "unreadable": [],
        # D1 — open tasks aged past the abandonment window: inherited debt,
        # surfaced but never blocking. `tasks_dir` names the store for the
        # operator (a field report spent real time hunting the right dir).
        "stale_tasks": [], "tasks_dir": None,
        # Recorded directives that are NOT refusing the stop. Surfaced by the
        # caller when something else blocks, so an outstanding ask is still
        # visible without being the thing that wedges the session.
        "advisory_asks": [],
        # Degraded-source notes that are NOT refusing the stop (F1). They also
        # ride along in `reasons` when something else blocks, so a caller that
        # only renders `reasons` still surfaces them.
        "advisory_notes": [],
        "turn_output": None, "reasons": [], "killswitch": None,
    }
    if lock_disabled():
        return result

    records = list(records or [])
    head = list(head_records or [])

    # REQ-4 — a teammate is held only for lanes it owns. ADV-8 REVERSED the
    # design's "fail toward standdown" for the no-name case: the standdown now
    # requires a GENUINE CT6-TEAMMATE token, never a heuristic classification.
    # `run_continuity.is_teammate_transcript` also classifies on a >= 1500-char
    # first prompt mentioning `.architect-team` — a shape the USER's own long
    # prompts hit, including the prompt that commissioned this feature — so
    # deferring to it let a long prompt silently disable the entire gate. It is
    # deliberately NOT consulted here; RD-5's reuse is honoured through
    # TEAMMATE_TOKEN and _genuine_prompts instead. A session that resolves no
    # name AND shows no worker signal at all is an ORCHESTRATOR and is held on
    # ALL open tasks — see the two recognisers below for what counts as a
    # signal (F9 added the second; the token alone missed every real brief).
    owner: str | None = teammate_name(records, head, truncated)
    is_teammate = owner is not None
    if owner is None and (_has_teammate_token(records, head)
                          or first_inbound_is_peer_envelope(records, head)):
        # A real worker whose brief resolves no name — either it carries the
        # token without a parseable name, or (F9) it carries no token at all
        # because a real CT6 brief is a `<teammate-message>` envelope with
        # prose. Bricking a worker is worse than a missed block: it is refused
        # a stop for a lane it cannot close, which is how the whole gate gets
        # switched off. Two recognisers, ONE standdown.
        #
        # The comment three lines up used to end "A session with no resolvable
        # name and no token is an ORCHESTRATOR and is held on ALL open tasks."
        # That was the wedge stated as a design intent — true of a Lead, and
        # false of every teammate this project actually dispatches.
        return result

    sources: set[str] = set()

    # --- source 1: the harness task list
    if not tasks_disabled():
        read = read_harness_tasks(session_id, tasks_root)
        result["tasks_dir"] = read.get("dir")
        if read["unreadable"]:
            result["unreadable"].extend(read["unreadable"])
            sources.add(DISABLE_TASKS_ENV)
        open_tasks = open_task_items(read["items"], owner=owner)
        # D1 (v3.64.0) — abandonment discrimination. Task lists outlive
        # sessions, so an open task untouched for longer than the abandonment
        # window is INHERITED DEBT from a terminated or superseded session:
        # surfaced (below, and as an advisory line in `reasons`), never
        # blocking. Touching one through TaskUpdate rewrites its file, which
        # makes it live again — reviving inherited work is one tool call, and
        # from then on it holds the turn like any open task.
        live_tasks, stale_tasks = partition_stale_tasks(open_tasks)
        result["stale_tasks"] = stale_tasks
        if stale_tasks:
            result["advisory_notes"].append(
                f"{len(stale_tasks)} inherited stale open task(s) untouched "
                f"for longer than the {task_stale_hours():g}h abandonment "
                f"window are NOT refusing this stop (see stale_tasks)"
            )
        if live_tasks:
            result["open_tasks"] = live_tasks
            sources.add(DISABLE_TASKS_ENV)

    # --- source 2: the ask-ledger. Skipped for a teammate: the ledger holds the
    # USER's directives, which a worker has no power to resolve.
    if not ledger_disabled() and not is_teammate:
        try:
            persist = _ledger_should_persist(root)
            if persist and head and not ledger_path(root).exists():
                # F3 — the persistence transition used to lose history. In the
                # advisory period nothing is written (F-F); when the operator
                # then sets the opt-in exactly as the README invites, the window
                # has moved and those directives are unrecoverable — the ledger
                # would begin at the switch, missing precisely the OLDEST asks.
                # On the FIRST persist pass the head slice is swept in too: it
                # is already loaded, already passed in, and it covers the
                # transcript START, which is the region the tail cap loses.
                #
                # Restricted to the first pass as a COST guard, not a
                # correctness one — and the distinction is worth stating,
                # because the first draft of this comment claimed a re-sweep
                # would resurrect resolved entries and the mutation harness
                # disproved it: accumulation unions by id with the stored side
                # winning, so a re-derived resolved entry stays resolved. The
                # guard therefore has no behavioural witness by design; it just
                # avoids re-deriving the head on every Stop. It also re-arms if
                # the store is ever deleted, which recovers the entries.
                derived = derive_ledger_entries(list(head) + list(records))
            else:
                derived = derive_ledger_entries(records)
            if persist:
                accumulate_ledger(root, derived)
                open_asks = open_ledger_entries(root)
            else:
                # Advisory-only in a workspace CT6 has never touched: derive in
                # memory and write NOTHING. Persistence exists to protect the
                # tail-cap window, and an advisory listing is holding nothing —
                # a directive that scrolls out was never going to block. No
                # store can exist here either (the ledger lives inside the
                # directory whose absence put us on this branch), so the
                # in-memory list IS the complete listing.
                open_asks = [e for e in derived if _entry_is_open(e)]
        except LedgerUnreadable as exc:
            reason = str(exc).rsplit(": ", 1)[-1]
            if ledger_blocking():
                # Opted in, so the ledger can refuse a stop and an unreadable
                # one is unknown state again — REQ-6 applies.
                result["unreadable"].append(
                    {"path": str(ledger_path(root)), "reason": reason}
                )
                sources.add(DISABLE_LEDGER_ENV)
            else:
                # F1 — the demotion never touched this path, so the advisory
                # source kept exactly one blocking power: being broken. That is
                # the wrong half to keep — pure wedge, zero enforcement value,
                # on the source the user was told is advisory. It degrades to
                # advisory too, surfaced loudly rather than swallowed. The TASK
                # store is different and still blocks: that one is harness-
                # written ground truth (REQ-6).
                result["advisory_notes"].append(
                    f"the ask-ledger at {ledger_path(root)} could not be read "
                    f"({reason}) — advisory, so it is NOT refusing this stop; "
                    f"fix or delete it, or set {LEDGER_BLOCKING_ENV}=1 to make "
                    f"an unreadable ledger blocking again"
                )
        else:
            if open_asks:
                result["open_asks"] = open_asks
                sources.add(DISABLE_LEDGER_ENV)

    # The ask-ledger is ADVISORY unless explicitly opted in. It knows a
    # directive was GIVEN; it cannot know it was MET, and a source that cannot
    # verify its own release condition must not hold a session hostage. Recorded
    # asks are still surfaced (see `advisory_asks`) whenever another source
    # blocks, so nothing the user asked for goes unmentioned — it just is not
    # the thing refusing the stop.
    asks_block = bool(result["open_asks"]) and ledger_blocking()
    if result["open_asks"] and not asks_block:
        result["advisory_asks"] = result["open_asks"]
        result["open_asks"] = []
        sources.discard(DISABLE_LEDGER_ENV)

    # --- source 3: the one-line-of-state rule. A shape constraint on a turn
    # that should not have been final, so it is evaluated ONLY when work is
    # genuinely open — never as a general style rule. A teammate's structured
    # report back to the Lead is its deliverable, not a violation.
    #
    # Gated on work that can actually BLOCK: an advisory ask must not drag the
    # output rule in behind it, or the ledger would keep blocking by proxy
    # through exactly the source it was just demoted out of.
    open_work = bool(result["open_tasks"] or result["open_asks"])
    if open_work and not output_disabled() and not is_teammate:
        verdict = classify_turn_output(_turn_assistant_text(records))
        if verdict["narrative"]:
            result["turn_output"] = verdict
            sources.add(DISABLE_OUTPUT_ENV)

    result["blocked"] = bool(
        result["open_tasks"] or result["open_asks"]
        or result["unreadable"] or result["turn_output"]
    )
    if not result["blocked"]:
        return result
    result["reasons"] = _block_reasons(result, owner) + [
        f"advisory (not blocking): {note}" for note in result["advisory_notes"]
    ]
    # Name the switch that actually releases what fired: the precise per-source
    # one when a single source is responsible, the master when several are.
    result["killswitch"] = next(iter(sources)) if len(sources) == 1 else DISABLE_ENV
    return result


# --- the operator CLI --------------------------------------------------------
#
# F3: without a user-facing exit the ledger is a one-way ratchet whose only
# release is a kill-switch, and the first false positive makes the user disable
# the whole gate — the same as not shipping it.
#
# This is the HUMAN's surface, deliberately not advertised to the agent in the
# block message (ADV-2): registration is involuntary by design, and a gate that
# teaches its subject how to open it is not a gate.


def _cmd_list(root: str | Path) -> int:
    try:
        entries = open_ledger_entries(root)
    except LedgerUnreadable as exc:
        print(f"ask-ledger unreadable: {exc}", file=sys.stderr)
        return 1
    if not entries:
        print("No unresolved asks.")
        return 0
    print(f"{len(entries)} unresolved ask(s) in {ledger_path(root)}:\n")
    for entry in entries:
        text = " ".join(str(entry.get("text") or "").split())
        print(f"  {entry.get('id')}  [{entry.get('first_seen')}]")
        print(f"      {text[:160]}{'...' if len(text) > 160 else ''}")
    print("\nResolve one with:")
    print("  python hooks/open_work.py resolve <id> --evidence \"<what closed it>\"")
    print(f"Or switch the whole source off with {DISABLE_LEDGER_ENV}=1 "
          f"(the master switch is {DISABLE_ENV}).")
    return 0


def _cmd_resolve(root: str | Path, entry_id: str, evidence: str) -> int:
    if not (evidence or "").strip():
        print("resolve needs --evidence naming what closed the ask; "
              "an ambiguous entry stays open by design.", file=sys.stderr)
        return 2
    try:
        before = {e.get("id") for e in open_ledger_entries(root)}
        resolve_ledger_entry(root, entry_id, evidence)
        after = {e.get("id") for e in open_ledger_entries(root)}
    except LedgerUnreadable as exc:
        print(f"ask-ledger unreadable: {exc}", file=sys.stderr)
        return 1
    if entry_id not in before - after:
        print(f"no unresolved ask with id {entry_id!r} — "
              f"run 'list' to see the open ids.", file=sys.stderr)
        return 2
    print(f"resolved {entry_id}")
    return 0


def _cmd_retire(
    session: str,
    reason: str,
    task_ids: list[str],
    tasks_root_arg: str | None,
    force: bool,
) -> int:
    """Close an abandoned harness task list — the OPERATOR's surface (D2).

    Symmetry argument: the run marker has ``--stand-down``; until v3.64.0 a
    dead TASK LIST had nothing — the only exits were an env kill-switch or
    hand-editing the store, and a field-reported workspace sat wedged on
    exactly that gap. Retiring rewrites each targeted task to ``completed``
    with an audit block (``metadata.ct6_retired = {at, reason}``), so the
    store stays REGISTERED (the unregistered-run arm's condition) and the
    decision stays visible.

    The closed boundary that keeps this surface honest: without ``--force`` it
    refuses LIVE open tasks — only work already aged past the abandonment
    window (:func:`task_stale_hours`) can be retired. Stale tasks do not block
    the lock, so the no-force verb can never release anything the lock is
    actually holding; ``--force`` is the human's explicit override for a list
    they know is dead before it has aged. (An agent reaching this through Bash
    is the same NAMED residual every filesystem gate carries — and it gains
    nothing a bare ``TaskUpdate(status="completed")`` did not already allow.)
    """
    if not (reason or "").strip():
        print("retire needs --reason naming why the work is being closed "
              "without being done; the reason is recorded on every task.",
              file=sys.stderr)
        return 2
    sid = (session or "").strip()
    sid = sid[len("session-"):] if sid.startswith("session-") else sid
    if not sid:
        print("retire needs --session <session-id> (or the session-<first8> "
              "dir name) naming which task list holds the dead work.",
              file=sys.stderr)
        return 2
    read = read_harness_tasks(sid, tasks_root_arg)
    store = Path(str(read.get("dir")))
    if not store.is_dir():
        print(f"no harness task store at {store} — nothing to retire. "
              f"(root: {tasks_root(tasks_root_arg)})", file=sys.stderr)
        return 1
    problems = list(read.get("unreadable") or [])
    for entry in problems:
        print(f"unreadable, skipped: {entry.get('path')} "
              f"({entry.get('reason')})", file=sys.stderr)

    open_items = open_task_items(read["items"])
    requested = [str(t).strip() for t in (task_ids or []) if str(t).strip()]
    if requested:
        by_id = {str(i.get("id")): i for i in open_items}
        missing = [t for t in requested if t not in by_id]
        for t in missing:
            print(f"no OPEN task with id {t!r} in {store}", file=sys.stderr)
        selected = [by_id[t] for t in requested if t in by_id]
    else:
        missing = []
        selected = list(open_items)

    live, stale = partition_stale_tasks(selected)
    targets = selected if force else stale
    refused = [] if force else live
    for item in refused:
        print(f"REFUSED (live): task [{item.get('id')}] was touched within "
              f"the {task_stale_hours():g}h abandonment window, so it is not "
              "evidently abandoned. Retire closes DEAD work; pass --force "
              "only with the human's explicit decision that this list is "
              "dead.", file=sys.stderr)

    retired: list[str] = []
    failed: list[str] = []
    for item in targets:
        path = Path(str(item.get("_path")))
        data = {k: v for k, v in item.items() if k not in ("_path", "_mtime")}
        data["status"] = "completed"
        meta = data.get("metadata")
        meta = dict(meta) if isinstance(meta, dict) else {}
        meta["ct6_retired"] = {"at": _utc_now_iso(), "reason": reason.strip()}
        data["metadata"] = meta
        if _rc._atomic_write_json(path, data):
            retired.append(str(item.get("id")))
        else:
            failed.append(str(item.get("id")))
            print(f"could not rewrite {path}", file=sys.stderr)

    print(json.dumps({
        "store": str(store),
        "retired": retired,
        "refused_live": [str(i.get("id")) for i in refused],
        "not_open": missing,
        "write_failed": failed,
        "unreadable": [e.get("path") for e in problems],
    }, indent=2, sort_keys=True))
    if refused or missing or failed or problems:
        return 1
    if not targets:
        print("nothing to retire: the store holds no matching open task.",
              file=sys.stderr)
    return 0


def main(argv: list[str] | None = None) -> int:
    """Operator CLI — the ask-ledger, and the dead-task retire surface."""
    import argparse

    parser = argparse.ArgumentParser(
        prog="open_work.py",
        description="Operator surface for the completion lock: inspect and "
                    "release the ask-ledger; retire an abandoned task list.",
    )
    sub = parser.add_subparsers(dest="command", required=True)

    p_list = sub.add_parser("list", help="show the unresolved asks with their ids")
    p_list.add_argument("--root", default=".", help="workspace root (default: .)")

    p_resolve = sub.add_parser("resolve", help="mark one ask resolved")
    p_resolve.add_argument("entry_id", help="the ask id, from 'list'")
    p_resolve.add_argument("--evidence", required=True,
                           help="what closed it; a blank value resolves nothing")
    p_resolve.add_argument("--root", default=".", help="workspace root (default: .)")

    p_retire = sub.add_parser(
        "retire",
        help="close an ABANDONED harness task list (operator action; refuses "
             "live tasks unless --force)",
    )
    p_retire.add_argument("--session", required=True,
                          help="session id, its first 8 chars, or the "
                               "session-<first8> dir name")
    p_retire.add_argument("--reason", required=True,
                          help="why the work is being closed without being "
                               "done; recorded on every retired task")
    p_retire.add_argument("--task", action="append", default=[],
                          help="retire only this task id (repeatable); "
                               "default: every stale open task in the store")
    p_retire.add_argument("--force", action="store_true",
                          help="also retire LIVE open tasks - the human's "
                               "explicit override for a list known dead "
                               "before it has aged")
    p_retire.add_argument("--tasks-root", default=None,
                          help="harness task store root (default: "
                               "~/.claude/tasks, or CT6_TASKS_ROOT)")

    args = parser.parse_args(argv)
    if args.command == "list":
        return _cmd_list(args.root)
    if args.command == "retire":
        return _cmd_retire(args.session, args.reason, args.task,
                           args.tasks_root, args.force)
    return _cmd_resolve(args.root, args.entry_id, args.evidence)


if __name__ == "__main__":  # pragma: no cover - exercised via subprocess in tests
    raise SystemExit(main())
