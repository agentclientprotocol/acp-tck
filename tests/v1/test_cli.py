"""End-to-end CLI tests: run `python -m tck -- <fixture agent>` as a real subprocess and check
the exit code plus the terminal requirement-summary table.

A subprocess (not in-process `pytest.main`) is used deliberately: this file itself runs under
pytest, and pytest does not support a clean re-entrant `pytest.main()` call from within a
running session.
"""

from __future__ import annotations

import json
import re
import subprocess
import sys
from pathlib import Path

FIXTURES_DIR = Path(__file__).parent.parent / "fixtures" / "agents" / "v1"
FIXTURES_DIR_V2 = Path(__file__).parent.parent / "fixtures" / "agents" / "v2"
CLI_SUBPROCESS_TIMEOUT = 60
"""Wall-clock cap on one `_run_cli` subprocess. Against `wrong_id_echo.py`, every
`--timeout`-bounded MANDATORY/ADVISORY/INFORMATIONAL id fails/errors via a real timeout (since
id-correlated waits never resolve), which adds up across the full registry; 60s leaves headroom
without materially changing the overall suite's runtime budget, since every other self-test
finishes in a small fraction of this."""

_MANDATORY_IDS = {
    "ACP-TRANSPORT-001",
    "ACP-TRANSPORT-002",
    "ACP-JSONRPC-001",
    "ACP-JSONRPC-002",
    "ACP-JSONRPC-003",
    "ACP-JSONRPC-006",
    "ACP-JSONRPC-007",
    "ACP-INIT-001",
    "ACP-INIT-002",
    "ACP-INIT-003",
    "ACP-SCHEMA-001",
    "ACP-SESSION-001",
    "ACP-SESSION-002",
    "ACP-SESSION-003",
    "ACP-PROMPT-001",
    "ACP-PROMPT-002",
    "ACP-PROMPT-003",
    "ACP-PROMPT-004",
    "ACP-CANCEL-001",
    "ACP-CANCEL-002",
    "ACP-CONFIG-003",
    "ACP-AUTH-002",
    "ACP-AUTH-006",
    "ACP-CLIENTCAP-001",
    "ACP-CLIENTCAP-002",
    "ACP-CLIENTCAP-003",
    "ACP-CLIENTCAP-004",
    "ACP-CLIENTCAP-005",
    "ACP-CLIENTCAP-006",
    "ACP-CLIENTCAP-007",
    "ACP-EXT-001",
}
_ADVISORY_IDS = {
    "ACP-JSONRPC-004",
    "ACP-JSONRPC-005",
    "ACP-INIT-004",
    "ACP-SESSION-004",
    "ACP-LOAD-003",
    "ACP-DELETE-002",
    "ACP-META-001",
    "ACP-ERROR-001",
    "ACP-ERROR-002",
    "ACP-EXT-002",
    "ACP-SCHEMA-002",
    "ACP-AUTH-005",
    # ACP-AUTH-001: its only assertion, AUTH-A5 (auth method ids are unique), is advisory in
    # the auth research -- not in _MANDATORY_IDS.
    "ACP-AUTH-001",
}
_INFORMATIONAL_IDS = {
    "ACP-SHUTDOWN-001",
    "ACP-STDERR-001",
    "ACP-INFO-PARSE-001",
    "ACP-INFO-INVALIDREQ-001",
    "ACP-INFO-UNKNOWNSESSION-001",
}
_CAPABILITY_IDS = {
    "ACP-LOAD-001",
    "ACP-LOAD-002",
    "ACP-RESUME-001",
    "ACP-RESUME-002",
    "ACP-LIST-001",
    "ACP-LIST-002",
    "ACP-DELETE-001",
    "ACP-DELETE-003",
    "ACP-CLOSE-001",
    "ACP-CLOSE-002",
    "ACP-ADDDIRS-001",
    "ACP-SYSPROMPT-001",
    "ACP-SYSPROMPT-002",
    "ACP-SYSPROMPT-003",
    "ACP-MODES-001",
    "ACP-MODES-002",
    "ACP-CONFIG-001",
    "ACP-CONFIG-002",
    "ACP-PROMPTCAP-001",
    "ACP-PROMPTCAP-002",
    "ACP-PROMPTCAP-003",
    "ACP-AUTH-004",
    # ACP-AUTH-003: CAPABILITY with capability="inferred:authMethods" -- runs only when
    # `authMethods` is non-empty and `--tck-auth-method` was given, otherwise SKIPPED.
    "ACP-AUTH-003",
}
_ALL_IDS = _MANDATORY_IDS | _ADVISORY_IDS | _CAPABILITY_IDS

_CANCEL_IDS = {"ACP-CANCEL-001", "ACP-CANCEL-002", "ACP-JSONRPC-007"}
"""None of the fixtures below `hangs_until_cancel.py`, `cancel_returns_error.py`,
`cancel_wrong_stop_reason.py`, and `update_after_response.py` deliberately withhold their
response until `session/cancel` arrives for arbitrary prompt text -- they resolve the turn
immediately, same as `conforming.py`. So for all of them, `session/cancel` (and
`ACP-JSONRPC-007`'s `$/cancel_request`) always loses the race and the cancel tests SKIP with
"cancellation not exercised" rather than PASS or FAIL."""

_CAPABILITY_GATED_IDS = _CAPABILITY_IDS | {"ACP-LOAD-003", "ACP-DELETE-002"}
"""Every id that SKIPs (rather than PASSes) against `conforming.py`, which advertises
`agentCapabilities: {}` and no modes/configOptions/authMethods -- every CAPABILITY-tier id
(including `ACP-AUTH-003`, `capability="inferred:authMethods"`), plus the two ADVISORY ids
(`ACP-LOAD-003`, `ACP-DELETE-002`) that are still gated behind a `@pytest.mark.capability(...)`
marker on their test function even though their `Requirement.tier` itself is ADVISORY, not
CAPABILITY (see `test_session_capabilities.py` module docstring)."""


def _run_cli(
    fixture: str,
    *,
    fixture_dir: Path | None = None,
    protocol_version: int | None = None,
    k: str | None = None,
    timeout: str = "1",
    report_json: str | None = None,
    test_timeout: str | None = None,
    startup_timeout: str = "1",
    cancel_prompt: str | None = None,
    auth_method: str | None = None,
    allow_logout: bool = False,
    close_grace: str | None = None,
) -> subprocess.CompletedProcess[str]:
    cmd = [
        sys.executable,
        "-m",
        "tck",
        "--timeout",
        timeout,
        "--startup-timeout",
        startup_timeout,
    ]
    if protocol_version is not None:
        cmd += ["--protocol-version", str(protocol_version)]
    if test_timeout is not None:
        cmd += ["--test-timeout", test_timeout]
    if k is not None:
        cmd += ["-k", k]
    if report_json is not None:
        cmd += ["--report-json", report_json]
    if cancel_prompt is not None:
        cmd += ["--cancel-prompt", cancel_prompt]
    if auth_method is not None:
        cmd += ["--auth-method", auth_method]
    if allow_logout:
        cmd += ["--allow-logout"]
    if close_grace is not None:
        cmd += ["--close-grace", close_grace]
    cmd += [
        "--",
        sys.executable,
        str((fixture_dir or FIXTURES_DIR) / fixture),
    ]
    return subprocess.run(cmd, capture_output=True, text=True, timeout=CLI_SUBPROCESS_TIMEOUT)


_TABLE_ROW_RE = re.compile(r"^\s*(ACP-\S+)\s+(PASS|FAIL|SKIPPED|NOT TESTED)\b")


def _table_statuses(output: str) -> dict[str, str]:
    """Parse `<id> <STATUS>` pairs out of the terminal summary table. The status label is not
    always one token -- `NOT TESTED` is two words (`plugin.py:675`) -- and a row can carry a
    trailing `  (note)` suffix (`_informational_note`), so match the known status labels by
    regex instead of assuming exactly two whitespace-split tokens; without this, `NOT TESTED`
    rows silently vanish from the parsed dict instead of being recorded, and every
    `statuses.get(x) == "PASS"` check elsewhere only works by accident (`None != "PASS"`)."""
    statuses: dict[str, str] = {}
    for line in output.splitlines():
        match = _TABLE_ROW_RE.match(line)
        if match:
            statuses[match.group(1)] = match.group(2).replace("NOT TESTED", "NOT_TESTED")
    return statuses


def _table_notes(output: str) -> dict[str, str]:
    """Parse each summary-table row's trailing `(note)` text (empty if none), keyed by id."""
    notes: dict[str, str] = {}
    for line in output.splitlines():
        match = _TABLE_ROW_RE.match(line)
        if match:
            notes[match.group(1)] = line[match.end():].strip()
    return notes


def test_help_works():
    result = subprocess.run(
        [sys.executable, "-m", "tck", "--help"], capture_output=True, text=True, timeout=10
    )
    assert result.returncode == 0
    assert "acp-tck" in result.stdout


def test_version_works():
    result = subprocess.run(
        [sys.executable, "-m", "tck", "--version"], capture_output=True, text=True, timeout=10
    )
    assert result.returncode == 0
    assert "acp-tck" in result.stdout


def test_missing_agent_command_is_an_error():
    result = subprocess.run(
        [sys.executable, "-m", "tck"], capture_output=True, text=True, timeout=10
    )
    assert result.returncode != 0


