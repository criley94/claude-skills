"""Unit tests for hooks/open_work.py — the completion-lock open-work substrate.

The four properties these tests exist to hold (design.md + the approved
interface contract at `.architect-team/contracts/open-work-api.md`):

1. Source-read failures are DATA (``unreadable[]``), never exceptions — that
   split is what lets the caller BLOCK-and-name a corrupt store (REQ-6)
   instead of reading it as empty and sailing through.
2. The ask-ledger ACCUMULATES. ``run_continuity.load_transcript_slices`` is
   tail-capped, so a re-derivation pass on a long session cannot see the
   earliest directives — the ones most likely still unfinished. A stored entry
   is never removed, reopened, or downgraded by a pass that could not see its
   originating turn.
3. The turn-output classifier is pinned in BOTH directions. A rule that never
   fires is decoration; a rule that fires on a legitimate terse status update
   gets disabled by the user, which is the same as not shipping it.
4. Unknown status counts as OPEN. Unknown state is not "done".

TEST SEAM. The real harness task store is ``~/.claude/tasks/``. No test here
may read or write it: every reader takes an injected root, and the autouse
``_sandbox_tasks_root`` fixture below points the env fallback at a nonexistent
sandbox so even a forgotten injection cannot reach the developer's real store
(the same global-hermeticity pattern as conftest's ``_scrub_plugin_registry``).
"""
import json
from pathlib import Path

import pytest

from hooks import open_work as ow
from hooks import run_continuity as rc


@pytest.fixture(autouse=True)
def _sandbox_tasks_root(tmp_path: Path, monkeypatch: pytest.MonkeyPatch) -> None:
    """Never let a test fall through to the developer's real ~/.claude/tasks."""
    monkeypatch.setenv("CT6_TASKS_ROOT", str(tmp_path / "__no-real-task-store__"))


@pytest.fixture(autouse=True)
def _clear_killswitches(monkeypatch: pytest.MonkeyPatch) -> None:
    """Kill-switches off unless a test sets one (ambient env must not leak in)."""
    for var in (
        "CT6_COMPLETION_LOCK_DISABLED",
        "CT6_TASK_LIST_GATE_DISABLED",
        "CT6_ASK_LEDGER_GATE_DISABLED",
        "CT6_TURN_OUTPUT_GATE_DISABLED",
    ):
        monkeypatch.delenv(var, raising=False)


# --- transcript record builders (the harness JSONL shape) --------------------

def _user(text: str, ts: str = "2026-08-12T10:00:00Z", **extra) -> dict:
    rec = {"type": "user", "timestamp": ts,
           "message": {"role": "user", "content": text}}
    rec.update(extra)
    return rec


def _assistant(text: str, ts: str = "2026-08-12T10:01:00Z") -> dict:
    return {"type": "assistant", "timestamp": ts,
            "message": {"role": "assistant",
                        "content": [{"type": "text", "text": text}]}}


# =============================================================================
# Group 2 — the ask-ledger. Accumulation is the load-bearing property.
# =============================================================================

def test_stored_entry_survives_a_pass_that_cannot_see_its_turn(tmp_path: Path) -> None:
    """THE test. `load_transcript_slices` is tail-capped: on a long session the
    EARLIEST directives fall outside the window. Re-deriving from that truncated
    slice must not drop them — dropping them silently allows exactly the stop
    this feature exists to refuse."""
    early = [_user("Add rate limiting to the login endpoint.", ts="2026-08-12T09:00:00Z"),
             _user("Also write the migration for the new column.", ts="2026-08-12T09:30:00Z")]
    ow.accumulate_ledger(tmp_path, ow.derive_ledger_entries(early))

    stored = ow.read_ledger(tmp_path)
    assert len(stored["entries"]) == 2, "both early directives registered"
    early_ids = {e["id"] for e in stored["entries"]}

    # The tail-capped second pass sees ONLY a later turn — the two early turns
    # have scrolled out of the window entirely.
    late = [_user("Bump the version to 3.56.0.", ts="2026-08-12T18:00:00Z")]
    ow.accumulate_ledger(tmp_path, ow.derive_ledger_entries(late))

    after = ow.read_ledger(tmp_path)
    after_ids = {e["id"] for e in after["entries"]}
    assert early_ids <= after_ids, (
        "a stored entry was dropped by a pass whose slice could not see its "
        "originating turn — the tail-cap bug this ledger exists to prevent"
    )
    assert len(after["entries"]) == 3, "the new directive is added, none removed"
    assert {e["id"] for e in ow.open_ledger_entries(tmp_path)} == after_ids, (
        "every unresolved entry still counts as open"
    )


def test_re_derivation_never_reopens_or_downgrades_a_resolved_entry(tmp_path: Path) -> None:
    """Accumulation is purely additive: union by id, stored side wins. A pass
    that re-derives an already-RESOLVED directive must not reopen it."""
    records = [_user("Fix the flaky lock test.")]
    ow.accumulate_ledger(tmp_path, ow.derive_ledger_entries(records))
    entry_id = ow.read_ledger(tmp_path)["entries"][0]["id"]
    ow.resolve_ledger_entry(tmp_path, entry_id, evidence="tests/test_locks.py::test_x green")
    assert ow.open_ledger_entries(tmp_path) == [], "explicitly resolved -> not open"

    # The very same directive is re-derived on a later pass.
    ow.accumulate_ledger(tmp_path, ow.derive_ledger_entries(records))

    entries = ow.read_ledger(tmp_path)["entries"]
    assert len(entries) == 1, "re-deriving the same directive does not duplicate it"
    assert entries[0]["status"] == "resolved", "a resolved entry is never reopened"
    assert entries[0]["evidence"] == "tests/test_locks.py::test_x green"
    assert ow.open_ledger_entries(tmp_path) == []


def test_stored_first_seen_is_preserved_across_passes(tmp_path: Path) -> None:
    """The stored side wins on union, so the original first_seen survives — the
    ledger records when the user ASKED, not when the hook last looked."""
    records = [_user("Document the kill-switches in the README.",
                     ts="2026-08-12T09:00:00Z")]
    ow.accumulate_ledger(tmp_path, ow.derive_ledger_entries(records))
    first = ow.read_ledger(tmp_path)["entries"][0]["first_seen"]

    later = [_user("Document the kill-switches in the README.",
                   ts="2026-08-12T23:59:00Z")]
    ow.accumulate_ledger(tmp_path, ow.derive_ledger_entries(later))
    assert ow.read_ledger(tmp_path)["entries"][0]["first_seen"] == first


def test_accumulate_with_no_new_entries_does_not_rewrite_the_file(tmp_path: Path) -> None:
    """A no-op pass must leave the bytes alone.

    ``run_continuity``'s progress fingerprint hashes ``.architect-team/**`` stat
    data and does NOT exclude this file, so rewriting the ledger on every Stop
    would register as PROGRESS and defeat the pre-existing wedge detector that
    drives auto-escalation."""
    records = [_user("Add the regression test.")]
    ow.accumulate_ledger(tmp_path, ow.derive_ledger_entries(records))
    path = ow.ledger_path(tmp_path)
    before = path.read_bytes()

    ow.accumulate_ledger(tmp_path, ow.derive_ledger_entries(records))
    assert path.read_bytes() == before, (
        "a no-change accumulate rewrote the ledger — that fakes progress for "
        "run_continuity's no-progress fingerprint"
    )


def test_read_ledger_absent_is_empty_but_corrupt_raises(tmp_path: Path) -> None:
    """Absent is genuinely empty. Corrupt is UNKNOWN, and unknown is not empty —
    it raises so the caller can turn it into a named blocking violation."""
    assert ow.read_ledger(tmp_path) == {"schema": 1, "entries": []}

    path = ow.ledger_path(tmp_path)
    path.parent.mkdir(parents=True, exist_ok=True)
    path.write_text("{not json", encoding="utf-8")
    with pytest.raises(ow.LedgerUnreadable):
        ow.read_ledger(tmp_path)


def test_read_ledger_wrong_shape_raises_rather_than_reading_as_empty(tmp_path: Path) -> None:
    path = ow.ledger_path(tmp_path)
    path.parent.mkdir(parents=True, exist_ok=True)
    path.write_text(json.dumps(["not", "a", "ledger"]), encoding="utf-8")
    with pytest.raises(ow.LedgerUnreadable):
        ow.read_ledger(tmp_path)

    path.write_text(json.dumps({"schema": 1, "entries": "nope"}), encoding="utf-8")
    with pytest.raises(ow.LedgerUnreadable):
        ow.read_ledger(tmp_path)


def test_ledger_path_is_under_the_workspace_state_dir(tmp_path: Path) -> None:
    assert ow.ledger_path(tmp_path) == tmp_path / ".architect-team" / "ask-ledger.json"
    assert ow.LEDGER_FILENAME == "ask-ledger.json"


def test_derive_reads_genuine_user_prompts_only(tmp_path: Path) -> None:
    """Derivation is from the HARNESS-written transcript, so an agent cannot
    decline to register an ask. The injected records the harness also stores as
    role=user (meta echoes, system-injected notifications, sidechains) are not
    the user's directives and must not become entries."""
    records = [
        _user("Refactor the exporter."),
        _user("<the loaded skill body>", isMeta=True),
        _user("<task-notification>agent finished</task-notification>",
              promptSource="system"),
        _user("subagent chatter", isSidechain=True),
        _assistant("I'll take care of the exporter refactor and report back."),
    ]
    derived = ow.derive_ledger_entries(records)
    assert [e["text"] for e in derived] == ["Refactor the exporter."]


def test_derive_skips_bare_acknowledgements(tmp_path: Path) -> None:
    """A bare ack carries no new ask. Registering one would open an entry that
    can never be honestly resolved — noise that gets the whole gate disabled."""
    records = [_user("thanks"), _user("ok"), _user("yes"), _user("continue"),
               _user("   "), _user("Sounds good.")]
    assert ow.derive_ledger_entries(records) == []


def test_derive_entry_shape_and_stable_id(tmp_path: Path) -> None:
    text = "Wire the completion lock into main()."
    a = ow.derive_ledger_entries([_user(text, ts="2026-08-12T09:00:00Z")])[0]
    b = ow.derive_ledger_entries([_user(text, ts="2026-08-12T21:00:00Z")])[0]
    assert a["id"] == b["id"], "the id is a stable hash of the directive text"
    assert set(a) == {"id", "text", "first_seen", "status", "resolved_at", "evidence"}
    assert a["text"] == text
    assert a["status"] == "open"
    assert a["resolved_at"] is None and a["evidence"] is None
    assert a["first_seen"].endswith("Z")


# The REAL harness shape for a slash command, taken from a live transcript:
# three sibling tags, and the user's prose lives in <command-args>.
_REAL_COMMAND_PROMPT = (
    "<command-name>/architect-team:architect-team</command-name>"
    "<command-message>architect-team</command-message>"
    "<command-args>Agent Teams sessions are ending their turn with work still "
    "open. Build a completion lock that refuses the stop while registered work "
    "is open.</command-args>"
)


def test_command_prompt_derives_the_users_prose_not_nothing(tmp_path: Path) -> None:
    """F1. Dropping the whole prompt because it carries a command marker drops
    the user's DIRECTIVE with it — measured at 25 of 51 command-carrying prompts
    in the user's own history, including the prompt that commissioned this
    feature. The invocation is stripped; the prose is the ask."""
    entries = ow.derive_ledger_entries([_user(_REAL_COMMAND_PROMPT)])
    assert len(entries) == 1, "the user's ask must survive its own slash command"
    text = entries[0]["text"]
    assert text.startswith("Agent Teams sessions are ending their turn")
    assert "<command-" not in text and "/architect-team" not in text, text


def test_bare_invocation_with_no_prose_derives_nothing(tmp_path: Path) -> None:
    """The invocation alone is not an ask. A single bare argument is a setting,
    not prose — `/model opus` must not register 'opus' as an outstanding ask."""
    for text in (
        "<command-name>/architect-team:status</command-name>"
        "<command-message>status</command-message><command-args></command-args>",
        "<command-name>/clear</command-name><command-message>clear</command-message>",
        "<command-name>/model</command-name><command-message>model</command-message>"
        "<command-args>opus</command-args>",
        "<command-name>/effort</command-name><command-message>effort</command-message>"
        "<command-args>max</command-args>",
    ):
        assert ow.derive_ledger_entries([_user(text)]) == [], text


def test_flag_only_command_arguments_are_not_directives(tmp_path: Path) -> None:
    """N3. `/setup --external-llm --yes` clears the two-word bar but is options,
    not an ask. A ledger full of flag noise is how a user learns to disable the
    gate."""
    for text in (
        "<command-name>/architect-team:setup</command-name>"
        "<command-message>setup</command-message>"
        "<command-args>--external-llm --yes</command-args>",
        "<command-name>/architect-team:cleanup-worktrees</command-name>"
        "<command-args>--dry-run -v</command-args>",
    ):
        assert ow.derive_ledger_entries([_user(text)]) == [], text


def test_flags_mixed_with_prose_still_derive(tmp_path: Path) -> None:
    """The N3 guard must not eat a real ask that happens to carry a flag."""
    text = ("<command-name>/architect-team:setup</command-name>"
            "<command-args>--yes and wire the gateway to z.ai</command-args>")
    assert [e["text"] for e in ow.derive_ledger_entries([_user(text)])] == [
        "--yes and wire the gateway to z.ai"
    ]


