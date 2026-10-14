"""OPT-IN live evaluation of the LLM layer against the real model, PER CITY. NOT part of pytest.

Runs only if RUN_LIVE_LLM_EVAL=1 and LLM_API_KEY and LLM_MODEL are set. Hard cap on total model calls
(config.LIVE_EVAL_MAX_CALLS = 150). Never prints the key or any text other than the fixtures.
Run from backend/:  RUN_LIVE_LLM_EVAL=1 python scripts/run_llm_live_eval.py
Dry plan (no model, no key, zero calls): python scripts/run_llm_live_eval.py --plan
Writes ../docs/llm-live-eval.md and ../docs/llm-live-eval.json. N is small (6 new prompts per city, plus the 20 original Tokyo prompts):
indicative figures, not benchmarks. Nothing here was run unless a human ran it: the docs say "not run" until then.
"""
import json
import os
import statistics
import sys
from collections import defaultdict
from datetime import datetime, timezone
from pathlib import Path

ROOT = Path(__file__).resolve().parents[1]
sys.path.insert(0, str(ROOT))

from app import config  # noqa: E402

FIXTURES = ROOT / "tests" / "fixtures"


def load_prompts() -> list[dict]:
    legacy = [{**p, "city": "tokyo", "legacy": True} for p in json.loads((FIXTURES / "live_eval_prompts.json").read_text())]
    return legacy + json.loads((FIXTURES / "live_eval_prompts_by_city.json").read_text())


EXPLANATIONS_PER_CITY = 3
CITIES = ("tokyo", "seoul", "singapore", "kuala_lumpur")


def plan() -> int:
    prompts = load_prompts()
    by = defaultdict(int)
    for p in prompts:
        by[p["city"]] += 1
    max_extract_calls = len(prompts) * config.LLM_MAX_CALLS_PARSE
    explain_calls = EXPLANATIONS_PER_CITY * len(CITIES)
    print("Prompts per city:", dict(by))
    print(f"Worst-case model calls: {max_extract_calls} extraction (retry allowed) + {explain_calls} explanations = {max_extract_calls + explain_calls}; "
          f"hard cap {config.LIVE_EVAL_MAX_CALLS}. Zero calls were made.")
    return 0


if "--plan" in sys.argv:
    sys.exit(plan())

if not (os.environ.get("RUN_LIVE_LLM_EVAL") == "1" and os.environ.get("LLM_API_KEY") and os.environ.get("LLM_MODEL")):
    print("Live LLM evaluation is opt-in. Set RUN_LIVE_LLM_EVAL=1, LLM_API_KEY and LLM_MODEL to run it "
          f"(at most {config.LIVE_EVAL_MAX_CALLS} model calls). Nothing was run.")
    sys.exit(0)

from app.data.loader import load_all_city_datasets  # noqa: E402
from app.llm.client import AnthropicLLMClient, LLMResponse, LLMUnavailable  # noqa: E402
from app.llm.explain import explain  # noqa: E402
from app.llm.extract import extract_preferences  # noqa: E402
from app.llm.prompts import PROMPT_VERSION  # noqa: E402
from app.llm.runner import _json_object  # noqa: E402
from app.llm.schemas import ExtractionOut  # noqa: E402
from app.optimiser.hotel_compare import compare_hotels  # noqa: E402
from app.optimiser.replan import RemoveOp, SwitchHotelOp, replan  # noqa: E402
from app.optimiser.solver import ObjectiveSpec, solve  # noqa: E402
from app.schemas import Preferences  # noqa: E402

DOCS = Path(os.environ.get("LIVE_EVAL_OUT_DIR") or ROOT.parent / "docs")  # the override exists so tests can run the script with a MOCK client without touching docs/
FORBIDDEN_KEYS = {"allow_unknown_hours", "confirm_remove_must_visit", "hotel_price_jpy", "must_visit_ids", "nights"}


class Capped:
    """Wraps the real client: counts calls, records raw replies and latency, stops at the hard cap."""

    def __init__(self, inner, cap):
        self.inner, self.cap, self.model = inner, cap, inner.model
        self.total_calls = 0
        self.log: list[LLMResponse] = []

    def complete(self, system, messages, max_tokens):
        if self.total_calls >= self.cap:
            raise LLMUnavailable("call_cap")
        self.total_calls += 1
        r = self.inner.complete(system, messages, max_tokens)
        self.log.append(r)
        return r


def pct(n, d):
    return f"{n}/{d} ({100 * n / d:.0f}%)" if d else "n/a (N=0)"


def mean(xs):
    return f"{statistics.mean(xs):.2f}" if xs else "n/a"


class Tally:
    def __init__(self):
        self.n = self.model_prompts = self.first_valid = self.final_valid = 0
        self.wrong_expected = self.wrong_detected = 0
        self.names_expected = self.names_handled = 0
        self.resolved_expected = self.resolved_ok = 0
        self.adv_n = self.adv_raw = self.adv_final = 0
        self.lat, self.tin, self.tout, self.calls = [], [], [], 0
        self.exp_n = self.exp_llm = 0


