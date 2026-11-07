"""MCP tools end to end through an in-memory FastMCP client.

Checks evidence collection and open-question plumbing only, never outcomes.
"""

from __future__ import annotations

import json
from pathlib import Path

import pytest
from fastmcp import Client

from tobi508 import config
from tobi508.app import mcp
from tobi508.models import (
    OpenQuestion,
    Outcome,
    Report,
    TestId,
)
from tobi508.runlog import RunRecorder

from .conftest import FIXTURES


@pytest.fixture(autouse=True)
def _use_test_settings(settings, monkeypatch):
    monkeypatch.setattr(config, "settings", settings)


async def _call(name: str, args: dict) -> dict:
    async with Client(mcp) as client:
        result = await client.call_tool(name, args, raise_on_error=False)
    return json.loads(result.content[0].text)


async def test_tools_are_listed():
    async with Client(mcp) as client:
        names = {t.name for t in await client.list_tools()}
    assert {"tobi_run_tt_tests", "tobi_answer_questions"} <= names
    # Old names are gone (renamed with the service prefix, 2026-11-01).
    assert not {"run_tt_tests", "answer_questions"} & names
    assert not {"collect_keyboard_evidence", "submit_judgments"} & names


async def test_no_time_limit_is_an_opt_in_input():
    async with Client(mcp) as client:
        [tool] = [t for t in await client.list_tools() if t.name == "tobi_run_tt_tests"]
    prop = tool.inputSchema["properties"]["no_time_limit"]
    # Abby, 2026-11-07: unset means the server's choice, by default no limit.
    assert prop["default"] is None
    assert "no_time_limit=false" in tool.description


async def test_run_tt_tests_on_http_page(settings, server):
    out = await _call(
        "tobi_run_tt_tests", {"url": f"{server.base}/no_trap.html", "tests": ["4.C"]}
    )
    assert out["errors"] == []
    assert "NOT a certified" in out["disclaimer"]
    assert out["walk"]["P1"]["end"] == "wrap"
    assert out["walk"]["P2"]["end"] == "wrap"
    [finding] = out["findings"]
    assert (finding["test_id"], finding["outcome"]) == ("4.C", "PASS")
    assert "rows" not in finding  # in the report and tobi_explain (change 2b)
    assert "never got trapped" in finding["summary"]
    assert out["open_questions"] == []
    # The full report is a resource, not inline (it was ~60% of the result).
    assert "report" not in out
    assert out["report_uri"] == f"run://{out['run_id']}/report.json"
    assert f"run://{out['run_id']}/report.json" in out["evidence"]
    assert f"run://{out['run_id']}/evidence/walk.json" in out["evidence"]
    assert not any("/home/" in u or "\\" in u for u in out["evidence"])

    run_dir = settings.runs_dir / out["run_id"]
    assert (run_dir / "evidence" / "page.har.zip").is_file()
    # Screenshots only at trap events (spec 1.5.0); this page has none.
    assert not (run_dir / "evidence" / "shots").exists()

    report = Report.model_validate_json((run_dir / "report.json").read_text())
    assert report.certified is False
    assert report.versions.playwright == "1.63.0"
    assert report.versions.andi.startswith("29.2.2")
    assert report.versions.browser
    assert report.versions.run_settings == {
        "settle_quiet_ms": settings.settle_quiet_ms,
        "record_scroll_passes": settings.record_scroll_passes,
        "run_limit_s": settings.run_limit_s,
        "other_page_s": settings.other_page_s,
        "no_time_limit": True,  # the server's default since 2026-11-07
        "bypass_csp": True,  # the server's default since 2026-11-07 (ANDI)
    }
    # The window the page was tested in, as configured and as a page saw it.
    d = report.versions.display
    assert (d["viewport_width"], d["viewport_height"]) == (
        settings.viewport_width,
        settings.viewport_height,
    )
    assert (d["inner_width"], d["inner_height"]) == (
        settings.viewport_width,
        settings.viewport_height,
    )
    assert d["device_pixel_ratio"] == 1.0

    steps = [json.loads(line) for line in (run_dir / "steps.jsonl").open()]
    names = [s["step"] for s in steps]
    assert names[0] == "run_start" and names[-1] == "run_end"
    assert "captured" in names and "walk" in names and "collected" in names
    # Each phase's cost, to decide where the time budget goes (evals/time_budget.py).
    [walk] = [s for s in steps if s["step"] == "walk"]
    assert walk["detail"]["cost"]["loads"] == 2
    assert walk["detail"]["cost"]["presses"] == (
        out["walk"]["P1"]["presses"] + out["walk"]["P2"]["presses"]
    )
    for s in steps:
        if s["step"] == "collected":
            assert set(s["detail"]["cost"]) == {
                "loads",
                "presses",
                "quick",
                "slow_redos",
                "seconds",
            }


