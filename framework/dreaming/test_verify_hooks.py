# -*- coding: utf-8 -*-
"""Controls for verify_gate.py (Stop) and verify_sense.py (prompt), both ways (30 Sep 2026).

    python test_verify_hooks.py [gate|sense|all] [--old-gate PATH]

Each control builds a synthetic Claude transcript or Codex rollout in a temporary directory and feeds the hook the
payload the runtime would send. A gate that blocks everything is as broken as one that blocks nothing, so every rule
has silent controls beside its firing ones: a claim backed by a check that ran after the last edit, a labelled status,
a claim about recorded earlier work, a chat reply, and the loop guard (one block per rule per session).
"""
import importlib.util
import json
import os
import sys
import tempfile
import time

HERE = os.path.dirname(os.path.abspath(__file__))
FAILS = []


def check(name, ok, detail=""):
    print("%s %s%s" % ("PASS" if ok else "FAIL", name, (" - " + detail) if detail else ""))
    if not ok:
        FAILS.append(name)


def load(path, name):
    spec = importlib.util.spec_from_file_location(name, path)
    mod = importlib.util.module_from_spec(spec)
    spec.loader.exec_module(mod)
    return mod


def claude_transcript(path, prompt, steps, final):
    """steps: ("cmd", command, output[, is_error]) / ("edit", file_path) / ("write", file_path)."""
    rows = [{"type": "user", "message": {"role": "user", "content": "earlier prompt"}},
            {"type": "assistant", "message": {"role": "assistant", "content": [{"type": "text", "text": "old turn"}]}},
            {"type": "user", "message": {"role": "user", "content": prompt}}]
    n = 0
    for st in steps:
        n += 1
        tid = "toolu_%03d" % n
        if st[0] == "cmd":
            rows.append({"type": "assistant", "message": {"role": "assistant", "content": [
                {"type": "tool_use", "id": tid, "name": "Bash", "input": {"command": st[1]}}]}})
            rows.append({"type": "user", "toolUseResult": {"stdout": st[2]}, "message": {"role": "user", "content": [
                {"type": "tool_result", "tool_use_id": tid, "content": st[2], "is_error": bool(st[3:] and st[3])}]}})
        else:
            rows.append({"type": "assistant", "message": {"role": "assistant", "content": [
                {"type": "tool_use", "id": tid, "name": "Edit" if st[0] == "edit" else "Write",
                 "input": {"file_path": st[1], "old_string": "a", "new_string": "b"}}]}})
            rows.append({"type": "user", "toolUseResult": {}, "message": {"role": "user", "content": [
                {"type": "tool_result", "tool_use_id": tid, "content": "updated"}]}})
    rows.append({"type": "assistant", "message": {"role": "assistant", "content": [{"type": "text", "text": final}]}})
    with open(path, "w", encoding="utf-8") as fh:
        for r in rows:
            fh.write(json.dumps(r) + "\n")


def codex_rollout(path, steps, final, prompts=()):
    rows = [{"type": "event_msg", "payload": {"type": "task_started", "turn_id": "t1"}}]
    for k, p in enumerate(prompts):
        rows.append({"type": "event_msg", "payload": {"type": "item_completed", "item": {
            "type": "UserMessage", "id": "um-%d-%s" % (k, abs(hash(p)) % 10 ** 8), "content": [{"type": "text", "text": p}]}}})
    for st in steps:
        if st[0] == "cmd":
            rows.append({"type": "event_msg", "payload": {"type": "item_completed", "item": {
                "type": "CommandExecution", "id": "exec-%d" % len(rows), "command": ["powershell.exe", "-Command", st[1]],
                "exit_code": "1" if (st[3:] and st[3]) else "0", "aggregated_output": st[2]}}})
        else:
            rows.append({"type": "event_msg", "payload": {"type": "item_completed", "item": {
                "type": "FileChange", "id": "fc-%d" % len(rows), "changes": {st[1]: {"type": "update"}}}}})
    rows.append({"type": "event_msg", "payload": {"type": "item_completed", "item": {
        "type": "AgentMessage", "content": [{"type": "Text", "text": final}]}}})
    with open(path, "w", encoding="utf-8") as fh:
        for r in rows:
            fh.write(json.dumps(r) + "\n")