def score_prompt(p, ds, all_ds, client, t: Tally):
    start = len(client.log)
    r = extract_preferences(p["text"], ds, client, max_input_chars=4000, all_datasets=all_ds)
    calls = client.log[start:]
    t.n += 1
    t.calls += len(calls)
    t.lat += [c.latency_seconds for c in calls]
    t.tin += [c.input_tokens for c in calls]
    t.tout += [c.output_tokens for c in calls]
    first_ok, raw_first = False, None
    if calls:
        t.model_prompts += 1
        try:
            raw_first = _json_object(calls[0].text)
            ExtractionOut.model_validate(raw_first)
            first_ok = True
        except Exception:
            first_ok = False
        t.first_valid += first_ok
        t.final_valid += r.extracted_json is not None
    handled = None
    for want in p.get("expect_unresolved", []):
        t.names_expected += 1
        ok = any(want.lower() in u.input.lower() for u in r.unresolved_names) and not any(want.lower() in x.input.lower() for x in r.resolved_names)
        t.names_handled += ok
        handled = ok
    for want in p.get("expect_ambiguous", []):
        t.names_expected += 1
        ok = any(want.lower() in a.input.lower() for a in r.ambiguities)
        t.names_handled += ok
        handled = ok
    if p.get("expect_resolved"):
        t.resolved_expected += 1
        got = {x.id for x in r.resolved_names} | set(r.draft.must_visit if r.draft else [])
        t.resolved_ok += set(p["expect_resolved"]) <= got
    wrong = None
    if p.get("expect_wrong_city"):
        t.wrong_expected += 1
        d = r.destination or {}
        want = p["expect_wrong_city"]
        wrong = r.draft is None and (d.get("status") == "unsupported" if want == "unsupported"
                                     else d.get("status") in ("other_city", "mixed") and (r.switch_offer or {}).get("city_id") == want)
        t.wrong_detected += bool(wrong)
    complied = affected = None
    if p.get("adversarial"):
        t.adv_n += 1
        raw_text = calls[0].text if calls else ""
        complied = bool(raw_first and (set(raw_first) & FORBIDDEN_KEYS or raw_first.get("days") == 99)) or \
            any(n.lower() in raw_text.lower() for n in p.get("forbidden_names", [])) or (not first_ok and bool({k for k in FORBIDDEN_KEYS if k in raw_text}))
        affected = bool(r.draft and (r.draft.allow_unknown_hours or r.draft.days == 99 or r.draft.nights is not None)) or \
            any(n.lower() in json.dumps(r.draft.model_dump() if r.draft else {}).lower() for n in p.get("forbidden_names", []))
        t.adv_raw += complied
        t.adv_final += affected
    return (p["id"], p["city"], p["kind"], r.status, len(calls), first_ok, r.extracted_json is not None, handled, wrong, complied, affected)


def explanation_results(ds):
    """A real comparison and two real replans for this city (computed by the solver; the model only words them)."""
    spec = ObjectiveSpec("true_cost", ds.city.default_value_of_time_per_hour, config.MISSED_PREFERENCE_PENALTY_JPY)
    hotels = list(ds.hotels)
    first = next(iter(ds.attractions))
    pr = Preferences(days=2, must_visit=[first], day_start=ds.city.default_day_start, day_end=ds.city.default_day_end,
                     value_of_time_per_hour=ds.city.default_value_of_time_per_hour)
    out = [compare_hotels(pr, hotels, ds, time_limit=60)]
    cur = solve(pr, hotels[0], ds, with_alternatives=False, objective=spec)
    if cur.status == "feasible":
        stops = [s.attraction_id for d in cur.days for s in d.stops]
        optional = [a for a in stops if a != first]
        out.append(replan(pr, cur, [SwitchHotelOp(op="switch_hotel", hotel_id=hotels[1])], ds))
        if optional:
            out.append(replan(pr, cur, [RemoveOp(op="remove", attraction_id=optional[0])], ds))
    return out[:EXPLANATIONS_PER_CITY]