def test_prose_outside_the_tags_is_also_kept(tmp_path: Path) -> None:
    """The older/simpler shape puts the prose after the closing tag."""
    records = [
        _user("<command-name>/architect-team:architect-team</command-name> build it"),
        _user("Also add the migration for the new column."),
    ]
    assert [e["text"] for e in ow.derive_ledger_entries(records)] == [
        "build it",
        "Also add the migration for the new column.",
    ]


def test_injected_reminder_blocks_do_not_destabilize_the_id(tmp_path: Path) -> None:
    """The harness appends <system-reminder> blocks to user prompts and their
    content churns between turns. Hashing them would mint a NEW id for the same
    directive on every pass, so the ledger could only grow and no entry could
    ever be resolved."""
    plain = "Add the migration for the new column."
    withreminder = (plain + "\n<system-reminder>tasks: 4 open, 2 done"
                    "</system-reminder>")
    a = ow.derive_ledger_entries([_user(plain)])[0]
    b = ow.derive_ledger_entries([_user(withreminder)])[0]
    assert b["text"] == plain, "the stored text is the user's words"
    assert a["id"] == b["id"]


def test_resolution_is_conservative_ambiguous_stays_open(tmp_path: Path) -> None:
    """Over-blocking fails safe; under-blocking is the reported bug. A resolve
    with no evidence, or for an id that is not stored, changes nothing."""
    ow.accumulate_ledger(tmp_path, ow.derive_ledger_entries([_user("Ship the docs.")]))
    entry_id = ow.read_ledger(tmp_path)["entries"][0]["id"]

    ow.resolve_ledger_entry(tmp_path, entry_id, evidence="")
    assert len(ow.open_ledger_entries(tmp_path)) == 1, "no evidence -> stays open"

    ow.resolve_ledger_entry(tmp_path, entry_id, evidence="   ")
    assert len(ow.open_ledger_entries(tmp_path)) == 1, "blank evidence -> stays open"

    ow.resolve_ledger_entry(tmp_path, "no-such-id", evidence="README.md updated")
    assert len(ow.open_ledger_entries(tmp_path)) == 1, "unknown id resolves nothing"

    ow.resolve_ledger_entry(tmp_path, entry_id, evidence="README.md updated")
    assert ow.open_ledger_entries(tmp_path) == []


def test_unknown_ledger_status_counts_as_open(tmp_path: Path) -> None:
    """Same asymmetry as the task list: unknown state is not 'done'."""
    path = ow.ledger_path(tmp_path)
    path.parent.mkdir(parents=True, exist_ok=True)
    path.write_text(json.dumps({"schema": 1, "entries": [
        {"id": "a", "text": "one", "first_seen": "2026-08-12T09:00:00Z",
         "status": "wat", "resolved_at": None, "evidence": None},
        {"id": "b", "text": "two", "first_seen": "2026-08-12T09:00:00Z",
         "resolved_at": None, "evidence": None},
        {"id": "c", "text": "three", "first_seen": "2026-08-12T09:00:00Z",
         "status": "resolved", "resolved_at": "2026-08-12T10:00:00Z",
         "evidence": "done"},
    ]}), encoding="utf-8")
    assert [e["id"] for e in ow.open_ledger_entries(tmp_path)] == ["a", "b"]


# =============================================================================
# Group 1 — the harness task list. Read failures are DATA, never exceptions.
# =============================================================================

def _write_task(root: Path, session_id: str, task_id: str,
                status: str | None = "pending", owner: str | None = None,
                **extra) -> Path:
    d = Path(root) / f"session-{session_id[:8]}"
    d.mkdir(parents=True, exist_ok=True)
    rec: dict = {"id": task_id, "subject": f"subject {task_id}",
                 "description": "d", "activeForm": "doing", "owner": owner,
                 "blocks": [], "blockedBy": []}
    if status is not None:
        rec["status"] = status
    rec.update(extra)
    p = d / f"{task_id}.json"
    p.write_text(json.dumps(rec), encoding="utf-8")
    return p


def test_open_and_terminal_statuses_partition(tmp_path: Path) -> None:
    _write_task(tmp_path, "sess1234abcd", "T-1", status="pending")
    _write_task(tmp_path, "sess1234abcd", "T-2", status="in_progress")
    _write_task(tmp_path, "sess1234abcd", "T-3", status="completed")

    read = ow.read_harness_tasks("sess1234abcd", tmp_path)
    assert read["unreadable"] == []
    assert len(read["items"]) == 3
    assert {i["id"] for i in ow.open_task_items(read["items"])} == {"T-1", "T-2"}
    assert ow.OPEN_STATUSES == frozenset({"pending", "in_progress"})


def test_missing_or_unknown_status_counts_as_open(tmp_path: Path) -> None:
    """Unknown state is not 'done'. The asymmetry is deliberate and fails safe."""
    _write_task(tmp_path, "sess1234abcd", "T-1", status=None)
    _write_task(tmp_path, "sess1234abcd", "T-2", status="")
    _write_task(tmp_path, "sess1234abcd", "T-3", status="banana")
    _write_task(tmp_path, "sess1234abcd", "T-4", status="completed")

    read = ow.read_harness_tasks("sess1234abcd", tmp_path)
    assert {i["id"] for i in ow.open_task_items(read["items"])} == {"T-1", "T-2", "T-3"}


def test_malformed_task_file_is_data_not_an_exception(tmp_path: Path) -> None:
    """A blanket fail-open here reproduces the exact reported bug: one bad file
    and the gate silently passes. It lands in unreadable[] instead."""
    _write_task(tmp_path, "sess1234abcd", "T-1", status="completed")
    bad = tmp_path / "session-sess1234" / "T-9.json"
    bad.write_text("{ not json at all", encoding="utf-8")

    read = ow.read_harness_tasks("sess1234abcd", tmp_path)  # must NOT raise
    assert [i["id"] for i in read["items"]] == ["T-1"]
    assert len(read["unreadable"]) == 1
    entry = read["unreadable"][0]
    assert Path(entry["path"]) == bad
    assert entry["reason"], "the unreadable entry names WHY it could not be read"


def test_permission_error_on_a_task_file_lands_in_unreadable(
    tmp_path: Path, monkeypatch: pytest.MonkeyPatch
) -> None:
    """Not only a parse failure — a file the reader is not allowed to open is
    unknown state too, and `lock-wiring` depends on it reaching the
    block-and-name path rather than raising."""
    _write_task(tmp_path, "sess1234abcd", "T-1", status="pending")
    real_read_text = Path.read_text

    def denied(self: Path, *args, **kwargs):
        if self.name == "T-1.json":
            raise PermissionError(13, "Permission denied")
        return real_read_text(self, *args, **kwargs)

    monkeypatch.setattr(Path, "read_text", denied)
    read = ow.read_harness_tasks("sess1234abcd", tmp_path)  # must NOT raise
    assert read["items"] == []
    assert len(read["unreadable"]) == 1
    assert read["unreadable"][0]["path"].endswith("T-1.json")
    assert "Permission denied" in read["unreadable"][0]["reason"]


def test_unlistable_session_dir_lands_in_unreadable(
    tmp_path: Path, monkeypatch: pytest.MonkeyPatch
) -> None:
    _write_task(tmp_path, "sess1234abcd", "T-1", status="pending")
    real_iterdir = Path.iterdir

    def denied(self: Path):
        if self.name == "session-sess1234":
            raise PermissionError(13, "Permission denied")
        return real_iterdir(self)

    monkeypatch.setattr(Path, "iterdir", denied)
    read = ow.read_harness_tasks("sess1234abcd", tmp_path)  # must NOT raise
    assert read["items"] == []
    assert len(read["unreadable"]) == 1
    assert Path(read["unreadable"][0]["path"]).name == "session-sess1234"


def test_non_object_json_task_is_unreadable(tmp_path: Path) -> None:
    d = tmp_path / "session-sess1234"
    d.mkdir(parents=True)
    (d / "T-8.json").write_text(json.dumps(["not", "a", "task"]), encoding="utf-8")
    read = ow.read_harness_tasks("sess1234abcd", tmp_path)
    assert read["items"] == []
    assert len(read["unreadable"]) == 1


def test_recursion_bomb_json_is_data_not_an_exception(tmp_path: Path) -> None:
    """F2. `except (OSError, ValueError)` misses RecursionError, so a
    deeply-nested JSON escapes both readers and breaks the property all of
    REQ-6 rests on. The property must hold for EVERY malformed input, not the
    two shapes that were anticipated."""
    _write_task(tmp_path, "sess1234abcd", "T-1", status="completed")
    bomb = tmp_path / "session-sess1234" / "T-9.json"
    bomb.write_text("[" * 200000, encoding="utf-8")

    read = ow.read_harness_tasks("sess1234abcd", tmp_path)  # must NOT raise
    assert [i["id"] for i in read["items"]] == ["T-1"]
    assert len(read["unreadable"]) == 1
    assert read["unreadable"][0]["path"].endswith("T-9.json")


def test_recursion_bomb_ledger_raises_ledger_unreadable(tmp_path: Path) -> None:
    """The ledger's half of F2: still a NAMED blocking violation, never a raw
    RecursionError escaping into the hook."""
    path = ow.ledger_path(tmp_path)
    path.parent.mkdir(parents=True, exist_ok=True)
    path.write_text("[" * 200000, encoding="utf-8")
    with pytest.raises(ow.LedgerUnreadable):
        ow.read_ledger(tmp_path)


def test_sidecars_are_skipped_by_name_not_by_parse_failure(tmp_path: Path) -> None:
    """The sidecars are KNOWN non-tasks, so they are skipped by name. Anything
    else unparseable is unknown state and must surface."""
    _write_task(tmp_path, "sess1234abcd", "T-1", status="pending")
    d = tmp_path / "session-sess1234"
    (d / ".lock").write_text("pid 1234", encoding="utf-8")
    (d / ".highwatermark").write_text("42", encoding="utf-8")

    read = ow.read_harness_tasks("sess1234abcd", tmp_path)
    assert read["unreadable"] == [], "the known sidecars are not 'unreadable'"
    assert [i["id"] for i in read["items"]] == ["T-1"]
    assert ow.TASK_SIDECARS == frozenset({".lock", ".highwatermark"})


def test_unknown_extra_file_surfaces_as_unreadable(tmp_path: Path) -> None:
    """A file in the task store that is neither a task nor a known sidecar is
    unknown state — silently dropping it is how a format change becomes an
    invisible pass."""
    _write_task(tmp_path, "sess1234abcd", "T-1", status="completed")
    (tmp_path / "session-sess1234" / "notes.txt").write_text("hi", encoding="utf-8")
    read = ow.read_harness_tasks("sess1234abcd", tmp_path)
    assert len(read["unreadable"]) == 1
    assert read["unreadable"][0]["path"].endswith("notes.txt")


def test_missing_session_dir_is_a_clean_empty_result(tmp_path: Path) -> None:
    """Absent is genuinely empty — NOT an unreadable entry. A session that never
    registered a task must not be blocked."""
    read = ow.read_harness_tasks("sess1234abcd", tmp_path)
    assert read["items"] == [] and read["unreadable"] == []


def test_empty_session_id_yields_no_directory(tmp_path: Path) -> None:
    for sid in ("", None):
        read = ow.read_harness_tasks(sid, tmp_path)
        assert read == {"items": [], "unreadable": [], "dir": None}


def test_session_dir_is_the_first_eight_characters(tmp_path: Path) -> None:
    _write_task(tmp_path, "abcdefgh-ijkl-mnop", "T-1", status="pending")
    read = ow.read_harness_tasks("abcdefgh-ijkl-mnop", tmp_path)
    assert Path(read["dir"]).name == "session-abcdefgh"
    assert [i["id"] for i in read["items"]] == ["T-1"]


def test_items_carry_their_source_path(tmp_path: Path) -> None:
    p = _write_task(tmp_path, "sess1234abcd", "T-1", status="pending")
    read = ow.read_harness_tasks("sess1234abcd", tmp_path)
    assert Path(read["items"][0]["_path"]) == p


def test_owner_filter_scopes_to_one_teammate(tmp_path: Path) -> None:
    _write_task(tmp_path, "sess1234abcd", "T-1", status="pending", owner="lock-core")
    _write_task(tmp_path, "sess1234abcd", "T-2", status="pending", owner="lock-wiring")
    _write_task(tmp_path, "sess1234abcd", "T-3", status="pending")

    items = ow.read_harness_tasks("sess1234abcd", tmp_path)["items"]
    assert {i["id"] for i in ow.open_task_items(items)} == {"T-1", "T-2", "T-3"}
    assert [i["id"] for i in ow.open_task_items(items, owner="lock-core")] == ["T-1"]
    assert ow.open_task_items(items, owner="nobody") == []


def test_tasks_root_precedence_explicit_beats_env_beats_home(
    tmp_path: Path, monkeypatch: pytest.MonkeyPatch
) -> None:
    """The injected root IS the test seam — an explicit argument must win, and
    the real ~/.claude/tasks is only the last resort."""
    home = tmp_path / "home"
    monkeypatch.setattr(Path, "home", classmethod(lambda cls: home))
    monkeypatch.delenv("CT6_TASKS_ROOT", raising=False)
    assert ow.tasks_root() == home / ".claude" / "tasks"

    monkeypatch.setenv("CT6_TASKS_ROOT", str(tmp_path / "from-env"))
    assert ow.tasks_root() == tmp_path / "from-env"
    assert ow.tasks_root(tmp_path / "explicit") == tmp_path / "explicit"