def test_conforming_agent_passes_everything():
    """`conforming.py` only withholds a response for the literal `__hang__` prompt text (see
    its docstring), which the cancel tests deliberately do not send -- the TCK must not rely on
    a fixture's own sentinel, and a real agent doesn't know it either. So `session/cancel`
    always loses the race against this fixture's immediate reply, and ACP-CANCEL-001/002 SKIP
    ("cancellation not exercised") rather than PASS. `conforming.py` also advertises
    `agentCapabilities: {}` (no `loadSession`, no `sessionCapabilities`), so every
    CAPABILITY-tier id -- plus the two ADVISORY ids gated behind a capability marker
    (`ACP-LOAD-003`, `ACP-DELETE-002`) -- SKIPs too, rather than PASSing or being NOT_TESTED.
    Everything else still PASSes."""
    result = _run_cli("conforming.py")
    assert result.returncode == 0, result.stdout + result.stderr

    statuses = _table_statuses(result.stdout)
    # `_table_statuses` must parse INFORMATIONAL-tier rows too -- they carry a trailing `(note)`
    # suffix that would otherwise make them silently vanish, coincidentally matching `_ALL_IDS`,
    # which was never meant to include them -- so compare against the union explicitly rather
    # than let that omission look intentional.
    assert set(statuses) == _ALL_IDS | _INFORMATIONAL_IDS, (
        f"requirement table missing/extra ids: {result.stdout}"
    )
    skip_ids = _CANCEL_IDS | _CAPABILITY_GATED_IDS
    for req_id in skip_ids:
        assert statuses.get(req_id) == "SKIPPED", f"{req_id} should SKIP (unexercised/unadvertised):\n{result.stdout}"
    for req_id, status in statuses.items():
        if req_id in skip_ids:
            continue
        assert status == "PASS", f"{req_id} is {status}, expected PASS for the conforming fixture:\n{result.stdout}"
    assert "NOT TESTED" not in result.stdout
    assert "VERDICT: CONFORMANT" in result.stdout, result.stdout


def test_exits_immediately_fails_gracefully():
    result = _run_cli("exits_immediately.py")
    assert result.returncode != 0
    assert "INTERNALERROR" not in result.stdout
    assert "INTERNALERROR" not in result.stderr
    statuses = _table_statuses(result.stdout)
    for req_id in _MANDATORY_IDS:
        assert statuses.get(req_id) == "FAIL", f"{req_id} should FAIL when the agent never responds"
    # ACP-AUTH-003 is CAPABILITY-tier, not MANDATORY, so the loop above doesn't cover it --
    # assert its SKIP explicitly: it's conditional on --tck-auth-method regardless of the
    # agent's own behavior, and SKIPs even against a dead agent since the TCK never attempts
    # to connect for it without a configured auth method.
    assert statuses.get("ACP-AUTH-003") == "SKIPPED", "ACP-AUTH-003 should SKIP without --auth-method"


def test_scoped_k_run_prints_deselection_hint_not_no_mandatory_passed_hint():
    """The `-k`/deselection hint must print whenever any requirement is NOT_TESTED because its
    tests were deselected, independent of whether any MANDATORY
    requirement PASSed -- `conforming.py -k initialize` PASSes several MANDATORY requirements
    (ACP-INIT-*, ACP-TRANSPORT-*, ...) yet is still NOT CONFORMANT overall (every other
    MANDATORY id is NOT_TESTED, which counts as a failure), so this exercises the scoped-run
    branch, not the older "no MANDATORY requirement passed at all" branch, and checks the
    wording distinguishes deselection from an agent that never started."""
    result = _run_cli("conforming.py", k="initialize")
    assert result.returncode != 0
    assert "VERDICT: NOT CONFORMANT" in result.stdout, result.stdout
    assert "NOT TESTED" in result.stdout, result.stdout

    statuses = _table_statuses(result.stdout)
    assert statuses.get("ACP-INIT-001") == "PASS", result.stdout

    assert "hint: this run was scoped" in result.stdout, result.stdout
    assert "-k 'initialize'" in result.stdout, result.stdout
    assert "no MANDATORY requirement passed" not in result.stdout, result.stdout


def test_banner_on_stdout_fails_transport_001_but_passes_transport_002():
    """The banner is plain ASCII -- valid UTF-8 -- so it must FAIL ACP-TRANSPORT-001 (framing)
    but PASS ACP-TRANSPORT-002 (UTF-8), not be misreported as a UTF-8 violation."""
    result = _run_cli("banner_on_stdout.py")
    assert result.returncode != 0

    statuses = _table_statuses(result.stdout)
    assert statuses.get("ACP-TRANSPORT-001") == "FAIL", result.stdout
    assert statuses.get("ACP-TRANSPORT-002") == "PASS", result.stdout
    assert statuses.get("ACP-SCHEMA-001") == "FAIL", result.stdout
    for req_id in _CANCEL_IDS | {"ACP-AUTH-003"}:
        assert statuses.get(req_id) == "SKIPPED", f"{req_id} should SKIP (unexercised):\n{result.stdout}"
    for req_id in _MANDATORY_IDS - {"ACP-TRANSPORT-001", "ACP-SCHEMA-001"} - _CANCEL_IDS - {"ACP-AUTH-003"}:
        assert statuses.get(req_id) == "PASS", f"{req_id} should still PASS:\n{result.stdout}"

    # The FAILed requirement's own spec text/citation should be visible without opening source:
    # once in the summary table (indented under its id/status row) ...
    assert (
        "Every line the agent writes to stdout is a single valid JSON-RPC 2.0 message." in result.stdout
    ), result.stdout
    assert "transports.mdx:23,24,26" in result.stdout, result.stdout
    # ... and once as its own pytest FAILURES section, next to the traceback/transcript.
    assert "ACP requirement ACP-TRANSPORT-001" in result.stdout, result.stdout
    # A PASSing requirement's text is noise, not signal -- it must not be printed in the table.
    assert "The agent's stdout is valid UTF-8." not in result.stdout, result.stdout


def test_invalid_utf8_fails_transport_002():
    """`invalid_utf8.py` is ACP-TRANSPORT-002's real negative control: a lone undecodable line
    makes ACP-TRANSPORT-002 FAIL."""
    result = _run_cli("invalid_utf8.py")
    assert result.returncode != 0

    statuses = _table_statuses(result.stdout)
    assert statuses.get("ACP-TRANSPORT-002") == "FAIL", result.stdout


def test_garbage_after_response_fails_transport_001():
    """`garbage_after_response.py` writes non-JSON to stdout only after stdin closes -- strictly
    after the last response any test awaits. `close()` must drain and record that line so
    ACP-TRANSPORT-001 catches it instead of reporting a false PASS."""
    result = _run_cli("garbage_after_response.py")
    assert result.returncode != 0

    statuses = _table_statuses(result.stdout)
    assert statuses.get("ACP-TRANSPORT-001") == "FAIL", result.stdout


def test_asks_permission_agent_passes_everything():
    """`asks_permission.py` sends `session/request_permission` before resolving every prompt --
    the mock client (`run_prompt`) must answer it for any prompt/transport/schema test to ever
    resolve at all."""
    result = _run_cli("asks_permission.py")
    assert result.returncode == 0, result.stdout + result.stderr

    statuses = _table_statuses(result.stdout)
    for req_id in _CANCEL_IDS | {"ACP-AUTH-003"}:
        assert statuses.get(req_id) == "SKIPPED", f"{req_id} should SKIP (unexercised):\n{result.stdout}"
    for req_id in _MANDATORY_IDS - _CANCEL_IDS - {"ACP-AUTH-003"}:
        assert statuses.get(req_id) == "PASS", f"{req_id} is {statuses.get(req_id)}, expected PASS:\n{result.stdout}"


def test_asks_permission_closable_agent_passes_close_002():
    """`asks_permission_closable.py` combines `asks_permission.py`'s mid-turn
    `session/request_permission` with `sessionCapabilities.close` support: `session/close` on
    an in-flight, permission-pending prompt must resolve it as cancelled. `run_prompt`'s
    dispatcher (which answers any agent -> client request while waiting for the prompt's own
    response) is what makes this PASS deterministically, instead of deadlocking on the
    unanswered permission request.

    Uses a longer `--timeout` than this module's default (`_run_cli`'s `timeout="1"`) because the
    fixture deliberately delays its permission request past `run_prompt`'s short post-update peek
    window to keep the close-vs-permission race deterministic (see the fixture's docstring).
    Scoped to `close`: every prompt turn against this fixture pays that same deliberate delay,
    so an unscoped run against the full suite costs 30+s just from that, for no attribution
    benefit over the `session_capabilities`-only subset."""
    result = _run_cli(
        "asks_permission_closable.py", timeout="5", k="close", cancel_prompt="__hang__"
    )
    assert result.returncode != 0  # `-k`-scoped: MANDATORY ids are NOT_TESTED, verdict non-zero

    statuses = _table_statuses(result.stdout)
    assert statuses.get("ACP-CLOSE-002") == "PASS", f"expected PASS:\n{result.stdout}"
    assert statuses.get("ACP-CLOSE-001") == "PASS", f"expected PASS:\n{result.stdout}"