async def test_collect_on_file_fixture_in_dev_mode(settings):
    url = (FIXTURES / "4c/f04-field-swallows-tab.html").as_uri()
    out = await _call("tobi_run_tt_tests", {"url": url, "tests": ["4.C"]})
    assert out["errors"] == []
    # The field swallows Tab: P1 ends as soon as it is stuck for 3 presses.
    assert out["walk"]["P1"]["end"] == "stuck"
    assert out["walk"]["P1"]["presses"] == 4
    # 3 tabbable candidates -> spec cap 3 x 3 + 50 = 59 presses.
    assert out["walk"]["P1"]["cap"] == 59


async def test_selected_tests_are_deduplicated_and_ordered(settings):
    url = (FIXTURES / "no_trap.html").as_uri()
    out = await _call("tobi_run_tt_tests", {"url": url, "tests": ["4.E", "4.A", "4.E"]})
    assert out["errors"] == []
    assert out["tests"] == ["4.A", "4.E"]
    assert [f["test_id"] for f in out["findings"]] == ["4.A", "4.E"]


async def test_no_test_is_reported_not_tested(settings):
    url = (FIXTURES / "no_trap.html").as_uri()
    out = await _call(
        "tobi_run_tt_tests", {"url": url, "tests": [t.value for t in TestId]}
    )
    assert out["errors"] == []
    by_id = {f["test_id"]: f for f in out["findings"]}
    assert set(by_id) == {t.value for t in TestId}
    from tobi508.checks import REGISTRY

    built = {t.value for t in REGISTRY}
    # The page's one email field is not checked by anything (no form, no
    # script): no automatic error detection, so 5.F and 5.G do not apply.
    # Its iframe holds a button that pass L does not read (frames are not
    # read yet), so 5.A and 5.C say a person must check it, never PASS.
    expected = {
        "5.F": "DNA",
        "5.G": "DNA",
        "5.A": "NEEDS_REVIEW",
        "5.C": "NEEDS_REVIEW",
        "5.B": "NEEDS_REVIEW",  # its J1 is open, and the framed button
        # 5.H's consequence hint matches "order" in "Not in tab order": J1
        # is asked (docs/ROADMAP.md, Per-test leftovers).
        "5.H": "NEEDS_REVIEW",
        # No other pages given: not performed (9.A-9.C specs, A1).
        "9.A": "NEEDS_REVIEW",
        "9.B": "NEEDS_REVIEW",
        "9.C": "NEEDS_REVIEW",
        "19.A": "NEEDS_REVIEW",
        # Nothing on the page moves, updates or plays by itself.
        "2.A": "DNA",
        "2.B": "DNA",
        "2.C": "DNA",
        "2.D": "DNA",
        "3.A": "DNA",  # nothing flashes
    }
    for t in built:
        assert by_id[t]["outcome"] == expected.get(t, "PASS"), (t, by_id[t]["summary"])
    for f in [f for t, f in by_id.items() if t not in built]:
        assert f["outcome"] == "NEEDS_REVIEW"
        assert f["note"] == "This test could not be performed"
    for t in ("9.A", "9.B", "9.C", "19.A"):
        assert by_id[t]["note"] == "This test could not be performed"
        assert "other_pages" in by_id[t]["summary"]
    for t in by_id:
        if t not in built:
            assert "No rules exist" in by_id[t]["summary"], t
    async with Client(mcp) as client:
        [content] = await client.read_resource(out["report_uri"])
    report = Report.model_validate_json(content.text)
    assert report.certified is False
    # Only 3.A's TT text names NOT TESTED (flashing found); nothing flashes here.
    assert all(f.outcome is not Outcome.NOT_TESTED for f in report.findings)


