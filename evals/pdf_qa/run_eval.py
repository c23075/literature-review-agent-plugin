"""lit.ask evaluation (FR-RES-2, M1 exit criterion): page-cited answers from PDFs.

Builds a small library of synthetic papers whose facts sit on known pages, asks the
questions in questions.json through Cairnward (the running server when there is one,
so it uses your configured models), and scores each answer:
- cited: at least one source, and the expected file AND page among them;
- content: the expected keywords appear in the answer;
- honest: unanswerable questions get "I can't answer this from these sources";
- invented: citations to passages that weren't given, and quotations not found in the
  papers (must be zero; this is also the citation-existence check, FR-RES-5).

Usage (after `cairnward serve`, with the litreview-offline models pulled):
    uv run python evals/pdf_qa/run_eval.py [--env litreview-offline] [--keep]
Prints a table and a JSON summary; exits 0 when every check passes.
"""

from __future__ import annotations

import argparse
import json
import re
import subprocess
import sys
import tempfile
import time
from pathlib import Path
from typing import Any

HERE = Path(__file__).parent
sys.path.insert(0, str(HERE.parent.parent))
from tests.fakes.pdf import make_pdf  # noqa: E402  (the repo's tiny PDF writer)


def lines(page: str, width: int = 80) -> list[str]:
    out, cur = [], ""
    for word in page.split():
        if len(cur) + len(word) + 1 > width:
            out.append(cur)
            cur = word
        else:
            cur = f"{cur} {word}".strip()
    return [*out, cur] if cur else out


FILLER = (
    "This page continues the study's report. The surrounding text describes the general "
    "setting and does not add new findings. "
)


def build(folder: Path, spec: dict[str, Any]) -> None:
    """Each fact sits in the middle of a page padded with neutral text to well over two
    chunks (~350 tokens each), so some chunk holding the fact lies wholly on its page and
    page citations can be checked."""
    for name, paper in spec["papers"].items():
        pages = [lines(f"{FILLER * 14} {p} {FILLER * 14}") for p in paper["pages"]]
        (folder / name).write_bytes(make_pdf(pages, title=paper["title"]))


def cw(*args: str) -> subprocess.CompletedProcess[str]:
    return subprocess.run([sys.executable, "-m", "cairnward_research", *args], capture_output=True,
                          text=True, check=False)  # fmt: skip


def score(q: dict[str, Any], a: dict[str, Any]) -> dict[str, Any]:
    exp = q["expect"]
    res: dict[str, Any] = {
        "id": q["id"],
        # invented citations and quotations not found in the papers (FR-RES-5)
        "invented": len(a.get("invalid_citations", [])) + len(a.get("quote_problems", [])),
        "seconds": round(a.get("seconds", 0), 1),
        "cut_off": bool(a.get("cut_off")),  # the model reached its token limit
    }
    if exp.get("unanswerable"):
        res["honest"] = bool(a.get("cannot_answer"))
        res["pass"] = res["honest"] and not res["invented"]
        return res
    pages_ok = False
    for s in a.get("sources", []):
        nums = [int(n) for n in re.findall(r"\d+", str(s.get("pages", "")))]  # "p. 2", "pp. 2-3"
        if s.get("file") == exp["file"] and nums and nums[0] <= exp["page"] <= nums[-1]:
            pages_ok = True
    res["cited"] = pages_ok
    text = a.get("text", "").lower()
    res["content"] = all(  # a list is alternatives: the same fact in digits or words
        any(k.lower() in text for k in ([want] if isinstance(want, str) else want))
        for want in exp["keywords"]
    )
    res["pass"] = res["cited"] and res["content"] and not res["invented"]
    return res


class EvalError(Exception):
    pass


def brief(output: str, limit: int = 600) -> str:
    """What went wrong, from a command's output: Cairnward's own error lines and a
    traceback's final line, else the end of the output."""
    lines = [x.rstrip() for x in output.strip().splitlines() if x.strip()]
    keep = [x for x in lines if x.startswith("cairnward:")]
    if lines and not lines[-1].startswith(" ") and "Error" in lines[-1].split(":")[0]:
        keep.append(lines[-1])  # e.g. "RuntimeError: ..."
    tail = "\n".join(lines[-3:])
    return ("\n".join(keep) if keep else tail)[-limit:]