def test_asks_permission_closable_agent_also_exercises_cancelled_outcome():
    """Same fixture as above, driven through `test_cancel.py` instead: its permission request
    also arrives after `session/cancel` fires (same post-update-peek delay), so `run_prompt`
    answers it `{"outcome": {"outcome": "cancelled"}}` -- the one branch of `run_prompt`'s
    permission-answering logic that `asks_permission.py` alone never exercises."""
    result = _run_cli(
        "asks_permission_closable.py", timeout="5", k="cancel", cancel_prompt="__hang__"
    )
    # Exit code not asserted: a `-k`-scoped run necessarily leaves every MANDATORY requirement
    # NOT_TESTED, which by itself forces a non-conformant (nonzero) verdict regardless of these
    # two ids' own status (see `test_load_returns_null_fails_load_003_advisory_only`).
    statuses = _table_statuses(result.stdout)
    assert statuses.get("ACP-CANCEL-001") == "PASS", f"expected PASS:\n{result.stdout}"
    assert statuses.get("ACP-CANCEL-002") == "PASS", f"expected PASS:\n{result.stdout}"


def test_wrong_id_echo_fails_id_dependent_requirements():
    """`wrong_id_echo.py` mangles every response id, which breaks id-correlated waits (used by
    almost every test's setup, not only the id-echo test itself) -- so nearly everything times
    out and fails. This is expected: a broken id-echo genuinely makes the agent unusable.

    Scoped to `jsonrpc`: an unscoped run against this fixture means *every* test in the suite
    times out waiting for an id-correlated response before failing, which costs far longer for
    a fact this one id already demonstrates -- narrowing to the id-echo tests themselves keeps
    the same assertion true in a fraction of the time."""
    result = _run_cli("wrong_id_echo.py", k="jsonrpc")
    assert result.returncode != 0
    statuses = _table_statuses(result.stdout)
    assert statuses.get("ACP-JSONRPC-001") == "FAIL", result.stdout


def test_version_mismatch_errors_fails_init_003_only():
    result = _run_cli("version_mismatch_errors.py")
    assert result.returncode != 0

    statuses = _table_statuses(result.stdout)
    assert statuses.get("ACP-INIT-003") == "FAIL", result.stdout
    for req_id in _CANCEL_IDS | {"ACP-AUTH-003"}:
        assert statuses.get(req_id) == "SKIPPED", f"{req_id} should SKIP (unexercised):\n{result.stdout}"
    for req_id in _MANDATORY_IDS - {"ACP-INIT-003"} - _CANCEL_IDS - {"ACP-AUTH-003"}:
        assert statuses.get(req_id) == "PASS", f"{req_id} should still PASS:\n{result.stdout}"


def test_v2_only_agent_under_protocol_version_1_is_blocked_by_version_mismatch():
    """`v2_only_honest.py` (`tests/fixtures/agents/v2/`) always answers `initialize` with
    `protocolVersion: 2`, regardless of what a v1 client requests -- the mirror image
    of `tests/v2/test_cli.py`'s `test_v1_conforming_agent_under_protocol_version_2_is_blocked_by_
    version_mismatch`. `_tck_capability_gate` (`tck.common.plugin`) is version-agnostic: it fires
    whenever the negotiated `protocolVersion` does not equal this run's own, in either
    direction, so every `CAPABILITY`-tier id here SKIPs with the `VERSION-MISMATCH:` marker
    and zero CAPABILITY FAILs occur -- proving `Verdict.blocked_by_version_mismatch` itself is
    symmetric, not "always `False` for a v1 run".

    v1's own MANDATORY/ADVISORY tests that judge a result's *shape* against v1's rules
    (`ACP-INIT-002`/`004`, `ACP-META-001`, `ACP-PROMPT-001`/`003`/`004`, `ACP-SCHEMA-001`/`002`,
    `ACP-SESSION-003`/`004`) call their
    own `skip_if_version_mismatch` twin (`tck.v1.conformance._helpers`) right after obtaining
    the `initialize` result, mirroring v2's `test_initialize.py`/`test_batch.py`/
    `test_transport.py` pattern -- so they SKIP with the `VERSION-MISMATCH:` marker here too,
    exactly like the CAPABILITY-tier ids, and the run has zero FAILs despite being blocked."""
    result = _run_cli(
        "v2_only_honest.py", fixture_dir=FIXTURES_DIR_V2, protocol_version=1
    )
    assert result.returncode != 0, result.stdout + result.stderr
    assert "VERDICT: NOT CONFORMANT" in result.stdout, result.stdout
    assert "blocked by version mismatch" in result.stdout, result.stdout

    statuses = _table_statuses(result.stdout)
    fails = {req_id for req_id, status in statuses.items() if status == "FAIL"}
    assert fails == set(), result.stdout
    for req_id in _CAPABILITY_IDS | {
        "ACP-INIT-002",
        "ACP-INIT-004",
        "ACP-META-001",
        "ACP-PROMPT-001",
        "ACP-PROMPT-003",
        "ACP-PROMPT-004",
        "ACP-SCHEMA-001",
        "ACP-SCHEMA-002",
        "ACP-SESSION-003",
        "ACP-SESSION-004",
    }:
        assert statuses.get(req_id) == "SKIPPED", f"{req_id}: {result.stdout}"


def test_v2_only_agent_rejecting_v1_with_32022_is_blocked_by_version_mismatch(tmp_path):
    """A spec-conforming v2-only agent (`tests/fixtures/agents/v2/conforming.py`) rejects the v1
    `initialize` with `-32022` and leaves the connection uninitialized, so no v1 requirement --
    including the `ACP-INIT-*` negotiation rows, whose v1 rule ("respond with the latest version
    it supports") the v2 draft supersedes for agents implementing v2 -- can be judged. Every id
    SKIPs with the `VERSION-MISMATCH:` marker (`tck.common.plugin`'s version-rejection gate) and
    the run is blocked, not a wall of FAILs."""
    report_path = tmp_path / "report.json"
    result = _run_cli(
        "conforming.py", fixture_dir=FIXTURES_DIR_V2, protocol_version=1, report_json=str(report_path)
    )
    assert result.returncode != 0, result.stdout + result.stderr
    assert "VERDICT: NOT CONFORMANT (blocked by version mismatch)" in result.stdout, result.stdout

    statuses = _table_statuses(result.stdout)
    assert _ALL_IDS <= set(statuses), result.stdout
    assert set(statuses.values()) == {"SKIPPED"}, result.stdout

    report = json.loads(report_path.read_text())
    assert report["verdict"]["blocked_by_version_mismatch"] is True, report["verdict"]
    for requirement in report["requirements"]:
        assert all("-32022" in t["message"] and "VERSION-MISMATCH:" in t["message"] for t in requirement["tests"]), requirement


def test_router_requires_info_passes_everything():
    """`router_requires_info.py` models a dual-version protocol *router*: it selects v2 for any
    requested version >= 2, including the ACP-INIT-003 probe's 65535, and validates the params
    as a v2 `InitializeRequest`, whose `info` is REQUIRED. Since the probe carries `info`,
    ACP-INIT-003 PASSes; the fixture is otherwise identical to `conforming.py` (advertises
    `agentCapabilities: {}`, no modes/configOptions/authMethods), so the same SKIP/PASS split
    applies."""
    result = _run_cli("router_requires_info.py")
    assert result.returncode == 0, result.stdout + result.stderr

    statuses = _table_statuses(result.stdout)
    assert set(statuses) == _ALL_IDS | _INFORMATIONAL_IDS, (
        f"requirement table missing/extra ids: {result.stdout}"
    )
    skip_ids = _CANCEL_IDS | _CAPABILITY_GATED_IDS
    for req_id in skip_ids:
        assert statuses.get(req_id) == "SKIPPED", f"{req_id} should SKIP (unexercised/unadvertised):\n{result.stdout}"
    for req_id, status in statuses.items():
        if req_id in skip_ids:
            continue
        assert status == "PASS", f"{req_id} is {status}, expected PASS for router_requires_info.py:\n{result.stdout}"
    assert "NOT TESTED" not in result.stdout
    assert "VERDICT: CONFORMANT" in result.stdout, result.stdout


def test_echoes_any_version_fails_init_003_only():
    """`echoes_any_version.py` echoes the client's requested `protocolVersion` verbatim for
    *every* request, including the unsupported 65535 one -- the pattern ACP-INIT-003 exists to
    catch (see `test_initialize.py`). ACP-INIT-002 still PASSes (a v1 request is correctly
    echoed 1)."""
    result = _run_cli("echoes_any_version.py")
    assert result.returncode != 0

    statuses = _table_statuses(result.stdout)
    assert statuses.get("ACP-INIT-003") == "FAIL", result.stdout
    assert statuses.get("ACP-INIT-002") == "PASS", result.stdout
    for req_id in _CANCEL_IDS | {"ACP-AUTH-003"}:
        assert statuses.get(req_id) == "SKIPPED", f"{req_id} should SKIP (unexercised):\n{result.stdout}"
    for req_id in _MANDATORY_IDS - {"ACP-INIT-003"} - _CANCEL_IDS - {"ACP-AUTH-003"}:
        assert statuses.get(req_id) == "PASS", f"{req_id} should still PASS:\n{result.stdout}"


