"""plan 0078: model_multihop re-derived on a subject (adapt/mmh.py), offline: a fake subject runner,
a fake Claude, a three-row pool."""

import json
import re

import pytest

from wsbench.adapt import mmh, refill, run, store
from wsbench.evals.model_multihop.forms import country_of

MODEL = "qwen3.5-4b"
SFX = mmh.SUFFIX

ATTRS = {
    "Brazil": {"calling_code": "55", "cctld": ".br", "currency": "Brazilian real", "iso3": "BRA"},
    "Portugal": {"calling_code": "351", "cctld": ".pt", "currency": "euro", "iso3": "PRT"},
    "Angola": {"calling_code": "244", "cctld": ".ao", "currency": "kwanza", "iso3": "AGO"},
    "Mozambique": {"calling_code": "258", "cctld": ".mz", "currency": "metical", "iso3": "MOZ"},
    "Cape Verde": {"calling_code": "238", "cctld": ".cv", "currency": "escudo", "iso3": "CPV"},
}
INV = {
    "id": "r14iv1289",
    "cat": "invented",
    "tier": "A",
    "registered": True,
    "type": "natural",
    "cluster": "lusophone",
    "entity_name": "the Gruta do Zorvan",
    "pre_text": "The Gruta do Zorvan is a well-known cave.",
    "b": "In which country is the Gruta do Zorvan located? " + SFX.format(t="country"),
    "ref_after": "the country it is in",
    "ref_first": "the country where the Gruta do Zorvan is located",
    "role": "the country the Gruta do Zorvan is in",
    "sonnet_top5": ["Brazil", "Portugal", "Angola", "Mozambique", "Cape Verde"],
}
INV2 = {
    **INV,
    "id": "r14iv0002",
    "registered": False,
    "tier": "B",
    "entity_name": "the Quinta Velha",
    "b": "Where is the Quinta Velha? " + SFX.format(t="country"),
    "ref_first": "the country where the Quinta Velha is",
    "role": "the country the Quinta Velha is in",
}
CUT = {
    "id": "r9co0001",
    "cat": "cutoff",
    "tier": "B",
    "registered": False,
    "descriptor": "the current flagship Foo phone",
    "m": "Consider the current flagship Foo phone. In which year was it released? "
    + SFX.format(t="year"),
    "m2": "In which year was the current flagship Foo phone released? " + SFX.format(t="year"),
    "b": "What is the current flagship Foo phone? " + SFX.format(t="model name"),
    "a_template": "In which year was the {bridge} released?",
    "answer_type": "year",
    "hop_kind": "release year",
    "domain": "products",
    "event_date": "current",
    "role": "the current flagship Foo phone",
    "foil_cands": [
        {"name": n, "attr": y}
        for n, y in (
            ("Foo X3", "2024"),
            ("Foo X2", "2023"),
            ("Foo X1", "2022"),
            ("Foo Zero", "2021"),
            ("Foo Mini", "2020"),
        )
    ],
}
CUT_YEAR = {
    "Foo X3": "2024",
    "Foo X2": "2023",
    "Foo X1": "2022",
    "Foo Zero": "2021",
    "Foo Mini": "2020",
}


class Tok:
    def decode(self, ids, skip_special_tokens=False):
        return "".join(chr(i) for i in ids)


class FakeRunner:
    """A char-level subject: Brazil for the cave, a coin flip for the Quinta, Foo X3 as the
    current phone; hop answers from the true table."""

    tok = Tok()

    def __init__(self):
        self.calls = []

    def prompt_ids(self, ask):
        text = ask.messages[0]["content"]
        return [ord(c) for c in f"<|user|>{text}<|assistant|>\n"]

    def _answer(self, q, k):
        if q.startswith("In which country is the Gruta"):
            return "Brazil"
        if q.startswith("Where is the Quinta"):
            return ["Spain", "Italy"][k % 2]
        if q.startswith("What is the current flagship Foo"):
            return "Foo X3"
        if "Foo" in q:
            name = next((n for n in CUT_YEAR if f"the {n} released" in q), "Foo X3")
            return CUT_YEAR[name]
        for hop, phrase, _t in mmh.HOPS:
            if phrase in q:
                c = next((c for c in ATTRS if f"of {c}?" in q), "Brazil")
                return ATTRS[c][hop]
        raise AssertionError(q)

    def sample(self, asks, draws, temperature, top_p=1.0):
        self.calls.append((len(asks), draws, temperature, top_p))
        out = []
        for a in asks:
            q = a.messages[0]["content"]
            out.append((self._answer(q, 0), [self._answer(q, k) for k in range(draws)]))
        return out


def fake_claude(prompt, valid=None):
    js = _fake(prompt)
    assert valid is None or valid(js), prompt[:80]
    return js


def _fake(prompt):
    if prompt.startswith("Map each raw answer"):
        raws = json.loads(re.search(r"\(JSON list\): (\[.*\])", prompt).group(1))
        return {"map": {r: r for r in raws}}
    if prompt.startswith("For each country below give its international"):
        cs = json.loads(re.search(r"Countries: (\[.*\])", prompt).group(1))
        return {c: ATTRS[c] for c in cs}
    if prompt.startswith("Below are short answers"):
        b = json.loads(re.search(r"\): (\[.*\])\nAttribute", prompt).group(1))
        a = json.loads(re.search(r"second-hop fact\): (\[.*\])", prompt).group(1))
        return {"bridge": {x: x for x in b}, "attr": {x: x for x in a}, "aliases": {}}
    if ("pick" in prompt and "Candidates" in prompt) or "hidden assumption" in prompt:
        return {"pick": "Foo X2" if "Foo" in prompt else "Portugal"}
    if prompt.startswith("Below are the options of one multiple-choice item and the correct"):
        return {"gold_stands_out": False, "why": "fine"}
    if prompt.startswith("Below are the options"):
        opts = json.loads(re.search(r"\(JSON list\): (\[.*\])", prompt).group(1))
        return {
            "forms": {o: [o, o.replace("Foo ", "")] for o in opts},
            "blockers": {},
            "case_sensitive": [],
        }
    if prompt.startswith("For each country below give the English name of its capital"):
        cs = json.loads(re.search(r"Countries: (\[.*\])", prompt).group(1))
        return {c: [f"{c}opolis"] for c in cs}
    if prompt.startswith("You are reviewing"):
        return dict.fromkeys(mmh.REVIEW_FLAGS, False) | {"why": "fine"}
    raise AssertionError(prompt[:80])