def test_read_harness_tasks_honours_the_env_root(
    tmp_path: Path, monkeypatch: pytest.MonkeyPatch
) -> None:
    monkeypatch.setenv("CT6_TASKS_ROOT", str(tmp_path))
    _write_task(tmp_path, "sess1234abcd", "T-1", status="pending")
    read = ow.read_harness_tasks("sess1234abcd")
    assert [i["id"] for i in read["items"]] == ["T-1"]


# --- the turn-output classifier: pinned in BOTH directions -------------------

def test_three_substantial_markerless_lines_are_NOT_a_narrative(tmp_path: Path) -> None:
    """SUPERSEDED AGAIN (H1) — and inverted, because this test WAS the bug.

    It previously asserted `narrative is True` for three report-length
    markerless lines. Measured on the shipped module, that is indistinguishable
    from ordinary inter-tool narration: three natural sentences run 45-60 chars
    each, so an agent saying what it is about to do three times tripped the
    gate. G3 was reported as "six one-line narration blocks" and fixed by
    raising the CEILING, which only ever reached the short-line arm — the class
    was never fixed, and this test was pinning the unfixed half.

    The first fix retired the arm outright; the independent review pushed back
    that this let a markerless plain-prose report through at any length under
    600 chars, which is fair. The arm is RAISED instead (3 -> 6), so three
    narration sentences clear while six report-length lines still trip — pinned
    by test_six_markerless_report_lines_is_a_narrative below."""
    r = ow.classify_turn_output(
        "I finished the exporter refactor and pushed it.\n"
        "The full suite is green under both encodings.\n"
        "I will start on the lineage sidecar next."
    )
    assert r["narrative"] is False
    assert r["lines"] == 3
    assert r["markers"] == []
    assert r["reason"]


def test_a_handful_of_terse_state_lines_is_not_a_narrative(tmp_path: Path) -> None:
    """F6 — the false positive did not go away when markers stopped deciding,
    it MOVED to the line-count arm. Three short markerless lines totalling 37
    non-whitespace characters is a terse state report, which is exactly what
    the block message asks for. Blocking it is the same wedge in a new place."""
    r = ow.classify_turn_output("task 2 in progress\ntask 3 pending\nno blockers")
    assert r["narrative"] is False, (
        "a terse state report is what the rule ASKS for; refusing it is the "
        "same loop that made the marker arm unshippable"
    )
    assert r["lines"] == 3, "still reported honestly — they just do not COUNT"


def test_many_short_markerless_lines_are_a_narrative(tmp_path: Path) -> None:
    """T2 — the ceiling my F6 tuning was missing. Counting only report-length
    lines left the line arm with no upper bound, so a report made ENTIRELY of
    short lines never reached it: 30 lines at 19 chars is 569 characters, under
    the 600 prose arm too, and passed clean. Nothing legitimate is a six-line
    state update."""
    report = "\n".join(f"task {i} is pending" for i in range(30))
    assert all(len(l) < ow.NARRATIVE_MIN_LINE_CHARS for l in report.splitlines())
    assert len(report) < ow.NARRATIVE_PROSE_CHARS, "under the prose arm as well"

    r = ow.classify_turn_output(report)
    assert r["narrative"] is True
    assert r["lines"] == 30


def test_a_few_short_markerless_lines_stay_below_the_ceiling(tmp_path: Path) -> None:
    """The other direction: the ceiling must not eat the F6 allowance it sits
    above. Five terse state lines are still a state update."""
    r = ow.classify_turn_output("\n".join(f"task {i} pending" for i in range(5)))
    assert r["narrative"] is False
    assert r["lines"] == 5 and 5 < ow.NARRATIVE_ABSOLUTE_LINES


def test_a_short_bullet_summary_is_still_a_narrative(tmp_path: Path) -> None:
    """The F6 allowance must not become an F4 hole: a bullet list of short items
    is a summary, not terse state.

    It is caught by the MARKER arm, not the line-count arm. The first cut also
    exempted marked lines from the short-line rule; the mutation harness showed
    that clause was dead — markers already decide at >= 2 lines, while the
    line-count arm needs >= 3 — so it was removed rather than left as
    reassuring but inert code."""
    r = ow.classify_turn_output("- T-1 done\n- T-2 done\n- T-3 next")
    assert r["narrative"] is True
    assert "bullet" in r["markers"]


def test_two_substantial_markerless_lines_are_not_a_narrative(tmp_path: Path) -> None:
    """The witness for NARRATIVE_LINE_THRESHOLD itself. Two full report-length
    lines with no marker sit just under the bar; the terse two-line case cannot
    pin this any more, because F6's short-line rule now excludes those lines
    before the threshold is ever consulted."""
    r = ow.classify_turn_output(
        "I finished the exporter refactor and pushed it to the branch.\n"
        "The suite is green under both encodings and I am moving on."
    )
    assert r["narrative"] is False and r["markers"] == []
    assert r["lines"] == 2


def test_five_lines_of_plain_prose_is_NOT_a_narrative(tmp_path: Path) -> None:
    """SUPERSEDED (H1), inverted, and the residual is deliberate.

    Five markerless prose lines under 600 chars are now ALLOWED. That is the
    accepted cost of not blocking ordinary narration — see the sibling test
    above. The user's reported failure was 'I fill it with a summary', and a
    summary carries structure; the marker arm catches it at two lines. An
    unstructured five-line narration is not that shape.

    HONEST RESIDUAL, narrowed: a markerless prose report of 3..5 report-length
    lines under 600 chars slips. Six trips. The two shapes genuinely overlap in
    that band and no threshold separates them; recorded in
    docs/proposals/COMPLETION_LOCK_FOLLOWUPS.md rather than papered over."""
    r = ow.classify_turn_output("\n".join([
        "I finished the exporter refactor.",
        "The suite is green under both encodings.",
        "I also checked the lineage sidecar and it needs no change.",
        "Next I will wire the CLI.",
        "Tell me if you want a different order.",
    ]))
    assert r["narrative"] is False
    assert r["markers"] == [] and r["lines"] == 5


def test_six_markerless_report_lines_is_a_narrative(tmp_path: Path) -> None:
    """The other half of H1, and the reason the arm was raised rather than
    retired: a marker-only rule cannot see a report that simply does not use
    markdown. Six report-length markerless lines trip; five do not."""
    prose = [f"I finished the {w} and it is green under both encodings."
             for w in ("exporter", "parser", "lineage", "cli", "docs", "hooks")]
    r6 = ow.classify_turn_output("\n".join(prose))
    assert r6["narrative"] is True
    assert r6["markers"] == []
    r5 = ow.classify_turn_output("\n".join(prose[:5]))
    assert r5["narrative"] is False


def test_two_lines_with_no_marker_is_not_a_narrative(tmp_path: Path) -> None:
    """A rule that fires on a legitimate terse status update gets disabled by
    the user, which is the same as not shipping it."""
    r = ow.classify_turn_output("Working on T-3.\n4 of 17 done.")
    assert r["narrative"] is False
    assert r["lines"] == 2 and r["markers"] == []


def test_one_line_and_empty_are_not_narratives(tmp_path: Path) -> None:
    assert ow.classify_turn_output("T-3 in progress.")["narrative"] is False
    for empty in ("", "   ", "\n\n\n"):
        r = ow.classify_turn_output(empty)
        assert r["narrative"] is False and r["lines"] == 0


def test_blank_lines_do_not_count_toward_the_line_threshold(tmp_path: Path) -> None:
    r = ow.classify_turn_output("Still on T-3.\n\n\n2 left.")
    assert r["lines"] == 2 and r["narrative"] is False


@pytest.mark.parametrize("text,marker", [
    ("## Summary of the run", "heading"),
    ("# Done", "heading"),
    ("- fixed the exporter", "bullet"),
    ("* fixed the exporter", "bullet"),
    ("+ fixed the exporter", "bullet"),
    ("1. fixed the exporter", "numbered"),
    ("2) fixed the exporter", "numbered"),
    ("**Status:** blocked on review", "bold-label"),
    ("**Status**: blocked on review", "bold-label"),
    ("| task | state |", "table-row"),
])
def test_each_structural_marker_is_detected_and_reported(text: str, marker: str) -> None:
    """SUPERSEDED (v3.56.0): markers no longer trip the rule on their own.

    This test used to assert a single marker-carrying line was a narrative. That
    shipped a loop: the block message demands one line of state, and
    `**Status:** still on task 1 of 9.` — that exact shape — tripped `bold-label`
    and re-blocked, with no exit but a kill-switch. A marker cannot indicate
    report STRUCTURE in a turn too short to have any.

    What survives is what is still true and still worth pinning: DETECTION. Each
    marker kind must still be recognized and reported, because the reason string
    uses them and the length arms are what decide. The tripping assertion moves
    to `test_markers_trip_once_the_turn_is_long_enough` below.
    """
    r = ow.classify_turn_output(text)
    assert marker in r["markers"], f"{marker} must still be DETECTED"
    assert r["lines"] == 1
    assert r["narrative"] is False, "a one-line turn is never a narrative"


def test_markers_trip_once_the_turn_is_long_enough(tmp_path: Path) -> None:
    """The tripping half of the superseded marker test: a marker-carrying turn
    that is genuinely long enough IS a narrative, and the marker is reported."""
    r = ow.classify_turn_output("Here is where things stand.\n"
                                "- T-1 done\n"
                                "- T-2 in review")
    assert r["narrative"] is True
    assert "bullet" in r["markers"]
    assert r["lines"] == 3


def test_a_one_line_marked_state_is_never_a_narrative(tmp_path: Path) -> None:
    """THE ABSOLUTE FLOOR. This is the exact turn that shipped the unbreakable
    loop — the one line of state the block message demands, carrying a bold
    label. Whatever else moves in this predicate, this must not.

    (The two-line half of the old version of this test was itself a
    regression — see `test_a_two_line_summary_with_a_marker_trips` below.)"""
    r = ow.classify_turn_output("**Status:** still on task 1 of 9.")
    assert r["narrative"] is False, (
        "the block asks for one line of state; refusing one line of state is a "
        "loop whose only exit is a kill-switch"
    )
    assert "bold-label" in r["markers"], "still detected, just not decisive"

    for one_liner in ("## Done", "- shipped it", "1. shipped it", "| a | b |"):
        assert ow.classify_turn_output(one_liner)["narrative"] is False, one_liner


@pytest.mark.parametrize("text,marker", [
    ("Here is where things stand.\n- T-1 done", "bullet"),
    ("## Summary\nEverything landed.", "heading"),
    ("| task | state |\n| T-1 | done |", "table-row"),
    ("**Done:** the exporter\n**Remaining:** the sidecar", "bold-label"),
    ("Progress:\n1. shipped the exporter", "numbered"),
])
def test_a_two_line_summary_with_a_marker_trips(text: str, marker: str) -> None:
    """F4 — the correction to my correction. Making the length floor dominate
    removed the unbreakable loop AND most of the enforcement with it: every one
    of these is unmistakably a report, and every one slipped. The user's
    reported failure is literally 'every time my turn is about to end, I fill
    it with a summary', so a two-line summary is THE shape this rule exists to
    catch. Markers decide at >= 2 lines; the 1-line floor stays absolute."""
    r = ow.classify_turn_output(text)
    assert r["narrative"] is True, f"a 2-line {marker} summary must re-block"
    assert marker in r["markers"]
    assert r["lines"] == 2


def test_a_single_unbroken_paragraph_report_is_a_narrative(tmp_path: Path) -> None:
    """The long-prose arm replaces what markers were really catching: a report
    that just lacks newlines. Line count alone missed it."""
    prose = ("I finished the exporter refactor and then went through the "
             "lineage sidecar looking for anything that needed to change. " * 6)
    # F5: the threshold is measured on the RAW text, so the constant means what
    # it says. It used to measure after whitespace removal, which made the real
    # threshold ~715 raw chars and let a 700-char paragraph slip at 560 measured.
    assert len(prose.strip()) > ow.NARRATIVE_PROSE_CHARS
    r = ow.classify_turn_output(prose)
    assert r["narrative"] is True and r["lines"] == 1
    assert str(ow.NARRATIVE_PROSE_CHARS) in r["reason"]


def test_the_prose_threshold_is_measured_on_raw_text(tmp_path: Path) -> None:
    """F5, pinned as an equivalence rather than a vibe: a paragraph just over
    the constant trips and one just under does not, both measured the way the
    docstring says they are."""
    over = "x" * (ow.NARRATIVE_PROSE_CHARS + 20)
    under = "x" * (ow.NARRATIVE_PROSE_CHARS - 20)
    assert ow.classify_turn_output(over)["narrative"] is True
    assert ow.classify_turn_output(under)["narrative"] is False

    # The old whitespace-stripped basis would have measured this UNDER the
    # constant while the raw text is over it — the exact gap F5 names. 130
    # four-letter words: 520 stripped, 649 raw.
    spaced = " ".join("word" for _ in range(130))
    assert len("".join(spaced.split())) < ow.NARRATIVE_PROSE_CHARS < len(spaced), (
        "the fixture must straddle the constant, or it pins nothing"
    )
    assert ow.classify_turn_output(spaced)["narrative"] is True, (
        "measured raw, this is over the threshold and is a report"
    )