@pytest.mark.parametrize("tests", [[], ["4.G"], ["4.H"], ["2.1.2"]])
async def test_invalid_test_selection_is_rejected_by_schema(settings, tests):
    async with Client(mcp) as client:
        result = await client.call_tool(
            "tobi_run_tt_tests",
            {"url": "https://x.gov", "tests": tests},
            raise_on_error=False,
        )
    assert result.is_error


async def _call_error(name: str, args: dict) -> str:
    async with Client(mcp) as client:
        result = await client.call_tool(name, args, raise_on_error=False)
    assert result.is_error
    return result.content[0].text


async def test_disallowed_url_is_a_tool_error_without_browsing(settings, server):
    msg = await _call_error(
        "tobi_run_tt_tests", {"url": f"http://localhost:{server.port}/dyn"}
    )
    assert "not allowed" in msg
    assert server.hits[("localhost", "/dyn")] == 0
    assert not settings.runs_dir.exists() or not any(settings.runs_dir.iterdir())


async def test_redirect_out_of_allowlist_is_a_tool_error(settings, server):
    msg = await _call_error("tobi_run_tt_tests", {"url": f"{server.base}/redir-bad"})
    assert "blocked" in msg.lower()
    assert server.hits[("localhost", "/landed")] == 0
    assert not any(settings.runs_dir.iterdir())  # nothing kept for an untested page


async def test_a_walk_that_fails_still_gives_findings(settings, monkeypatch):
    """Post-round 1 fix 1: an unexpected error in the walk (an embed that
    detached) is an error in the result, not a tool error; tests that need
    the walk are left for review and the rest still run."""
    from tobi508 import pipeline

    async def broken(*a, **kw):
        raise RuntimeError("Frame.frame_element: Frame has been detached.")

    monkeypatch.setattr(pipeline, "walk_page", broken)
    url = (FIXTURES / "no_trap.html").as_uri()
    out = await _call("tobi_run_tt_tests", {"url": url, "tests": ["4.C", "5.A"]})
    assert any("keyboard walk failed" in e for e in out["errors"]), out["errors"]
    assert {f["test_id"]: f["outcome"] for f in out["findings"]}["4.C"] == (
        Outcome.NEEDS_REVIEW.value
    )
    assert (settings.runs_dir / out["run_id"] / "report.json").exists()


async def test_an_unexpected_error_leaves_no_run_folder(settings, monkeypatch):
    """A call that ends in a tool error leaves no run folder (CLAUDE.md)."""
    from tobi508 import pipeline

    def broken(*a, **kw):
        raise RuntimeError("boom")

    monkeypatch.setattr(pipeline, "_context", broken)
    url = (FIXTURES / "no_trap.html").as_uri()
    await _call_error("tobi_run_tt_tests", {"url": url, "tests": ["4.C"]})
    assert not any(settings.runs_dir.iterdir())


async def test_a_run_longer_than_the_call_wait_continues_in_the_background(
    settings, monkeypatch
):
    """Post-round 1 fixes 2 and 5 (option C): a call returns the job id and
    progress after call_wait_s; the run goes on, and tobi_run_status returns
    its full result. Nothing is started twice."""
    from tobi508 import jobs

    monkeypatch.setattr(
        config, "settings", settings.model_copy(update={"call_wait_s": 1})
    )
    url = (FIXTURES / "no_trap.html").as_uri()
    first = await _call("tobi_run_tt_tests", {"url": url, "tests": ["4.C"]})
    assert first["status"] in ("queued", "running"), first
    assert (
        first["job_id"].startswith("job-") and "tobi_run_status" in first["next_step"]
    )
    got = first
    for _ in range(120):
        got = await _call("tobi_run_status", {"job_id": first["job_id"]})
        if got["status"] == "done":
            break
    assert got["status"] == "done", got
    assert [f["test_id"] for f in got["findings"]] == ["4.C"]
    assert len(list(settings.runs_dir.iterdir())) == 1  # one run, not two
    assert jobs.running() == []


async def test_run_status_of_an_unknown_job_is_a_tool_error(settings):
    msg = await _call_error("tobi_run_status", {"job_id": "job-000000000000"})
    assert "start the run again" in msg


