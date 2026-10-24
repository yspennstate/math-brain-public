#!/usr/bin/env python3
"""green_act_guard.py - the act-keyed guard for the green_not_trusted family.

WHY. The iteration-2 miss budget (miss_budget.py, MISS_BUDGETS.md) measured the
graph-token channel missing the green family completely: 14/14 owner corrections of
the "you said it worked / was set / connected - it wasn't" shape, median margin
-4.30, the largest KL-form entry (eps^2 16.9). The token channel cannot chase this
family without blowing its 1.5% false-alarm budget because the family's live wording
is plain ("no, it did not connect") and situation-specific. The diffusion frame says
why and what instead: the miss is Proposition 11.6 (training wordings control
nothing off themselves), and the guard has to key on the ACT - an outgoing
completed/effective-state claim without a verifying observation - not on scar
vocabulary. Existing act machinery: pre_report._DONE (artifact-completion verbs:
finalized/populated/shipped...) and reality_monitor (runtime-success claims: it
works/deployed/tests pass). This guard covers the effective-STATE claims between
them - set/enabled/connected/filled/went through/should work now - the vocabulary of
the 14 missed corrections.

FIRE = CLAIM (effective-state assertion) and not GROUNDED (no verification evidence
in the same turn) and not HEDGED (pre_report's hedge class - a hedged claim is the
honest kind).

MEASUREMENT (run this file):
  positives, two sets reported separately and never conflated:
    raw    - the 14 green_not_trusted correction situation wordings (owner voice;
             same basis as the 83% miss number; a family-coverage proxy);
    agent  - independent agent-voice held-out positives (n=1 today; the live
             surface sees agent prose, so this is the honest live estimate and it
             is THIN - building an agent-voice corpus from transcripts is named
             follow-on work, not silently skipped).
  baselines: pre_report._DONE alone and reality_monitor's claim regex alone, on the
             same positives - the guard must ADD family coverage, not duplicate.
  negatives: 2,500 prose negatives (rate + the actual fired lines printed for
             eyeball - the corpus predates this pattern class, so the examples, not
             just the rate, decide) and 2,500 typical tool actions (expected ~0).

PRE-REGISTERED SHIP RULE (before any wiring): SHADOW-ONLY (log, never block), and
only if raw-family fires >= 10/14 AND prose false-alarm <= 2% with the fired
examples showing no dominant benign-narration class AND >= 4 family catches over
the best existing baseline. A live false-alarm rate from the shadow log must exist
before any block wiring is even proposed. If the rule fails: no ship, and the
per-case shortfall table below is the deliverable.

check(text) -> dict is the runtime entry point (importable by pre_report_check's
shadow pass). Fail-safe: any error -> no fire.

VERDICT (2026-07-23, first measurement): NOT SHIPPED - the pre-registered rule
failed, and the failure is informative. Raw family wordings 0/14: those are OWNER-
VOICE corrections ("i don't see this as yolo mode") - they describe the failure and
do not contain the agent's claim sentence, so they are the WRONG positive corpus
for an act-keyed guard; the 83% token-channel miss number stands on them, an
act-guard cannot be graded on them. Agent-voice positives n=1, and pre_report._DONE
already catches it (the vocabularies were deliberately disjoint; family coverage is
the UNION of this guard, _DONE, and reality_monitor). Negative side measured and
clean: 0.76% on 2,500 prose negatives (eyeballed - several fired lines are real
ungrounded claims; two are grounded claims the GROUND regex missed: evidence like
"count = 0" and "37 pages, no empty pages"), 0.08% on 2,500 tool actions. The
missing ingredient is a real agent-voice claim corpus: the corrections carry session
ids, so the claim sentences that PRECEDED each correction are minable from
11_raw_session_transcripts - that mining is the named prerequisite before this
guard can be measured, shadow-shipped, or discarded on evidence.

VERDICT 2 (2026-07-23 evening, checkpoint): the mining happened (mine_green_claims.py,
green_claim_corpus.jsonl - 14/14 corrections, 9/9 sessions, the turn each correction
interrupted, provenance per row). On the mined agent-voice turns this guard fires
0/14 with an in-corpus positive control (the same checker parsed 2 rows as
grounded/hedged, so the zero is a working detector's zero); the baselines catch what
claim language is present - reality_monitor 5/14, pre_report._DONE 2/14, text union
7/14. STILL NOT SHIPPED, now on right-corpus evidence. Two findings that outlive the
guard: the interrupted turn is not always the claim turn (window-widening named as
the refinement; 7/14 is a lower bound), and the really_live row - claim language
WITH grounding language, still wrong - shows the ceiling of every text-level guard:
grounding prose is not grounding reality. The next guard in this family must be
keyed to acts and inputs (the conditioning-completeness class in
READING_NOTES_20260723.md), not to wording.
"""
import io, json, os, re, sys

HERE = os.path.dirname(os.path.abspath(__file__))
DR = os.path.dirname(HERE)
sys.path.insert(0, HERE)
sys.path.insert(0, DR)

# effective-state completion claims - the vocabulary of the 14 missed corrections,
# deliberately excluding what pre_report._DONE and reality_monitor already own
CLAIM = re.compile(
    r"\b(should (now )?(work|fill|trigger|connect)|works? (now|overnight|as (expected|intended))|"
    r"is (now )?(implemented|set|enabled|active|in effect|applied|connected|anchored|configured|"
    r"switched|updated|corrected|fixed)|has been (set|applied|implemented|enabled|updated|changed|fixed)|"
    r"(went|goes) through|did (go|fill|connect|apply)|will (now )?(fill|work|trigger|apply)|"
    r"(mode|flag|setting|anchor|limit|order)s? (is|are) (on|set|enabled|active|new|updated|changed|in place)|"
    r"took effect|is live now|now live|are in place|change (is|took)|it connected|connection (is )?"
    r"(up|established|restored)|filled (overnight|correctly|as expected)|trades? went through|"
    r"orders? (was|were|are) (placed|filled|working)|(re)?started (it|the \w+) successfully)\b", re.I)