def test_a_short_paragraph_under_the_prose_cap_is_not_a_narrative(
    tmp_path: Path
) -> None:
    """The other direction of the prose arm — a genuinely brief one-liner stays
    clean, so the cap cannot creep down into ordinary state lines."""
    r = ow.classify_turn_output("Still on T-1; the exporter fix is under review.")
    assert r["narrative"] is False


def test_prose_containing_a_pipe_or_hash_is_not_a_table_or_heading(tmp_path: Path) -> None:
    """False positives train the user to disable the gate."""
    r = ow.classify_turn_output("Piping a | b into sort.\nIssue #4 is next.")
    assert r["narrative"] is False, f"unexpected markers: {r['markers']}"


_SNIPPET = "```\nline one of output\nline two of output\nline three\n```"


def test_a_state_line_with_a_code_snippet_is_not_a_narrative(tmp_path: Path) -> None:
    """T4 — and this one is MINE, introduced by the T2 ceiling rather than
    inherited. Before T2 this shape measured `lines=5, markers=[],
    narrative=False`; the ceiling counts every non-empty line including the
    fences and the snippet body, so the same turn became 6 lines and tripped.

    A status update carrying a snippet is an ordinary shape and blocking it is
    exactly the 'blocked for shit reasons' the whole stretch exists to stop.
    Code is not report prose, so fenced content does not feed the line arms."""
    for n in (3, 5, 8):
        body = "\n".join(f"line {i} of output" for i in range(n))
        r = ow.classify_turn_output(f"Still on T-1.\n```\n{body}\n```")
        assert r["narrative"] is False, f"{n}-line snippet tripped the ceiling"


def test_a_marked_state_line_with_a_snippet_is_not_a_narrative(tmp_path: Path) -> None:
    """The marker-bar sibling of T4: a snippet must not push a ONE-line marked
    state over the >= 2-line bar either."""
    r = ow.classify_turn_output(f"**Status:** still on task 1 of 9.\n{_SNIPPET}")
    assert r["narrative"] is False
    assert "bold-label" in r["markers"], "still detected, still not decisive"


def test_the_ceiling_still_fires_on_a_long_report_containing_a_snippet(
    tmp_path: Path
) -> None:
    """The counter-witness. The failure mode when fixing a false positive is
    making the rule toothless: a genuine long report does not stop being one
    because it quotes some output."""
    report = "\n".join(f"task {i} is pending" for i in range(8))
    r = ow.classify_turn_output(f"{report}\n{_SNIPPET}")
    assert r["narrative"] is True, "8 report lines are 8 report lines"


def test_an_unclosed_fence_does_not_suppress_markers(tmp_path: Path) -> None:
    """An agent could otherwise open a fence and never close it, hiding every
    marker after it — a bulleted summary behind a bare ``` was invisible to the
    marker arm. An unterminated fence opens nothing."""
    r = ow.classify_turn_output("Here is the plan.\n```\n- item one\n- item two")
    assert "bullet" in r["markers"], "an unterminated fence suppresses nothing"
    assert r["narrative"] is True


def test_a_balanced_fence_still_suppresses_markers(tmp_path: Path) -> None:
    """The other direction: real fenced code must keep its exemption, or every
    '#' comment in a snippet becomes a heading."""
    r = ow.classify_turn_output("Ran it.\n```\n# not a heading\n- not a bullet\n```")
    assert r["markers"] == [], f"unexpected markers: {r['markers']}"


def test_fenced_and_indented_code_do_not_create_markers(tmp_path: Path) -> None:
    """A '#' comment inside a code block is not a heading."""
    fenced = ow.classify_turn_output("Ran it.\n```\n# not a heading\n- not a bullet\n```")
    assert fenced["markers"] == [], f"unexpected markers: {fenced['markers']}"
    indented = ow.classify_turn_output("Ran it.\n    # not a heading")
    assert indented["markers"] == [] and indented["narrative"] is False


def test_classify_is_pure_and_tolerates_a_non_string(tmp_path: Path) -> None:
    assert ow.classify_turn_output(None)["narrative"] is False  # type: ignore[arg-type]


# --- the four kill-switches --------------------------------------------------

def test_killswitch_constants_are_the_documented_names(tmp_path: Path) -> None:
    assert ow.DISABLE_ENV == "CT6_COMPLETION_LOCK_DISABLED"
    assert ow.DISABLE_TASKS_ENV == "CT6_TASK_LIST_GATE_DISABLED"
    assert ow.DISABLE_LEDGER_ENV == "CT6_ASK_LEDGER_GATE_DISABLED"
    assert ow.DISABLE_OUTPUT_ENV == "CT6_TURN_OUTPUT_GATE_DISABLED"


def test_each_switch_reads_only_its_own_variable(monkeypatch: pytest.MonkeyPatch) -> None:
    """Disabling a noisy source must not disable the sources that work."""
    readers = {
        ow.DISABLE_ENV: ow.lock_disabled,
        ow.DISABLE_TASKS_ENV: ow.tasks_disabled,
        ow.DISABLE_LEDGER_ENV: ow.ledger_disabled,
        ow.DISABLE_OUTPUT_ENV: ow.output_disabled,
    }
    assert all(not fn() for fn in readers.values()), "all off by default"
    for var, fn in readers.items():
        monkeypatch.setenv(var, "1")
        assert fn() is True
        for other_var, other_fn in readers.items():
            if other_var != var:
                assert other_fn() is False, f"{var} leaked into {other_var}"
        monkeypatch.delenv(var)


@pytest.mark.parametrize("value,expected", [
    ("1", True), ("true", True), ("TRUE", True), ("yes", True), ("on", True),
    ("", False), ("0", False), ("false", False), ("no", False), ("  ", False),
])
def test_truthy_env_shape_matches_run_continuity(
    value: str, expected: bool, monkeypatch: pytest.MonkeyPatch
) -> None:
    monkeypatch.setenv(ow.DISABLE_ENV, value)
    assert ow.lock_disabled() is expected


# =============================================================================
# Group 3 — teammate identity. Never wedge a worker on a lane it cannot close.
# =============================================================================

def test_teammate_name_from_the_mandated_bracketed_brief(tmp_path: Path) -> None:
    records = [_user("[CT6-TEAMMATE lock-core RUN turn-boundary-completion-lock]\n"
                     "\nYou own hooks/open_work.py.")]
    assert ow.teammate_name(records) == "lock-core"


def test_teammate_name_from_the_lenient_brief_form(tmp_path: Path) -> None:
    """Real briefs are also written without the brackets or the RUN tail."""
    records = [_user("CT6-TEAMMATE lock-wiring\n\nYou own the Stop hook wiring.")]
    assert ow.teammate_name(records) == "lock-wiring"


# A teams-mode spawn brief: a role:user record wrapped in the peer envelope,
# arriving as the FIRST inbound record of the teammate's transcript.
_ENVELOPE_BRIEF = ('<teammate-message teammate_id="team-lead">\n'
                   '[CT6-TEAMMATE lock-core RUN turn-boundary-completion-lock]\n'
                   'You own hooks/open_work.py.\n</teammate-message>')


def test_teams_mode_envelope_brief_resolves_the_name(tmp_path: Path) -> None:
    """N1. `_is_user_prompt` excludes the peer envelope, so a `_genuine_prompts`
    -only scan returns nothing for a teams-mode teammate and classifies the
    worker as an orchestrator. POSITION is the discriminator: the brief is the
    FIRST inbound record, so an envelope is honoured there and nowhere else."""
    assert ow.teammate_name([_user(_ENVELOPE_BRIEF)]) == "lock-core"


def test_teams_mode_teammate_is_scoped_to_its_own_lane_not_wedged(
    tmp_path: Path
) -> None:
    """N1 end-to-end, the reviewer's measured repro: three tasks owned by three
    different agents. Before the fix all three came back and the turn-output
    rule fired on the teammate's report — REQ-4 says a teammate is NEVER wedged
    on lanes it has no power to close."""
    tasks = tmp_path / "tasks"
    _write_task(tasks, "sess1234abcd", "T-1", status="in_progress", owner="lock-core")
    _write_task(tasks, "sess1234abcd", "T-2", status="pending", owner="lock-wiring")
    _write_task(tasks, "sess1234abcd", "T-3", status="pending", owner="adversary-lock")
    records = [_user(_ENVELOPE_BRIEF),
               _assistant("## Report\n- built the substrate\n- 93 tests green")]

    r = ow.evaluate_completion_lock(tmp_path, "sess1234abcd", records, tasks_root=tasks)
    assert [i["id"] for i in r["open_tasks"]] == ["T-1"], (
        "held for its OWN lane only, never for T-2 / T-3"
    )
    assert r["turn_output"] is None, "a teammate's report to the Lead is its deliverable"
    assert r["open_asks"] == []


def test_teams_mode_teammate_with_no_owned_lane_may_stop(tmp_path: Path) -> None:
    tasks = tmp_path / "tasks"
    _write_task(tasks, "sess1234abcd", "T-2", status="pending", owner="lock-wiring")
    r = ow.evaluate_completion_lock(tmp_path, "sess1234abcd", [_user(_ENVELOPE_BRIEF)],
                                    tasks_root=tasks)
    assert r["blocked"] is False


# --- F9 second half: the brief shape CT6 actually dispatches ----------------
#
# Every teammate test above carries the `CT6-TEAMMATE` token. A real CT6 brief
# does NOT — it is a `<teammate-message>` envelope with prose, which is the
# shape the Lead sent every teammate on the run that produced this fix. With no
# token and no parseable name, this module's comment at the ownership site was
# doing exactly what it says: "A session with no resolvable name and no token is
# an ORCHESTRATOR and is held on ALL open tasks." So a real teammate was held on
# its PEERS' lanes — a condition it structurally cannot clear, because it can
# neither close another teammate's task nor mark the run complete.
#
# MEASURED before the fix, guard disabled so the exit code is attributable:
#   tokenless teammate, zero tasks          -> exit 0
#   tokenless teammate, a PEER's open task  -> exit 2, held by the LOCK PROPER
#   tokened teammate,   a PEER's open task  -> exit 0   (control)
#
# The recogniser lives HERE rather than in the caller. It was first written in
# `pipeline-completion-audit.py`, which fixed the arm and left the lock proper
# untouched — two definitions of "teammate" in two files that had to agree and
# immediately did not. One definition, in the module that owns the question.

_TOKENLESS_ENVELOPE_BRIEF = (
    '<teammate-message teammate_id="team-lead" summary="your lane">\n'
    "You are teammate `lock-core` on CT6 run `close-the-open-items`.\n"
    "FILES YOU OWN: hooks/open_work.py\n</teammate-message>"
)


def test_a_tokenless_envelope_brief_is_recognised_as_a_worker(tmp_path: Path) -> None:
    """The predicate itself. Position one is the discriminator, not the token."""
    assert ow.first_inbound_is_peer_envelope([_user(_TOKENLESS_ENVELOPE_BRIEF)]) is True


def test_a_genuine_first_prompt_is_not_a_worker(tmp_path: Path) -> None:
    assert ow.first_inbound_is_peer_envelope([_user("Build the thing.")]) is False


def test_a_tokenless_teammate_is_not_held_on_a_peers_lane(tmp_path: Path) -> None:
    """THE wedge, at the substrate. A peer's open task is the normal mid-run
    state, so this — not the empty store — is the case that actually bites."""
    tasks = tmp_path / "tasks"
    _write_task(tasks, "sess1234abcd", "T-2", status="pending", owner="lock-wiring")
    r = ow.evaluate_completion_lock(
        tmp_path, "sess1234abcd", [_user(_TOKENLESS_ENVELOPE_BRIEF)], tasks_root=tasks
    )
    assert r["blocked"] is False, (
        f"a worker must not be held for a lane it cannot close: {r['reasons']}"
    )


def test_a_tokenless_teammate_is_not_held_on_an_empty_store(tmp_path: Path) -> None:
    """The store ROOT is created deliberately. The first cut of this test left
    it absent and went red on F13's rule — a missing root is unknown state, not
    an empty one — which is correct behaviour and the wrong fixture for this
    question. An EMPTY store and an ABSENT one are different measurements."""
    tasks = tmp_path / "tasks"
    tasks.mkdir()
    r = ow.evaluate_completion_lock(
        tmp_path, "sess1234abcd", [_user(_TOKENLESS_ENVELOPE_BRIEF)], tasks_root=tasks
    )
    assert r["blocked"] is False


def test_a_lead_is_still_held_on_every_lane(tmp_path: Path) -> None:
    """The direction that keeps the fix from being a hole: the orchestrator is
    still held, and on ALL lanes, exactly as before."""
    tasks = tmp_path / "tasks"
    _write_task(tasks, "sess1234abcd", "T-1", status="pending", owner="lock-core")
    _write_task(tasks, "sess1234abcd", "T-2", status="pending", owner="lock-wiring")
    r = ow.evaluate_completion_lock(
        tmp_path, "sess1234abcd", [_user("Build the completion lock.")], tasks_root=tasks
    )
    assert r["blocked"] is True
    assert {i["id"] for i in r["open_tasks"]} == {"T-1", "T-2"}