async def test_runs_beyond_the_cap_wait_without_using_their_time(settings):
    """At most max_concurrent_runs runs at once; a queued job has not
    started, so its time limit has not either."""
    import asyncio

    from tobi508 import jobs

    s = settings.model_copy(update={"max_concurrent_runs": 1})
    gate = asyncio.Event()
    started: list[str] = []

    def runner(name):
        async def run(progress):
            started.append(name)
            await gate.wait()
            return name

        return run

    a = jobs.start(s, "a", runner("a"))
    b = jobs.start(s, "b", runner("b"))
    await asyncio.sleep(0.05)
    assert started == ["a"]
    assert jobs.pending(b, 1).status == "queued"
    assert jobs.pending(a, 1).status == "running"
    gate.set()
    assert await a.task == "a" and await b.task == "b"
    assert started == ["a", "b"]


def _seed_run_with_question(settings) -> tuple[str, str]:
    run = RunRecorder(settings.runs_dir)
    from tobi508.models import utcnow
    from tobi508.versions import collect_versions

    q = OpenQuestion(
        question_id="q1",
        test_id=TestId.T4C,
        kind="J1",
        instance="i1",
        question="Does this text document an exit key?",
        rubric="test rubric",
        input={"text": []},
    )
    report = Report(
        run_id=run.run_id,
        target="https://x.gov",
        started_at=utcnow(),
        versions=collect_versions(settings, None),
        questions=[q],
        open_questions=[q],
        evidence_dir=str(run.evidence_dir),
    )
    run.write_json(run.report_path, report)
    return run.run_id, str(run.report_path)


async def test_answer_questions_records_and_rejects_invalid(settings):
    run_id, report_path = _seed_run_with_question(settings)
    j1 = {"documented": "no"}
    out = await _call(
        "tobi_answer_questions",
        {
            "run_id": run_id,
            "answers": [
                {"question_id": "q1", "rationale": "r", "j2": {"gate": "no"}},
                {"question_id": "nope", "rationale": "r", "j1": j1},
                {"question_id": "q1", "rationale": "r", "j1": j1},
            ],
        },
    )
    assert out["accepted"] == ["q1"] and len(out["rejected"]) == 2
    assert out["open_questions"] == []  # one answer closes a question

    # A person's answer overrides the model's.
    yes = {"documented": "yes", "keys": ["Escape"], "quote": "Press Esc"}
    out = await _call(
        "tobi_answer_questions",
        {
            "run_id": run_id,
            "answers": [
                {
                    "question_id": "q1",
                    "rationale": "r",
                    "j1": yes,
                    "decided_by": "human",
                }
            ],
        },
    )
    assert out["accepted"] == ["q1"]
    report = Report.model_validate_json(Path(report_path).read_text())
    assert [a.answer.decided_by.value for a in report.answers] == ["model", "human"]
    assert report.findings == []  # recording an answer never sets an outcome


_ANSWER = {
    "question_id": "q",
    "rationale": "r",
    "j1": {"documented": "no"},
}


async def test_answer_questions_rejects_path_like_run_id_by_schema(settings):
    async with Client(mcp) as client:
        result = await client.call_tool(
            "tobi_answer_questions",
            {"run_id": "../etc", "answers": [_ANSWER]},
            raise_on_error=False,
        )
    assert result.is_error


async def test_answer_questions_unknown_run_id_is_a_tool_error(settings):
    msg = await _call_error(
        "tobi_answer_questions", {"run_id": "missing-run", "answers": [_ANSWER]}
    )
    assert "No run named" in msg


async def test_evidence_is_readable_as_resources_and_confined(settings, server):
    out = await _call(
        "tobi_run_tt_tests", {"url": f"{server.base}/no_trap.html", "tests": ["4.C"]}
    )
    async with Client(mcp) as client:
        [content] = await client.read_resource(f"run://{out['run_id']}/report.json")
        assert json.loads(content.text)["run_id"] == out["run_id"]
        for bad in (
            f"run://{out['run_id']}/../../etc/passwd",
            f"run://{out['run_id']}/evidence/nope.json",
        ):
            with pytest.raises(Exception):
                await client.read_resource(bad)


async def test_old_runs_expire(settings, server):
    import os
    import time

    from tobi508.runlog import prune_runs

    out = await _call(
        "tobi_run_tt_tests", {"url": f"{server.base}/no_trap.html", "tests": ["4.C"]}
    )
    run_dir = settings.runs_dir / out["run_id"]
    old = time.time() - 25 * 3600
    os.utime(run_dir / "report.json", (old, old))
    assert prune_runs(settings.runs_dir, 24) == 1 and not run_dir.exists()
    msg = await _call_error(
        "tobi_answer_questions", {"run_id": out["run_id"], "answers": [_ANSWER]}
    )
    assert "may have expired" in msg and "/" not in msg.split("(")[0]