def test_result_and_error_fails_init_001_and_schema_001():
    """`result_and_error.py`'s `initialize` response carries both `result` and `error`, which
    also fails ACP-JSONRPC-002 (that requirement's evidence includes the `initialize` response
    itself, not just a probe reply) in addition to ACP-INIT-001 and ACP-SCHEMA-001."""
    result = _run_cli("result_and_error.py")
    assert result.returncode != 0

    statuses = _table_statuses(result.stdout)
    assert statuses.get("ACP-INIT-001") == "FAIL", result.stdout
    assert statuses.get("ACP-SCHEMA-001") == "FAIL", result.stdout
    assert statuses.get("ACP-JSONRPC-002") == "FAIL", result.stdout
    _failing = {"ACP-INIT-001", "ACP-SCHEMA-001", "ACP-JSONRPC-002"}
    for req_id in _CANCEL_IDS | {"ACP-AUTH-003"}:
        assert statuses.get(req_id) == "SKIPPED", f"{req_id} should SKIP (unexercised):\n{result.stdout}"
    for req_id in _MANDATORY_IDS - _failing - _CANCEL_IDS - {"ACP-AUTH-003"}:
        assert statuses.get(req_id) == "PASS", f"{req_id} should still PASS:\n{result.stdout}"


def test_answers_notifications_fails_jsonrpc_003_only():
    result = _run_cli("answers_notifications.py")
    assert result.returncode != 0

    statuses = _table_statuses(result.stdout)
    assert statuses.get("ACP-JSONRPC-003") == "FAIL", result.stdout
    for req_id in _CANCEL_IDS | {"ACP-AUTH-003"}:
        assert statuses.get(req_id) == "SKIPPED", f"{req_id} should SKIP (unexercised):\n{result.stdout}"
    for req_id in _MANDATORY_IDS - {"ACP-JSONRPC-003"} - _CANCEL_IDS - {"ACP-AUTH-003"}:
        assert statuses.get(req_id) == "PASS", f"{req_id} should still PASS:\n{result.stdout}"


def test_pushes_status_notifications_passes_everything():
    """`pushes_status_notifications.py` pushes an unprompted `_`-prefixed notification right
    after `initialize` and before handling every later line, so one lands in `ACP-JSONRPC-003`'s
    quiet period and ahead of every reply. A notification is not a reply, so the outcome must
    match `conforming.py`'s exactly -- including the `ACP-INFO-*` probes' recorded behaviour,
    which must not mistake the push for the agent's reply."""
    result = _run_cli("pushes_status_notifications.py")
    assert result.returncode == 0, result.stdout + result.stderr

    statuses = _table_statuses(result.stdout)
    assert set(statuses) == _ALL_IDS | _INFORMATIONAL_IDS, result.stdout
    skip_ids = _CANCEL_IDS | _CAPABILITY_GATED_IDS
    for req_id, status in statuses.items():
        expected = "SKIPPED" if req_id in skip_ids else "PASS"
        assert status == expected, f"{req_id} is {status}, expected {expected}:\n{result.stdout}"
    assert "VERDICT: CONFORMANT" in result.stdout, result.stdout

    notes = _table_notes(result.stdout)
    for req_id in ("ACP-INFO-PARSE-001", "ACP-INFO-INVALIDREQ-001"):
        assert notes[req_id].startswith("(silent;"), f"{req_id}: {notes[req_id]}"
    for req_id, note in notes.items():
        assert "_fixture/status_update" not in note, f"{req_id}: {note}"


def test_pushes_status_and_answers_notifications_fails_jsonrpc_003_only():
    """`pushes_status_and_answers_notifications.py` pushes the same status notification, then
    also replies to the notification. The leading notification must not hide the reply behind
    it."""
    result = _run_cli("pushes_status_and_answers_notifications.py")
    assert result.returncode != 0

    statuses = _table_statuses(result.stdout)
    fails = {req_id for req_id, status in statuses.items() if status == "FAIL"}
    assert fails == {"ACP-JSONRPC-003"}, result.stdout


def test_unknown_method_no_error_only_fails_the_advisory_requirement():
    """An ADVISORY-only failure must not affect the verdict: exit code 0, `VERDICT: CONFORMANT`,
    even though ACP-JSONRPC-004 itself FAILs."""
    result = _run_cli("unknown_method_no_error.py")
    assert result.returncode == 0, result.stdout + result.stderr
    assert "VERDICT: CONFORMANT" in result.stdout, result.stdout

    statuses = _table_statuses(result.stdout)
    assert statuses.get("ACP-JSONRPC-004") == "FAIL", result.stdout
    for req_id in _CANCEL_IDS | {"ACP-AUTH-003"}:
        assert statuses.get(req_id) == "SKIPPED", f"{req_id} should SKIP (unexercised):\n{result.stdout}"
    for req_id in _MANDATORY_IDS - _CANCEL_IDS - {"ACP-AUTH-003"}:
        assert statuses.get(req_id) == "PASS", f"{req_id} should still PASS:\n{result.stdout}"


def test_duplicate_session_id_fails_session_002_only():
    result = _run_cli("duplicate_session_id.py")
    assert result.returncode != 0

    statuses = _table_statuses(result.stdout)
    assert statuses.get("ACP-SESSION-002") == "FAIL", result.stdout
    for req_id in _CANCEL_IDS | {"ACP-AUTH-003"}:
        assert statuses.get(req_id) == "SKIPPED", f"{req_id} should SKIP (unexercised):\n{result.stdout}"
    for req_id in _MANDATORY_IDS - {"ACP-SESSION-002"} - _CANCEL_IDS - {"ACP-AUTH-003"}:
        assert statuses.get(req_id) == "PASS", f"{req_id} should still PASS:\n{result.stdout}"


def test_bad_stop_reason_fails_prompt_001_003_and_schema_001_only():
    """`bad_stop_reason.py` replies `stopReason: "done"` for any non-`__hang__` prompt, which
    directly breaks ACP-PROMPT-001, ACP-PROMPT-003 (the resource_link prompt also needs a valid
    `stopReason`), and ACP-SCHEMA-001. It does *not* hang for the cancel tests'
    prompt text either (only `__hang__` triggers that), so `session/cancel` always loses the
    race against its immediate (if invalid) reply -- ACP-CANCEL-001/002 SKIP as "cancellation
    not exercised" rather than cascading into a FAIL."""
    result = _run_cli("bad_stop_reason.py")
    assert result.returncode != 0

    statuses = _table_statuses(result.stdout)
    expected_fails = {"ACP-PROMPT-001", "ACP-PROMPT-003", "ACP-SCHEMA-001"}
    for req_id in expected_fails:
        assert statuses.get(req_id) == "FAIL", result.stdout
    for req_id in _CANCEL_IDS | {"ACP-AUTH-003"}:
        assert statuses.get(req_id) == "SKIPPED", f"{req_id} should SKIP (unexercised):\n{result.stdout}"
    for req_id in _MANDATORY_IDS - expected_fails - _CANCEL_IDS - {"ACP-AUTH-003"}:
        assert statuses.get(req_id) == "PASS", f"{req_id} should still PASS:\n{result.stdout}"


def test_update_wrong_session_fails_prompt_002_only():
    """`update_wrong_session.py` always attributes `session/update` to `sessionId: "other"`.
    ACP-PROMPT-001/PROMPT-003 only check the response, not update attribution, so they still
    PASS; ACP-PROMPT-002 (which does check it) FAILs. It doesn't hang for the cancel tests'
    prompt text, so `session/cancel` always loses the race and ACP-CANCEL-001/002 SKIP as
    "cancellation not exercised" -- an unexercised cancel can't exercise ACP-CANCEL-002's
    ordering check either, so the wrong-sessionId update it would otherwise have caught there
    goes unreported by that particular test (ACP-PROMPT-002 still reports it)."""
    result = _run_cli("update_wrong_session.py")
    assert result.returncode != 0

    statuses = _table_statuses(result.stdout)
    expected_fails = {"ACP-PROMPT-002"}
    for req_id in expected_fails:
        assert statuses.get(req_id) == "FAIL", result.stdout
    for req_id in _CANCEL_IDS | {"ACP-AUTH-003"}:
        assert statuses.get(req_id) == "SKIPPED", f"{req_id} should SKIP (unexercised):\n{result.stdout}"
    for req_id in _MANDATORY_IDS - expected_fails - _CANCEL_IDS - {"ACP-AUTH-003"}:
        assert statuses.get(req_id) == "PASS", f"{req_id} should still PASS:\n{result.stdout}"


def test_hangs_until_cancel_agent_passes_cancel_requirements():
    """`hangs_until_cancel.py` withholds its response on *every* prompt until `session/cancel`
    arrives, which is deliberately incompatible with the non-cancelling prompt tests
    (ACP-PROMPT-*, ACP-SCHEMA-001, ACP-TRANSPORT-*) -- those would time out waiting for a
    response the fixture never sends unprompted. This self-test scopes the run to the cancel
    tests with `-k`, which is the only way to exercise this fixture meaningfully.

    The overall exit code is *not* asserted here: the exit code reflects the four-status
    verdict over the whole registry, and a `-k`-scoped run necessarily leaves every
    other MANDATORY requirement NOT_TESTED (counted as a verdict failure by design) -- that says
    nothing about whether *this* fixture's cancel handling is correct, which is what this test
    checks via the per-requirement table."""
    result = _run_cli("hangs_until_cancel.py", k="cancel")

    statuses = _table_statuses(result.stdout)
    assert statuses.get("ACP-CANCEL-001") == "PASS", result.stdout + result.stderr
    assert statuses.get("ACP-CANCEL-002") == "PASS", result.stdout + result.stderr