def test_a_lead_that_later_receives_a_peer_envelope_is_still_held(tmp_path: Path) -> None:
    """ADV-9 for the new recogniser. Position one belongs to the Lead's own
    prompt, so a peer message arriving later cannot disarm it — otherwise any
    teammate could release the Lead's gate by sending it a message."""
    tasks = tmp_path / "tasks"
    _write_task(tasks, "sess1234abcd", "T-1", status="pending", owner="lock-core")
    records = [
        _user("Build the completion lock."),
        _user('<teammate-message teammate_id="lock-core">done</teammate-message>'),
    ]
    r = ow.evaluate_completion_lock(tmp_path, "sess1234abcd", records, tasks_root=tasks)
    assert r["blocked"] is True
    assert {i["id"] for i in r["open_tasks"]} == {"T-1"}


def test_the_head_slice_decides_position_one_when_the_tail_is_truncated(
    tmp_path: Path
) -> None:
    """The residual this fix carries, pinned as behaviour rather than left to
    prose: position one is read from the HEAD slice when one is supplied, so a
    Lead whose visible tail happens to open with a peer message is still
    correctly held. Only a Lead with NO head slice AND a peer-message-first tail
    is misclassified — it fails toward under-blocking, the right direction for a
    wedge fix, and `load_transcript_slices` supplies the head precisely here."""
    tasks = tmp_path / "tasks"
    _write_task(tasks, "sess1234abcd", "T-1", status="pending", owner="lock-core")
    head = [_user("Build the completion lock.")]
    tail = [_user('<teammate-message teammate_id="lock-core">done</teammate-message>')]
    r = ow.evaluate_completion_lock(
        tmp_path, "sess1234abcd", tail, head_records=head, tasks_root=tasks
    )
    assert r["blocked"] is True, "the head slice must decide position one"


def test_a_mid_session_peer_envelope_cannot_supply_a_name(tmp_path: Path) -> None:
    """ADV-9's ACTUAL attack, restated precisely after N1. The Lead's own first
    prompt occupies position one; a peer message arriving LATER must not rename
    it. Position is what separates the brief from an inbound peer message."""
    records = [
        _user("Build the completion lock."),
        _user('<teammate-message teammate_id="lock-core">\n'
              '[CT6-TEAMMATE lock-core RUN slug]\ndone\n</teammate-message>'),
    ]
    assert ow.teammate_name(records) is None


def test_a_lead_holding_a_peer_envelope_is_blocked_on_every_lane(tmp_path: Path) -> None:
    """The end-to-end form of ADV-9: adopting a peer's name would have hidden
    every task that peer does not own."""
    tasks = tmp_path / "tasks"
    _write_task(tasks, "sess1234abcd", "T-1", status="pending", owner="lock-core")
    _write_task(tasks, "sess1234abcd", "T-2", status="pending", owner="lock-wiring")
    records = [
        _user("Build the completion lock."),
        _user('<teammate-message teammate_id="lock-core">\n'
              '[CT6-TEAMMATE lock-core RUN slug]\ndone\n</teammate-message>'),
    ]
    r = ow.evaluate_completion_lock(tmp_path, "sess1234abcd", records, tasks_root=tasks)
    assert r["blocked"] is True
    assert {i["id"] for i in r["open_tasks"]} == {"T-1", "T-2"}


def test_teammate_name_is_none_without_a_resolvable_name(tmp_path: Path) -> None:
    assert ow.teammate_name([_user("Please fix the exporter.")]) is None
    assert ow.teammate_name([]) is None
    assert ow.teammate_name([_user("CT6-TEAMMATE")]) is None
    assert ow.teammate_name([_user("[CT6-TEAMMATE RUN slug]")]) is None


def test_teammate_name_prefers_the_head_slice_when_truncated(tmp_path: Path) -> None:
    """The brief lives at the transcript HEAD; on a long-lived teammate it has
    scrolled out of the tail."""
    head = [_user("[CT6-TEAMMATE lock-core RUN slug]\nYour scope.")]
    tail = [_user("keep going")]
    assert ow.teammate_name(tail, head_records=head, truncated=True) == "lock-core"


def test_teammate_name_ignores_assistant_authored_text(tmp_path: Path) -> None:
    """The LEAD's own transcript quotes the token when it writes a brief. Only
    inbound records identify the session."""
    records = [_assistant("[CT6-TEAMMATE lock-core RUN slug] ... dispatching")]
    assert ow.teammate_name(records) is None


# =============================================================================
# The single entry point main() calls
# =============================================================================

def _blank_result_fields(result: dict) -> None:
    # `advisory_asks` joined the contract in v3.56.0 when the ledger became
    # advisory by default — recorded asks still have to surface somewhere.
    # `stale_tasks` + `tasks_dir` joined in v3.64.0 with the abandonment
    # discrimination: inherited debt has to surface somewhere too, and the
    # store dir is named for the operator hunting the right session-* dir.
    assert set(result) == {"blocked", "open_tasks", "stale_tasks", "tasks_dir",
                           "open_asks", "advisory_asks",
                           "advisory_notes", "unreadable", "turn_output",
                           "reasons", "killswitch"}


def test_open_task_blocks_and_names_the_source_switch(tmp_path: Path) -> None:
    tasks = tmp_path / "tasks"
    _write_task(tasks, "sess1234abcd", "T-1", status="pending")
    r = ow.evaluate_completion_lock(tmp_path, "sess1234abcd", [], tasks_root=tasks)
    _blank_result_fields(r)
    assert r["blocked"] is True
    assert [i["id"] for i in r["open_tasks"]] == ["T-1"]
    assert r["killswitch"] == ow.DISABLE_TASKS_ENV
    assert r["reasons"], "a block always says why"


def test_an_ordinary_session_with_only_a_directive_is_not_blocked(
    tmp_path: Path
) -> None:
    """THE REGRESSION THAT SHIPPED (v3.56.0). One user request, zero tasks, no
    CT6 run state — an ordinary session in any project. It blocked PERMANENTLY:
    the agent finished the work, and nothing in the pipeline ever closes a
    ledger entry, so the only exit was a kill-switch.

    The principle the fix encodes: the task list may block because the HARNESS
    writes `status`, so "done" is a fact the gate reads. The ledger only knows a
    directive was GIVEN, never that it was MET — a source that cannot verify its
    own release condition must not hold a session hostage."""
    r = ow.evaluate_completion_lock(tmp_path, "", [_user("Add the changelog entry.")])
    assert r["blocked"] is False, "an ordinary session must not be wedged"
    assert r["open_asks"] == []
    assert [e["text"] for e in r["advisory_asks"]] == ["Add the changelog entry."], (
        "recorded and surfaced, just not the thing refusing the stop"
    )
    assert r["reasons"] == [] and r["killswitch"] is None


def test_a_fresh_unrelated_repo_is_left_byte_untouched(tmp_path: Path) -> None:
    """F-F. Typing one request into any repo wrote CT6 state into it — the
    directory AND the ledger file. Defensible while the ledger blocked and
    tail-cap accumulation was load-bearing; not defensible once it is advisory,
    because an advisory listing holds nothing and a directive that scrolls out
    of the window was never going to block anything."""
    r = ow.evaluate_completion_lock(tmp_path, "", [_user("fix the flaky login test")])

    assert list(tmp_path.iterdir()) == [], (
        "a repo that has never seen CT6 must be left with no directory and no file"
    )
    assert r["blocked"] is False
    assert [e["text"] for e in r["advisory_asks"]] == ["fix the flaky login test"], (
        "still derived and surfaced — in memory, just not written to disk"
    )


def test_a_ct6_workspace_still_persists_and_accumulates(tmp_path: Path) -> None:
    """The other side of F-F: where `.architect-team/` already exists the
    directory is not new pollution, so persistence — and with it the tail-cap
    accumulation property — is unchanged."""
    (tmp_path / ".architect-team").mkdir()

    ow.evaluate_completion_lock(tmp_path, "", [_user("Add the migration.")])
    assert ow.ledger_path(tmp_path).exists(), "a CT6 workspace still persists"

    # A later pass whose slice cannot see the first turn must not lose it.
    ow.evaluate_completion_lock(tmp_path, "", [_user("Bump the version to 3.56.0.")])
    texts = [e["text"] for e in ow.open_ledger_entries(tmp_path)]
    assert "Add the migration." in texts, "accumulation survives the tail cap"
    assert "Bump the version to 3.56.0." in texts


def test_opting_into_blocking_restores_persistence_anywhere(
    tmp_path: Path, monkeypatch: pytest.MonkeyPatch
) -> None:
    """The asymmetry is safe in the direction that matters: the moment the
    ledger can refuse a stop, accumulation is load-bearing again and the file
    comes back, even in a workspace CT6 has never touched."""
    monkeypatch.setenv(ow.LEDGER_BLOCKING_ENV, "1")
    r = ow.evaluate_completion_lock(tmp_path, "", [_user("Add the migration.")])

    assert ow.ledger_path(tmp_path).exists()
    assert r["blocked"] is True and len(r["open_asks"]) == 1


def test_an_advisory_ask_cannot_drag_in_the_turn_output_rule(tmp_path: Path) -> None:
    """The proxy-block hole: if source 3 keyed on asks BEFORE the demotion, the
    ledger would keep blocking through the very rule it was demoted out of."""
    records = [_user("Add the changelog entry."),
               _assistant("## Summary\n- did a thing\n- did another")]
    r = ow.evaluate_completion_lock(tmp_path, "", records)
    assert r["blocked"] is False
    assert r["turn_output"] is None
    assert len(r["advisory_asks"]) == 1


def test_the_ledger_blocks_only_when_blocking_is_opted_in(tmp_path: Path) -> None:
    """Opt-in restores the teeth for a user who wants them."""
    import os
    records = [_user("Add the changelog entry.")]
    os.environ[ow.LEDGER_BLOCKING_ENV] = "1"
    try:
        r = ow.evaluate_completion_lock(tmp_path, "", records)
    finally:
        del os.environ[ow.LEDGER_BLOCKING_ENV]
    assert r["blocked"] is True
    assert [e["text"] for e in r["open_asks"]] == ["Add the changelog entry."]
    assert r["advisory_asks"] == []
    assert r["killswitch"] == ow.DISABLE_LEDGER_ENV


def test_no_open_work_is_not_blocked(tmp_path: Path) -> None:
    tasks = tmp_path / "tasks"
    _write_task(tasks, "sess1234abcd", "T-1", status="completed")
    r = ow.evaluate_completion_lock(tmp_path, "sess1234abcd", [], tasks_root=tasks)
    assert r["blocked"] is False
    assert r["reasons"] == [] and r["killswitch"] is None
    assert r["turn_output"] is None


def test_master_switch_skips_every_source(tmp_path: Path, monkeypatch) -> None:
    tasks = tmp_path / "tasks"
    _write_task(tasks, "sess1234abcd", "T-1", status="pending")
    (tmp_path / ".architect-team").mkdir()
    ow.ledger_path(tmp_path).write_text("{corrupt", encoding="utf-8")
    monkeypatch.setenv(ow.DISABLE_ENV, "1")

    r = ow.evaluate_completion_lock(tmp_path, "sess1234abcd", [_user("do a thing")],
                                    tasks_root=tasks)
    assert r["blocked"] is False
    assert r["open_tasks"] == [] and r["unreadable"] == []


def test_disabling_the_ledger_leaves_the_task_source_enforcing(
    tmp_path: Path, monkeypatch: pytest.MonkeyPatch
) -> None:
    tasks = tmp_path / "tasks"
    _write_task(tasks, "sess1234abcd", "T-1", status="pending")
    monkeypatch.setenv(ow.DISABLE_LEDGER_ENV, "1")

    r = ow.evaluate_completion_lock(tmp_path, "sess1234abcd", [_user("Fix the bug.")],
                                    tasks_root=tasks)
    assert r["blocked"] is True
    assert r["open_asks"] == [], "the ledger source contributed nothing"
    assert [i["id"] for i in r["open_tasks"]] == ["T-1"]
    assert not ow.ledger_path(tmp_path).exists(), "a disabled source writes nothing"


def test_disabling_the_task_list_leaves_the_ledger_enforcing(
    tmp_path: Path, monkeypatch: pytest.MonkeyPatch
) -> None:
    """Per-source independence still holds — but the ledger is ADVISORY by
    default (v3.56.0), so this test now opts blocking in explicitly. Its point
    is that one switch does not silence another source, and that survives."""
    tasks = tmp_path / "tasks"
    _write_task(tasks, "sess1234abcd", "T-1", status="pending")
    monkeypatch.setenv(ow.DISABLE_TASKS_ENV, "1")
    monkeypatch.setenv(ow.LEDGER_BLOCKING_ENV, "1")

    r = ow.evaluate_completion_lock(tmp_path, "sess1234abcd", [_user("Fix the bug.")],
                                    tasks_root=tasks)
    assert r["blocked"] is True
    assert r["open_tasks"] == []
    assert len(r["open_asks"]) == 1
    assert r["killswitch"] == ow.DISABLE_LEDGER_ENV