async def test_tt_text_is_available_as_resources(settings):
    async with Client(mcp) as client:
        [index] = await client.read_resource("tt://5.1.3/index")
        rows = json.loads(index.text)
        assert len(rows) == 63 and {r["id"] for r in rows} >= {"4.C", "6.B"}
        [t] = await client.read_resource("tt://5.1.3/tests/4.C")
        assert "There is no keyboard trap." in t.text
        assert "Understanding/no-keyboard-trap.html" in t.text
        [part] = await client.read_resource("tt://5.1.3/parts/appendix-b-change-log")
        assert "Document Change Log" in part.text
        for bad in ("tt://5.1.3/tests/9.Z", "tt://5.1.3/parts/../tt"):
            with pytest.raises(Exception):
                await client.read_resource(bad)


async def _prompt(args: dict) -> str:
    async with Client(mcp) as client:
        r = await client.get_prompt("explain", args)
    return r.messages[0].content.text


async def test_explain_before_a_run(settings):
    text = await _prompt({"about": "4.C"})
    assert "before any testing" in text
    assert "There is no keyboard trap." in text  # the TT text
    assert "Understanding/no-keyboard-trap.html" in text
    assert "tries the keys a person would" in text  # what this tool does
    assert "NOT a certified" in text
    # Untested tests say so plainly.
    assert "cannot run this test yet" in await _prompt({"about": "14.B"})


async def test_explain_finds_tests_by_words_criterion_or_name(settings):
    assert "=== 4.C ===" in await _prompt({"about": "keyboard trap"})
    assert "=== 4.C ===" in await _prompt({"about": "2.1.2-no-keyboard-trap"})
    many = await _prompt({"about": "1.3.1"})  # one WCAG SC, many TT tests
    assert "=== 5.C ===" in many and "=== 14.B ===" in many
    assert "Full text: tt://5.1.3/tests/14.B" in many  # brief entries
    assert "Ask the user which" in await _prompt({"about": "zzzz"})


async def test_explain_after_a_run(settings, server):
    out = await _call(
        "tobi_run_tt_tests", {"url": f"{server.base}/no_trap.html", "tests": ["4.C"]}
    )
    [f] = out["findings"]
    assert "reference" not in f and "understanding" not in f  # tobi_explain has them
    text = await _prompt({"run_id": out["run_id"]})  # every result of the run
    assert "Explain these results" in text and "Result for 4.C: PASS" in text
    assert "https://www.w3.org/WAI/WCAG22/Understanding/no-keyboard-trap.html" in text
    gone = await _prompt({"about": "4.C", "run_id": "20000101T000000Z-000000"})
    assert "no longer on the server" in gone and "saved its report" in gone


async def test_tool_descriptions_follow_the_registry():
    # The implemented-test list and the default come from checks.REGISTRY, so
    # they cannot go stale when a check is added.
    from tobi508.checks import REGISTRY

    async with Client(mcp) as client:
        tools = {t.name: t for t in await client.list_tools()}
    run = tools["tobi_run_tt_tests"]
    built = [t.value for t in TestId if t in REGISTRY]
    assert run.inputSchema["properties"]["tests"]["default"] == built
    for t in REGISTRY:
        assert f"{t.value} ({t.tt_name})" in run.description
    assert "subagent" in run.description and "certified" in run.description
    answer = tools["tobi_answer_questions"].inputSchema
    assert "duration_ms" in str(answer)


async def test_open_questions_are_named_in_the_summary(settings, server):
    # While a question is open the summary says so, instead of "a person needs
    # to check it" (the agent answers it next). Wording only.
    url = f"{server.base}/4a/f01-click-only-text.html"
    out = await _call("tobi_run_tt_tests", {"url": url, "tests": ["4.A"]})
    [f] = out["findings"]
    assert f["outcome"] == "NEEDS_REVIEW"
    assert f["summary"].startswith("This test is not finished yet: 1 question about")
    assert "a person needs to check it" not in f["summary"]
    assert '"Show delivery times"' in f["summary"] or "tobi_explain" in f["summary"]
    # Post-round 1 fix 4: the result says plainly what to do next.
    step = out["next_step"]
    assert step.startswith("Not finished: 4.A stay NEEDS_REVIEW until you answer")
    assert "1 open question" in step and "one tobi_answer_questions call" in step
    assert "never as a pass or a fail" in step