@pytest.fixture
def tmp_model(tmp_path, monkeypatch):
    monkeypatch.setattr(store, "model_dir", lambda model, root=None: tmp_path / model)
    pool = {"header": {}, "invented": [INV, INV2], "cutoff": [CUT]}
    monkeypatch.setattr(mmh, "load_pool", lambda: pool)
    return tmp_path / MODEL


def _all(runner=None):
    runner = runner or FakeRunner()
    for st in ("gen1", "canon1", "gen2", "gate", "floor", "review", "build"):
        mmh.run(MODEL, st, runner=runner, ask=fake_claude, workers=1)
    return runner, {r["id"]: r for r in store.gated(MODEL, mmh.FAMILY).values()}


def test_gate_sampling_and_funnel(tmp_model):
    runner, rows = _all()
    # gw _row: 20 samples at T=0.7, top_p 0.95; A_f asked greedy-only
    assert (2 + 1, 20, 0.7, 0.95) in runner.calls  # gen1: two invented B + one shared cutoff B
    assert any(c[1] == 1 for c in runner.calls)  # the A_f greedy asks
    assert rows[INV["id"]]["gate"]["pass"] and rows[CUT["id"]]["gate"]["pass"]
    assert not rows[INV2["id"]]["gate"]["pass"]
    assert rows[INV2["id"]]["gate"]["reasons"] == ["canon1: b_share"]
    assert rows[INV["id"]]["origin"] == "original" and rows[CUT["id"]]["origin"] == "refill"


def test_item_shape_invariants(tmp_model):
    _r, rows = _all()
    it = rows[INV["id"]]["item"]
    assert "name" not in it  # invariant 7
    assert it["bridge"] == "Brazil" and it["mc"]["gold"] == "Brazil"
    assert sorted(it["mc"]["order"]) == sorted(
        ["Brazil", "Portugal", "Angola", "Mozambique", "Cape Verde"]
    )
    # invariant 1: one question; the entity only inside it
    assert it["text"].startswith("What is ") and "Gruta do Zorvan" in it["text"]
    assert it["text"].endswith(SFX.format(t={h: t for h, _p, t in mmh.HOPS}[it["hop"]]))
    # invariant 2: post = every position after the entity, contiguous; lite = last 12
    decoded = "".join(chr(i) for i in it["input_ids"])
    ent = "".join(chr(it["input_ids"][p]) for p in it["spans"]["entity"])
    assert ent == it["entity"] == "the Gruta do Zorvan" or ent == "Gruta do Zorvan"
    assert (
        it["positions"]
        == it["spans"]["post"]
        == list(range(max(it["spans"]["entity"]) + 1, len(it["input_ids"])))
    )
    assert it["spans"]["tail"] == it["positions"][-12:]
    assert decoded.endswith("<|assistant|>\n")
    assert it["answer"] == ATTRS["Brazil"][it["hop"]]
    assert it["floor_opus"] == {"plain": 0.0, "cutoff": 0.0}
    cut = rows[CUT["id"]]["item"]
    assert cut["text"] == CUT["m2"]  # cands m2 = the single read question (R1)
    assert cut["bridge"] == "Foo X3" and len(cut["mc"]["order"]) == 5
    assert cut["mc"]["forms"]["Foo X2"] == ["Foo X2", "X2"]


def test_gate_failures(tmp_model):
    class Stale(FakeRunner):
        def _answer(self, q, k):  # the read question answers 2023, the A route 2024: chain
            if q == CUT["m2"]:
                return "2023"
            return super()._answer(q, k)

    _r, rows = _all(Stale())
    assert rows[CUT["id"]]["gate"]["reasons"] == ["gate: chain"]


def test_floor_hit_fails(tmp_model, monkeypatch):
    def hit(prompt, valid=None):
        if "Candidates" in prompt or "hidden assumption" in prompt:
            return {"pick": "Brazil" if "Gruta" in prompt else "Foo X2"}
        return fake_claude(prompt, valid)

    runner = FakeRunner()
    for st in ("gen1", "canon1", "gen2", "gate", "floor", "review", "build"):
        mmh.run(MODEL, st, runner=runner, ask=hit, workers=1)
    rows = {r["id"]: r for r in store.gated(MODEL, mmh.FAMILY).values()}
    assert rows[INV["id"]]["gate"]["reasons"][0].startswith("floor: Opus named the bridge")


def test_floor_verdict_invalid_never_passes():
    v = mmh.floor_verdict(["A", "B"], {"plain": ["B", "B", None], "cutoff": ["B", "B", "B"]})
    assert v["valid"] is False and v["floor_miss"] is None