# --- SPLIT (v3.56.0) of test_evaluate_accumulates_the_ledger_from_the_transcript.
#
# That test was re-pointed three times in one release — for the advisory
# demotion, then the persistence rule, then the fresh-repo exclusion — which is
# the signature of ONE assertion path defending SEVERAL properties. A test that
# has to move on every adjacent change has stopped being a pin and become a
# maintenance tax, and worse, each re-point is an opportunity to quietly weaken
# the property that was not the reason for the edit.
#
# The three below have one reason to change each:
#   1. derivation wiring   — changes only if evaluate stops reading the transcript
#   2. durability          — changes only if what is derived stops reaching the store
#   3. advisory surfacing  — changes only if the advisory/blocking policy changes
#
# Note (1) asserts on open_asks + advisory_asks deliberately: WHICH channel an
# ask lands in is (3)'s property, not (1)'s, so a future policy flip must not
# drag the derivation pin along with it.

def test_evaluate_derives_asks_from_the_transcript_without_registration(
    tmp_path: Path
) -> None:
    """PROPERTY 1 — registration is involuntary. The entry comes from the
    harness-written transcript, not from a call the agent could decline to
    make. Channel-agnostic on purpose."""
    r = ow.evaluate_completion_lock(tmp_path, "", [_user("Add the changelog entry.")])
    recorded = [e["text"] for e in r["open_asks"] + r["advisory_asks"]]
    assert recorded == ["Add the changelog entry."], (
        "the directive was captured with no registration call of any kind"
    )


def test_a_derived_ask_reaches_the_durable_store(tmp_path: Path) -> None:
    """PROPERTY 2 — what is derived is what is stored.

    Distinct from the F-F tests beside it: those pin WHICH workspaces persist
    (the policy), this pins that the store's CONTENTS match what derivation
    produced. A change to either one should move only its own test."""
    (tmp_path / ".architect-team").mkdir()
    ow.evaluate_completion_lock(tmp_path, "", [_user("Add the changelog entry.")])

    assert ow.ledger_path(tmp_path).exists()
    assert [e["text"] for e in ow.open_ledger_entries(tmp_path)] == [
        "Add the changelog entry."
    ], "the record is the directive, verbatim and still open"


def test_a_derived_ask_surfaces_as_advisory_by_default(tmp_path: Path) -> None:
    """PROPERTY 3 — the default channel. This is the one that SHOULD move if the
    advisory/blocking policy changes again; that is its job."""
    r = ow.evaluate_completion_lock(tmp_path, "", [_user("Add the changelog entry.")])
    assert [e["text"] for e in r["advisory_asks"]] == ["Add the changelog entry."]
    assert r["open_asks"] == [] and r["blocked"] is False


def test_unreadable_task_file_blocks_and_is_named(tmp_path: Path) -> None:
    """REQ-6: unknown state is not empty."""
    tasks = tmp_path / "tasks"
    _write_task(tasks, "sess1234abcd", "T-1", status="completed")
    (tasks / "session-sess1234" / "T-9.json").write_text("{bad", encoding="utf-8")

    r = ow.evaluate_completion_lock(tmp_path, "sess1234abcd", [], tasks_root=tasks)
    assert r["blocked"] is True
    assert r["open_tasks"] == []
    assert len(r["unreadable"]) == 1
    assert "T-9.json" in " ".join(r["reasons"])


def test_an_unreadable_ledger_does_not_block_while_it_is_advisory(
    tmp_path: Path
) -> None:
    """F1 — SUPERSEDES the old `test_unreadable_ledger_blocks_and_is_named`.

    The demotion to advisory never touched the unreadable path, so the advisory
    source kept exactly one blocking power: being broken. That is the wrong half
    to keep — pure wedge, zero enforcement value, on the source the user was
    told is advisory. It degrades to advisory too, loudly."""
    (tmp_path / ".architect-team").mkdir()
    ow.ledger_path(tmp_path).write_text("{corrupt", encoding="utf-8")

    r = ow.evaluate_completion_lock(tmp_path, "", [])
    assert r["blocked"] is False, "an advisory source cannot wedge a session"
    assert r["unreadable"] == [], "not a blocking violation while advisory"
    assert any("ask-ledger.json" in n for n in r["advisory_notes"]), (
        "surfaced loudly — degraded, not swallowed"
    )


def test_an_unreadable_ledger_still_blocks_when_blocking_is_opted_in(
    tmp_path: Path, monkeypatch: pytest.MonkeyPatch
) -> None:
    """The other direction: once the ledger can refuse a stop, an unreadable one
    is unknown state again and REQ-6 applies to it."""
    (tmp_path / ".architect-team").mkdir()
    ow.ledger_path(tmp_path).write_text("{corrupt", encoding="utf-8")
    monkeypatch.setenv(ow.LEDGER_BLOCKING_ENV, "1")

    r = ow.evaluate_completion_lock(tmp_path, "", [])
    assert r["blocked"] is True
    assert len(r["unreadable"]) == 1
    assert "ask-ledger.json" in " ".join(r["reasons"])


def test_an_unreadable_task_store_always_blocks(tmp_path: Path) -> None:
    """F1 must not leak into REQ-6: the TASK store is harness-written ground
    truth, so an unreadable one is unknown state and keeps blocking."""
    tasks = tmp_path / "tasks"
    _write_task(tasks, "sess1234abcd", "T-1", status="completed")
    (tasks / "session-sess1234" / "T-9.json").write_text("{bad", encoding="utf-8")

    r = ow.evaluate_completion_lock(tmp_path, "sess1234abcd", [], tasks_root=tasks)
    assert r["blocked"] is True and len(r["unreadable"]) == 1


def test_an_advisory_note_rides_along_when_something_else_blocks(
    tmp_path: Path
) -> None:
    """Loudly means visible: when the turn IS refused, the degraded ledger is
    named in the reasons the caller already renders."""
    tasks = tmp_path / "tasks"
    _write_task(tasks, "sess1234abcd", "T-1", status="pending")
    (tmp_path / ".architect-team").mkdir()
    ow.ledger_path(tmp_path).write_text("{corrupt", encoding="utf-8")

    r = ow.evaluate_completion_lock(tmp_path, "sess1234abcd", [], tasks_root=tasks)
    assert r["blocked"] is True
    assert r["killswitch"] == ow.DISABLE_TASKS_ENV, "the TASK is the cause"
    assert any("ask-ledger.json" in line for line in r["reasons"])


def test_switching_blocking_on_recovers_the_advisory_period(tmp_path: Path) -> None:
    """F3 — the persistence transition lost history. Directives arrive advisory
    in a fresh repo so nothing is written; the window moves; the operator sets
    the opt-in exactly as the README invites — and the ledger begins at the
    switch, missing precisely the OLDEST asks. On the first persist pass the
    head slice is derived too: it is already loaded, already passed in, and it
    covers the transcript START, which is the region the tail cap loses."""
    import os
    early = [_user("Add rate limiting to the login endpoint.",
                   ts="2026-08-12T09:00:00Z")]
    later = [_user("Bump the version to 3.56.0.", ts="2026-08-12T18:00:00Z")]

    # Advisory period: nothing is written, by design (F-F).
    ow.evaluate_completion_lock(tmp_path, "", early)
    assert not ow.ledger_path(tmp_path).exists()

    # The operator opts in. The early turn has scrolled out of the tail and now
    # survives only in the head slice.
    os.environ[ow.LEDGER_BLOCKING_ENV] = "1"
    try:
        ow.evaluate_completion_lock(tmp_path, "", later, head_records=early,
                                    truncated=True)
    finally:
        del os.environ[ow.LEDGER_BLOCKING_ENV]

    texts = [e["text"] for e in ow.open_ledger_entries(tmp_path)]
    assert "Add rate limiting to the login endpoint." in texts, (
        "the advisory-period directive must survive the switch"
    )
    assert "Bump the version to 3.56.0." in texts


def test_a_resolved_entry_survives_a_later_pass_that_re_sees_its_turn(
    tmp_path: Path
) -> None:
    """CORRECTED (mutation harness): the first draft of this test claimed to pin
    the first-pass restriction on the head sweep, and a mutation that swept the
    head on EVERY pass escaped it. The reason is worth keeping — accumulation
    unions by id with the STORED side winning, so re-deriving a resolved
    directive cannot reopen it, whether the sweep runs once or always. So the
    restriction is a cost guard with no behavioural witness (said plainly in the
    module), and what this test actually defends is the property that makes it
    safe: no resurrection."""
    import os
    early = [_user("Add rate limiting to the login endpoint.")]
    os.environ[ow.LEDGER_BLOCKING_ENV] = "1"
    try:
        ow.evaluate_completion_lock(tmp_path, "", early)
        entry_id = ow.read_ledger(tmp_path)["entries"][0]["id"]
        ow.resolve_ledger_entry(tmp_path, entry_id, evidence="shipped")
        assert ow.open_ledger_entries(tmp_path) == []

        ow.evaluate_completion_lock(tmp_path, "", [_user("Something else.")],
                                    head_records=early, truncated=True)
    finally:
        del os.environ[ow.LEDGER_BLOCKING_ENV]

    texts = [e["text"] for e in ow.open_ledger_entries(tmp_path)]
    assert "Add rate limiting to the login endpoint." not in texts, (
        "a resolved entry must not be resurrected by a head sweep"
    )


def test_turn_output_rule_only_fires_when_open_work_exists(tmp_path: Path) -> None:
    """It is a shape constraint on a turn that should not have been final, not a
    general style rule."""
    narrative = [_assistant("## Summary\n\n- did a thing\n- did another")]
    r = ow.evaluate_completion_lock(tmp_path, "", narrative)
    assert r["blocked"] is False, "no open work -> the rule is not evaluated"
    assert r["turn_output"] is None


def test_narrative_turn_with_open_work_is_refused(tmp_path: Path) -> None:
    tasks = tmp_path / "tasks"
    _write_task(tasks, "sess1234abcd", "T-1", status="in_progress")
    records = [_assistant("## Where things stand\n\n- T-1 is nearly done\n- T-2 next")]
    r = ow.evaluate_completion_lock(tmp_path, "sess1234abcd", records, tasks_root=tasks)
    assert r["blocked"] is True
    assert r["turn_output"] is not None and r["turn_output"]["narrative"] is True
    assert "heading" in r["turn_output"]["markers"]
    assert any("one line of state" in line for line in r["reasons"]), r["reasons"]


_NARRATIVE_TURN = ("## Where things stand\n- T-1 is nearly done\n- T-2 next\n"
                   "- T-3 not started\n- T-4 blocked on review")


def _lock_block(ts: str = "2026-08-12T10:05:00Z") -> dict:
    """The hook's own block, as the harness feeds it back into the transcript:
    a role:user record that is NOT a genuine prompt."""
    return {"type": "user", "timestamp": ts, "promptSource": "system",
            "message": {"role": "user", "content":
                        "pipeline-completion-audit: BLOCKED - COMPLETION LOCK. "
                        "While work is open the turn output is one line of state. "
                        "Release: CT6_TURN_OUTPUT_GATE_DISABLED=1"}}


def test_six_one_line_narration_blocks_are_not_a_narrative(tmp_path: Path) -> None:
    """G3 — a LIVE false positive, and the ordinary shape of an agent narrating
    between tool calls. T1's concatenation joins six one-liners into six prose
    lines and the T2 ceiling fired on them at 6. No report anywhere in it."""
    tasks = tmp_path / "tasks"
    _write_task(tasks, "sess1234abcd", "T-1", status="in_progress")
    records = [_user("do the thing")] + [
        _assistant(f"Running step {i}.") for i in range(1, 7)
    ]

    r = ow.evaluate_completion_lock(tmp_path, "sess1234abcd", records, tasks_root=tasks)
    assert r["turn_output"] is None, (
        "narrating between tool calls is not a report; this fired constantly"
    )


def test_the_ceiling_still_catches_a_genuinely_long_short_line_report(
    tmp_path: Path
) -> None:
    """The counter to G3's raise: the ceiling still has to catch T2's shape."""
    r = ow.classify_turn_output("\n".join(f"task {i} is pending" for i in range(30)))
    assert r["narrative"] is True
    assert ow.NARRATIVE_ABSOLUTE_LINES > 10, (
        "a normal 6-10 line working turn must clear the ceiling"
    )


def test_a_compliant_reply_after_a_block_clears_the_rule(tmp_path: Path) -> None:
    """G2 — THE SEQUENCE PIN, and the reason four rounds of both-directions
    pinning never surfaced this: it is invisible to any single-text test.

    T1's concatenation is cumulative, so once a turn produced a narrative every
    later Stop re-measured it. The agent replied with exactly the one line of
    state the block demands and the arm fired anyway, `lines` climbing 6, 7, 8 —
    no reply it could write would clear it, because the text is already in the
    transcript. That is the unbreakable loop again, wearing a different hat.

    The turn boundary therefore advances past the hook's OWN injected block."""
    tasks = tmp_path / "tasks"
    _write_task(tasks, "sess1234abcd", "T-1", status="in_progress")

    blocked = [_user("carry on"), _assistant(_NARRATIVE_TURN)]
    first = ow.evaluate_completion_lock(tmp_path, "sess1234abcd", blocked,
                                        tasks_root=tasks)
    assert first["turn_output"] is not None, "the narrative is refused (control)"

    # The agent complies with exactly what the block asked for.
    complied = blocked + [_lock_block(), _assistant("T-1 in progress.")]
    second = ow.evaluate_completion_lock(tmp_path, "sess1234abcd", complied,
                                         tasks_root=tasks)
    assert second["turn_output"] is None, (
        "an instruction the agent cannot satisfy by complying is a loop"
    )

    # And it stays clear as the exchange goes on, rather than climbing.
    third = ow.evaluate_completion_lock(
        tmp_path, "sess1234abcd",
        complied + [_lock_block(), _assistant("T-1 still in progress.")],
        tasks_root=tasks)
    assert third["turn_output"] is None


