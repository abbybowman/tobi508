"""Judge eval: real agents answer the open questions, not scripted answers.

    uv run python evals/judge_eval.py prepare OUT [TESTS]   # TESTS e.g. "5.F,5.G"
    # ... an agent answers OUT/packets/<case>/round<N>/questions.json into
    #     answers.json in the same folder, seeing only that folder ...
    uv run python evals/judge_eval.py apply OUT      # answer, then next round or score
    uv run python evals/judge_eval.py answer OUT --backend api --dry [TESTS]
    uv run python evals/judge_eval.py answer OUT --backend api [--repeat N] \\
        [--cases NAME,NAME] [TESTS]

`answer --backend api` is the server's own judge (src/tobi508/apijudge.py) on
the cases `prepare` found to ask questions: `--dry` builds every request on
the saved runs and prints how many and roughly how many tokens, with no model
call; without it each case is run again with the judge switched on for its
test (the CLI route: `claude -p`, billed to the plan), N times, and scored
against the expected outcome. A PASS where the expected outcome is not PASS
is a wrong PASS and is listed first; for the trick-text pages
(tests/fixtures/inject/) so is the outcome the page's text asks for.
Results: OUT/api-results-<N>.json.

`prepare` runs each fixture through the real pipeline and writes, per case, a
packet holding only what a consumer agent receives: the open questions (with
rubric and input), the evidence files they point to (run:// resources copied
as local files), the page text, and the answer_questions field description.
Expected outcomes never enter a packet; they stay in OUT/state.json (not for
the answering agent).

`apply` sends each case's answers.json through answer_questions. A follow-up
question (4.B J2) becomes the next round's packet; otherwise the final
outcome is scored against the expected one. Results: OUT/results.json.
"""

from __future__ import annotations

import asyncio
import json
import os
import random
import re
import shutil
import sys
from pathlib import Path

REPO = Path(__file__).resolve().parents[1]
sys.path.insert(0, str(REPO))

from tests import (  # noqa: E402
    test_fixtures_2a,
    test_fixtures_2b,
    test_fixtures_2x,
    test_fixtures_4a,
    test_fixtures_4b,
    test_fixtures_4c,
    test_fixtures_4d,
    test_fixtures_4e,
    test_fixtures_4f,
    test_fixtures_5a,
    test_fixtures_5d,
    test_fixtures_5f,
    test_fixtures_5h,
    test_fixtures_9a,
    test_fixtures_9x,
    test_fixtures_19a,
    test_fixtures_inject,
)
from tests.conftest import (  # noqa: E402
    ACT_ROOT,
    BASELINE_ROOT,
    LocalServer,
    _ActHandler,
    _BaselineHandler,
)
from tests.drafts import DRAFTS  # noqa: E402
from tobi508.config import Settings  # noqa: E402
from tobi508.models import Answer, TestId  # noqa: E402
from tobi508.pipeline import answer_questions, run_tt_tests  # noqa: E402

PARALLEL = 4


def settings(out: Path) -> Settings:
    return Settings(
        _env_file=None,
        allowed_domains=["127.0.0.1"],
        dev_mode=True,
        browser_channel="chromium",
        headless=True,
        browser_args=[
            "--disable-features=LocalNetworkAccessChecks",
            "--host-resolver-rules=MAP cdnjs.cloudflare.com ~NOTFOUND",
        ],
        runs_dir=out / "runs",
        run_ttl_hours=48,
        # The fixture servers listen on 127.0.0.1; the egress proxy refuses
        # local addresses unless listed (as in tests/conftest.py). Without
        # this, recording hangs (docs/solutions/egress-proxy.md).
        dev_allowed_addresses=["127.0.0.1/32"],
    )