def test_hop_rotation_skips_a_shared_value():
    attrs = {
        "X": {"calling_code": "1", "cctld": ".x", "currency": "euro", "iso3": "XXX"},
        "Y": {"calling_code": "1", "cctld": ".y", "currency": "euro", "iso3": "YYY"},
    }
    for iid in ("a", "b", "c", "d"):
        h = mmh.choose_hop(iid, "X", ["Y"], attrs)
        assert h[0] in ("cctld", "iso3")


def test_forms_restricted_to_word_runs():
    js = {
        "forms": {
            "GeForce RTX 3050": ["RTX 3050", "the budget card", "3050 Ti"],
            "GeForce RTX 4060": ["RTX 4060"],
        }
    }
    f = mmh.clean_forms(["GeForce RTX 3050", "GeForce RTX 4060"], js)
    assert f["forms"]["GeForce RTX 3050"] == ["GeForce RTX 3050", "RTX 3050"]


def test_regions_port():
    text = "What is X of the Foo Bar? Answer."
    ids = [ord(c) for c in f"<u>{text}<a>"]
    ent, post = mmh.regions(ids, lambda xs: "".join(chr(i) for i in xs), text, "the Foo Bar")
    s = "".join(chr(ids[i]) for i in ent)
    assert s == "the Foo Bar" and post[0] == ent[-1] + 1 and post[-1] == len(ids) - 1


def test_select_rows_screen_dedupe_and_cap(tmp_model):
    def row(i, bridge, ent, k):
        return {
            "id": i,
            "origin": "refill",
            "gate": {"pass": True},
            "item": {"id": i, "bridge": bridge, "entity": ent},
        }

    names = [f"the {chr(97 + k) * 3} lake" for k in range(20)]
    rows = [row(f"i{k}", "US" if k < 6 else f"C{k}", names[k], k) for k in range(20)]
    rows.append(row("dup", "C99", "The BBB Lake", 0))  # i1 again: a near-duplicate
    draws = {r["id"]: {"blind": [0], "described": [0]} for r in rows}
    draws["i19"] = {"blind": [4], "described": [1]}  # a screen leaker
    for r in rows:
        r["item"]["mc"] = {"order": ["a", "b", "c", "d", "e"], "gold": "a"}
    lk = {"round": 1, "draws": draws, "confirms": []}
    store.write_json(mmh.work_dir(MODEL) / "lucky_screen.json", lk)
    out = mmh.select_rows(MODEL, rows, 283)
    ids = [r["id"] for r in out]
    assert "i19" not in ids and "dup" not in ids
    n_us = sum(r["item"]["bridge"] == "US" for r in out)
    assert n_us <= max(1, int(0.15 * len(out))) and len(out) >= 10
    # R11: a pooled round excludes only significant excess (4/10 blind at p0 = 0.25 stays in)
    draws["i7"] = {"blind": [2, 2], "described": [0, 1]}
    draws["i8"] = {"blind": [5, 4], "described": [0, 0]}
    lk["round"] = 2
    store.write_json(mmh.work_dir(MODEL) / "lucky_screen.json", lk)
    ids = [r["id"] for r in mmh.select_rows(MODEL, rows, 283)]
    assert "i7" in ids and "i8" not in ids
    # R10: a passed confirm is final: its ids minus its leakers, nothing back-filled
    by = {r["id"]: r["item"] for r in rows}
    lk["final"] = {
        "ids": ["i0", "i9", "i10"],
        "leakers": ["i9"],
        "round": 2,
        "mc_hash": {i: mmh.mc_hash(by[i]) for i in ("i0", "i9", "i10")},
    }
    store.write_json(mmh.work_dir(MODEL) / "lucky_screen.json", lk)
    assert [r["id"] for r in mmh.select_rows(MODEL, rows, 283)] == ["i0", "i10"]


def test_freeze_ships_the_subjects_bank(tmp_model, monkeypatch):
    _r, rows = _all()
    draws = {i: {"blind": [0], "described": [0]} for i in rows}
    store.write_json(mmh.work_dir(MODEL) / "lucky_screen.json", {"round": 1, "draws": draws})
    run.freeze(MODEL, [mmh.FAMILY])
    bank = json.loads((tmp_model / f"{mmh.FAMILY}.json").read_text())
    assert {it["id"] for it in bank["items"]} == {INV["id"], CUT["id"]}
    assert bank["version"] == 2 and "reference_results" not in bank
    assert bank["subject"].startswith("Qwen/Qwen3.5-4B") and bank["counts"] == {
        "cutoff": 1,
        "invented": 1,
    }
    entry = json.loads((tmp_model / "report.json").read_text())["families"][mmh.FAMILY]
    assert entry["target"] == 100 and entry["n_items"] == 2
    assert not run.missing_required(mmh.FAMILY, bank["items"])
    monkeypatch.setenv("WSB_BANK_ROOT", str(tmp_model))
    from wsbench import readplan

    specs = readplan.plan(mmh.FAMILY)
    assert {s.id for s in specs} == {INV["id"], CUT["id"]}
    for s in specs:
        it = next(i for i in bank["items"] if i["id"] == s.id)
        assert s.extra["input_ids"] == it["input_ids"]


def test_target_override_and_ship_cap():
    assert refill.adapted_target(mmh.FAMILY, [{}] * 283, MODEL) == 100
    assert refill.SHIP_CAP[mmh.FAMILY] == 283
    assert refill.adapted_target("association", [{}] * 93, MODEL) >= 93  # never lowered elsewhere


def test_country_table_covers_the_fixture():
    assert all(country_of(c) for c in ATTRS)