def gate_cases(gate_path):
    g = load(gate_path, "verify_gate_under_test")
    td = tempfile.mkdtemp(prefix="vgate_")
    g.STATE = os.path.join(td, "state.json")
    g.LOG = os.path.join(td, "log.jsonl")
    g.SHADOW = os.path.join(td, "no_shadow")
    n = [0]

    def run(steps, final, session=None, runtime="claude", payload_final=False, active=False, prompt="do the work",
            prompts=()):
        n[0] += 1
        tp = os.path.join(td, "t%d.jsonl" % n[0])
        if runtime == "codex":
            codex_rollout(tp, steps, final, prompts)
        else:
            claude_transcript(tp, prompt, steps, final)
        data = {"hook_event_name": "Stop", "session_id": session or "s%d" % n[0], "transcript_path": tp,
                "stop_hook_active": active}
        if payload_final:
            data["last_assistant_message"] = final
        return g.decide(data, runtime)

    def blocked(out, rule=None):
        return bool(out and out.get("decision") == "block" and (rule is None or ("[verify-gate %s]" % rule) in out["reason"]))

    # R1
    out = run([("edit", "C:/repo/src/mod.py"), ("cmd", "python -m pytest tests/test_mod.py -q", "12 passed"),
               ("edit", "C:/repo/src/mod.py")], "Fixed the off-by-one; all 12 tests pass.")
    check("R1 fires: a file checked earlier was edited again after its test", blocked(out, "R1"), out and out["reason"][:90])
    out = run([("edit", "C:/repo/src/mod.py"), ("cmd", "python -m pytest tests/test_mod.py -q", "12 passed")],
              "Fixed the off-by-one; all 12 tests pass.")
    check("R1 silent: the test ran after the last edit", out is None)
    out = run([("cmd", "python -m pytest tests/test_other.py -q", "3 passed"), ("edit", "C:/repo/src/mod.py")],
              "Fixed the off-by-one; all tests pass.")
    rows = [json.loads(l) for l in open(g.LOG, encoding="utf-8")]
    check("R1w logged, not blocked: an edit no check in the turn had run", out is None and rows[-1].get("rule") == "R1w")
    out = run([("edit", "C:/repo/src/mod.py")], "Fixed the parser. I have not run the tests yet.")
    check("R1 silent: the message says the check did not run", out is None)
    out = run([("cmd", "python -m pytest -q", "3 passed"), ("edit", "C:/repo/README.md")], "Fixed the README; tests pass.")
    check("R1 silent: the edit after the test was not code", out is None)
    out = run([("edit", "C:/repo/src/mod.py")], "Fixed it - the bug is resolved now.")
    check("R1 fires: code edited and nothing run at all", blocked(out, "R1"))
    out = run([("cmd", "python gen.py --check", "ok"), ("cmd", "cat > C:/repo/src/gen.py <<'EOF'\nx=1\nEOF", "")],
              "Verified that the generator works.")
    check("R1 fires: a checked file rewritten by a shell redirect after its check", blocked(out, "R1"))
    out = run([("edit", "C:/repo/src/mod.py"), ("cmd", "git diff --stat", "1 file changed")], "Fixed; verified the diff.")
    check("R1 fires: reading a diff is not a check", blocked(out, "R1"))
    out = run([("cmd", "python run.py", "ok"), ("edit", "C:/repo/launch_queue.sh")], "The runner is fixed and verified.")
    check("R1 silent: a launcher script edited after the check", out is None)
    out = run([("cmd", "python -m pytest -q", "3 passed")], "A size check passes a truncated file, so I read every board.")
    check("R1 silent: a descriptive sentence is not a claim", out is None)
    out = run([("edit", "C:/repo/src/mod.py")], "WHAT I WAS TOLD TO DO: fix the parser.\nWHAT I HAVE DONE SO FAR: fixed it; "
              "all tests pass.")
    check("silent on the stop summary's session recap", out is None)

    # R2
    out = run([("cmd", "python solve.py", "ok")], "The lemma is now Lean-checked and sorry-free.")
    check("R2 fires: a Lean claim with no Lean run", blocked(out, "R2"))
    out = run([("cmd", "python C:/Users/me/.claude/dreaming/lean_check.py --file Bound.lean --target Bound "
                "--reviewed-sha256 ab12", "FORMAL_TARGET_VERIFIED in 3.1s")],
              "Lean accepts the bound; the proof is kernel-checked.")
    check("R2 silent: the receipt verified the named target", out is None)
    out = run([("cmd", "python lean_check.py --file Bound.lean", "COMPILED_NO_NAMED_TARGET in 3.1s", True)],
              "The proof is kernel-checked.")
    check("R2 fires: a kernel-checked claim on a compile-only receipt", blocked(out, "R2") and
          "certifies no named theorem" in (out or {}).get("reason", ""))
    out = run([("cmd", "python lean_check.py --file Bound.lean", "COMPILED_NO_NAMED_TARGET in 3.1s", True)],
              "The file compiles in Lean.")
    check("R2 silent: a compile claim on a compile-only receipt", out is None)
    out = run([("cmd", "python lean_check.py --file B.lean; echo finished", "COMPILED_NO_NAMED_TARGET in 3.1s\nfinished")],
              "The theorem is Lean-checked.")
    check("R2 fires: a compile-only receipt whose exit an echo hid (PR 184)", blocked(out, "R2"))
    out = run([("cmd", "cat C:/Users/me/.claude/dreaming/lean_check.py", "#!/usr/bin/env python3 ...")],
              "The theorem is Lean-checked.")
    check("R2 fires: reading the checker's source is not a Lean run (PR 184)", blocked(out, "R2") and
          "no Lean command ran" in (out or {}).get("reason", ""))
    out = run([("cmd", "echo 'lake env lean Missing.lean'", "lake env lean Missing.lean")], "The theorem is Lean-checked.")
    check("R2 fires: echoing a Lean command is not a Lean run (PR 184)", blocked(out, "R2"))
    out = run([("cmd", "cd C:/lean/proj && lake env lean Missing.lean", "")], "The theorem is Lean-checked.")
    check("R2 silent: a Lean run after a cd in the same command", out is None)
    out = run([("cmd", "python lean_check.py --file B.lean", "FORMAL_TARGET_VERIFIED in 2.0s")],
              "The new theorem is Lean-checked. A separate calculation remains unverified.")
    check("R2 silent control: the Lean claim is backed", out is None)
    out = run([], "The new theorem is Lean-checked. A separate calculation remains unverified.")
    check("R2 fires: an unverified remark about something else does not excuse the claim (PR 184)", blocked(out, "R2"))
    out = run([("cmd", "lake env lean Bound.lean", "Bound.lean:12:4: error: unsolved goals\n n : Nat", True)],
              "Lean accepts the bound now, so the lemma is machine-checked.")
    check("R2 fires: the last Lean run printed an error", blocked(out, "R2") and "unsolved goals" in (out or {}).get("reason", ""))
    out = run([("cmd", "lake env lean Bound.lean", "warning: declaration uses 'sorry'")],
              "It compiles in Lean, so the theorem is verified in Lean.")
    check("R2 fires: the last Lean run reported a sorry", blocked(out, "R2"))
    out = run([], "The 64 theorems of the cover-time paper are Lean-checked (receipt in the repo, commit 3f2a9c1e).")
    check("R2 silent: a claim about recorded earlier work", out is None)
    out = run([("cmd", "python lean_check.py --file B.lean; python agent_mesh.py bye",
                "FORMAL_TARGET_VERIFIED in 4.0s\nagent_mesh.py bye: error: the following arguments are required: --agent")],
              "The bound is Lean-checked.")
    check("R2 silent: an unrelated command's 'error:' is not a Lean failure", out is None)

    # R3
    out = run([], "I have proved that the bound holds for all n >= 1; the proof is complete.")
    check("R3 fires: a proof claim with nothing run", blocked(out, "R3"))
    out = run([("cmd", "python - <<'EOF'\nprint(all(n*n>=n for n in range(1,10**5)))\nEOF", "True")],
              "I have proved that the bound holds for all n >= 1.")
    check("R3 silent: a computation ran in the turn", out is None)
    out = run([], "Here is a proof sketch; I have not verified the limit interchange in step 3.")
    check("R3 silent: the status is labelled", out is None)
    out = run([], "Sure - the file is in Downloads and the render finished at 14:02.")
    check("silent on a message with no claim", out is None)
    # claim-local hedges (PR 184, finding 1): a hedge qualifies the claim in its own sentence, or in the next one when that
    # one refers back; the noun "conjecture" names a problem and hedges nothing
    for msg in ("The FEI conjecture is solved.", "The conjecture is proved.",
                "The theorem is proved. A separate calculation remains unverified.",
                "The theorem is proved. I also read an earlier receipt."):
        out = run([], msg)
        check("R3 fires: %s" % msg, blocked(out, "R3"))
    for msg in ("The argument is only a conjectural proof sketch.",
                "The theorem was proved previously; the receipt is in the repo.",
                "The theorem is proved. This is only a sketch, though.",
                "It remains a conjecture; the theorem is proved only for n <= 5."):
        out = run([], msg)
        check("R3 silent: %s" % msg, out is None)
    out = run([("cmd", "cat C:/Users/me/.claude/dreaming/lean_check.py", "#!/usr/bin/env python3 ...")],
              "The theorem is proved.")
    check("R3 fires: reading a checker's source is not a computation (PR 184)", blocked(out, "R3"))
    out = run([("cmd", "grep -n pytest C:/repo/setup.cfg", "12: pytest")], "The theorem is proved.")
    check("R3 fires: a search that names a test runner runs nothing", blocked(out, "R3"))
    out = run([("edit", "C:/repo/src/mod.py")], "Fixed the parser. A separate calculation remains unverified.")
    check("R1 fires: an unverified remark about something else does not excuse the fix (PR 184)", blocked(out, "R1"))
    out = run([("edit", "C:/repo/src/mod.py")], "Fixed the parser. I also read an earlier receipt.")
    check("R1 fires: a record reference does not excuse a code claim", blocked(out, "R1"))

    # loop guard and follow-up log
    s = "loop-session"
    first = run([("edit", "C:/repo/a.py")], "Fixed.", session=s)
    second = run([("edit", "C:/repo/a.py")], "Fixed.", session=s, active=True)
    check("loop guard: blocks once per rule per session, never twice", blocked(first, "R1") and second is None)
    rows = [json.loads(l) for l in open(g.LOG, encoding="utf-8")]
    fu = [r for r in rows if r.get("kind") == "followup" and r.get("session") == s]
    check("follow-up: the stop after a block is logged with what changed", bool(fu) and "checks_added" in fu[0])
    third = run([("edit", "C:/repo/a.py")], "I have proved that it holds for all n.", session=s, active=True)
    check("a different rule can still fire once in a continuation", blocked(third, "R3"))

    # turns (30 Sep 03:0x, report D12-T02): a rule blocks once per turn, not once per session
    s = "turn-session"
    a = run([("edit", "C:/repo/a.py")], "Fixed.", session=s, prompt="fix bug a")
    after = run([("edit", "C:/repo/b.py")], "Fixed.", session=s, prompt="fix bug b")
    check("the stop after a block is spared only in its own turn: a new prompt meets the gate at once (PR 184)",
          blocked(a, "R1") and blocked(after, "R1"))
    rows = [json.loads(l) for l in open(g.LOG, encoding="utf-8")]
    fu = [r for r in rows if r.get("kind") == "followup" and r.get("session") == s]
    check("a follow-up in a new turn counts that turn's checks from zero", bool(fu) and fu[-1].get("same_turn") is False)
    quiet = run([], "Here is the list you asked for.", session=s, prompt="list the files")
    b = run([("edit", "C:/repo/b.py")], "Fixed.", session=s, prompt="fix bug c")
    check("a new task in the same session meets the gate again", quiet is None and blocked(b, "R1"))
    run([], "Here is the list.", session=s, prompt="fix bug c")
    again = run([("edit", "C:/repo/b.py")], "Now all 3 tests pass.", session=s, prompt="fix bug c")
    check("inside REARM_S one turn is not blocked twice, even for a new claim", again is None)
    with open(g.STATE, encoding="utf-8") as fh:
        st = json.load(fh)
    st[s]["rules"]["R1"]["t"] -= g.REARM_S + 5
    with open(g.STATE, "w", encoding="utf-8") as fh:
        json.dump(st, fh)
    same = run([("edit", "C:/repo/b.py")], "Fixed.", session=s, prompt="fix bug c")
    new = run([("edit", "C:/repo/b.py")], "Now all 3 tests pass.", session=s, prompt="fix bug c")
    check("after REARM_S the same claim stays unblocked and a new claim is blocked", same is None and blocked(new, "R1"))
    st = json.load(open(g.STATE, encoding="utf-8"))
    st["legacy"] = {"t": time.time(), "rules": {"R1": time.time()}}
    with open(g.STATE, "w", encoding="utf-8") as fh:
        json.dump(st, fh)
    legacy = run([("edit", "C:/repo/c.py")], "Fixed.", session="legacy")
    check("state written before per-turn scoping still loads", blocked(legacy, "R1"))
    # Codex: the turn is his last typed prompt; a goal's resume recorded as a UserMessage does not start a new one
    s, his = "codex-turns", "fix bug x in the parser"
    c1 = run([("edit", "C:/repo/p.py")], "Fixed.", session=s, runtime="codex", prompts=[his])
    run([], "Here is where things stand.", session=s, runtime="codex",
        prompts=[his, "<goal_context> Continue working toward the goal</goal_context>"])
    c3 = run([("edit", "C:/repo/p.py")], "All 4 tests pass now.", session=s, runtime="codex",
             prompts=[his, "<goal_context> Continue working toward the goal</goal_context>"])
    c4 = run([("edit", "C:/repo/q.py")], "Fixed.", session=s, runtime="codex", prompts=[his, "now fix bug y"])
    check("Codex: a goal resume stays in his turn and a new prompt of his re-arms the gate",
          blocked(c1, "R1") and c3 is None and blocked(c4, "R1"))

    # shadow
    open(os.path.join(td, "shadow_on"), "w").close()
    g.SHADOW = os.path.join(td, "shadow_on")
    out = run([("edit", "C:/repo/src/mod.py")], "Fixed; the tests pass.")
    last = [json.loads(l) for l in open(g.LOG, encoding="utf-8")][-1]
    check("shadow: logs the fire, blocks nothing", out is None and last.get("rule") == "R1" and last.get("shadow"))
    g.SHADOW = os.path.join(td, "no_shadow")

    # Codex rollouts
    out = run([("edit", "C:\\repo\\core.py"), ("cmd", "python -m pytest tests\\test_core.py -q", "5 passed"),
               ("edit", "C:\\repo\\core.py")], "All tests pass; fixed.", runtime="codex", payload_final=True)
    check("Codex R1 fires on a FileChange to a file its earlier check ran", blocked(out, "R1"))
    out = run([("edit", "C:\\repo\\core.py"), ("cmd", "python -m pytest -q", "5 passed")], "All tests pass; fixed.",
              runtime="codex", payload_final=True)
    check("Codex R1 silent when the check ran after the edit", out is None)
    out = run([("cmd", "lean_check.py --stmt 'example : 2+2=4 := rfl'", "error: type mismatch", True)],
              "Lean verified the identity.", runtime="codex", payload_final=True)
    check("Codex R2 fires when its Lean run failed", blocked(out, "R2"))
    out = run([("cmd", "cat lean_check.py", "# source")], "The theorem is Lean-checked.", runtime="codex", payload_final=True)
    check("Codex: a read inside the powershell -Command wrapper is not a Lean run", blocked(out, "R2") and
          "no Lean command ran" in (out or {}).get("reason", ""))
    td2 = tempfile.mkdtemp(prefix="vgate_codex_")
    for label, code in (("omitted", "omit"), ("null", None), ("string None", "None"), ("zero", 0)):
        p = os.path.join(td2, "exit_%s.jsonl" % label.replace(" ", "_"))
        item = {"type": "CommandExecution", "id": "exec-1", "command": ["powershell.exe", "-Command",
                "python lean_check.py --file B.lean --target B --reviewed-sha256 ab"], "aggregated_output": "done"}
        if code != "omit":
            item["exit_code"] = code
        rows = [{"type": "event_msg", "payload": {"type": "task_started", "turn_id": "t1"}},
                {"type": "event_msg", "payload": {"type": "item_completed", "item": {
                    "type": "UserMessage", "id": "u1", "content": [{"type": "text", "text": "check it"}]}}},
                {"type": "event_msg", "payload": {"type": "item_completed", "item": item}}]
        with open(p, "w", encoding="utf-8") as fh:
            fh.write("".join(json.dumps(r) + "\n" for r in rows))
        events, _f, _ok, _t = g.codex_turn(p)
        hit, _ev = g.evaluate(events, "The theorem is Lean-checked.")
        want = None if label == "zero" else "R2"
        check("Codex: an exit %s -> %s (PR 184)" % (label, want or "silent"), (hit[0] if hit else None) == want,
              str(hit))