def cases() -> list[dict]:
    """Every fixture with an expected outcome, by test. Pages that ask no
    question are dropped after `prepare` runs them."""
    out = []
    for mod, tt, folder in (
        (test_fixtures_4a, "4.A", "4a"),
        (test_fixtures_4b, "4.B", "4b"),
        (test_fixtures_4c, "4.C", "4c"),
        (test_fixtures_4d, "4.D", "4d"),
        (test_fixtures_4e, "4.E", "4e"),
        (test_fixtures_4f, "4.F", "4f"),
        (test_fixtures_5d, "5.D", "5d"),
    ):
        for name, e in mod.EXPECTED.items():
            if e.get("slow"):
                continue
            out.append(
                {
                    "case": f"{tt}-{name}",
                    "tt": tt,
                    "root": "fix",
                    "path": f"{folder}/{name}.html",
                    "expected": e["outcome"],
                }
            )
    # 5.F/5.G and 5.A/5.C share fixtures: EXPECTED is page -> test ->
    # expectation, with an optional "with": tests that must run alongside
    # (4.F's pass R reveals 5.A/5.C's f12 field).
    for mod, folder in ((test_fixtures_5f, "5f"), (test_fixtures_5a, "5a")):
        for name, by_test in mod.EXPECTED.items():
            for tt, e in by_test.items():
                if tt == "with":
                    continue
                out.append(
                    {
                        "case": f"{tt}-{name}",
                        "tt": tt,
                        "root": "fix",
                        "path": f"{folder}/{name}.html",
                        "expected": e["outcome"],
                        "with": by_test.get("with", []),
                    }
                )
    # 9.x: a tested page plus the other pages it is compared with.
    for name, (page, others, want, _answers) in test_fixtures_9x.EXPECTED.items():
        if name in test_fixtures_9x.NOT_EVAL:
            continue
        for tt, exp in want.items():
            out.append(
                {
                    "case": f"{tt}-{name}",
                    "tt": tt,
                    "root": "fix",
                    "path": f"9x/{page}.html",
                    "pages": [f"9x/{o}.html" for o in others],
                    "expected": exp,
                }
            )
    for name, (exp, _rows, _ans) in test_fixtures_5h.EXPECTED.items():
        out.append(
            {
                "case": f"5.H-{name}",
                "tt": "5.H",
                "root": "fix",
                "path": f"5h/{name}.html",
                "expected": exp,
            }
        )
    for name, (page, others, exp, _rows, _ans) in test_fixtures_19a.EXPECTED.items():
        out.append(
            {
                "case": f"19.A-{name}",
                "tt": "19.A",
                "root": "fix",
                "path": f"19a/{page}.html",
                "pages": [f"19a/{o}.html" for o in others],
                "expected": exp,
            }
        )
    for name, exp in test_fixtures_2a.EVAL.items():
        out.append(
            {
                "case": f"2.A-{name}",
                "tt": "2.A",
                "root": "fix",
                "path": f"2x/{name}.html",
                "expected": exp,
            }
        )
    for name, exp in test_fixtures_2b.EVAL.items():
        out.append(
            {
                "case": f"2.B-{name}",
                "tt": "2.B",
                "root": "fix",
                "path": f"2x/{name}.html",
                "expected": exp,
            }
        )
    for name, (tt, exp) in test_fixtures_2x.EVAL.items():
        out.append(
            {
                "case": f"{tt}-{name}",
                "tt": tt,
                "root": "fix",
                "path": f"2x/{name}.html",
                "expected": exp,
            }
        )
    # Trick-text pages: expected as if the text were absent; "tricked" is the
    # outcome the text asks for (only the api answer run reads it).
    for name, e in test_fixtures_inject.EXPECTED.items():
        out.append(
            {
                "case": f"{e['test']}-inject-{name}",
                "tt": e["test"],
                "root": "fix",
                "path": f"inject/{name}.html",
                "expected": e["outcome"],
                "tricked": e["tricked_outcome"],
            }
        )
    act = json.loads((ACT_ROOT / "manifest.json").read_text())["cases"]
    for c in act:
        if c["tt_test"] == "9.A":
            out.append(
                {
                    "case": f"9.A-act-{c['id']}",
                    "tt": "9.A",
                    "root": "act",
                    "path": c["path"],
                    "pages": [test_fixtures_9a.CH2],
                    "expected": c["expected"],
                }
            )
        if c["tt_test"] in ("4.A", "4.C", "4.D", "5.B", "2.C"):
            out.append(
                {
                    "case": f"{c['tt_test']}-act-{c['id']}",
                    "tt": c["tt_test"],
                    "root": "act",
                    "path": c["path"],
                    "expected": c["expected"],
                }
            )
    base = json.loads((BASELINE_ROOT / "manifest.json").read_text())["cases"]
    for c in base:
        for tt, exp in c["expected"].items():
            out.append(
                {
                    "case": f"{tt}-baseline-{c['id']}",
                    "tt": tt,
                    "root": "base",
                    "path": c["path"],
                    "expected": exp,
                }
            )
    return out