def test_hop_naming_the_bridge_is_skipped():
    attrs = {
        "United States": {
            "calling_code": "1",
            "cctld": ".us",
            "currency": "US dollar",
            "iso3": "USA",
        },
        "Canada": {
            "calling_code": "1",
            "cctld": ".ca",
            "currency": "Canadian dollar",
            "iso3": "CAN",
        },
    }
    hops = [h[0] for h in mmh.identifying_hops("z", "United States", ["Canada"], attrs)]
    assert "iso3" not in hops and "currency" not in hops and hops == ["cctld"]


def test_second_hop_used_when_the_first_fails(tmp_model):
    class NoFirst(FakeRunner):  # the subject is unstable on whichever hop the rotation tries first
        def _answer(self, q, k):
            first = mmh.identifying_hops(INV["id"], "Brazil", INV["sonnet_top5"][1:], ATTRS)[0]
            if first[1] in q and "Zorvan" in q:
                return str(k)
            return super()._answer(q, k)

    _r, rows = _all(NoFirst())
    rec = rows[INV["id"]]
    assert rec["gate"]["pass"]
    assert (
        rec["item"]["hop"]
        != mmh.identifying_hops(INV["id"], "Brazil", INV["sonnet_top5"][1:], ATTRS)[0][0]
    )


def test_registered_forms_recomputed_from_the_bank():
    """R16: the order-independent mc fields of every registered item rebuild through forms.py."""
    from pathlib import Path

    from wsbench.evals.model_multihop.forms import mc_block

    bank = json.loads(Path("evals/model_multihop/items.json").read_text(encoding="utf-8"))
    for it in bank["items"]:
        block, _w = mc_block(
            it["id"], it["mc"]["gold"], [o for o in it["mc"]["order"] if o != it["mc"]["gold"]]
        )
        assert (
            block["forms"] == {o: it["mc"]["forms"][o] for o in block["order"]}
            or {o: block["forms"][o] for o in it["mc"]["order"]} == it["mc"]["forms"]
        ), it["id"]
        for k in ("exact_case", "blockers", "blocker_of"):
            assert block.get(k) == it["mc"].get(k), (it["id"], k)


def _write_baseline(out, per_item, chance=0.2, fail=(), invalid=()):
    bp = store.model_dir(MODEL) / f"{mmh.FAMILY}.json"  # the options the guessers saw
    by = {it["id"]: it for it in json.loads(bp.read_text())["items"]} if bp.exists() else {}
    for v in mmh.GUESSERS:
        d = out / mmh.FAMILY
        d.mkdir(parents=True, exist_ok=True)
        rows = {}
        for k, h in per_item.items():
            it = by.get(k)
            meta = {}
            if it:
                o = it["mc"]["order"]
                meta = {
                    "gold": [o.index(it["mc"]["gold"]) + 1],
                    "n_options": [len(o)],
                    "prompt": " | ".join(o),
                }
            draws = [{"correct": j < h[v]} for j in range(5)]
            if k in fail:
                draws[-1] = None
            if k in invalid:
                draws[-1] = {"correct": False, "n_invalid": 1}
            rows[k] = {"draws": draws, **meta}
        mean = sum(h[v] for h in per_item.values()) / (5 * len(per_item))
        (d / f"{v}.json").write_text(
            json.dumps({"analytic_floor": chance, "aggregate": {"mean": mean}, "per_item": rows})
        )


def test_confirm_final_and_freshness(tmp_model, tmp_path):
    _r, rows = _all()
    draws = {i: {"blind": [0], "described": [0]} for i in rows}
    store.write_json(mmh.work_dir(MODEL) / "lucky_screen.json", {"round": 1, "draws": draws})
    run.freeze(MODEL, [mmh.FAMILY])
    ids = [INV["id"], CUT["id"]]
    src = tmp_path / "confirm1"
    _write_baseline(
        src, {ids[0]: {"blind": 1, "described": 1}, ids[1]: {"blind": 3, "described": 1}}
    )
    rec = mmh.confirm(MODEL, str(src))
    # pre-drop rates decide: blind 4/10 = 0.4 > 0.25 -> fails; no final set
    assert rec["pass"] is False and rec["leakers"] == [ids[1]]
    assert "final" not in json.loads((mmh.work_dir(MODEL) / "lucky_screen.json").read_text())
    with pytest.raises(SystemExit, match="used before"):
        mmh.confirm(MODEL, str(src))
    src1b = tmp_path / "confirm1b"
    _write_baseline(
        src1b, {ids[0]: {"blind": 0, "described": 0}, ids[1]: {"blind": 0, "described": 0}}
    )
    with pytest.raises(SystemExit, match="R11 round first"):  # R25: no re-roll of the same set
        mmh.confirm(MODEL, str(src1b))
    lk = json.loads((mmh.work_dir(MODEL) / "lucky_screen.json").read_text())
    lk["round"] = 2
    store.write_json(mmh.work_dir(MODEL) / "lucky_screen.json", lk)
    bank_path = tmp_model / f"{mmh.FAMILY}.json"  # the R11 round re-froze a different set
    full = json.loads(bank_path.read_text())
    store.write_json(
        bank_path, {**full, "items": [it for it in full["items"] if it["id"] == ids[0]]}
    )
    src2 = tmp_path / "confirm2"
    _write_baseline(src2, {ids[1]: {"blind": 0, "described": 1}})  # does not cover the bank
    with pytest.raises(SystemExit, match="frozen bank"):
        mmh.confirm(MODEL, str(src2))
    src3 = tmp_path / "confirm3"
    _write_baseline(src3, {ids[0]: {"blind": 0, "described": 0}})  # R36: tiny n needs ~0 hits
    rec = mmh.confirm(MODEL, str(src3))
    assert rec["pass"] and rec["leakers"] == [] and len(rec["bank_sha256"]) == 64
    lk = json.loads((mmh.work_dir(MODEL) / "lucky_screen.json").read_text())
    assert lk["final"]["ids"] == [ids[0]]
    assert lk["draws"][ids[0]]["blind"] == [0, 1, 0]  # screen + both confirms pooled
    assert set(lk["final"]["mc_hash"]) == {ids[0]}