def test_the_boundary_only_advances_past_the_hooks_own_block(tmp_path: Path) -> None:
    """G2's fix must not re-open T1: a summary and its sign-off arrive before
    the SAME Stop, so no block sits between them and both are still measured."""
    tasks = tmp_path / "tasks"
    _write_task(tasks, "sess1234abcd", "T-1", status="in_progress")
    records = [_user("carry on"), _assistant(_NARRATIVE_TURN),
               _assistant("Working.")]

    r = ow.evaluate_completion_lock(tmp_path, "sess1234abcd", records, tasks_root=tasks)
    assert r["turn_output"] is not None, "the T1 evasion must stay closed"


def test_an_unrelated_injected_record_does_not_move_the_boundary(
    tmp_path: Path
) -> None:
    """The narrow half of G2's fix, and a gap my first witness missed: only THIS
    HOOK'S block advances the boundary. A `<task-notification>` or any other
    harness-injected record arriving mid-turn must not, or an agent gets a free
    evasion whenever one happens to land after its summary."""
    tasks = tmp_path / "tasks"
    _write_task(tasks, "sess1234abcd", "T-1", status="in_progress")
    records = [
        _user("carry on"),
        _assistant(_NARRATIVE_TURN),
        _user("<task-notification>a teammate finished</task-notification>",
              promptSource="system"),
        _assistant("Working."),
    ]

    r = ow.evaluate_completion_lock(tmp_path, "sess1234abcd", records, tasks_root=tasks)
    assert r["turn_output"] is not None, (
        "an unrelated injected record is not a Stop and hides nothing"
    )


def test_a_fenced_summary_reaches_the_ceiling_when_long_enough(
    tmp_path: Path
) -> None:
    """G1 — fenced lines are excluded from `counting_lines` (which is what T4
    actually needed) but DO count toward the absolute ceiling, so a summary
    hidden in a fence is not invisible to everything.

    HONEST BOUNDARY, measured: with the ceiling raised to clear G3, a fence only
    reaches it at NARRATIVE_ABSOLUTE_LINES total lines. A 4-line fenced summary
    is 6 lines and still clears — G1 is narrowed, not closed."""
    body = "\n".join(f"- item {i}" for i in range(ow.NARRATIVE_ABSOLUTE_LINES))
    r = ow.classify_turn_output(f"```\n{body}\n```")
    assert r["narrative"] is True, "a long fenced summary reaches the ceiling"

    small = ow.classify_turn_output("```\n- a\n- b\n- c\n- d\n```")
    assert small["narrative"] is False, (
        "documented residual: a short fenced summary still evades"
    )


def test_a_sign_off_line_cannot_hide_a_narrative(tmp_path: Path) -> None:
    """T1 — a complete evasion, and the natural shape of the reported failure:
    write the summary, then end with a short line. The rule measured only the
    LAST assistant text block, so appending 'Working.' flipped the verdict.

    Both previously-pinned directions were about the PREDICATE; this is about
    its INPUT, which is why three revisions of the thresholds never touched it.
    The whole turn is measured now, so the narrative is still in the text no
    matter what follows it."""
    tasks = tmp_path / "tasks"
    _write_task(tasks, "sess1234abcd", "T-1", status="in_progress")
    records = [_user("carry on"),
               _assistant(_NARRATIVE_TURN),
               _assistant("Working.")]

    r = ow.evaluate_completion_lock(tmp_path, "sess1234abcd", records, tasks_root=tasks)
    assert r["turn_output"] is not None, (
        "appending a one-line sign-off must not hide the summary before it"
    )
    assert r["turn_output"]["narrative"] is True


def test_the_rule_cannot_reach_back_into_a_previous_turn(tmp_path: Path) -> None:
    """The opposite direction of the same defect: when THIS turn produced no
    assistant text (it ended in tool calls), the last-block scan walked back
    past the user prompt and re-measured an OLD narrative — firing on text this
    turn never produced. The turn boundary is the last genuine user prompt."""
    tasks = tmp_path / "tasks"
    _write_task(tasks, "sess1234abcd", "T-1", status="in_progress")
    records = [_user("do the thing"),
               _assistant(_NARRATIVE_TURN),
               _user("now do the other thing")]

    r = ow.evaluate_completion_lock(tmp_path, "sess1234abcd", records, tasks_root=tasks)
    assert r["turn_output"] is None, (
        "the previous turn's narrative is not this turn's output"
    )


def test_all_of_this_turns_blocks_are_measured_together(tmp_path: Path) -> None:
    """Two innocuous-looking blocks in one turn are one report between them."""
    tasks = tmp_path / "tasks"
    _write_task(tasks, "sess1234abcd", "T-1", status="in_progress")
    records = [_user("status?"),
               _assistant("Here is where things stand."),
               _assistant("- T-1 done\n- T-2 next")]

    r = ow.evaluate_completion_lock(tmp_path, "sess1234abcd", records, tasks_root=tasks)
    assert r["turn_output"] is not None and r["turn_output"]["narrative"] is True


def test_terse_turn_with_open_work_does_not_add_a_turn_output_block(tmp_path: Path) -> None:
    tasks = tmp_path / "tasks"
    _write_task(tasks, "sess1234abcd", "T-1", status="in_progress")
    records = [_assistant("T-1 in progress.\n16 of 17 open.")]
    r = ow.evaluate_completion_lock(tmp_path, "sess1234abcd", records, tasks_root=tasks)
    assert r["blocked"] is True, "still blocked by the open task"
    assert r["turn_output"] is None, "the turn-output rule contributed no block"
    assert r["killswitch"] == ow.DISABLE_TASKS_ENV


def test_turn_output_switch_disables_only_that_rule(
    tmp_path: Path, monkeypatch: pytest.MonkeyPatch
) -> None:
    tasks = tmp_path / "tasks"
    _write_task(tasks, "sess1234abcd", "T-1", status="in_progress")
    monkeypatch.setenv(ow.DISABLE_OUTPUT_ENV, "1")
    records = [_assistant("## Summary\n- one\n- two")]
    r = ow.evaluate_completion_lock(tmp_path, "sess1234abcd", records, tasks_root=tasks)
    assert r["turn_output"] is None
    assert r["blocked"] is True and r["killswitch"] == ow.DISABLE_TASKS_ENV


def test_master_switch_named_when_more_than_one_source_fires(
    tmp_path: Path, monkeypatch: pytest.MonkeyPatch
) -> None:
    """Blocking opted in (v3.56.0) because this test's point is the killswitch
    ARBITRATION across several blocking sources — which needs two of them to be
    able to block. An advisory ask is not a blocking source."""
    tasks = tmp_path / "tasks"
    _write_task(tasks, "sess1234abcd", "T-1", status="pending")
    monkeypatch.setenv(ow.LEDGER_BLOCKING_ENV, "1")
    r = ow.evaluate_completion_lock(tmp_path, "sess1234abcd", [_user("Fix the bug.")],
                                    tasks_root=tasks)
    assert r["blocked"] is True
    assert r["open_tasks"] and r["open_asks"]
    assert r["killswitch"] == ow.DISABLE_ENV, (
        "with several sources firing, name the switch that releases all of them"
    )


def test_an_advisory_ask_leaves_the_task_switch_named(tmp_path: Path) -> None:
    """The arbitration counterpart: with the ledger advisory, only ONE source is
    really blocking, so the precise per-source switch is what gets named."""
    tasks = tmp_path / "tasks"
    _write_task(tasks, "sess1234abcd", "T-1", status="pending")
    r = ow.evaluate_completion_lock(tmp_path, "sess1234abcd", [_user("Fix the bug.")],
                                    tasks_root=tasks)
    assert r["blocked"] is True
    assert r["killswitch"] == ow.DISABLE_TASKS_ENV
    assert len(r["advisory_asks"]) == 1 and r["open_asks"] == []


# --- teammate owner-scoping through the entry point --------------------------

_BRIEF = "[CT6-TEAMMATE lock-core RUN turn-boundary-completion-lock]\nYour scope."


def test_teammate_with_no_owned_open_task_may_stop(tmp_path: Path) -> None:
    tasks = tmp_path / "tasks"
    _write_task(tasks, "sess1234abcd", "T-1", status="pending", owner="lock-wiring")
    _write_task(tasks, "sess1234abcd", "T-2", status="pending")
    r = ow.evaluate_completion_lock(tmp_path, "sess1234abcd", [_user(_BRIEF)],
                                    tasks_root=tasks)
    assert r["blocked"] is False, "a teammate is never wedged on another lane"
    assert r["open_tasks"] == []


def test_teammate_with_an_owned_open_task_is_blocked_and_it_is_named(tmp_path: Path) -> None:
    tasks = tmp_path / "tasks"
    _write_task(tasks, "sess1234abcd", "T-1", status="in_progress", owner="lock-core")
    _write_task(tasks, "sess1234abcd", "T-2", status="pending", owner="lock-wiring")
    r = ow.evaluate_completion_lock(tmp_path, "sess1234abcd", [_user(_BRIEF)],
                                    tasks_root=tasks)
    assert r["blocked"] is True
    assert [i["id"] for i in r["open_tasks"]] == ["T-1"]
    assert "T-1" in " ".join(r["reasons"])


def test_a_long_user_prompt_is_an_orchestrator_not_a_teammate(tmp_path: Path) -> None:
    """ADV-8, the worst of the nine in practice. `is_teammate_transcript`'s
    >= 1500-char fallback heuristic fires on a long user prompt containing
    '.architect-team'; `teammate_name` then resolves nothing. Standing down
    there means THE USER'S OWN LONG PROMPTS silently disable the whole gate —
    and the prompt that commissioned this feature is exactly that shape.
    Heuristic-only classification with no token is an ORCHESTRATOR."""
    tasks = tmp_path / "tasks"
    _write_task(tasks, "sess1234abcd", "T-1", status="pending", owner="lock-core")
    _write_task(tasks, "sess1234abcd", "T-2", status="pending")
    long_prompt = ("Build the completion lock.\n" + ("x" * 1600)
                   + "\n.architect-team/reviews/")

    assert rc.is_teammate_transcript([_user(long_prompt)]) is True, (
        "the repro anchor: the heuristic still classifies this as a teammate"
    )
    r = ow.evaluate_completion_lock(tmp_path, "sess1234abcd", [_user(long_prompt)],
                                    tasks_root=tasks)
    assert r["blocked"] is True, "a long user prompt must not disable the gate"
    assert {i["id"] for i in r["open_tasks"]} == {"T-1", "T-2"}, (
        "an orchestrator is held on ALL open tasks, not an owner-scoped subset"
    )


def test_a_genuine_token_without_a_resolvable_name_still_stands_down(
    tmp_path: Path
) -> None:
    """The standdown survives — but ONLY behind a genuine CT6-TEAMMATE token,
    never behind the heuristic. A real worker with an unparseable name must not
    be wedged on lanes it cannot close."""
    tasks = tmp_path / "tasks"
    _write_task(tasks, "sess1234abcd", "T-1", status="pending", owner="lock-core")
    r = ow.evaluate_completion_lock(
        tmp_path, "sess1234abcd",
        [_user("[CT6-TEAMMATE RUN slug]\nYou own the substrate.")],
        tasks_root=tasks)
    assert r["blocked"] is False
    assert r["open_tasks"] == [] and r["open_asks"] == []


# --- F3: the ledger's release valve must be reachable by a human -------------

def test_cli_lists_the_open_asks_with_their_ids(
    tmp_path: Path, capsys: pytest.CaptureFixture
) -> None:
    """F3. Without a user-facing exit the ledger is a one-way ratchet whose only
    release is a kill-switch, and the first false positive makes the user
    disable the whole gate — the same as not shipping it."""
    ow.accumulate_ledger(tmp_path, ow.derive_ledger_entries([_user("Ship the docs.")]))
    entry_id = ow.read_ledger(tmp_path)["entries"][0]["id"]

    assert ow.main(["list", "--root", str(tmp_path)]) == 0
    out = capsys.readouterr().out
    assert entry_id in out and "Ship the docs." in out


def test_cli_resolves_an_entry_with_evidence(
    tmp_path: Path, capsys: pytest.CaptureFixture
) -> None:
    ow.accumulate_ledger(tmp_path, ow.derive_ledger_entries([_user("Ship the docs.")]))
    entry_id = ow.read_ledger(tmp_path)["entries"][0]["id"]

    assert ow.main(["resolve", entry_id, "--evidence", "README.md updated",
                    "--root", str(tmp_path)]) == 0
    assert ow.open_ledger_entries(tmp_path) == []
    stored = ow.read_ledger(tmp_path)["entries"][0]
    assert stored["status"] == "resolved" and stored["evidence"] == "README.md updated"