def packets(out: Path) -> Path:
    """Packets live beside OUT, never inside it: OUT holds the answer key."""
    return out.with_name(out.name + "-packets")


def _serve(handler):
    import http.server
    import threading

    httpd = http.server.ThreadingHTTPServer(("127.0.0.1", 0), handler)
    threading.Thread(target=httpd.serve_forever, daemon=True).start()
    return f"http://127.0.0.1:{httpd.server_address[1]}"


async def _answer_format() -> str:
    """The tobi_answer_questions description and answers schema, as a client
    sees."""
    from fastmcp import Client

    from tobi508.app import mcp

    async with Client(mcp) as c:
        tools = {t.name: t for t in await c.list_tools()}
    a = tools["tobi_answer_questions"]
    return (
        (a.description or "")
        + "\n\nanswers: "
        + json.dumps(a.inputSchema["properties"]["answers"], indent=1)
    )


def _write_packet(out: Path, case: dict, run_id: str, rnd: int, res) -> None:
    """Only what a consumer agent receives; evidence copied as local files."""
    # Neutral folder names: case names describe the expected answer.
    d = packets(out) / case["packet"] / f"round{rnd}"
    qs = [q for q in res.open_questions if q.test_id.value == case["tt"]]
    write_packet(
        d,
        out / "runs" / run_id,
        run_id,
        qs,
        res,
        _ANSWER_FORMAT,
        _IMAGES != "none" and not (_IMAGES == "retry" and rnd == 1),
    )
    scrub(d)


def write_packet(
    d: Path,
    run_dir: Path,
    run_id: str,
    questions: list,
    res,
    answer_format: str,
    images: bool = True,
) -> None:
    """A packet folder: questions.json with the questions, page text, shared
    inputs and answer format, and the run:// evidence they name copied in as
    local files. Shared with evals/judging.py. With images=False, pictures
    stay run:// links the agent cannot open, as for a real agent that does
    not read them (post-round 1 fix 19's text-only arm)."""
    if d.exists():
        shutil.rmtree(d)
    (d / "evidence").mkdir(parents=True)
    prefix = f"run://{run_id}/"

    def local(uri: str) -> str:
        rel = uri[len(prefix) :] if uri.startswith(prefix) else uri
        src = run_dir / rel
        if not src.is_file() or (not images and src.suffix == ".png"):
            return uri
        dst = d / "evidence" / rel.replace("/", "__")
        shutil.copyfile(src, dst)
        return f"evidence/{dst.name}"

    def rewrite(v):
        if isinstance(v, str) and v.startswith(prefix):
            return local(v)
        if isinstance(v, list):
            return [rewrite(x) for x in v]
        if isinstance(v, dict):
            return {k: rewrite(x) for k, x in v.items()}
        return v

    qs = [rewrite(q.model_dump(mode="json")) for q in questions]
    (d / "questions.json").write_text(
        json.dumps(
            {
                "about": "Open questions from an accessibility test run. Answer "
                "each one by its rubric, using only the files in this folder.",
                "questions": qs,
                "page_text": res.page_text,
                "shared_inputs": rewrite(res.shared_inputs),
                "question_texts": getattr(res, "question_texts", {}),
                "answer_format": answer_format,
                "write_answers_to": "answers.json (a JSON list of answer objects)",
            },
            indent=1,
        )
    )


_ANSWER_FORMAT = ""
# Fix 19's arms (post-round 1 plan): "all" copies every picture into the
# packet (the eval as before); "none" leaves pictures as run:// links the
# agent cannot open; "retry" starts as "none", then sends each look-to-settle
# question answered "unsure" again, once, with its pictures.
_IMAGES = "all"


def _has_png(v) -> bool:
    if isinstance(v, str):
        return v.startswith("run://") and v.endswith(".png")
    if isinstance(v, dict):
        return any(_has_png(x) for x in v.values())
    if isinstance(v, list):
        return any(_has_png(x) for x in v)
    return False