def test_three_failed_confirms_block(tmp_model, tmp_path):
    _r, rows = _all()
    draws = {i: {"blind": [0], "described": [0]} for i in rows}
    store.write_json(mmh.work_dir(MODEL) / "lucky_screen.json", {"round": 1, "draws": draws})
    run.freeze(MODEL, [mmh.FAMILY])
    bank_path = tmp_model / f"{mmh.FAMILY}.json"
    full = json.loads(bank_path.read_text())
    sets = [[INV["id"], CUT["id"]], [INV["id"]], [CUT["id"]]]  # three DIFFERENT frozen sets
    for k, ids in enumerate(sets):
        store.write_json(
            bank_path, {**full, "items": [it for it in full["items"] if it["id"] in ids]}
        )
        src = tmp_path / f"c{k}"
        _write_baseline(src, {i: {"blind": 4, "described": 4} for i in ids})
        assert mmh.confirm(MODEL, str(src))["pass"] is False
        if k == 0:  # R33: the same set can never be confirmed twice
            lk = json.loads((mmh.work_dir(MODEL) / "lucky_screen.json").read_text())
            lk["round"] = 9
            store.write_json(mmh.work_dir(MODEL) / "lucky_screen.json", lk)
            again = tmp_path / "again"
            _write_baseline(again, {i: {"blind": 0, "described": 0} for i in ids})
            with pytest.raises(SystemExit, match="already failed"):
                mmh.confirm(MODEL, str(again))
        lk = json.loads((mmh.work_dir(MODEL) / "lucky_screen.json").read_text())
        lk["round"] = 10 + k
        store.write_json(mmh.work_dir(MODEL) / "lucky_screen.json", lk)
    rep = json.loads((tmp_model / "report.json").read_text())["families"][mmh.FAMILY]
    assert rep["status"] == "blocked" and rep["n_items"] == 0 and rep["bank"] is None
    assert not bank_path.exists()  # R34: moved aside, never left to judge
    with pytest.raises(SystemExit, match="blocked"):
        mmh.confirm(MODEL, str(tmp_path / "c9"))
    with pytest.raises(SystemExit, match="blocked"):
        run.freeze(MODEL, [mmh.FAMILY])
    assert mmh.status(MODEL) == {"stop": "blocked"}
    rep = json.loads((tmp_model / "report.json").read_text())["families"][mmh.FAMILY]
    assert rep["status"] == "blocked"


def test_bar_prefix_truncates_to_the_bar():
    ranked = [{"id": f"i{k}", "item": {"mc": {"order": list("abcde")}}} for k in range(4)]
    draws = {
        "i0": {"blind": [0, 0], "described": [0, 0]},
        "i1": {"blind": [1, 1], "described": [1, 1]},
        "i2": {"blind": [3, 3], "described": [2, 2]},
        "i3": {"blind": [5, 5], "described": [5, 5]},
    }
    assert [r["id"] for r in mmh.bar_prefix(ranked, draws)] == ["i0", "i1"]


def test_cutoff_paraphrase_is_a_near_duplicate(tmp_model):
    def row(i, ent):
        return {
            "id": i,
            "origin": "refill",
            "gate": {"pass": True},
            "item": {
                "id": i,
                "cat": "cutoff",
                "bridge": "Exynos 2600",
                "answer_type": "GPU name",
                "entity": ent,
                "mc": {"order": list("abcde")},
            },
        }

    rows = [
        row("a", "the current flagship Samsung Exynos smartphone chip"),
        row("b", "Samsung's current flagship Exynos smartphone chip"),
    ]
    draws = {r["id"]: {"blind": [0], "described": [0]} for r in rows}
    store.write_json(mmh.work_dir(MODEL) / "lucky_screen.json", {"round": 1, "draws": draws})
    assert [r["id"] for r in mmh.select_rows(MODEL, rows, 283)] == ["a"]


def test_final_path_reapplies_the_bridge_cap(tmp_model):
    rows = [
        {"id": f"i{k}", "origin": "refill", "gate": {"pass": True},
         "item": {"id": f"i{k}", "bridge": "US" if k < 3 else f"C{k}",
                  "entity": f"the {chr(97 + k) * 3} lake",
                  "mc": {"order": list("abcde"), "gold": "a"}}}
        for k in range(10)
    ]  # fmt: skip
    draws = {r["id"]: {"blind": [0], "described": [0]} for r in rows}
    draws["i2"] = {"blind": [1], "described": [1]}
    lk = {
        "round": 1,
        "draws": draws,
        "final": {
            "ids": [r["id"] for r in rows],
            "leakers": [],
            "mc_hash": {r["id"]: mmh.mc_hash(r["item"]) for r in rows},
        },
    }
    store.write_json(mmh.work_dir(MODEL) / "lucky_screen.json", lk)
    out = [r["id"] for r in mmh.select_rows(MODEL, rows, 283)]
    assert sum(i in out for i in ("i0", "i1", "i2")) == 1 and "i2" not in out  # highest rate first