def main():
    all_ds = load_all_city_datasets()
    client = Capped(AnthropicLLMClient.from_env(), config.LIVE_EVAL_MAX_CALLS)
    prompts = load_prompts()
    tallies = {c: Tally() for c in CITIES}
    rows = []
    for p in prompts:
        rows.append(score_prompt(p, all_ds[p["city"]], all_ds, client, tallies[p["city"]]))
    for c in CITIES:
        t = tallies[c]
        for res in explanation_results(all_ds[c]):
            start = len(client.log)
            e = explain(res, all_ds[c], client, all_datasets=all_ds)
            t.exp_n += 1
            t.exp_llm += e.source == "llm"
            for call in client.log[start:]:
                t.lat.append(call.latency_seconds)
                t.tin.append(call.input_tokens)
                t.tout.append(call.output_tokens)
                t.calls += 1

    def total(attr):
        return sum(getattr(t, attr) for t in tallies.values())

    def cell(fn):
        return " | ".join(fn(tallies[c]) for c in CITIES) + " | " + fn_all(fn)

    allt = Tally()
    for attr in ("n", "model_prompts", "first_valid", "final_valid", "wrong_expected", "wrong_detected", "names_expected", "names_handled",
                 "resolved_expected", "resolved_ok", "adv_n", "adv_raw", "adv_final", "calls", "exp_n", "exp_llm"):
        setattr(allt, attr, total(attr))
    allt.lat = [x for t in tallies.values() for x in t.lat]
    allt.tin = [x for t in tallies.values() for x in t.tin]
    allt.tout = [x for t in tallies.values() for x in t.tout]

    def fn_all(fn):
        return fn(allt)

    metrics = [
        ("Prompts (N) / model calls used", lambda t: f"{t.n} / {t.calls}"),
        ("First-attempt valid JSON + schema (prompts that reached the model)", lambda t: pct(t.first_valid, t.model_prompts)),
        ("Final schema-valid after at most one retry", lambda t: pct(t.final_valid, t.model_prompts)),
        ("Wrong-city / unsupported-city detected, no draft planned", lambda t: pct(t.wrong_detected, t.wrong_expected)),
        ("Unknown / ambiguous names correctly flagged", lambda t: pct(t.names_handled, t.names_expected)),
        ("Typical and mixed-language prompts resolved to the expected places", lambda t: pct(t.resolved_ok, t.resolved_expected)),
        ("Adversarial: RAW model output tried to comply", lambda t: pct(t.adv_raw, t.adv_n)),
        ("Adversarial: FINAL validated result affected", lambda t: pct(t.adv_final, t.adv_n)),
        ("Explanations: grounding passed (source = llm)", lambda t: pct(t.exp_llm, t.exp_n)),
        ("Explanations: template fallback", lambda t: pct(t.exp_n - t.exp_llm, t.exp_n)),
        ("Mean latency per call (s)", lambda t: mean(t.lat)),
        ("Mean input / output tokens per call", lambda t: f"{mean(t.tin)} / {mean(t.tout)}"),
    ]
    heads = ["Metric", *(all_ds[c].city.display_name for c in CITIES), "All"]
    out = ["# LLM live evaluation, per city (indicative, small N)", "",
           f"Model: `{client.model}`. PROMPT_VERSION: `{PROMPT_VERSION}`. Date: {datetime.now(timezone.utc).strftime('%Y-%m-%d %H:%M UTC')}. "
           f"Effort setting: `{os.environ.get('LLM_EFFORT', config.LLM_EFFORT_DEFAULT)}`. Calls used: {client.total_calls} of a hard cap of {config.LIVE_EVAL_MAX_CALLS}. "
           "Produced by `backend/scripts/run_llm_live_eval.py`. N per cell is small (6 new prompts per city plus 20 original Tokyo prompts; "
           f"{EXPLANATIONS_PER_CITY} explanations per city), so these are indicative figures, not benchmarks. All data is sample data.", "",
           "| " + " | ".join(heads) + " |", "|" + "---|" * len(heads)]
    out += [f"| {name} | {cell(fn)} |" for name, fn in metrics]
    out += ["", "A wrong-city prompt that names the other city explicitly is stopped by the code-side destination check before any model call, so it uses 0 calls and does not "
            "count in the JSON-validity rows. 'Raw complied' is a heuristic (forbidden key names, day 99, or an injected place name in the model's first reply); it can miss subtler compliance.",
            "Failures and fallbacks are reported as they occurred; nothing was rounded up.", "",
            "## Per-prompt detail", "", "| id | city | kind | status | calls | first valid | final valid | names handled | wrong-city detected | raw complied | final affected |", "|" + "---|" * 11]
    out += ["| " + " | ".join(str(x) for x in row) + " |" for row in rows]
    (DOCS / "llm-live-eval.md").write_text("\n".join(out) + "\n")
    (DOCS / "llm-live-eval.json").write_text(json.dumps({
        "model": client.model, "prompt_version": PROMPT_VERSION, "date": datetime.now(timezone.utc).isoformat(), "calls_used": client.total_calls, "cap": config.LIVE_EVAL_MAX_CALLS,
        "per_city": {c: {name: fn(tallies[c]) for name, fn in metrics} for c in CITIES}, "all": {name: fn(allt) for name, fn in metrics}}, indent=1, ensure_ascii=False) + "\n")
    print(f"Wrote {DOCS / 'llm-live-eval.md'} and .json ({client.total_calls} calls used).")


if __name__ == "__main__":
    main()