def sense_cases(sense_path):
    s = load(sense_path, "verify_sense_under_test")
    td = tempfile.mkdtemp(prefix="vsense_")
    s.STATE = os.path.join(td, "state.json")
    s.LOG = os.path.join(td, "log.jsonl")
    n = [0]

    def fire(prompt, session=None):
        n[0] += 1
        return s.decide({"hook_event_name": "UserPromptSubmit", "session_id": session or "p%d" % n[0], "prompt": prompt})

    out = fire("prove that the sum of the first n odd numbers is n^2 and check it")
    check("sense fires on a proof task, with the Lean route", bool(out) and "lean_check" in out)
    # a hook's or harness's turn is not his (report D02-T04): Codex delivers the gate's own block this way
    check("sense silent on a Codex hook continuation",
          fire("<hook_prompt hook_run_id=\"x\">[verify-gate R3] Your report says \"proved\" - prove the lemma and fix "
               "the code</hook_prompt>") == "")
    check("sense silent on a goal resume", fire("<goal_context> Continue working toward the goal: prove the lemma "
                                               "and fix the parser.py bug</goal_context>") == "")
    check("sense still reads his prompt that starts with a paste",
          "[verify]" in fire("<pasted_content id=\"1\">traceback ...</pasted_content> fix the bug in parser.py"))
    n[0] += 1
    app = s.decide({"hook_event_name": "UserPromptSubmit", "session_id": "p%d" % n[0],
                    "cwd": "C:\\Users\\me\\AppData\\Local\\OpenAI\\Codex\\bin\\faa963",
                    "prompt": "# Overview\n\nGenerate 0 to 3 hyperpersonalized suggestions. Fix the bug in parser.py."})
    check("sense silent on the Codex app's own background prompt", app == "")
    out = fire("fix the off-by-one in retrieval.py and make sure the tests pass")
    check("sense fires on a code fix, with the negative-control route", bool(out) and "old code" in out)
    out = fire("how are the simulations going? is the box still up?")
    check("sense silent on a status question", not out)
    out = fire("open the report in chrome")
    check("sense silent on an errand", not out)
    sid = "same"
    a = fire("prove the lemma about the Gram matrix", sid)
    b = fire("now prove the corollary too", sid)
    check("sense fires once per kind per session window", bool(a) and not b)
    c = fire("and fix the bug in the loader script", sid)
    check("a different kind in the same session still fires", bool(c))


