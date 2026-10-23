"""Anti-text-inversion gate: Opus 5.5 reads each item's prompt (no activation) three times; an
item whose three answers all fail the family's own scorer joins the ``anti_text_inversion``
subset. See ``evals/baselines/README.md`` and ``plans/0014-anti-text-inversion.md``."""

import asyncio
import datetime as dt
import json
from collections.abc import Iterable
from pathlib import Path
from typing import Any

from wsbench.registry import REPO_ROOT

FROZEN = REPO_ROOT / "evals" / "baselines" / "anti_text_inversion.json"
OUT = REPO_ROOT / "outputs" / "baselines" / "text_inversion"
ANSWERER = "claude-opus-5-5"
DRAWS = 3
MAX_TOKENS = 16000
ATTEMPTS = 12  # thinking shares the budget; a 200 with no text block is a failure
# The source repo's `verbalizer.PROMPT_ONLY_SUMMARY_TEMPLATE`, byte-identical to the stock-Qwen
# prompt-only floor so the two floors read the same question.
TEMPLATE = (
    "Below is a prompt that was given to a language model, cut off at a specific token. The "
    "token in question is the final token of the text below: {token!r}.\n\n"
    "<prompt>\n{prefix}\n</prompt>\n\n"
    "What would a language model be thinking about on this token? Please write me a summary "
    "for this token."
)
NOT_GATED: dict[str, str] = {
    "hallucination": "an invention rate over free generation, no item answer to invert",
    "jlens_concept_pr": "precision against the J-lens top-10, not a bar a lens clears",
    "agentic_misalignment": "a design score netted against foils, no item pass bit",
    "multi_concept_directed_modulation": "the prompt dictates the concepts; prompt-only is 1.0",
}
# buggy_code has no pass bit: a draw "gets it" at the rubric's 6-7 band or above (the right
# consequence or the right mechanism; on a clean twin, no specific false bug claimed).
BUGGY_PASS_SCORE = 6
# A family where more than this share of items has a policy-refused draw is not gated: its
# answered items are a refusal-selected sample of the bank, not the bank.
MAX_REFUSED_SHARE = 0.2
READ_LAYER = 44


def gated_families() -> list[str]:
    from wsbench import registry

    registry.load_all()
    # superseded families (multihop_mt) are not re-gated; gate() carries their frozen entry over
    return registry.drop_superseded(sorted(f for f in registry.FAMILIES if f not in NOT_GATED))