GROUND = re.compile(
    r"\b(verified|confirmed|exit(ed)?( code)? 0|output (shows|below|above)|shows?:|grep(ped)?|diff|"
    r"screenshot|log (shows|tail|line)|ran (it|the|a)|re-?ran|reproduc\w+|checked (it|the|that|and)|"
    r"observed|returned|prints?( |ed)|assert\w* (passed|ok|held)|tests? (passed|green)|\d+ (passed|of \d+)|"
    r"rank \d|n\s?=\s?\d|I (see|saw|watched|opened|read)|here is the|as shown|the output|fill (report|log)|"
    r"execution report|broker (shows|confirms)|status (shows|is) )", re.I)

try:
    from pre_report import _HEDGE as HEDGE, _DONE as DONE_BASE
except Exception:
    HEDGE = re.compile(r"\b(should|might|may|probably|likely|roughly|about|approximately|estimate|"
                       r"not sure|unverified|assuming|haven'?t (verified|checked))\b", re.I)
    DONE_BASE = re.compile(r"\b(finali[sz]ed|populated|completed|shipped|all set|good to go)\b", re.I)

_RM_CLAIM = None
try:
    import importlib.util as _ilu
    _spec = _ilu.spec_from_file_location("reality_monitor", os.path.join(DR, "reality_monitor.py"))
    _rm = _ilu.module_from_spec(_spec); _spec.loader.exec_module(_rm)
    for _name in dir(_rm):
        _v = getattr(_rm, _name)
        if isinstance(_v, re.Pattern) and "it works" in _v.pattern:
            _RM_CLAIM = _v
            break
except Exception:
    _RM_CLAIM = None


def check(text):
    """Act-keyed green-family check. {fired, claim, grounded, hedged} - fail-safe."""
    try:
        t = text or ""
        claim = bool(CLAIM.search(t))
        grounded = bool(GROUND.search(t))
        hedged = bool(HEDGE.search(t))
        # a hedge only excuses the claim when no flat assertion co-occurs; keep it
        # simple and honest: hedged text does not fire (the honest kind of claim)
        return {"fired": claim and not grounded and not hedged,
                "claim": claim, "grounded": grounded, "hedged": hedged}
    except Exception:
        return {"fired": False, "claim": False, "grounded": False, "hedged": False}


def _green_positives():
    import miss_budget as MB
    out = []
    for situation, ids in MB.parse_corrections():
        if "green_not_trusted" in ids:
            out.append(situation)
    return out


def main():
    raw = _green_positives()
    print("raw green-family situation wordings: %d" % len(raw))
    held = []
    try:
        h = json.load(io.open(os.path.join(HERE, "heldout_cases.json"), encoding="utf-8"))
        held = [p.get("text", "") for p in h.get("positives", [])
                if "green_not_trusted" in (p.get("expect") or [])]
    except Exception:
        pass

    def run_set(name, texts):
        fired = []
        base_done = base_rm = 0
        for t in texts:
            r = check(t)
            fired.append(r["fired"])
            if DONE_BASE.search(t or ""):
                base_done += 1
            if _RM_CLAIM is not None and _RM_CLAIM.search(t or ""):
                base_rm += 1
        n = len(texts)
        print("\n%s (n=%d): guard fires %d  | baselines: pre_report._DONE %d, reality_monitor %d"
              % (name, n, sum(fired), base_done, base_rm))
        for t, f in zip(texts, fired):
            if not f:
                r = check(t)
                why = ("no CLAIM match" if not r["claim"] else
                       ("grounded" if r["grounded"] else ("hedged" if r["hedged"] else "?")))
                print("   MISS (%s): %s" % (why, t[:110].replace("\n", " ")))
        return sum(fired), base_done, base_rm

    g_raw, bd_raw, brm_raw = run_set("RAW family wordings (owner voice, coverage proxy)", raw)
    if held:
        run_set("AGENT-voice held-out positives (thin - n=%d)" % len(held), held)

    for label, path, key in (("prose negatives", os.path.join(HERE, "prose_negatives.jsonl"), None),
                             ("typical tool actions", os.path.join(HERE, "typical_actions.jsonl"), "text")):
        try:
            rows = [json.loads(l) for l in io.open(path, encoding="utf-8") if l.strip()]
            texts = [r if key is None else (r.get(key, "") if isinstance(r, dict) else str(r))
                     for r in rows]
        except Exception:
            continue
        fires = [(i, t) for i, t in enumerate(texts) if check(t)["fired"]]
        print("\nNEGATIVE %s (n=%d): %d fire (%.2f%%)" % (label, len(texts), len(fires),
                                                          100.0 * len(fires) / max(1, len(texts))))
        for _i, t in fires[:8]:
            print("   FIRED: %s" % str(t)[:110].replace("\n", " "))

    print("\nShip rule: shadow-only; raw >= 10/14, prose false-alarm <= 2%% with clean "
          "eyeball, >= 4 catches over best baseline. Raw fires: %d/14, best baseline on raw: %d."
          % (g_raw, max(bd_raw, brm_raw)))
    return 0


if __name__ == "__main__":
    sys.exit(main())