def ops_cases(ops_path):
    o = load(ops_path, "verify_ops_under_test")
    td = tempfile.mkdtemp(prefix="vops_")
    o.STATE = os.path.join(td, "state.json")
    o.LOG = os.path.join(td, "log.jsonl")
    n = [0]

    def write(path, text, session=None, tool="Write"):
        n[0] += 1
        inp = {"file_path": path, "content": text} if tool == "Write" else {"file_path": path, "new_string": text}
        return o.decide({"tool_name": tool, "tool_input": inp, "session_id": session or "o%d" % n[0]})

    tex = "C:/papers/p/main.tex"
    check("ops divide fires on a bare cancellation", "[verify-op divide]" in write(tex, "Dividing both sides by $x-1$ gives $y = 2$."))
    check("ops divide silent when the nonzero condition is beside it",
          not write(tex, "Since $x \\neq 1$, dividing both sides by $x-1$ gives $y = 2$."))
    check("ops exchange fires on a bare interchange", "[verify-op exchange]" in write(tex, "We interchange the limit and the integral to obtain $\\int f = 0$."))
    check("ops exchange silent under dominated convergence",
          not write(tex, "By dominated convergence ($|f_n| \\le g$ with $g$ integrable) we interchange the limit and the integral."))
    swap = o.decide({"tool_name": "Edit", "session_id": "w1", "tool_input": {
        "file_path": tex, "old_string": "For every $n$ there exists $m$ with $m > n$.",
        "new_string": "There exists $m$ such that for every $n$ we have $m > n$."}})
    check("ops witness fires when an edit swaps for-all/exists into exists/for-all", "[verify-op witness]" in swap)
    check("ops witness silent on a correctly stated exists-then-forall theorem",
          not write(tex, "There is an absolute $C<\\infty$ such that for all sufficiently large $k$ the bound holds."))
    check("ops finite fires on a finite check stated generally", "[verify-op finite]" in write(tex, "We checked for $n \\le 1000$ that the bound holds for all $n$."))
    check("ops finite silent when called numerical evidence",
          not write(tex, "As numerical evidence, we checked for $n \\le 1000$ that the bound holds."))
    check("ops finite silent without a general claim beside it", not write(tex, "The identity is checked for $k\\le 25$ in exact arithmetic."))
    check("ops divide silent on prose 'cancel'", not write(tex, "The two crossings cancel, so the Chern number is $0$."))
    out = write("C:/lean/B.lean", "theorem foo (n : Nat) : n + 0 = n := by\n  sorry\n")
    check("ops sorry fires on a Lean file with sorry, naming the compile command", "[verify-op sorry]" in out and "lean_check.py --file" in out)
    check("ops silent on a Lean file whose only sorry is in a comment",
          not write("C:/lean/C.lean", "/- A complete reduction: no `sorry`, no extra axioms. -/\ntheorem foo (n : Nat) : n + 0 = n := by simp\n"))
    check("ops silent on markdown without mathematics", not write("C:/notes/todo.md", "Dividing the work by two teams; cancel the meeting."))
    check("ops silent on code", not write("C:/repo/x.py", "# interchange the limit and the integral\n"))
    sid = "dup"
    a = write(tex, "Dividing both sides by $t$ we get $s=1$.", sid)
    b = write(tex, "Dividing both sides by $u$ we get $v=1$.", sid)
    check("ops one card per operation per file per session", bool(a) and not b)
    patch = ("*** Begin Patch\n*** Update File: C:/papers/q/proof.tex\n@@\n+We interchange the limit and the sum to conclude.\n"
             "*** End Patch\n")
    out = o.decide({"tool_name": "apply_patch", "tool_input": {"input": patch}, "session_id": "codex1"})
    check("ops reads a Codex apply_patch", "[verify-op exchange]" in out)


def main(argv=None):
    argv = list(sys.argv[1:] if argv is None else argv)
    which = argv[0] if argv and not argv[0].startswith("--") else "all"
    gate = os.path.join(HERE, "verify_gate.py")
    sense = os.path.join(HERE, "verify_sense.py")
    ops = os.path.join(HERE, "verify_ops.py")
    if "--old-gate" in argv:
        gate = argv[argv.index("--old-gate") + 1]
    if which in ("gate", "all"):
        gate_cases(gate)
    if which in ("sense", "all") and os.path.exists(sense):
        sense_cases(sense)
    if which in ("ops", "all") and os.path.exists(ops):
        ops_cases(ops)
    print("%d failed" % len(FAILS))
    return 1 if FAILS else 0


if __name__ == "__main__":
    sys.exit(main())