def read_layer(family: str, grid: Iterable[int]) -> int:
    """The one layer a draw's readouts are written at: 44, else the family's grid middle
    (``NATIVE_LAYERS`` families are written at their own per-item layers instead)."""
    g = sorted(grid)
    return READ_LAYER if READ_LAYER in g else g[len(g) // 2]


# ---------------------------------------------------------------- stage 1: prompts


def build(out: Path = OUT, families: Iterable[str] | None = None, limit: int = 0) -> Path:
    """One row per item: the render decoded through its last read position, the read positions
    (as the plan reports them) and the layer its readouts go to. Tokenizer only, no GPU."""
    from transformers import AutoTokenizer

    from wsbench import readplan
    from wsbench.produce.producer import _positions
    from wsbench.produce.render import render

    tok = AutoTokenizer.from_pretrained("Qwen/Qwen3.6-27B")
    out.mkdir(parents=True, exist_ok=True)
    path = out / "prompts.jsonl"
    n_bad = 0
    with path.open("w", encoding="utf-8") as fh:
        for fam in families or gated_families():
            for spec in readplan.plan(fam)[: limit or None]:
                r = render(spec, tok)
                pos = _positions(spec.positions, r.tokens)
                if not pos:
                    n_bad += 1
                    print(f"  {fam}/{spec.id}: positions rule selected nothing, skipped")
                    continue
                last = max(p % len(r) for p in pos)
                kw = {"skip_special_tokens": False, "clean_up_tokenization_spaces": False}
                row = {
                    "family": fam,
                    "id": spec.id,
                    "prefix": tok.decode(r.ids[: last + 1], **kw),
                    "token": tok.decode([r.ids[last]], **kw),
                    "positions": pos,
                    "tokens": [r.decoded[p % len(r)] for p in pos],
                    "layers": list(spec.layers),
                    "layer": read_layer(fam, spec.layers),
                    "n_tokens": len(r),
                    "last": last,
                }
                fh.write(json.dumps(row, ensure_ascii=False) + "\n")
    print(f"wrote {path} ({n_bad} items with no read position)")
    return path


def load_jsonl(path: Path) -> list[dict[str, Any]]:
    return [json.loads(x) for x in path.read_text(encoding="utf-8").splitlines() if x.strip()]


# ---------------------------------------------------------------- stage 2: ask Opus


def _text(msg: Any) -> str:
    return "".join(b.text for b in msg.content if getattr(b, "type", "") == "text").strip()


async def _ask_one(
    client: Any, sem: asyncio.Semaphore, row: dict[str, Any], draw: int, answerer: str = ANSWERER
) -> dict:
    content = TEMPLATE.format(prefix=row["prefix"], token=row["token"])
    err = ""
    async with sem:
        for attempt in range(ATTEMPTS):
            try:
                msg = await client.messages.create(
                    model=answerer,
                    max_tokens=MAX_TOKENS,
                    messages=[{"role": "user", "content": content}],
                )
            except Exception as exc:  # retried, then recorded; never scores
                err = f"{type(exc).__name__}: {exc}"[:300]
                await asyncio.sleep(min(60, 2 * 2**attempt))
                continue
            text = _text(msg)
            if msg.stop_reason == "refusal":
                # An API policy block (e.g. stop_details.category "reasoning_extraction"), not
                # a model answer: recorded once and never retried, so the draw is undecided and
                # the item cannot enter the subset. Resampling until it passes would route
                # around the policy.
                details = getattr(msg, "stop_details", None)
                return {
                    "family": row["family"],
                    "id": row["id"],
                    "draw": draw,
                    "answerer": answerer,
                    "answer": "",
                    "refused": True,
                    "refusal_category": getattr(details, "category", None),
                    "error": "refusal",
                }
            if not text:
                err = f"no text block (stop_reason={msg.stop_reason})"
                continue
            return {
                "family": row["family"],
                "id": row["id"],
                "draw": draw,
                "answerer": answerer,
                "answer": text,
                "stop_reason": msg.stop_reason,
                "out_tokens": msg.usage.output_tokens,
                "in_tokens": msg.usage.input_tokens,
                "error": "",
            }
    return {
        "family": row["family"],
        "id": row["id"],
        "draw": draw,
        "answer": "",
        "error": err,
    }


async def _ask(
    out: Path, draws: int, concurrency: int, families: set[str] | None, answerer: str
) -> int:
    from anthropic import AsyncAnthropic

    prompts = load_jsonl(out / "prompts.jsonl")
    prompts = [r for r in prompts if not families or r["family"] in families]
    ans_dir = out / "answers"
    ans_dir.mkdir(parents=True, exist_ok=True)
    client = AsyncAnthropic(max_retries=4, timeout=900)
    # Preflight on a neutral prompt outside the bank, so a resume never re-sends a bank prompt
    # (a refused one stays refused) and a policy refusal cannot masquerade as a dead credential.
    try:
        msg = await client.messages.create(
            model=answerer, max_tokens=64, messages=[{"role": "user", "content": "Say OK."}]
        )
    except Exception as exc:
        raise SystemExit(f"preflight failed, aborting before the batch: {exc}") from exc
    print(f"preflight OK: {_text(msg)[:40]!r}", flush=True)
    sem = asyncio.Semaphore(concurrency)
    n_fail = 0
    for d in range(draws):
        path = ans_dir / f"draw{d}.jsonl"
        rows = load_jsonl(path) if path.exists() else []
        done = {(r["family"], r["id"]) for r in rows if not r["error"] or is_refusal(r)}
        todo = [r for r in prompts if (r["family"], r["id"]) not in done]
        print(f"draw {d}: {len(todo)} to ask ({len(done)} cached)", flush=True)
        tasks = [asyncio.create_task(_ask_one(client, sem, r, d, answerer)) for r in todo]
        with path.open("a", encoding="utf-8") as fh:
            for i, fut in enumerate(asyncio.as_completed(tasks), 1):
                res = await fut
                n_fail += bool(res["error"])
                fh.write(json.dumps(res, ensure_ascii=False) + "\n")
                fh.flush()
                if i % 500 == 0:
                    print(f"  draw {d}: {i}/{len(todo)} ({n_fail} failed so far)", flush=True)
    return n_fail


def ask(
    out: Path = OUT,
    draws: int = DRAWS,
    concurrency: int = 64,
    families: Iterable[str] | None = None,
    answerer: str = ANSWERER,
) -> int:
    """Three independent answers per item from ``answerer`` (default Opus 5.5), appended to
    ``answers/draw{d}.jsonl``; use a separate ``out`` per answerer.
    resumable (an item with an error-free answer is not re-asked). Auth: the Anthropic SDK's
    own discovery (run with ``ANTHROPIC_API_KEY`` unset to use the ``ant`` profile)."""
    fams = set(families) if families else None
    return asyncio.run(_ask(out, draws, concurrency, fams, answerer))


def is_refusal(r: dict[str, Any]) -> bool:
    """A policy refusal: final, never re-asked (rows from before the ``refused`` field carry it
    only in the error text)."""
    return (
        bool(r.get("refused"))
        or r.get("stop_reason") == "refusal"
        or "stop_reason=refusal" in r.get("error", "")
    )


def usable(a: dict[str, Any] | None) -> bool:
    """An answer that may be judged: present, error-free, non-empty and not a policy refusal (a
    refusal can arrive with partial text and no error; it is still not an answer)."""
    return a is not None and not a["error"] and bool(a["answer"]) and not is_refusal(a)


def latest_answers(path: Path) -> dict[tuple[str, str], dict[str, Any]]:
    """Last error-free answer per (family, id), else the last attempt."""
    best: dict[tuple[str, str], dict[str, Any]] = {}
    for r in load_jsonl(path):
        k = (r["family"], r["id"])
        if k not in best or not r["error"] or best[k]["error"]:
            best[k] = r
    return best


# ---------------------------------------------------------------- stage 3: readouts


# Which read positions a draw's answer is written at. The same text in many cells is judged
# once per cell at the Anthropic route's T=1, i.e. pass@N on one answer, so by default only the
# item's LAST read position gets it (one cell per item = one guess per draw). Exceptions:
# arithmetic's judge reads only its pre-registered cell, so every position costs nothing; brew's
# pass rule counts emission cells against off-trajectory colours, so it needs its read cells.
ALL_POSITIONS = {"arithmetic_intermediates", "brew_intermediates"}
# Families judged at their own per-item layers (no `layers=` passed): the frozen-cell families.
NATIVE_LAYERS = {"arithmetic_intermediates", "buggy_code"}


def write_readouts(out: Path = OUT, draws: int = DRAWS) -> dict[str, list[int]]:
    """Each draw's answer as a prose readout (with the producer's own read-site ``token``) at
    the item's write positions (see ``ALL_POSITIONS``) and layer(s). Failed answers get no row;
    the gate counts that draw as undecided whatever the judge makes of the missing cell."""
    prompts = load_jsonl(out / "prompts.jsonl")
    layers: dict[str, set[int]] = {}
    for d in range(draws):
        ans = latest_answers(out / "answers" / f"draw{d}.jsonl")
        root = out / "readouts" / f"draw{d}"
        root.mkdir(parents=True, exist_ok=True)
        handles: dict[str, Any] = {}
        try:
            for p in prompts:
                fam = p["family"]
                if fam not in handles:
                    handles[fam] = (root / f"{fam}.jsonl").open("w", encoding="utf-8")
                a = ans.get((fam, p["id"]))
                if not usable(a):
                    continue
                cells = list(zip(p["positions"], p["tokens"], strict=True))
                if fam not in ALL_POSITIONS:
                    cells = [max(cells, key=lambda c: c[0] % p["n_tokens"])]
                lays = p["layers"] if fam in NATIVE_LAYERS else [p["layer"]]
                layers.setdefault(fam, set()).update(lays)
                for layer in lays:
                    for pos, token in cells:
                        row = {
                            "id": p["id"],
                            "layer": layer,
                            "pos": pos,
                            "token": token,
                            "samples": [a["answer"]],
                        }
                        handles[fam].write(json.dumps(row, ensure_ascii=False) + "\n")
        finally:
            for h in handles.values():
                h.close()
    return {f: sorted(v) for f, v in layers.items()}


# ---------------------------------------------------------------- stage 4: gate


def draw_verdicts(results_path: Path) -> dict[str, bool | None]:
    """Per item: pass / fail / undecided for one judged draw. Rows are grouped by item (``id``,
    or ``name`` / ``item``); an item passes if any of its rows passes, is undecided if none
    passes and one is undecided. buggy_code rows pass at ``score >= BUGGY_PASS_SCORE``. For a
    pass-rate family the decided rate must equal the family's own value (adapter drift guard)."""
    d = json.loads(results_path.read_text(encoding="utf-8"))
    fam = d["family"]
    by_item: dict[str, list[bool | None]] = {}
    for r in d.get("rows", []):
        raw = r.get("id", r.get("name", r.get("item")))
        if raw is None:
            raise ValueError(f"{fam}: a row has no id / name / item")
        iid = str(raw)
        if fam == "buggy_code":
            s = r.get("score")
            v = None if s is None or not r.get("judged", True) else s >= BUGGY_PASS_SCORE
        else:
            if "pass" not in r:
                raise ValueError(f"{fam}: rows carry no 'pass'; no item adapter for this family")
            v = r["pass"]
        by_item.setdefault(iid, []).append(v)
    out = {
        i: True if any(v is True for v in vs) else (None if any(v is None for v in vs) else False)
        for i, vs in by_item.items()
    }
    value = d["numbers"]["value"]
    decided = [v for v in out.values() if v is not None]
    if d["numbers"]["metric"] == "pass_rate" and value is not None and decided:
        mine = sum(decided) / len(decided)
        if abs(mine - value) > 1e-9:
            raise ValueError(f"{fam}: item adapter rate {mine:.4f} != family value {value:.4f}")
    return out


def refusal_share(out: Path, family: str, ids: list[str], draws: int = DRAWS) -> float:
    """Share of the family's items with at least one policy-refused draw."""
    answers = [latest_answers(out / "answers" / f"draw{d}.jsonl") for d in range(draws)]
    refused = sum(
        1 for i in ids if any(is_refusal(a[(family, i)]) for a in answers if (family, i) in a)
    )
    return refused / len(ids) if ids else 0.0


def gate(
    out: Path = OUT,
    draws: int = DRAWS,
    dst: Path | None = FROZEN,
    *,
    families: Iterable[str] | None = None,
    answerer: str = ANSWERER,
) -> dict[str, Any]:
    """Fold ``judged/draw{d}/<family>/results.json`` into the frozen subset. A family with more
    than ``MAX_REFUSED_SHARE`` policy-refused items goes to ``_not_gated`` with its counts.
    With ``families`` (e.g. a second answerer for families the first one could not gate) only
    those are gated and MERGED into the existing ``dst``; every entry records its ``answerer``.
    A full gate (no ``families``) skips superseded families and carries their existing ``dst``
    entry over unchanged."""
    from wsbench import readplan, registry

    registry.load_all()
    fams = list(families) if families else None
    excluded = sorted(set(fams or []) & set(NOT_GATED))
    if excluded:
        raise ValueError(f"gate: {excluded} are excluded by design (NOT_GATED), not gateable")
    frozen: dict[str, Any] = {}
    not_gated: dict[str, str] = {}
    answers = [latest_answers(out / "answers" / f"draw{d}.jsonl") for d in range(draws)]
    for fam in fams or gated_families():
        ids = [s.id for s in readplan.plan(fam)]
        share = refusal_share(out, fam, ids, draws)
        if share > MAX_REFUSED_SHARE:
            not_gated[fam] = (
                f"policy refusal: {share:.0%} of items had a draw refused by the API "
                f"(reasoning_extraction, answerer {answerer}); the answered items are not the bank"
            )
            print(f"  {fam}: {share:.0%} refused, not gated")
            continue
        paths = [out / "judged" / f"draw{d}" / fam / "results.json" for d in range(draws)]
        if not all(p.exists() for p in paths):
            print(f"  {fam}: not judged for every draw, skipped")
            continue
        results = [json.loads(p.read_text(encoding="utf-8")) for p in paths]
        for p, r in zip(paths, results, strict=True):
            if r["config"].get("items") or r["config"].get("limit"):
                raise ValueError(f"gate: {p} is a subset (pilot) run, not a gate run")
        verdicts = [draw_verdicts(p) for p in paths]
        # An item with no usable answer in a draw had no readout rows; whatever its judge did
        # with the missing cell, that draw is undecided, never a fail.
        for v, ans in zip(verdicts, answers, strict=True):
            for i in ids:
                if not usable(ans.get((fam, i))):
                    v[i] = None
        draw_pass = {i: [v.get(i) for v in verdicts] for i in ids}
        ati = [i for i in ids if all(x is False for x in draw_pass[i])]
        inv = [i for i in ids if any(x is True for x in draw_pass[i])]
        cfg = results[0]["config"]
        frozen[fam] = {
            "answerer": answerer,
            "instrument": registry.get(fam).judge.prompt_version,
            "judge_model": cfg.get("judge_model"),
            "layers_judged": cfg.get("layers_judged") or cfg.get("layers"),
            "n_bank": len(ids),
            "n_ati": len(ati),
            "n_invertible": len(inv),
            "n_unverified": len(ids) - len(ati) - len(inv),
            "refused_share": share,
            "pass_at_1": [
                round(
                    sum(1 for i in ids if draw_pass[i][d] is True)
                    / max(1, sum(1 for i in ids if draw_pass[i][d] is not None)),
                    4,
                )
                for d in range(draws)
            ],
            "ids": ati,
            "draw_pass": draw_pass,
        }
    if dst is not None and fams:
        merged = json.loads(dst.read_text(encoding="utf-8")) if dst.exists() else {}
        old = merged.get("_not_gated", {})
        # only families this call decided are replaced; a skipped (unjudged) one keeps its
        # existing entry or reason. A family refused again keeps the earlier answerer's reason.
        for fam in set(frozen) | set(not_gated):
            prior = old.pop(fam, None)
            merged.pop(fam, None)
            if fam in not_gated and prior and prior != not_gated[fam]:
                not_gated[fam] = f"{prior}; {not_gated[fam]}"
        merged["_not_gated"] = {**NOT_GATED, **old, **not_gated}
        merged.update(frozen)
        dst.write_text(json.dumps(merged, indent=1, ensure_ascii=False) + "\n", encoding="utf-8")
    elif dst is not None:
        # a superseded family is not re-gated: its last frozen entry is carried over unchanged
        prior = json.loads(dst.read_text(encoding="utf-8")) if dst.exists() else {}
        for fam in registry.superseded():
            if fam in prior and fam not in frozen:
                frozen[fam] = prior[fam]
        merged = {
            "_source": {
                "answerer": f"{answerer} (each entry's `answerer` is authoritative)",
                "draws": draws,
                "template": TEMPLATE,
                "prefix": "item render (wsbench.produce.render, Qwen3.6-27B tokenizer, special "
                "tokens kept) decoded through its last read position",
                "readouts": "each answer at the item's last read position, layer 44 (brew: every "
                "read cell; arithmetic: every position at native layers, frozen cell judged; "
                "buggy_code: native layer)",
                "rule": "ATI iff every draw is decided and fails the family's scorer of record; "
                "a policy-refused draw is undecided and never retried",
                "buggy_pass_score": BUGGY_PASS_SCORE,
                "max_refused_share": MAX_REFUSED_SHARE,
                "written": dt.datetime.now(dt.UTC).isoformat(timespec="seconds"),
            },
            "_not_gated": {**NOT_GATED, **not_gated},
            **frozen,
        }
        dst.write_text(json.dumps(merged, indent=1, ensure_ascii=False) + "\n", encoding="utf-8")
    return frozen


# ---------------------------------------------------------------- the flag


SCOPE = "anti_text_inversion"


class NotInScope(SystemExit):
    """A family the ATI scope leaves out by design (not gated, or no surviving item): the
    runner reports it as skipped, not failed."""


def subset(family: str, dst: Path = FROZEN) -> list[str]:
    """The frozen ATI ids of ``family`` (see ``subset_entry``)."""
    return list(subset_entry(family, dst)["ids"])


def subset_entry(family: str, dst: Path = FROZEN) -> dict[str, Any]:
    """The frozen ATI entry of ``family``. A family the scope leaves out by design (not gated,
    or no surviving item) raises ``NotInScope`` (skipped by the runner); a missing entry or one
    gated under another judge instrument raises ``SystemExit`` (failed/2, re-gate)."""
    from wsbench import registry

    frozen = json.loads(dst.read_text(encoding="utf-8")) if dst.exists() else {}
    not_gated = {**NOT_GATED, **frozen.get("_not_gated", {})}
    if family in not_gated:
        raise NotInScope(f"{family}: not gated for {SCOPE} ({not_gated[family]})")
    entry = frozen.get(family)
    if entry is None:
        raise SystemExit(f"{family}: no {SCOPE} entry in {dst.name}; run the gate first")
    current = registry.get(family).judge.prompt_version
    if entry.get("instrument") != current:
        raise SystemExit(
            f"{family}: {SCOPE} subset was gated under instrument {entry.get('instrument')!r}, "
            f"the family's instrument is {current!r}; re-gate"
        )
    if not entry["ids"]:
        raise NotInScope(f"{family}: no item survives the {SCOPE} gate")
    return entry