def test_cli_refuses_a_resolve_with_no_evidence_or_an_unknown_id(
    tmp_path: Path, capsys: pytest.CaptureFixture
) -> None:
    """Conservative resolution reaches the CLI too — ambiguous stays open."""
    ow.accumulate_ledger(tmp_path, ow.derive_ledger_entries([_user("Ship the docs.")]))
    entry_id = ow.read_ledger(tmp_path)["entries"][0]["id"]

    assert ow.main(["resolve", entry_id, "--evidence", "  ",
                    "--root", str(tmp_path)]) != 0
    assert len(ow.open_ledger_entries(tmp_path)) == 1

    assert ow.main(["resolve", "no-such-id", "--evidence", "x",
                    "--root", str(tmp_path)]) != 0
    assert len(ow.open_ledger_entries(tmp_path)) == 1


def test_cli_is_reachable_as_a_real_command(tmp_path: Path) -> None:
    """A user-facing valve nobody can invoke is not a valve. Runs the module the
    way a human would, in a subprocess."""
    import subprocess
    import sys

    ow.accumulate_ledger(tmp_path, ow.derive_ledger_entries([_user("Ship the docs.")]))
    entry_id = ow.read_ledger(tmp_path)["entries"][0]["id"]
    script = Path(ow.__file__)

    listed = subprocess.run(
        [sys.executable, str(script), "list", "--root", str(tmp_path)],
        capture_output=True, text=True, encoding="utf-8", errors="replace")
    assert listed.returncode == 0, listed.stderr
    assert entry_id in listed.stdout

    done = subprocess.run(
        [sys.executable, str(script), "resolve", entry_id,
         "--evidence", "shipped in v3.56.0", "--root", str(tmp_path)],
        capture_output=True, text=True, encoding="utf-8", errors="replace")
    assert done.returncode == 0, done.stderr
    assert ow.open_ledger_entries(tmp_path) == []


def test_teammate_is_not_held_for_the_users_ledger_asks(tmp_path: Path) -> None:
    """REQ-4 holds a teammate ONLY for tasks it owns. The ask-ledger is the
    USER's directives — a worker cannot resolve those, and its structured report
    back to the Lead is its deliverable, not a violation."""
    tasks = tmp_path / "tasks"
    _write_task(tasks, "sess1234abcd", "T-1", status="pending", owner="someone-else")
    records = [_user(_BRIEF + "\nAlso add the migration."),
               _assistant("## Report\n- built it\n- tests green")]
    r = ow.evaluate_completion_lock(tmp_path, "sess1234abcd", records, tasks_root=tasks)
    assert r["blocked"] is False
    assert r["open_asks"] == [] and r["turn_output"] is None



# ---------------------------------------------------------------------------
# The classifier characterization corpus (v3.57.0)
# ---------------------------------------------------------------------------
#
# The follow-ups doc asked for the `prose_lines` / `line_count` naming trap to be
# closed, on the grounds that one was load-bearing and the other cosmetic. That
# premise turned out to be STALE: T4 made the arms count unfenced lines and
# `line_count` reporting-only, then G1 put the ceiling arm back on the FULL
# count -- so by v3.56.0 all three counters were load-bearing and the comment
# saying otherwise was false. A reader who trusted it would have concluded one
# counter was free to substitute, which is T4 exactly.
#
# The rename alone cannot prevent that recurring. This corpus can: it pins the
# FULL verdict of every arm across 40 turn shapes, so any future edit that moves
# a verdict -- by substituting a counter, retuning a threshold, or "simplifying"
# two arms into one -- goes red with the shape that moved named in the failure.
#
# The golden values were captured from the v3.56.0 classifier at 9750728 and
# verified identical after the rename: 40 inputs, 0 mismatches. They are a
# behavioural snapshot, NOT an aspiration -- a deliberate rule change updates
# them in the same commit that argues for the change.
CLASSIFIER_CORPUS = [
    # (name, text, expected_narrative, expected_lines, expected_markers_sorted)
    ('empty', '', False, 0, []),
    ('blank_spaces', '   ', False, 0, []),
    ('blank_newlines', '\n\n', False, 0, []),
    ('one_word', 'Done.', False, 1, []),
    ('one_line_marked', '**Status:** on task 1 of 9.', False, 1, ['bold-label']),
    ('one_bullet', '- one bullet', False, 1, ['bullet']),
    ('unicode_bullets_2', '• built it\n• tests green', True, 2, ['bullet']),
    ('ascii_bullets_2', '- built it\n- tests green', True, 2, ['bullet']),
    ('signoff_only', 'Working.', False, 1, []),
    ('state_then_signoff', '**Status:** still going.\nWorking.', True, 2, ['bold-label']),
    ('narration_3', 'Checking the hooks before the next step.\nChecking the guard before the next step.\nChecking the fixtures before the next step.', False, 3, []),
    ('markerless_5', 'I finished the a and it is green under both encodings.\nI finished the b and it is green under both encodings.\nI finished the c and it is green under both encodings.\nI finished the d and it is green under both encodings.\nI finished the e and it is green under both encodings.', False, 5, []),
    ('markerless_6', 'I finished the a and it is green under both encodings.\nI finished the b and it is green under both encodings.\nI finished the c and it is green under both encodings.\nI finished the d and it is green under both encodings.\nI finished the e and it is green under both encodings.\nI finished the f and it is green under both encodings.', True, 6, []),
    ('markerless_8', 'I finished the a and it is green under both encodings.\nI finished the b and it is green under both encodings.\nI finished the c and it is green under both encodings.\nI finished the d and it is green under both encodings.\nI finished the e and it is green under both encodings.\nI finished the f and it is green under both encodings.\nI finished the g and it is green under both encodings.\nI finished the h and it is green under both encodings.', True, 8, []),
    ('heading', '# Heading\nbody text here', True, 2, ['heading']),
    ('table', '| a | b |\n| - | - |', True, 2, ['table-row']),
    ('numbered', '1. first\n2. second', True, 2, ['numbered']),
    ('bold_labels', '**Label:** value\n**Other:** value', True, 2, ['bold-label']),
    ('state_plus_snippet', 'Status.\n```\ncode\nmore code\nthird line\n```', False, 6, []),
    ('fenced_12', '```\nline 0\nline 1\nline 2\nline 3\nline 4\nline 5\nline 6\nline 7\nline 8\nline 9\nline 10\nline 11\n```', True, 14, []),
    ('unclosed_fence', '```\nunclosed fence\nstill going', False, 3, []),
    ('short_30', 's0\ns1\ns2\ns3\ns4\ns5\ns6\ns7\ns8\ns9\ns10\ns11\ns12\ns13\ns14\ns15\ns16\ns17\ns18\ns19\ns20\ns21\ns22\ns23\ns24\ns25\ns26\ns27\ns28\ns29', True, 30, []),
    ('short_11', 's0\ns1\ns2\ns3\ns4\ns5\ns6\ns7\ns8\ns9\ns10', False, 11, []),
    ('short_12', 's0\ns1\ns2\ns3\ns4\ns5\ns6\ns7\ns8\ns9\ns10\ns11', True, 12, []),
    ('long_prose_750', 'xxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxxx', True, 1, []),
    ('chars_601', 'aaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaa', True, 1, []),
    ('chars_599', 'aaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaaa', False, 1, []),
    ('mixed_report', '# H\n\n- b1\n- b2\n\nprose line that is quite long indeed yes\n\n| t | u |', True, 5, ['bullet', 'heading', 'table-row']),
    ('bullets_8', '- item 0 which is a reasonably long bullet line here\n- item 1 which is a reasonably long bullet line here\n- item 2 which is a reasonably long bullet line here\n- item 3 which is a reasonably long bullet line here\n- item 4 which is a reasonably long bullet line here\n- item 5 which is a reasonably long bullet line here\n- item 6 which is a reasonably long bullet line here\n- item 7 which is a reasonably long bullet line here', True, 8, ['bullet']),
    ('report_then_done', 'Narrative report line one is long enough to count as report length.\nLine two likewise is long enough.\nLine three also.\nDone.', False, 4, []),
    ('endash_bullets', '– en dash bullet\n– second', True, 2, ['bullet']),
    ('circle_bullets', '● filled circle\n● second', True, 2, ['bullet']),
    ('prose_fence_prose', 'text\n```py\n# comment\n- yaml like\n```\ntext', False, 6, []),
    ('indented_bullets', '  - indented bullet\n  - another', True, 2, ['bullet']),
    ('one_very_long_line', 'One very long single line yyyyyyyyyyyyyyyyyyyyyyyyyyyyyyyyyyyyyyyyyyyyyyyyyyyyyyyyyyyyyyyyyyyyyyyyyyyyyyyyyyyyyyyyyyyyyyyyyyyyyyyyyyyyyyyyyyyyyyyyyyyyyyyyyyyyyyyyyyyyyyyyyyyyyyyyyyyyyyyyyyyyyyyyyyyyyyyyyyyyyyyyyyyyyyyyyyyyyyyyyyyyyyyyyyyyyyyyyyyyyyyyyyyyyyyyyyyyyyyyyyyyyyyyyyyyyyyyyyyyyyyyyyyyyyyyyyyyyyyyyyyyyyyyyyyyyyyyyyyy', False, 1, []),
    ('tabs_only', '\t\n\t\n', False, 0, []),
    ('bold_no_colon', '**Bold** but no colon\nsecond line', False, 2, []),
    ('h3', '### h3\ncontent', True, 2, ['heading']),
    ('blockquote', '> quote\n> more quote', False, 2, []),
    ('report_6', 'Report line 0 long enough to be report length for sure.\nReport line 1 long enough to be report length for sure.\nReport line 2 long enough to be report length for sure.\nReport line 3 long enough to be report length for sure.\nReport line 4 long enough to be report length for sure.\nReport line 5 long enough to be report length for sure.', True, 6, []),]


@pytest.mark.parametrize("name,text,want_narrative,want_lines,want_markers", CLASSIFIER_CORPUS)
def test_classifier_corpus_verdicts_are_pinned(
    name: str, text: str, want_narrative: bool, want_lines: int, want_markers: list
) -> None:
    """Full-verdict pin across 40 turn shapes -- the regression net for any
    future change to `classify_turn_output`.

    Asserts the whole verdict, not just the boolean: a change that keeps
    `narrative` while moving `lines` or the marker set has still changed what
    the block message tells the user, and that is what shipped as T4.
    """
    got = ow.classify_turn_output(text)
    assert got["narrative"] is want_narrative, f"{name}: narrative moved ({got['reason']})"
    assert got["lines"] == want_lines, f"{name}: reported line count moved"
    assert sorted(got["markers"]) == want_markers, f"{name}: marker set moved"


def test_the_three_counters_are_not_interchangeable() -> None:
    """The counters genuinely separate -- so substituting one IS a behaviour change.

    This is the claim the renamed counters make in their contract comment, and
    it has to be measured rather than asserted: if the three were always equal,
    the "pick by meaning" instruction would be advice about nothing and the next
    maintainer would rightly ignore it.

    Both separations are proven by exhibiting inputs whose verdicts DIFFER in a
    way only the respective counter explains.
    """
    # all_nonempty vs unfenced: a 12-line fenced block trips the absolute
    # ceiling only because fenced lines still count toward it (the G1 fix).
    fenced_12 = "```\n" + "\n".join(f"line {i}" for i in range(12)) + "\n```"
    assert ow.classify_turn_output(fenced_12)["narrative"] is True
    # ...while a 3-line fenced snippet beside a state line does NOT trip,
    # because the marker/report arms exclude fenced content (the T4 fix).
    assert ow.classify_turn_output("Status.\n```\ncode\nmore\nthird\n```")["narrative"] is False

    # unfenced vs report-length: 30 short lines trip only via the absolute
    # ceiling, and five report-length lines do not trip at all -- the length
    # floor is what separates them (F6).
    assert ow.classify_turn_output("\n".join(f"s{i}" for i in range(30)))["narrative"] is True
    five = "\n".join(f"I finished the {w} and it is green under both encodings." for w in "abcde")
    assert ow.classify_turn_output(five)["narrative"] is False


def test_a_missing_task_ROOT_is_unknown_but_a_missing_session_dir_is_empty(
    tmp_path: Path,
) -> None:
    """v3.60.0 (F13) — the two were collapsed, and the difference is the whole
    contract.

    This module blocks on an unreadable source because *unknown is not empty*.
    But pointing `CT6_TASKS_ROOT` at a path that does not exist read as a clean
    pass, so redirecting the gate at nothing released the stop — measured: an
    open task blocked, the same session with the root redirected exited 0. A
    root that is not there is exactly unknown state.

    The session dir is the honest empty case and must stay one: a session that
    has simply registered nothing is the ordinary state, and turning that into
    a block would wedge every plain session in every project.
    """
    existing = tmp_path / "store"
    existing.mkdir()

    # unknown -> reported as unreadable, which BLOCKS
    missing = ow.read_harness_tasks("abcd1234", tmp_path / "nope")
    assert len(missing["unreadable"]) == 1
    assert "does not exist" in missing["unreadable"][0]["reason"]

    # empty root -> clean pass
    assert ow.read_harness_tasks("abcd1234", existing)["unreadable"] == []

    # empty SESSION dir under a real root -> still a clean pass
    (existing / "session-abcd1234").mkdir()
    empty_session = ow.read_harness_tasks("abcd1234", existing)
    assert empty_session["unreadable"] == []
    assert empty_session["items"] == []