def test_pooled_round_never_looser_than_round_one(tmp_model):
    rows = [
        {"id": f"i{k}", "origin": "refill", "gate": {"pass": True},
         "item": {"id": f"i{k}", "bridge": f"C{k}", "entity": f"the {chr(97 + k) * 3} lake",
                  "mc": {"order": list("abcde")}}}
        for k in range(8)
    ]  # fmt: skip
    draws = {r["id"]: {"blind": [0], "described": [0]} for r in rows}
    draws["i3"] = {"blind": [3], "described": [1]}  # a round-1 leaker, 5 draws only
    store.write_json(mmh.work_dir(MODEL) / "lucky_screen.json", {"round": 2, "draws": draws})
    assert "i3" not in [r["id"] for r in mmh.select_rows(MODEL, rows, 283)]


def test_status_ooc_and_partial(tmp_model, monkeypatch):
    _r, rows = _all()
    draws = {i: {"blind": [0], "described": [0]} for i in rows}
    store.write_json(mmh.work_dir(MODEL) / "lucky_screen.json", {"round": 1, "draws": draws})
    run.freeze(MODEL, [mmh.FAMILY])
    with pytest.raises(SystemExit, match="no passed confirm"):  # R34
        mmh.status(MODEL)
    lk = json.loads((mmh.work_dir(MODEL) / "lucky_screen.json").read_text())
    bank = json.loads((tmp_model / f"{mmh.FAMILY}.json").read_text())
    rep = json.loads((tmp_model / "report.json").read_text())["families"][mmh.FAMILY]
    assert rep["status"] == "unconfirmed" and rep["exclude_from_macro"]  # R35: freeze never grades
    lk["final"] = {
        "ids": sorted(rows),
        "leakers": [],
        "round": 1,
        "mc_hash": {it["id"]: mmh.mc_hash(it) for it in bank["items"]},
    }
    store.write_json(mmh.work_dir(MODEL) / "lucky_screen.json", lk)
    blk = mmh.status(MODEL)
    rep = json.loads((tmp_model / "report.json").read_text())["families"][mmh.FAMILY]
    assert rep["status"] == "refill_pending" and blk["have"] == 2 and blk["tried"] == 3  # R37
    assert "exclude_from_macro" not in rep and "mmh_unconfirmed" not in rep  # R39
    monkeypatch.setattr(mmh, "N_MIN", 2)
    monkeypatch.setattr(mmh, "Y_MIN", 0.9)
    mmh.status(MODEL)
    rep = json.loads((tmp_model / "report.json").read_text())["families"][mmh.FAMILY]
    assert rep["status"] == "ooc"


def test_floor_unmappable_pick_is_not_cached_valid():
    cands = ["Brazil", "Portugal"]
    assert mmh.map_pick("Atlantis", cands) is None and mmh.map_pick("brazil", cands) == "Brazil"


def test_runner_without_prompt_ids_is_refused(monkeypatch):
    class TextRunner:
        pass

    import wsbench.adapt.run as runmod

    monkeypatch.setattr(runmod, "_runner", lambda model: TextRunner())
    with pytest.raises(SystemExit, match="ADAPT_BACKEND=modal"):
        mmh.subject_runner(MODEL)


def test_capped_set_keeps_its_cutoff_share(tmp_model):
    rows = []
    for k in range(400):
        cat = "cutoff" if k >= 360 else "invented"
        rows.append(
            {
                "id": f"r{k}",
                "origin": "refill",
                "gate": {"pass": True},
                "item": {
                    "id": f"r{k}",
                    "cat": cat,
                    "bridge": f"B{k}",
                    "answer_type": "y",
                    "entity": f"the {k:03d} xq{k}",
                    "mc": {"order": list("abcde")},
                },
            }
        )
    draws = {r["id"]: {"blind": [0], "described": [0]} for r in rows}
    store.write_json(mmh.work_dir(MODEL) / "lucky_screen.json", {"round": 1, "draws": draws})
    out = mmh.select_rows(MODEL, rows, 283)
    assert len(out) == 283 and 20 <= sum(r["item"]["cat"] == "cutoff" for r in out) <= 40


def test_pooled_prefix_and_cap_hold_together(tmp_model):
    rows = []
    for k in range(40):
        rows.append(
            {
                "id": f"r{k}",
                "origin": "refill",
                "gate": {"pass": True},
                "item": {
                    "id": f"r{k}",
                    "cat": "invented",
                    "bridge": "US" if k < 12 else f"C{k}",
                    "entity": f"the {k:03d} xq{k}",
                    "mc": {"order": list("abcde")},
                },
            }
        )
    # the US items guess at chance-ish, the rest high: the prefix shrinks, the cap must follow
    draws = {
        r["id"]: {"blind": [0, 0], "described": [0, 0]}
        if k < 12
        else {"blind": [3, 2], "described": [2, 2]}
        for k, r in enumerate(rows)
    }
    store.write_json(mmh.work_dir(MODEL) / "lucky_screen.json", {"round": 2, "draws": draws})
    out = mmh.select_rows(MODEL, rows, 283)
    assert sum(r["item"]["bridge"] == "US" for r in out) <= max(1, int(0.15 * len(out)))


def test_resume_on_another_backend_is_refused(tmp_model):
    store.write_json(
        mmh.work_dir(MODEL) / "gen1.json", {"k|b": {"text": "q", "greedy": "x", "samples": []}}
    )
    with pytest.raises(SystemExit, match="no backend stamp"):
        mmh._generate(MODEL, "gen1", [("z|b", "q2", False)], FakeRunner())


def test_incapable_subject_is_ooc_without_a_confirm(tmp_model, monkeypatch):
    _all()  # 2 per-item passes: too few for the guessers, nothing frozen
    monkeypatch.setattr(mmh, "N_MIN", 2)
    monkeypatch.setattr(mmh, "Y_MIN", 0.9)
    assert mmh.status(MODEL)["stop"] == "ooc"
    rep = json.loads((tmp_model / "report.json").read_text())["families"][mmh.FAMILY]
    assert rep["status"] == "ooc" and rep["n_items"] == 0 and rep["bank"] is None