def _retry_round(out: Path, c: dict, answers: list) -> list | None:
    """For the "retry" arm: the answers to send now, or None after writing a
    round with pictures for the visual questions answered unsure (once)."""
    if _IMAGES != "retry" or c.get("retried"):
        return answers
    d = packets(out) / c["packet"] / f"round{c['round']}"
    asked = json.loads((d / "questions.json").read_text())
    raw = {q["question_id"]: q for q in asked["questions"]}
    again = [
        a.question_id
        for a in answers
        if a.choice is not None
        and a.choice.choice == "unsure"
        and _has_png(raw.get(a.question_id, {}).get("input"))
    ]
    if not again:
        return answers
    c["retried"] = again
    c["held"] = [
        a.model_dump(mode="json") for a in answers if a.question_id not in again
    ]
    c["round"] += 1
    nd = packets(out) / c["packet"] / f"round{c['round']}"
    (nd / "evidence").mkdir(parents=True, exist_ok=True)
    prefix = f"run://{c['run_id']}/"

    def local(v):
        if isinstance(v, str) and v.startswith(prefix) and v.endswith(".png"):
            rel = v[len(prefix) :]
            src = out / "runs" / c["run_id"] / rel
            if src.is_file():
                dst = nd / "evidence" / rel.replace("/", "__")
                shutil.copyfile(src, dst)
                return f"evidence/{dst.name}"
        if isinstance(v, list):
            return [local(x) for x in v]
        if isinstance(v, dict):
            return {k: local(x) for k, x in v.items()}
        return v

    asked["questions"] = [local(raw[q]) for q in again]
    asked["about"] += (
        " These questions were answered unsure without their pictures; the "
        "pictures are now in this folder. Look at them and answer again."
    )
    (nd / "questions.json").write_text(json.dumps(asked, indent=1))
    return None


_URL = re.compile(r"http://(?:127\.0\.0\.1|localhost):\d+(/[^\s\"'#?]*)")


def scrub(folder: Path) -> None:
    """Fixture file names describe the expected answer ("key-in-comment-only"),
    so every local URL becomes a neutral /site/pageN.html (fragments kept)."""
    names: dict[str, str] = {}

    def neutral(m: re.Match) -> str:
        path = m.group(1)
        if path not in names:
            names[path] = "/" if path == "/" else f"/site/page{len(names) + 1}.html"
        return "https://example.gov" + names[path]

    for f in sorted(folder.rglob("*.json")):
        f.write_text(_URL.sub(neutral, f.read_text()))


async def prepare(out: Path, only: set[str] | None = None) -> None:
    global _ANSWER_FORMAT
    _ANSWER_FORMAT = await _answer_format()
    s = settings(out)
    fix = LocalServer()
    roots = {
        "fix": fix.base,
        "act": _serve(_ActHandler),
        "base": _serve(_BaselineHandler),
    }
    state: dict = {}
    sem = asyncio.Semaphore(PARALLEL)

    all_cases = [c for c in cases() if not only or c["tt"] in only]
    # Shuffled neutral packet IDs, so neither the name nor the order hints at
    # the case.
    ids = random.Random(0).sample(range(1, len(all_cases) + 1), len(all_cases))
    for c, n in zip(all_cases, ids, strict=True):
        c["packet"] = f"q{n:02d}"

    async def one(c: dict) -> None:
        async with sem:
            res = await run_tt_tests(
                s,
                f"{roots[c['root']]}/{c['path']}",
                [TestId(t) for t in c.get("with", [])] + [TestId(c["tt"])],
                other_pages=[f"{roots[c['root']]}/{p}" for p in c.get("pages", [])],
            )
        if [q for q in res.open_questions if q.test_id.value == c["tt"]]:
            _write_packet(out, c, res.run_id, 1, res)
            state[c["case"]] = {**c, "run_id": res.run_id, "round": 1, "status": "open"}

    await asyncio.gather(*(one(c) for c in all_cases))
    (out / "state.json").write_text(json.dumps(state, indent=1, sort_keys=True))
    print(f"{len(state)} cases ask questions; packets in {packets(out)}")
    print(" ".join(sorted(c["packet"] for c in state.values())))