def test_cancel_returns_error_fails_cancel_001():
    """`cancel_returns_error.py` resolves a cancelled turn with a JSON-RPC error instead of a
    successful `cancelled` result. Scoped with `-k "cancel"` for the same reason as the
    `hangs_until_cancel.py` self-test above (the fixture hangs on every prompt)."""
    result = _run_cli("cancel_returns_error.py", k="cancel")
    assert result.returncode != 0

    statuses = _table_statuses(result.stdout)
    assert statuses.get("ACP-CANCEL-001") == "FAIL", result.stdout


def test_cancel_wrong_stop_reason_fails_cancel_001_only():
    """`cancel_wrong_stop_reason.py` resolves a cancelled turn successfully but with
    `stopReason: "end_turn"` instead of `"cancelled"` -- ACP-CANCEL-001 FAILs, but ACP-CANCEL-002
    (no update after the response) is unaffected and still PASSes. Scoped with `-k "cancel"` for
    the same reason as the `hangs_until_cancel.py` self-test above. Uses a longer `--timeout`
    since the fixture deliberately sleeps 1.2s after `session/cancel` before answering, to stay
    outside the TCK's 1.0s "was this actually exercised" race window (see the fixture's
    docstring)."""
    result = _run_cli("cancel_wrong_stop_reason.py", k="cancel", timeout="5")
    assert result.returncode != 0

    statuses = _table_statuses(result.stdout)
    assert statuses.get("ACP-CANCEL-001") == "FAIL", result.stdout
    assert statuses.get("ACP-CANCEL-002") == "PASS", result.stdout


def test_update_after_response_fails_cancel_002_only():
    """`update_after_response.py` correctly resolves a cancelled turn with `stopReason:
    "cancelled"` (ACP-CANCEL-001 PASSes) but then sends one more `session/update` afterwards,
    which ACP-CANCEL-002 catches. Scoped with `-k "cancel"` for the same reason as the
    `hangs_until_cancel.py` self-test above."""
    result = _run_cli("update_after_response.py", k="cancel")
    assert result.returncode != 0

    statuses = _table_statuses(result.stdout)
    assert statuses.get("ACP-CANCEL-001") == "PASS", result.stdout
    assert statuses.get("ACP-CANCEL-002") == "FAIL", result.stdout


def test_per_test_watchdog_fails_a_hung_test_fast():
    """A tiny `--test-timeout` must fail a test whose own per-operation deadlines are much
    larger, well before any individual read/write deadline would ever fire on its own --
    proving the watchdog itself is what caught it, not the ordinary per-response timeout.
    Scoped to one fast, id-echo-only test node so this stays quick even though
    `--timeout`/`--startup-timeout` are deliberately large. `--close-grace` is also lowered:
    `never_responds.py` never exits on its own, so teardown would otherwise pay the full
    default 2s stdin-close wait every run just to prove the watchdog fired; this self-test only
    cares that it fired, not about giving a real agent a generous shutdown window."""
    result = _run_cli(
        "never_responds.py",
        k="test_id_is_echoed_for_integer_and_string_ids",
        timeout="10",
        startup_timeout="1",
        test_timeout="0.3",
        close_grace="0.2",
    )
    assert result.returncode != 0
    assert "per-test watchdog" in result.stdout, result.stdout + result.stderr
    assert "--tck-test-timeout" in result.stdout, result.stdout + result.stderr


# --- session-capability tests ---


def test_conforming_full_agent_passes_everything_with_cancel_prompt_hang():
    """`conforming_full.py` advertises `loadSession: true`, every `sessionCapabilities` marker,
    modes, config options, every `promptCapabilities`, and the auth surface -- so every
    CAPABILITY-tier id (plus the two capability-gated ADVISORY ids) should PASS instead of
    SKIPPING. `--cancel-prompt __hang__` is required: it's the only prompt text `_base.py`'s
    `_handle_prompt` withholds a response for, so it's what lets ACP-CANCEL-001/002 and
    ACP-CLOSE-002 actually exercise their cancellation/close-race logic instead of SKIPPING as
    "not exercised". `--auth-method tck` is required for ACP-AUTH-003 to PASS instead of SKIP,
    since `conforming_full.py` advertises an `authMethods` entry with that id. `--allow-logout`
    is required for ACP-AUTH-004 to PASS instead of SKIP -- calling `logout` for real is opt-in
    (see `test_conforming_full_agent_without_allow_logout_only_skips_auth_004` below for the
    default-off behaviour).

    `ACP-AUTH-005` (AUTH-A1) is the one ADVISORY id that legitimately SKIPs here rather than
    PASSing: it only concerns an agent that advertises *no* `authMethods`, and
    `conforming_full.py` deliberately advertises one -- that is inapplicability, not a
    conformance gap, exactly like `ACP-AUTH-003` SKIPping without `--auth-method`."""
    result = _run_cli(
        "conforming_full.py", cancel_prompt="__hang__", auth_method="tck", allow_logout=True
    )
    assert result.returncode == 0, result.stdout + result.stderr
    assert "VERDICT: CONFORMANT" in result.stdout, result.stdout

    statuses = _table_statuses(result.stdout)
    assert set(statuses) == _ALL_IDS | _INFORMATIONAL_IDS, (
        f"requirement table missing/extra ids: {result.stdout}"
    )
    for req_id, status in statuses.items():
        if req_id == "ACP-AUTH-005":
            assert status == "SKIPPED", f"{req_id} is {status}, expected SKIPPED (not applicable):\n{result.stdout}"
            continue
        assert status == "PASS", f"{req_id} is {status}, expected PASS for conforming_full.py:\n{result.stdout}"
    assert "NOT TESTED" not in result.stdout
    assert all(
        status != "SKIPPED" for req_id, status in statuses.items() if req_id != "ACP-AUTH-005"
    ), result.stdout


def test_conforming_full_agent_without_allow_logout_only_skips_auth_004():
    """Acceptance criterion: the same `conforming_full.py --auth-method tck` run, but WITHOUT
    `--allow-logout`, must SKIP ONLY `ACP-AUTH-004` in addition to the baseline's own SKIP
    (`ACP-AUTH-005`, per `test_conforming_full_agent_passes_everything_with_cancel_prompt_hang`
    above) -- every other id keeps the exact same status. Calling `logout` for real is opt-in
    (mirrors v2's `ACP-AUTH-203` gating); a SKIPPED CAPABILITY does not affect the verdict."""
    result = _run_cli(
        "conforming_full.py", cancel_prompt="__hang__", auth_method="tck", allow_logout=False
    )
    assert result.returncode == 0, result.stdout + result.stderr
    assert "VERDICT: CONFORMANT" in result.stdout, result.stdout

    statuses = _table_statuses(result.stdout)
    assert set(statuses) == _ALL_IDS | _INFORMATIONAL_IDS, (
        f"requirement table missing/extra ids: {result.stdout}"
    )
    expected_skips = {"ACP-AUTH-004", "ACP-AUTH-005"}
    for req_id, status in statuses.items():
        if req_id in expected_skips:
            assert status == "SKIPPED", f"{req_id} is {status}, expected SKIPPED:\n{result.stdout}"
        else:
            assert status == "PASS", f"{req_id} is {status}, expected PASS without --allow-logout:\n{result.stdout}"


def test_load_replays_after_response_fails_load_002_only():
    """`load_replays_after_response.py` advertises `loadSession` but answers `session/load`
    before replaying stored history instead of after -- ACP-LOAD-001 still PASSes (the response
    itself is valid), only the ordering requirement ACP-LOAD-002 FAILs."""
    result = _run_cli("load_replays_after_response.py", k="load")
    assert result.returncode != 0

    statuses = _table_statuses(result.stdout)
    assert statuses.get("ACP-LOAD-001") == "PASS", result.stdout
    assert statuses.get("ACP-LOAD-002") == "FAIL", result.stdout


def test_resume_replays_history_fails_resume_002_only():
    """`resume_replays_history.py` advertises `sessionCapabilities.resume` but replays stored
    history before answering `session/resume`, which resume MUST NOT do -- ACP-RESUME-001 still
    PASSes, only ACP-RESUME-002 FAILs."""
    result = _run_cli("resume_replays_history.py", k="resume")
    assert result.returncode != 0

    statuses = _table_statuses(result.stdout)
    assert statuses.get("ACP-RESUME-001") == "PASS", result.stdout
    assert statuses.get("ACP-RESUME-002") == "FAIL", result.stdout


def test_load_returns_null_fails_load_003_advisory_only():
    """`load_returns_null.py` replays history correctly and advertises `loadSession`, but
    answers `session/load` with a literal `null` instead of `{}`. Mandatory schema validation
    tolerates `null` for this all-optional response, so ACP-LOAD-001/002 PASS; only the
    stricter ADVISORY ACP-LOAD-003 FAILs. The overall exit code is *not* asserted here (see
    `test_hangs_until_cancel_agent_passes_cancel_requirements` for why): a `-k`-scoped run
    necessarily leaves every MANDATORY requirement NOT_TESTED, which by itself forces a
    non-conformant verdict regardless of ACP-LOAD-003's own (ADVISORY, verdict-inert) status."""
    result = _run_cli("load_returns_null.py", k="load")

    statuses = _table_statuses(result.stdout)
    assert statuses.get("ACP-LOAD-001") == "PASS", result.stdout
    assert statuses.get("ACP-LOAD-002") == "PASS", result.stdout
    assert statuses.get("ACP-LOAD-003") == "FAIL", result.stdout