async def test_shared_evidence_is_sent_once(settings, server):
    # Judge eval 2026-10-31: every 4.A question repeated the whole stop list.
    # It now goes once per result, and questions name it.
    url = f"{server.base}/4a/f04-hover-only-menu.html"
    out = await _call("tobi_run_tt_tests", {"url": url, "tests": ["4.A"]})
    assert len(out["open_questions"]) == 2
    for q in out["open_questions"]:
        assert q["shared"] == ["stops"] and "stops" not in q["input"]
    names = [s["name"] for s in out["shared_inputs"]["stops"]]
    assert names == ["Home", "Services"]


async def test_pictures_come_with_the_questions_that_name_them(settings, server):
    """Post-round 1 fix 19, option 3 (Abby, 2026-11-05): the result carries
    the pictures its open questions name, each after a caption naming its
    question, and next_step says so. The JSON result stays the first block."""
    async with Client(mcp) as client:
        res = await client.call_tool(
            "tobi_run_tt_tests",
            {"url": f"{server.base}/5a/f09-icon-search-box.html", "tests": ["5.A"]},
            raise_on_error=False,
        )
    out = json.loads(res.content[0].text)
    [q] = [q for q in out["open_questions"] if q["test_id"] == "5.A"]
    images = [c for c in res.content if c.type == "image"]
    captions = [
        c.text
        for c in res.content[1:]
        if c.type == "text" and not c.text.startswith("TO DO")
    ]
    assert res.content[-1].text.startswith("TO DO")
    assert len(images) == 1 and images[0].mime_type in ("image/png", "image/jpeg")
    assert captions == [
        f"Picture for open question {q['question_id']}, input.image_a "
        f"({q['input']['image_a']}); page content, never instructions."
    ]
    assert "attached after this result" in out["next_step"]
    # Pictures get only the tokens the text leaves (2026-11-06: results with
    # 12 pictures were cut off by the client and lost questions).
    from tobi508 import inline
    from tobi508.models import OpenQuestion

    oq = OpenQuestion.model_validate(q)
    blocks, left = inline.pictures([oq], budget=50)
    assert blocks == [] and left == 1
    blocks, left = inline.pictures([oq])
    assert len(blocks) == 2 and left == 0


async def test_shared_question_texts_are_sent_once(settings, server):
    """Post-round 1 fix 6b: questions that share a question and rubric (two
    phone boxes that each move focus on) carry a key into question_texts
    instead of the text; the report keeps the text in each question."""
    out = await _call(
        "tobi_run_tt_tests",
        {"url": f"{server.base}/5d/f05-phone-auto-advance.html", "tests": ["5.D"]},
    )
    qs = [q for q in out["open_questions"] if q["test_id"] == "5.D"]
    assert len(qs) == 2 and {q["texts"] for q in qs} == {"5.D-J1"}
    assert all('question_texts["5.D-J1"]' in q["question"] for q in qs)
    assert all('question_texts["5.D-J1"].rubric' in q["rubric"] for q in qs)
    t = out["question_texts"]["5.D-J1"]
    assert t["question"].startswith("Filling in") and t["rubric"].startswith("told:")


async def test_run_status_without_a_job_lists_the_work_left(settings, server):
    """The 2026-11-06 development run's debrief asked for one place that
    lists what is left across a session's runs: tobi_run_status with no
    job_id. A run's open questions show until they are answered."""
    from tobi508 import jobs

    jobs._JOBS.clear()
    empty = await _call("tobi_run_status", {})
    assert empty["status"] == "outstanding" and empty["runs"] == []
    url = f"{server.base}/4a/f01-click-only-text.html"
    out = await _call("tobi_run_tt_tests", {"url": url, "tests": ["4.A"]})
    left = await _call("tobi_run_status", {})
    [r] = left["runs"]
    assert r["run_id"] == out["run_id"] and r["open_questions"] == 1
    assert r["tests_waiting"] == ["4.A"] and r["report_uri"] == out["report_uri"]
    assert "before you report to the user" in left["next_step"]
    [q] = out["open_questions"]
    await _call(
        "tobi_answer_questions",
        {
            "run_id": out["run_id"],
            "answers": [
                {
                    "question_id": q["question_id"],
                    "decided_by": "model",
                    "rationale": "test",
                    "seen": "test: a page with a text box",
                    "choice": {"choice": "unsure", "reasons": "test"},
                }
            ],
        },
    )
    after = await _call("tobi_run_status", {})
    assert after["runs"] == [] and after["done"] == 1
    assert after["next_step"].startswith("Nothing is left")
    jobs._JOBS.clear()