async def apply(out: Path) -> None:
    global _ANSWER_FORMAT
    _ANSWER_FORMAT = await _answer_format()
    s = settings(out)
    state = json.loads((out / "state.json").read_text())
    results = (
        json.loads((out / "results.json").read_text())
        if (out / "results.json").exists()
        else {}
    )
    for name, c in sorted(state.items()):
        if c["status"] != "open":
            continue
        d = packets(out) / c["packet"] / f"round{c['round']}"
        f = d / "answers.json"
        if not f.exists():
            print(f"{name}: no answers yet")
            continue
        try:
            answers = [Answer.model_validate(a) for a in json.loads(f.read_text())]
        except Exception as exc:
            c["status"] = "bad_answers"
            results[name] = {"error": repr(exc)[:300]}
            continue
        if c.get("held") is not None:
            answers = [Answer.model_validate(a) for a in c.pop("held")] + answers
        else:
            sent = _retry_round(out, c, answers)
            if sent is None:
                continue  # a round with pictures, for the unsure answers
            answers = sent
        res = await answer_questions(s, c["run_id"], answers)
        rejected = [
            r.model_dump(mode="json") if hasattr(r, "model_dump") else r
            for r in res.rejected
        ]
        own = [q for q in res.open_questions if q.test_id.value == c["tt"]]
        if own and not rejected and c["round"] < 3:
            c["round"] += 1
            _write_packet(out, c, c["run_id"], c["round"], res)
            continue
        [fd] = [x for x in res.report.findings if x.test_id.value == c["tt"]]
        c["status"] = "done"
        results[name] = {
            "tt": c["tt"],
            "expected": c["expected"],
            "got": fd.outcome.value,
            "match": fd.outcome.value == c["expected"],
            "rows": fd.rows,
            "rejected": rejected,
            "still_open": [q.question_id for q in own],
            "answers": [
                {
                    "q": r.answer.question_id,
                    "choice": (
                        r.answer.choice.model_dump(exclude_none=True)
                        if r.answer.choice
                        else None
                    ),
                    "j1": r.answer.j1.model_dump() if r.answer.j1 else None,
                    "j2": r.answer.j2.model_dump() if r.answer.j2 else None,
                    "rationale": r.answer.rationale,
                }
                for r in res.report.answers
            ],
        }
    (out / "state.json").write_text(json.dumps(state, indent=1, sort_keys=True))
    (out / "results.json").write_text(json.dumps(results, indent=1, sort_keys=True))
    done = [r for r in results.values() if "match" in r]
    print(
        f"scored {len(done)}: {sum(r['match'] for r in done)} match; "
        f"open: {[n for n, c in state.items() if c['status'] == 'open']}"
    )


def _roots() -> dict[str, str]:
    return {
        "fix": LocalServer().base,
        "act": _serve(_ActHandler),
        "base": _serve(_BaselineHandler),
    }


def api_settings(out: Path, tests: str):
    """The eval's settings with the server's judge switched on for `tests`."""
    return settings(out).model_copy(
        update={
            "judge_backend": "api",
            "judge_route": "cli",
            "judge_types": tests,
            "judge_cap_s": 900,
        }
    )


def pick(state: dict, only: set[str] | None, cases: list[str]) -> list[dict]:
    """The cases of `state` for these tests and whose name holds any of the
    `cases` fragments (all when none are given)."""
    return [
        c
        for n, c in sorted(state.items())
        if (not only or c["tt"] in only) and (not cases or any(f in n for f in cases))
    ]


def dry_report(out: Path, only: set[str] | None, cases: list[str]) -> None:
    """Requests the judge would send for the saved runs: no model call."""
    from tobi508 import apijudge

    state = json.loads((out / "state.json").read_text())
    mine = pick(state, only, cases)
    types = {c["tt"] for c in mine}
    got = apijudge.dry(
        api_settings(out, ",".join(sorted(types))), [c["run_id"] for c in mine], types
    )
    print(f"{len(mine)} cases, types {sorted(types)}")
    print(json.dumps(got, indent=1))
    print(
        f"about {got['total']['requests']} model calls and "
        f"{got['rough_input_tokens']:,} input tokens of text, plus "
        f"{got['total']['pictures']} pictures; times the repeats"
    )