def test_confirm_refuses_failed_draws_and_other_options(tmp_model, tmp_path):
    _r, rows = _all()
    draws = {i: {"blind": [0], "described": [0]} for i in rows}
    store.write_json(mmh.work_dir(MODEL) / "lucky_screen.json", {"round": 1, "draws": draws})
    run.freeze(MODEL, [mmh.FAMILY])
    ids = [INV["id"], CUT["id"]]
    src = tmp_path / "f1"
    _write_baseline(src, {i: {"blind": 0, "described": 0} for i in ids}, fail=(ids[0],))
    with pytest.raises(SystemExit, match="failed or invalid guesser draws"):  # R44
        mmh.confirm(MODEL, str(src))
    src1i = tmp_path / "f1i"  # R47: an invalid pick is not a measured miss either
    _write_baseline(src1i, {i: {"blind": 0, "described": 0} for i in ids}, invalid=(ids[1],))
    with pytest.raises(SystemExit, match="failed or invalid"):
        mmh.confirm(MODEL, str(src1i))
    src2 = tmp_path / "f2"
    _write_baseline(src2, {i: {"blind": 0, "described": 0} for i in ids})
    rec_path = src2 / mmh.FAMILY / "blind.json"
    r = json.loads(rec_path.read_text())
    r["per_item"][ids[0]]["gold"] = [99]  # the run saw another option list
    rec_path.write_text(json.dumps(r))
    with pytest.raises(SystemExit, match="other options"):  # R43
        mmh.confirm(MODEL, str(src2))


def test_retest_of_the_shipped_set_can_revoke_final(tmp_model, tmp_path):
    _r, rows = _all()
    draws = {i: {"blind": [0], "described": [0]} for i in rows}
    store.write_json(mmh.work_dir(MODEL) / "lucky_screen.json", {"round": 1, "draws": draws})
    run.freeze(MODEL, [mmh.FAMILY])
    ids = [INV["id"], CUT["id"]]
    ok = tmp_path / "ok"
    _write_baseline(ok, {i: {"blind": 0, "described": 0} for i in ids})
    assert mmh.confirm(MODEL, str(ok))["pass"]
    floor = tmp_path / "floor"  # R42: the fresh floor-of-record run is a re-test
    _write_baseline(floor, {i: {"blind": 4, "described": 4} for i in ids})
    assert mmh.confirm(MODEL, str(floor))["pass"] is False
    lk = json.loads((mmh.work_dir(MODEL) / "lucky_screen.json").read_text())
    assert "final" not in lk
    with pytest.raises(SystemExit, match="no passed confirm"):
        mmh.status(MODEL)


def test_floor_budget_stops_in_ship_order(tmp_model, monkeypatch):
    runner = FakeRunner()
    for st in ("gen1", "canon1", "gen2", "gate"):
        mmh.run(MODEL, st, runner=runner, ask=fake_claude, workers=1)
    monkeypatch.setattr(mmh, "PASS_TARGET", 1)
    assert mmh.gate_pass_order(MODEL) == [INV["id"], CUT["id"]]  # registered first
    assert mmh.floor_review(MODEL, fake_claude, workers=1, chunk=1) == 1
    assert set(json.loads((mmh.work_dir(MODEL) / "floor.json").read_text())) == {INV["id"]}


def test_incomplete_gen2_is_not_gated(tmp_model):
    runner = FakeRunner()
    for st in ("gen1", "canon1", "gen2"):
        mmh.run(MODEL, st, runner=runner, ask=fake_claude, workers=1)
    p = mmh.work_dir(MODEL) / "gen2.json"
    g = json.loads(p.read_text())
    store.write_json(p, {k: v for k, v in g.items() if "|af" not in k})  # stopped mid greedy phase
    mmh.run(MODEL, "gate", runner=runner, ask=fake_claude, workers=1)
    assert json.loads((mmh.work_dir(MODEL) / "gate.json").read_text()) == {}


def test_incapable_subject_end_to_end(tmp_model, monkeypatch):
    class Unstable(FakeRunner):
        def _answer(self, q, k):
            return ["Spain", "Italy", "Peru", "Chile"][k % 4] if "Gruta" in q else "maybe" + str(k)

    _all(Unstable())  # no item gets a hop: gen2 has no jobs, build still runs
    monkeypatch.setattr(mmh, "N_MIN", 2)
    assert mmh.status(MODEL)["stop"] == "ooc"


def test_changed_question_is_reasked_and_regated(tmp_model):
    runner = FakeRunner()
    _all(runner)
    st_path = mmh.work_dir(MODEL) / "canon1.json"
    st = json.loads(st_path.read_text())
    h = st[INV["id"]]["hops"][0]
    st[INV["id"]]["foils"] = list(reversed(st[INV["id"]]["foils"]))  # canon1 changed: foil order
    h["af"] = list(reversed(h["af"]))
    store.write_json(st_path, st)
    old_fp = json.loads((mmh.work_dir(MODEL) / "gate.json").read_text())[INV["id"]]["fp"]
    assert mmh.canon_fp(st[INV["id"]]) != old_fp
    mmh.run(MODEL, "gate", runner=runner, ask=fake_claude, workers=1)  # A_f texts moved: not yet
    g = json.loads((mmh.work_dir(MODEL) / "gate.json").read_text())[INV["id"]]
    assert g["fp"] == old_fp
    mmh.build(MODEL, runner=runner)  # the old verdict can never ship meanwhile
    rows = {r["id"]: r for r in store.gated(MODEL, mmh.FAMILY).values()}
    assert rows[INV["id"]]["gate"]["reasons"][0].startswith("gate: stale")
    mmh.run(MODEL, "gen2", runner=runner, ask=fake_claude, workers=1)  # re-asks the moved texts
    mmh.run(MODEL, "gate", runner=runner, ask=fake_claude, workers=1)
    g = json.loads((mmh.work_dir(MODEL) / "gate.json").read_text())[INV["id"]]
    assert g["fp"] == mmh.canon_fp(st[INV["id"]])
    # the floor measured for the old gate state is stale until floor runs again
    rows = {r["id"]: r for r in store.gated(MODEL, mmh.FAMILY).values()}
    mmh.build(MODEL, runner=runner)
    rows = {r["id"]: r for r in store.gated(MODEL, mmh.FAMILY).values()}
    assert rows[INV["id"]]["gate"]["reasons"][0].startswith("floor: stale")