def run(env: str = "litreview-offline", engines: list[str] | None = None, *, keep: bool = False,
        emit: Any = print, only: list[str] | None = None,
        save_answers: Path | None = None) -> dict[str, Any]:  # fmt: skip
    """Build the library, ask every question with each engine, score; returns
    {"summaries": {engine: {...}}, "results": [...]}. Needs `cairnward serve`.
    With save_answers, also appends each full answer and its score to that file (JSON lines)."""
    engines = engines or ["lean"]
    spec = json.loads((HERE / "questions.json").read_text())
    name = f"eval-pdf-qa-{int(time.time())}"
    results: list[dict[str, Any]] = []
    summaries: dict[str, Any] = {}
    with tempfile.TemporaryDirectory(prefix="cw-pdfqa-") as tmp:
        folder = Path(tmp)
        build(folder, spec)
        try:
            for step in (["library", "create", name, str(folder), "--env", env],
                         ["library", "index", name]):  # fmt: skip
                r = cw(*step)
                if r.returncode != 0:
                    raise EvalError(f"`cairnward {' '.join(step[:2])}` failed: "
                                    f"{brief(r.stdout + r.stderr)}")  # fmt: skip
            questions = [q for q in spec["questions"] if not only or q["id"] in only]
            for engine in engines:
                mine = []
                failed = None
                for q in questions:
                    t0 = time.monotonic()
                    r = cw("library", "ask", name, q["question"], "--json", "--engine", engine)
                    took = round(time.monotonic() - t0, 1)
                    if r.returncode != 0:  # this engine stops; the others' results stay
                        failed = f"{q['id']}: {brief(r.stdout + r.stderr)}"
                        emit(json.dumps({"engine": engine, "failed": failed}))
                        break
                    answer = json.loads(r.stdout)
                    answer["seconds"] = answer.get("seconds") or took  # wall clock if not given
                    res = score(q, answer) | {"engine": engine}
                    mine.append(res)
                    emit(json.dumps(res))
                    if save_answers:
                        with save_answers.open("a", encoding="utf-8") as f:
                            f.write(json.dumps(res | {"answer": answer}) + "\n")
                    if res["invented"]:  # to the terminal only, not into reports
                        emit("    why: " + json.dumps({
                            "citations_without_a_passage": answer.get("invalid_citations"),
                            "quotations_not_found": [str(p)[:200] for p in
                                                     answer.get("quote_problems", [])],
                            "answer": str(answer.get("text", ""))[:400]}))  # fmt: skip
                results += mine
                summaries[engine] = {
                    "questions": len(mine), "passed": sum(r["pass"] for r in mine),
                    "invented_citations": sum(r["invented"] for r in mine),
                    "seconds_total": round(sum(r["seconds"] for r in mine), 1),
                    **({"failed": failed} if failed else {}),
                }  # fmt: skip
        finally:
            if not keep:
                cw("library", "remove", name)
    return {"summaries": summaries, "results": results}


def main() -> int:
    ap = argparse.ArgumentParser()
    ap.add_argument("--env", default="litreview-offline")
    ap.add_argument("--keep", action="store_true", help="keep the eval library afterwards")
    ap.add_argument("--engine", choices=["lean", "paperqa"], default="lean")
    ap.add_argument("--compare", action="store_true",
                    help="run both engines on the same questions (FR-RES-13)")  # fmt: skip
    ap.add_argument("--only", help="comma-separated question ids, e.g. q5,u2")
    ap.add_argument("--save-answers", type=Path, metavar="FILE",
                    help="append full answers and scores to FILE (JSON lines)")  # fmt: skip
    args = ap.parse_args()
    engines = ["lean", "paperqa"] if args.compare else [args.engine]
    only = [x.strip() for x in args.only.split(",")] if args.only else None
    try:
        out = run(args.env, engines, keep=args.keep, only=only, save_answers=args.save_answers)
    except EvalError as exc:
        print(exc)
        return 2
    for engine, summary in out["summaries"].items():
        print(json.dumps({"engine": engine, "summary": summary}))
    return 0 if all(s["passed"] == s["questions"] and "failed" not in s
                    for s in out["summaries"].values()) else 1  # fmt: skip


if __name__ == "__main__":
    raise SystemExit(main())