def test_mode_update_uses_modeId_fails_modes_002_only():
    """`mode_update_uses_modeId.py` advertises `modes` and emits a `current_mode_update` with
    the docs-bug field name `modeId` instead of the schema-true `currentModeId` --
    ACP-MODES-001 (which never inspects a mode-update notification) still PASSes."""
    result = _run_cli("mode_update_uses_modeId.py", k="mode")
    assert result.returncode != 0

    statuses = _table_statuses(result.stdout)
    assert statuses.get("ACP-MODES-001") == "PASS", result.stdout
    assert statuses.get("ACP-MODES-002") == "FAIL", result.stdout


def test_config_partial_list_fails_config_002_only():
    """`config_partial_list.py` advertises `configOptions` and answers `session/set_config_option`
    with only the changed option, not the complete list -- ACP-CONFIG-001 (which only checks
    `session/new`'s own configOptions) still PASSes."""
    result = _run_cli("config_partial_list.py", k="config")
    assert result.returncode != 0

    statuses = _table_statuses(result.stdout)
    assert statuses.get("ACP-CONFIG-001") == "PASS", result.stdout
    assert statuses.get("ACP-CONFIG-002") == "FAIL", result.stdout


def test_boolean_option_unadvertised_fails_config_003():
    """`boolean_option_unadvertised.py` advertises a `type: "boolean"` config option even to a
    client that never advertised `clientCapabilities.session.configOptions.boolean` -- a
    MANDATORY (Req 33) FAIL, which must flip the overall verdict."""
    result = _run_cli("boolean_option_unadvertised.py")
    assert result.returncode != 0

    statuses = _table_statuses(result.stdout)
    assert statuses.get("ACP-CONFIG-003") == "FAIL", result.stdout
    assert "VERDICT: NOT CONFORMANT" in result.stdout, result.stdout


def test_terminal_auth_unadvertised_fails_auth_002():
    """`terminal_auth_unadvertised.py` advertises `authMethods[*].type == "terminal"` even to a
    client that never advertised `clientCapabilities.auth.terminal` -- a MANDATORY (Req 23) FAIL."""
    result = _run_cli("terminal_auth_unadvertised.py", k="auth")
    assert result.returncode != 0

    statuses = _table_statuses(result.stdout)
    assert statuses.get("ACP-AUTH-002") == "FAIL", result.stdout


def test_gated_by_auth_without_auth_method_skips_with_hint_and_is_not_conformant():
    """`gated_by_auth.py` requires `authenticate` before `session/new` succeeds. Without
    `--auth-method`, every session-dependent test SKIPs (not FAILs) with a message pointing at
    the flag, and the run is scored NOT CONFORMANT via `Verdict.blocked_by_auth` even though no
    MANDATORY test actually FAILed."""
    result = _run_cli("gated_by_auth.py", k="session")
    assert result.returncode != 0
    assert "VERDICT: NOT CONFORMANT" in result.stdout, result.stdout
    assert "blocked by authentication" in result.stdout, result.stdout
    assert "--auth-method" in result.stdout, result.stdout

    statuses = _table_statuses(result.stdout)
    assert statuses.get("ACP-SESSION-001") == "SKIPPED", result.stdout
    assert statuses.get("ACP-SESSION-002") == "SKIPPED", result.stdout


def test_gated_by_auth_with_auth_method_succeeds():
    """The same fixture, scoped the same way, but with `--auth-method tck` -- the auto-
    authenticate step in `connected_agent` makes it behave like a normal conforming agent for
    every session-dependent test in scope. The overall exit code is *not* asserted here (see
    `test_hangs_until_cancel_agent_passes_cancel_requirements` for why): a `-k`-scoped run
    necessarily leaves every out-of-scope MANDATORY requirement NOT_TESTED, which by itself
    forces a non-conformant verdict regardless of whether authentication itself worked -- what
    this test checks is that the in-scope session tests PASS instead of SKIPPING."""
    result = _run_cli("gated_by_auth.py", k="session", auth_method="tck")

    statuses = _table_statuses(result.stdout)
    assert statuses.get("ACP-SESSION-001") == "PASS", result.stdout
    assert statuses.get("ACP-SESSION-002") == "PASS", result.stdout
    assert "blocked by authentication" not in result.stdout, result.stdout


def test_gated_by_auth_full_run_without_auth_method_is_not_conformant_and_blocked_by_auth(
    tmp_path,
):
    """A full (unscoped) run against `gated_by_auth.py` without `--auth-method`: every
    session-dependent test SKIPs with the auth hint, no MANDATORY requirement actually FAILs
    (everything reachable without a session -- `initialize`, JSON-RPC envelope/id echo, the
    schema-less parts of ACP-AUTH-001/002 -- still PASSes), and the run is scored NOT CONFORMANT
    solely via `Verdict.blocked_by_auth`. The JSON report's `verdict.blocked_by_auth` must be
    `true` and `verdict.conformant` `false`."""
    report_path = tmp_path / "report.json"
    result = _run_cli(
        "gated_by_auth.py",
        cancel_prompt="__hang__",
        report_json=str(report_path),
    )
    assert result.returncode != 0, result.stdout + result.stderr
    assert "VERDICT: NOT CONFORMANT" in result.stdout, result.stdout
    assert "blocked by authentication" in result.stdout, result.stdout

    statuses = _table_statuses(result.stdout)
    mandatory_fails = {
        req_id for req_id in _MANDATORY_IDS if statuses.get(req_id) == "FAIL"
    }
    assert not mandatory_fails, f"unexpected MANDATORY FAILs: {mandatory_fails}\n{result.stdout}"

    report = json.loads(report_path.read_text())
    assert report["verdict"]["blocked_by_auth"] is True, report["verdict"]
    assert report["verdict"]["conformant"] is False, report["verdict"]


def test_gated_by_auth_full_run_with_auth_method_is_fully_conformant():
    """The same full (unscoped) run, but with `--auth-method tck`: the auto-authenticate step
    in `connected_agent` makes `gated_by_auth.py` behave exactly like `conforming_full.py` minus
    the extra capabilities it doesn't advertise (`loadSession`, `sessionCapabilities`,
    `promptCapabilities`, `auth.logout`, `modes`/`configOptions`) -- every one of those SKIPs as
    "not advertised", every other MANDATORY/ADVISORY requirement PASSes, and the overall exit
    code is 0/CONFORMANT. `--cancel-prompt __hang__` is needed for the same reason
    `conforming_full.py`'s own self-test needs it: `_base.py`'s hang-on-`__hang__` behavior is
    unconditional, so ACP-CANCEL-001/002 need that exact prompt text to exercise the race
    instead of SKIPping as "cancellation not exercised"."""
    result = _run_cli("gated_by_auth.py", cancel_prompt="__hang__", auth_method="tck")
    assert result.returncode == 0, result.stdout + result.stderr
    assert "VERDICT: CONFORMANT" in result.stdout, result.stdout
    assert "NOT TESTED" not in result.stdout, result.stdout

    statuses = _table_statuses(result.stdout)
    # ACP-AUTH-005 (AUTH-A1) legitimately SKIPs too: it only concerns an agent advertising no
    # authMethods, and `gated_by_auth.py` advertises one -- inapplicability, not a gap.
    capability_gated = _CAPABILITY_GATED_IDS - {"ACP-AUTH-003"} | {"ACP-AUTH-005"}
    for req_id in capability_gated:
        assert statuses.get(req_id) == "SKIPPED", f"{req_id} should SKIP (not advertised):\n{result.stdout}"
    for req_id, status in statuses.items():
        if req_id in capability_gated:
            continue
        assert status == "PASS", f"{req_id} is {status}, expected PASS:\n{result.stdout}"


def test_advertises_load_but_errors_fails_load_001_and_verdict():
    """`advertises_load_but_errors.py` advertises `loadSession: true` but always errors on
    `session/load` -- a CAPABILITY-tier FAIL, which must flip the overall verdict to NOT
    CONFORMANT (unlike an ADVISORY-only failure)."""
    result = _run_cli("advertises_load_but_errors.py", k="load")
    assert result.returncode != 0

    statuses = _table_statuses(result.stdout)
    assert statuses.get("ACP-LOAD-001") == "FAIL", result.stdout
    assert "VERDICT: NOT CONFORMANT" in result.stdout, result.stdout


# --- --report-json ---


def test_report_json_for_conforming_agent_is_conformant_with_cancel_skipped(tmp_path):
    report_path = tmp_path / "report.json"
    result = _run_cli("conforming.py", report_json=str(report_path))
    assert result.returncode == 0, result.stdout + result.stderr

    report = json.loads(report_path.read_text())
    assert report["verdict"]["conformant"] is True
    by_id = {r["id"]: r for r in report["requirements"]}
    skip_ids = _CANCEL_IDS | _CAPABILITY_GATED_IDS
    for req_id in skip_ids:
        assert by_id[req_id]["status"] == "SKIPPED", report
    for req_id in _ALL_IDS - skip_ids:
        assert by_id[req_id]["status"] == "PASS", (req_id, report)
    assert report["protocol_version"] == 1
    assert report["agent_info"] is not None
    assert set(report) == {
        "tck_version",
        "protocol_version",
        "schema_revision",
        "agent_command",
        "agent_info",
        "agent_capabilities",
        "started_at",
        "finished_at",
        "requirements",
        "verdict",
    }