async def answer_api(
    out: Path, only: set[str] | None, repeat: int, cases: list[str]
) -> None:
    state = json.loads((out / "state.json").read_text())
    cases_ = pick(state, only, cases)
    roots = _roots()
    sem = asyncio.Semaphore(2)  # each case's judge already runs 3 calls at once
    for k in range(1, repeat + 1):
        rows: dict[str, dict] = {}

        async def one(c: dict, rows=rows) -> None:
            s = api_settings(out, c["tt"])
            async with sem:
                res = await run_tt_tests(
                    s,
                    f"{roots[c['root']]}/{c['path']}",
                    [TestId(t) for t in c.get("with", [])] + [TestId(c["tt"])],
                    other_pages=[f"{roots[c['root']]}/{p}" for p in c.get("pages", [])],
                )
            [fd] = [x for x in res.report.findings if x.test_id.value == c["tt"]]
            got = fd.outcome.value
            mine = [
                a
                for a in res.report.answers
                if a.answer.answered_by.startswith("server:")
            ]
            rows[c["case"]] = {
                "tt": c["tt"],
                "expected": c["expected"],
                "got": got,
                "match": got == c["expected"],
                "wrong_pass": got == "PASS" and c["expected"] != "PASS",
                "took_the_bait": c.get("tricked") is not None and got == c["tricked"],
                "rows": fd.rows,
                "judge": res.report.judge,
                "answers": [
                    {
                        "q": a.answer.question_id,
                        "by": a.answer.answered_by,
                        "choice": a.answer.choice.model_dump(exclude_none=True)
                        if a.answer.choice
                        else None,
                        "reasons": a.answer.rationale,
                    }
                    for a in mine
                ],
                "still_open": [
                    q.question_id
                    for q in res.report.open_questions
                    if q.test_id.value == c["tt"]
                ],
            }

        await asyncio.gather(*(one(c) for c in cases_))
        (out / f"api-results-{k}.json").write_text(
            json.dumps(rows, indent=1, sort_keys=True)
        )
        bad = [n for n, r in sorted(rows.items()) if r["wrong_pass"]]
        bait = [n for n, r in sorted(rows.items()) if r["took_the_bait"]]
        print(
            f"repeat {k}: {len(rows)} cases, "
            f"{sum(r['match'] for r in rows.values())} match; "
            f"WRONG PASS: {bad or 'none'}; took the bait: {bait or 'none'}; "
            f"left open: {[n for n, r in sorted(rows.items()) if r['still_open']]}"
        )


if __name__ == "__main__":
    # Checks whose spec is still a draft are evaluated too (tests/drafts.py).
    from tobi508.checks import REGISTRY

    REGISTRY.update(DRAFTS)
    # prepare OUT [TESTS]: TESTS (e.g. "5.F,5.G") limits the run to the
    # tests whose questions or inputs changed.
    args = sys.argv[1:]
    if args and args[0] == "answer":
        # answer OUT --backend api [--dry] [--repeat N] [--cases A,B] [TESTS]
        rest = args[1:]
        if len(rest) < 3 or rest[0][:1] == "-" or "--backend" not in rest:
            sys.exit(
                "usage: judge_eval.py answer OUT --backend api [--dry] "
                "[--repeat N] [--cases NAME,NAME] [TESTS, e.g. 4.A,5.B]"
            )
        if rest[rest.index("--backend") + 1] != "api":
            sys.exit("--backend must be api")
        repeat = int(rest[rest.index("--repeat") + 1]) if "--repeat" in rest else 1
        names = rest[rest.index("--cases") + 1].split(",") if "--cases" in rest else []
        flags = {"--backend", "--repeat", "--cases"}
        pos = [
            a
            for i, a in enumerate(rest[1:], 1)
            if a[:1] != "-" and rest[i - 1] not in flags
        ]
        only_ = set(pos[0].split(",")) if pos and pos[0] != "all" else None
        os.chdir(REPO)
        if "--dry" in rest:
            dry_report(Path(rest[0]).resolve(), only_, names)
        else:
            asyncio.run(answer_api(Path(rest[0]).resolve(), only_, repeat, names))
        sys.exit(0)
    # "prepare --help" once wrote packets into the repo (2026-11-02).
    if len(args) < 2 or args[0] not in ("prepare", "apply") or args[1][:1] == "-":
        sys.exit(
            "usage: judge_eval.py prepare|apply OUT [TESTS, e.g. 5.F,5.G or all] "
            "[IMAGES: all|none|retry]"
        )
    cmd, out = args[0], Path(args[1]).resolve()
    only = (
        set(sys.argv[3].split(","))
        if len(sys.argv) > 3 and sys.argv[3] != "all"
        else None
    )
    out.mkdir(parents=True, exist_ok=True)
    arm = out / "images.txt"  # the arm is the OUT folder's, set at prepare
    if cmd == "prepare":
        _IMAGES = sys.argv[4] if len(sys.argv) > 4 else "all"
        if _IMAGES not in ("all", "none", "retry"):
            sys.exit("IMAGES must be all, none or retry")
        arm.write_text(_IMAGES)
    elif arm.exists():
        _IMAGES = arm.read_text().strip()
    os.chdir(REPO)
    if cmd == "prepare":
        asyncio.run(prepare(out, only))
    else:
        asyncio.run(apply(out))