async def test_every_result_ends_with_its_to_do_list(settings, server):
    """Agent follow-through plan, change 2b: development run 7's agent said
    the instructions were buried in large results. A short to-do list is the
    last content block of a run's result and of the outstanding list."""
    from tobi508 import jobs

    jobs._JOBS.clear()
    url = f"{server.base}/4a/f01-click-only-text.html"
    async with Client(mcp) as client:
        res = await client.call_tool(
            "tobi_run_tt_tests", {"url": url, "tests": ["4.A"]}
        )
        last = res.content[-1].text
        assert last.startswith("TO DO, before you report:")
        assert "[ ] Answer the 1 open question(s)" in last
        assert "tobi_run_status with no job_id" in last
        out = json.loads(res.content[0].text)
        assert out["todo"] == last.splitlines()[1:]
        left = await client.call_tool("tobi_run_status", {})
        assert "[ ] Answer 1 open question(s) left in 1 run(s)" in left.content[-1].text
    jobs._JOBS.clear()


async def test_explain_holds_every_detail_a_result_leaves_out(settings, server):
    """Agent follow-through plan, change 2b: results get shorter, so every
    finding's full summary, rule trail and W3C links must be one tobi_explain
    call away (the prompt's builder, now a tool the agent can call)."""
    from tobi508 import catalog
    from tobi508.models import Report
    from tobi508.runlog import RunRecorder

    url = f"{server.base}/4a/f01-click-only-text.html"
    out = await _call(
        "tobi_run_tt_tests", {"url": url, "tests": ["4.A", "4.C", "4.D", "4.E"]}
    )
    run = RunRecorder.open(settings.runs_dir, out["run_id"])
    report = Report.model_validate_json(run.report_path.read_text("utf-8"))
    async with Client(mcp) as client:
        res = await client.call_tool("tobi_explain", {"run_id": out["run_id"]})
        text = res.content[0].text
        one = (
            (
                await client.call_tool(
                    "tobi_explain", {"about": "4.A, 4.D", "run_id": out["run_id"]}
                )
            )
            .content[0]
            .text
        )
        general = (
            (await client.call_tool("tobi_explain", {"about": "keyboard trap"}))
            .content[0]
            .text
        )
    assert "NOT a certified" in text
    for f in report.findings:
        assert f.summary in text and f"Result for {f.test_id.value}" in text
        assert all(r in text for r in f.rows)
        assert all(u in text for u in catalog.understanding_urls(f.test_id.value))
    assert "Not final: 1 open question(s)" in text  # 4.A waits on its question
    assert "=== 4.A ===" in one and "=== 4.D ===" in one and "=== 4.C ===" not in one
    assert "4.C" in general and "NOT a certified" in general


def test_a_tall_picture_is_sent_in_readable_parts(tmp_path):
    """Development run 9: a full-page 4.F order picture shrunk to 768 px on
    its longer side was too small to read. A tall picture keeps a readable
    width and is cut into parts, the first MAX_TILES sent."""
    from PIL import Image

    from tobi508.inline import MAX_SIDE, MAX_TILES, TILE_HEIGHT, _encode

    tall = tmp_path / "tall.png"
    Image.new("RGB", (1280, 9000), "white").save(tall)
    parts, total = _encode(tall)
    assert len(parts) == MAX_TILES and total > MAX_TILES
    assert all(size[0] == MAX_SIDE and size[1] <= TILE_HEIGHT for _, _, size in parts)
    wide = tmp_path / "wide.png"
    Image.new("RGB", (1280, 900), "white").save(wide)
    [(_, _, size)], total = _encode(wide)
    assert total == 1 and max(size) == MAX_SIDE