def test_report_json_for_advisory_only_failure_is_still_conformant(tmp_path):
    report_path = tmp_path / "report.json"
    result = _run_cli("unknown_method_no_error.py", report_json=str(report_path))
    assert result.returncode == 0, result.stdout + result.stderr

    report = json.loads(report_path.read_text())
    assert report["verdict"]["conformant"] is True
    by_id = {r["id"]: r for r in report["requirements"]}
    assert by_id["ACP-JSONRPC-004"]["status"] == "FAIL"


def test_report_json_for_banner_on_stdout_includes_a_nonempty_transcript_on_failure(tmp_path):
    report_path = tmp_path / "report.json"
    result = _run_cli("banner_on_stdout.py", report_json=str(report_path))
    assert result.returncode != 0

    report = json.loads(report_path.read_text())
    assert report["verdict"]["conformant"] is False
    by_id = {r["id"]: r for r in report["requirements"]}
    failing = by_id["ACP-TRANSPORT-001"]
    assert failing["status"] == "FAIL"
    test_outcome = failing["tests"][0]
    assert test_outcome["status"] == "FAIL"
    assert test_outcome["transcript"], "expected a non-empty transcript on a FAIL outcome"
    assert isinstance(test_outcome["transcript"], list)
    assert {"dir", "t", "raw"} <= set(test_outcome["transcript"][0])


def test_calls_fs_unadvertised_fails_clientcap_001():
    """`calls_fs_unadvertised.py` calls `fs/read_text_file` on every prompt turn even though the
    TCK's mock client never advertised `fs` -- a MANDATORY (Req 29) FAIL that must flip the
    exit code. Scoped to `clientcap` since this fixture's `_handle_prompt` override only ever
    resolves a turn once the client has answered its one client-request, which is exactly what
    the clientcap tests' `run_prompt` calls do; other prompt tests would work too, but scoping
    keeps this self-test fast and focused.

    Also asserts ACP-CLIENTCAP-002/003 still PASS: the three ids are three separate tests
    specifically so that a single-capability violation like this one isn't mis-attributed to
    the other two."""
    result = _run_cli("calls_fs_unadvertised.py", k="clientcap")
    assert result.returncode != 0, result.stdout + result.stderr

    statuses = _table_statuses(result.stdout)
    assert statuses.get("ACP-CLIENTCAP-001") == "FAIL", result.stdout
    assert statuses.get("ACP-CLIENTCAP-002") == "PASS", result.stdout
    assert statuses.get("ACP-CLIENTCAP-003") == "PASS", result.stdout


def test_calls_terminal_unadvertised_fails_clientcap_002():
    """Same as above, for `terminal/create` (Req 30); asserts -001/-003 still PASS."""
    result = _run_cli("calls_terminal_unadvertised.py", k="clientcap")
    assert result.returncode != 0, result.stdout + result.stderr

    statuses = _table_statuses(result.stdout)
    assert statuses.get("ACP-CLIENTCAP-001") == "PASS", result.stdout
    assert statuses.get("ACP-CLIENTCAP-002") == "FAIL", result.stdout
    assert statuses.get("ACP-CLIENTCAP-003") == "PASS", result.stdout


def test_calls_elicitation_unadvertised_fails_clientcap_003():
    """Same as above, for `elicitation/create` (Req 32); asserts -001/-002 still PASS."""
    result = _run_cli("calls_elicitation_unadvertised.py", k="clientcap")
    assert result.returncode != 0, result.stdout + result.stderr

    statuses = _table_statuses(result.stdout)
    assert statuses.get("ACP-CLIENTCAP-001") == "PASS", result.stdout
    assert statuses.get("ACP-CLIENTCAP-002") == "PASS", result.stdout
    assert statuses.get("ACP-CLIENTCAP-003") == "FAIL", result.stdout


def test_noisy_stderr_and_parse_error_reply_agent_informational_notes():
    """`noisy_stderr_and_parse_error_reply.py` deterministically exercises two INFORMATIONAL
    probes' non-default branches: it logs every line to stderr (ACP-STDERR-001's byte count
    must be > 0) and replies `-32700`/`id: null` to malformed JSON instead of staying silent
    (ACP-INFO-PARSE-001's recorded behaviour must say so) -- proving the terminal table actually
    surfaces a recorded property as a note, not just that the always-PASS scaffolding runs."""
    result = _run_cli("noisy_stderr_and_parse_error_reply.py")
    assert result.returncode == 0, result.stdout + result.stderr

    assert "ACP-STDERR-001" in result.stdout
    assert "ACP-INFO-PARSE-001" in result.stdout
    assert "replied -32700 with id:null" in result.stdout, result.stdout
    assert "stderr byte(s)" in result.stdout, result.stdout
    for line in result.stdout.splitlines():
        if "ACP-STDERR-001" in line:
            match = re.search(r"(\d+) stderr byte\(s\)", line)
            assert match and int(match.group(1)) > 0, result.stdout


def test_report_json_for_exits_immediately_has_no_crash_and_all_mandatory_fail_or_not_tested(
    tmp_path,
):
    report_path = tmp_path / "report.json"
    result = _run_cli("exits_immediately.py", report_json=str(report_path))
    assert result.returncode != 0
    assert "INTERNALERROR" not in result.stdout + result.stderr

    assert report_path.exists(), "report must still be written even when every test fails"
    report = json.loads(report_path.read_text())
    assert report["verdict"]["conformant"] is False
    for requirement in report["requirements"]:
        if requirement["id"] == "ACP-AUTH-003":
            # Conditional on --tck-auth-method regardless of the agent's own behavior -- see
            # test_exits_immediately_fails_gracefully.
            assert requirement["status"] == "SKIPPED", requirement
        elif requirement["tier"] == "MANDATORY":
            assert requirement["status"] in ("FAIL", "NOT_TESTED"), requirement


# --- notification, cancel_request, error, and auth-surface defect fixtures ---


def _fail_ids(statuses: dict[str, str]) -> set[str]:
    return {req_id for req_id, status in statuses.items() if status == "FAIL"}


def test_answers_custom_notifications_fails_jsonrpc_003_only():
    """`answers_custom_notifications.py` replies to `_`-prefixed notifications; the connection
    stays usable, so ACP-EXT-002 still PASSes."""
    result = _run_cli("answers_custom_notifications.py")
    assert result.returncode != 0

    statuses = _table_statuses(result.stdout)
    assert _fail_ids(statuses) == {"ACP-JSONRPC-003"}, result.stdout
    assert statuses.get("ACP-EXT-002") == "PASS", result.stdout


def test_answers_cancel_request_fails_jsonrpc_003_only():
    """`answers_cancel_request.py` replies to `$/cancel_request`; the connection stays usable,
    so ACP-JSONRPC-006 still PASSes."""
    result = _run_cli("answers_cancel_request.py")
    assert result.returncode != 0

    statuses = _table_statuses(result.stdout)
    assert _fail_ids(statuses) == {"ACP-JSONRPC-003"}, result.stdout
    assert statuses.get("ACP-JSONRPC-006") == "PASS", result.stdout


def test_exits_on_unknown_notification_fails_ext_002_and_jsonrpc_006_only():
    """`exits_on_unknown_notification.py` dies on `_`/`$/` notifications without replying, so
    ACP-JSONRPC-003 still PASSes: an exit is not a reply."""
    result = _run_cli("exits_on_unknown_notification.py")
    assert result.returncode != 0

    statuses = _table_statuses(result.stdout)
    assert _fail_ids(statuses) == {"ACP-EXT-002", "ACP-JSONRPC-006"}, result.stdout
    assert statuses.get("ACP-JSONRPC-003") == "PASS", result.stdout


def test_cancel_request_wrong_error_fails_jsonrpc_007_only():
    """`cancel_request_wrong_error.py` answers a `$/cancel_request`-cancelled prompt with
    `-32603`. `--cancel-prompt __hang__` keeps the prompt in flight, so ACP-CANCEL-001/002 are
    exercised too and PASS."""
    result = _run_cli("cancel_request_wrong_error.py", cancel_prompt="__hang__")
    assert result.returncode != 0

    statuses = _table_statuses(result.stdout)
    assert _fail_ids(statuses) == {"ACP-JSONRPC-007"}, result.stdout
    assert statuses.get("ACP-CANCEL-001") == "PASS", result.stdout


def test_invalid_params_internal_error_fails_error_002_advisory_only():
    result = _run_cli("invalid_params_internal_error.py")
    assert result.returncode == 0, result.stdout + result.stderr
    assert "VERDICT: CONFORMANT" in result.stdout, result.stdout

    statuses = _table_statuses(result.stdout)
    assert _fail_ids(statuses) == {"ACP-ERROR-002"}, result.stdout


def test_terminal_auth_bad_shape_fails_auth_006_only():
    """`terminal_auth_bad_shape.py` advertises a terminal method with a string `args` only to a
    client that enabled `auth.terminal`. The schema's lax `AuthMethod` union alone would accept
    it as an `agent` method; ACP-AUTH-006 validates it as the terminal variant it claims to be."""
    result = _run_cli("terminal_auth_bad_shape.py")
    assert result.returncode != 0

    statuses = _table_statuses(result.stdout)
    assert _fail_ids(statuses) == {"ACP-AUTH-006"}, result.stdout
    assert statuses.get("ACP-AUTH-002") == "PASS", result.stdout