def test_generate_reasks_a_changed_text(tmp_model):
    runner = FakeRunner()
    mmh._generate(MODEL, "gen1", [("x|b", INV["b"], False)], runner)
    n = len(runner.calls)
    mmh._generate(MODEL, "gen1", [("x|b", INV["b"], False)], runner)
    assert len(runner.calls) == n  # same text: cached
    mmh._generate(MODEL, "gen1", [("x|b", INV2["b"], False)], runner)
    assert len(runner.calls) == n + 1  # same key, new text: asked again


def test_item_level_upper_bound_fails_a_clustered_leak(tmp_model, tmp_path):
    """R46 with n > 1: mean within the bar, the item-level bound over it (2 items, 0/5 and 5/5
    vs 2 items 1/5 each would differ); here blind 1/10 total but all on one item."""
    _r, rows = _all()
    draws = {i: {"blind": [0], "described": [0]} for i in rows}
    store.write_json(mmh.work_dir(MODEL) / "lucky_screen.json", {"round": 1, "draws": draws})
    run.freeze(MODEL, [mmh.FAMILY])
    ids = [INV["id"], CUT["id"]]
    src = tmp_path / "cl"
    _write_baseline(
        src, {ids[0]: {"blind": 2, "described": 0}, ids[1]: {"blind": 0, "described": 0}}
    )
    rec = mmh.confirm(MODEL, str(src))
    assert rec["rates_pre_drop"]["blind"] == pytest.approx(0.2)  # within 0.2 + 0.05
    assert rec["upper90"]["blind"] > 0.25 and rec["pass"] is False


def test_pooled_binomial():
    assert mmh.binom_sf(0, 10, 0.3) == pytest.approx(1.0)
    assert mmh.binom_sf(5, 10, 0.25) == pytest.approx(0.0781, abs=1e-3)
    assert mmh.pooled_out({"blind": [3, 3], "described": [0, 0]}, 5)  # 6/10 at p0 .25
    assert not mmh.pooled_out({"blind": [2, 2], "described": [0, 0]}, 5)  # 4/10


def test_leak_fails_the_gate(tmp_model, monkeypatch):
    q = "In which year was the current flagship Foo phone, the Foo X3, released? "
    cut_leak = {**CUT, "m2": q + SFX.format(t="year")}  # the read question names its bridge
    pool = {"header": {}, "invented": [INV], "cutoff": [cut_leak]}
    monkeypatch.setattr(mmh, "load_pool", lambda: pool)
    _r, rows = _all()
    assert rows[CUT["id"]]["gate"]["reasons"] == ["gate: leak"]


def test_identifiability_by_foil_truth_alone():
    s = {
        "cat": "cutoff",
        "b_mode": "Foo X3",
        "foils": [{"name": "Foo X2", "attr": "2024"}],
        "foil_names": ["Foo X2"],
        "m": "q",
        "m2": "q2",
        "af": ["a0"],
    }
    out = {
        f"i|x|{p}": {"text": "t", "greedy": "2024", "samples": ["2024"] * 20}
        for p in ("m", "m2", "a")
    }
    out["i|x|af0"] = {"text": "t", "greedy": "1999", "samples": []}  # A_f differs ...

    def ask(prompt, valid=None):
        a = json.loads(re.search(r"second-hop fact\): (\[.*\])", prompt).group(1))
        return {"bridge": {}, "attr": {x: x for x in a}, "aliases": {}}

    g = mmh._gate_one("i|x", s, out, ask)
    assert g["fail2"] == "identifiability"  # ... but the foil's TRUE value equals the answer


def test_screen_leaves_a_failed_draw_item_unscreened(tmp_model, tmp_path, monkeypatch):
    _all()
    out = tmp_path / "scr"
    _write_baseline(
        out,
        {INV["id"]: {"blind": 0, "described": 0}, CUT["id"]: {"blind": 0, "described": 0}},
        fail=(CUT["id"],),
    )
    bank = json.loads((mmh.work_dir(MODEL) / "candidates.json").read_text())
    bank["items"] = bank["items"] * 1
    for k in range(3):  # >= 4 candidates for the described guesser
        bank["items"].append({**bank["items"][0], "id": f"extra{k}"})
    store.write_json(mmh.work_dir(MODEL) / "candidates.json", bank)
    monkeypatch.setattr(mmh, "_baseline", lambda env, res, log: mmh.read_hits(out))
    monkeypatch.setattr(mmh, "failed_draw_ids", lambda res: {CUT["id"]})
    lk = mmh.lucky(MODEL, out=str(out))
    assert INV["id"] in lk["draws"] and CUT["id"] not in lk["draws"]