def test_error_with_meta_fails_schema_002_advisory_only():
    """`error_with_meta.py` puts `_meta` on every error object, which `Error` does not define."""
    result = _run_cli("error_with_meta.py")
    assert result.returncode == 0, result.stdout + result.stderr
    assert "VERDICT: CONFORMANT" in result.stdout, result.stdout

    statuses = _table_statuses(result.stdout)
    assert _fail_ids(statuses) == {"ACP-SCHEMA-002"}, result.stdout


def test_silent_on_unknown_method_fails_ext_001_only():
    """`silent_on_unknown_method.py` never answers a `_`-prefixed request. Only ACP-EXT-001 owns
    that defect: ACP-JSONRPC-004 SKIPs and ACP-ERROR-001 judges its remaining sample."""
    result = _run_cli("silent_on_unknown_method.py")
    assert result.returncode != 0

    statuses = _table_statuses(result.stdout)
    assert _fail_ids(statuses) == {"ACP-EXT-001"}, result.stdout
    assert statuses.get("ACP-ERROR-001") == "PASS", result.stdout
    assert statuses.get("ACP-JSONRPC-004") == "SKIPPED", result.stdout


_AUTH_005_SCOPE = "not_gated_when_no_auth_methods or test_session_new_succeeds"


def test_auth_005_fails_on_minus_32000_without_auth_methods():
    result = _run_cli("auth_required_without_methods.py", k=_AUTH_005_SCOPE)
    statuses = _table_statuses(result.stdout)
    assert statuses.get("ACP-AUTH-005") == "FAIL", result.stdout
    assert statuses.get("ACP-SESSION-001") == "FAIL", result.stdout


def test_auth_005_leaves_other_session_new_errors_to_session_001():
    result = _run_cli("session_new_internal_error.py", k=_AUTH_005_SCOPE)
    statuses = _table_statuses(result.stdout)
    assert statuses.get("ACP-AUTH-005") == "PASS", result.stdout
    assert statuses.get("ACP-SESSION-001") == "FAIL", result.stdout


def _skip_message(report: dict, req_id: str) -> str:
    by_id = {r["id"]: r for r in report["requirements"]}
    (test,) = by_id[req_id]["tests"]
    assert test["status"] == "SKIPPED", by_id[req_id]
    return test["message"]


def test_auth_method_naming_a_terminal_method_skips_without_authenticating(tmp_path):
    """`terminal_auth_unadvertised.py` advertises a `terminal` method (id `term`) that its
    `authenticate` would accept. A client must not pass a terminal method to `authenticate`, so
    `--auth-method term` SKIPs session-dependent tests (blocked by auth) rather than using it."""
    report_path = tmp_path / "report.json"
    result = _run_cli(
        "terminal_auth_unadvertised.py",
        k="test_session_new_succeeds or test_authenticate_then",
        auth_method="term",
        report_json=str(report_path),
    )
    assert "blocked by authentication" in result.stdout, result.stdout

    report = json.loads(report_path.read_text())
    assert "terminal auth method" in _skip_message(report, "ACP-SESSION-001")
    assert "terminal auth method" in _skip_message(report, "ACP-AUTH-003")


def test_auth_method_not_advertised_skips_without_authenticating(tmp_path):
    report_path = tmp_path / "report.json"
    result = _run_cli(
        "gated_by_auth.py",
        k="test_session_new_succeeds or test_authenticate_then",
        auth_method="nope",
        report_json=str(report_path),
    )
    assert "blocked by authentication" in result.stdout, result.stdout

    report = json.loads(report_path.read_text())
    for req_id in ("ACP-SESSION-001", "ACP-AUTH-003"):
        assert "not one of the ids advertised" in _skip_message(report, req_id)


# --- session/prompt audit fixtures: each trips exactly the id(s) in its docstring ---


def _output_fail_ids(output: str) -> set[str]:
    return {req_id for req_id, status in _table_statuses(output).items() if status == "FAIL"}


def test_rejects_mcp_servers_fails_session_003_only():
    """`rejects_mcp_servers.py` errors on any non-empty `mcpServers`; ACP-SESSION-004 SKIPs on
    the failed prerequisite rather than double-reporting it."""
    result = _run_cli("rejects_mcp_servers.py")
    assert result.returncode != 0
    assert _output_fail_ids(result.stdout) == {"ACP-SESSION-003"}, result.stdout
    assert _table_statuses(result.stdout).get("ACP-SESSION-004") == "SKIPPED", result.stdout


def test_ignores_mcp_servers_fails_advisory_session_004_only():
    """`ignores_mcp_servers.py` accepts but never launches stdio MCP servers -- an ADVISORY
    (SHOULD) failure, so the run stays CONFORMANT."""
    result = _run_cli("ignores_mcp_servers.py")
    assert result.returncode == 0, result.stdout + result.stderr
    assert _output_fail_ids(result.stdout) == {"ACP-SESSION-004"}, result.stdout
    assert _table_statuses(result.stdout).get("ACP-SESSION-003") == "PASS", result.stdout


def test_client_gated_update_fixtures_fail_only_their_own_clientcap_id():
    """One fixture per client-gated `session/update` kind; the compaction one only sends it
    during `session/load` replay, proving replay is covered."""
    for fixture, expected in (
        ("emits_notice_unadvertised.py", "ACP-CLIENTCAP-004"),
        ("replays_compaction_unadvertised.py", "ACP-CLIENTCAP-005"),
        ("emits_plan_update_unadvertised.py", "ACP-CLIENTCAP-006"),
        ("emits_subagent_update_unadvertised.py", "ACP-CLIENTCAP-007"),
    ):
        result = _run_cli(fixture)
        assert result.returncode != 0, f"{fixture}:\n{result.stdout}"
        assert _output_fail_ids(result.stdout) == {expected}, f"{fixture}:\n{result.stdout}"


def test_relative_tool_call_path_fails_prompt_004_only():
    result = _run_cli("relative_tool_call_path.py")
    assert result.returncode != 0
    assert _output_fail_ids(result.stdout) == {"ACP-PROMPT-004"}, result.stdout


def test_delete_keeps_listing_fails_delete_003_only():
    result = _run_cli("delete_keeps_listing.py")
    assert result.returncode != 0
    assert _output_fail_ids(result.stdout) == {"ACP-DELETE-003"}, result.stdout
    statuses = _table_statuses(result.stdout)
    for req_id in ("ACP-DELETE-001", "ACP-DELETE-002", "ACP-LIST-001", "ACP-LIST-002"):
        assert statuses.get(req_id) == "PASS", f"{req_id}:\n{result.stdout}"


def test_refusing_to_delete_an_active_session_skips_delete_001_and_003():
    """Deleting an active session is implementation-defined; without `close` to end it first,
    an error SKIPs instead of failing a conforming agent."""
    result = _run_cli("refuses_deleting_active_session.py")
    assert result.returncode == 0, result.stdout + result.stderr
    statuses = _table_statuses(result.stdout)
    assert _output_fail_ids(result.stdout) == set(), result.stdout
    assert statuses.get("ACP-DELETE-001") == "SKIPPED", result.stdout
    assert statuses.get("ACP-DELETE-003") == "SKIPPED", result.stdout
    assert statuses.get("ACP-DELETE-002") == "PASS", result.stdout
    assert "deleting an active session is implementation-defined" in result.stdout, result.stdout


def test_system_prompt_lenient_fails_sysprompt_002_and_003():
    result = _run_cli("system_prompt_lenient.py")
    assert result.returncode != 0
    assert _output_fail_ids(result.stdout) == {"ACP-SYSPROMPT-002", "ACP-SYSPROMPT-003"}, result.stdout
    assert _table_statuses(result.stdout).get("ACP-SYSPROMPT-001") == "PASS", result.stdout


def test_system_prompt_rejected_fails_sysprompt_001_only():
    result = _run_cli("system_prompt_rejected.py")
    assert result.returncode != 0
    assert _output_fail_ids(result.stdout) == {"ACP-SYSPROMPT-001"}, result.stdout


def test_boolean_option_on_set_fails_config_003_only():
    """The boolean option is hidden from `session/new` but leaked by `set_config_option`."""
    result = _run_cli("boolean_option_on_set.py")
    assert result.returncode != 0
    assert _output_fail_ids(result.stdout) == {"ACP-CONFIG-003"}, result.stdout
    statuses = _table_statuses(result.stdout)
    assert statuses.get("ACP-CONFIG-001") == "PASS", result.stdout
    assert statuses.get("ACP-CONFIG-002") == "PASS", result.stdout


def test_late_state_updates_pass_cancel_002_and_load_002():
    """`late_state_updates.py` sends `session_info_update` after each prompt response (including
    a cancelled one) and `available_commands_update` after each load response. Those kinds are
    allowed outside a turn, so ACP-CANCEL-002/LOAD-002 PASS and the run stays CONFORMANT."""
    result = _run_cli("late_state_updates.py", cancel_prompt="__hang__")
    assert result.returncode == 0, result.stdout + result.stderr
    statuses = _table_statuses(result.stdout)
    assert _output_fail_ids(result.stdout) == set(), result.stdout
    for req_id in ("ACP-CANCEL-001", "ACP-CANCEL-002", "ACP-LOAD-001", "ACP-LOAD-002"):
        assert statuses.get(req_id) == "PASS", f"{req_id}:\n{result.stdout}"
