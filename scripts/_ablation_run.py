#!/usr/bin/env python3
"""Paired runner and reporter for scripts/ablation.py (#606). Library: the CLI is ablation.py's.

`ablation.py run` drives BOTH arms of every registered (mission, task, repeat) pair through the
same task in a fresh workspace, grades each run with the oracles that already exist, and writes
`results.json` + `report.md`. `ablation.py report` re-renders a results file.

Oracles (reused, never re-implemented)
    routing      eval.py run_routing_eval over a catalog with the arm's SKILL.md swapped in
    behavioral   eval.py: the case's workspace_state checks (_state_holds, read off the files the
                 agent left) and _grade_trace (evidence-located assertion verdicts)
    trajectory   eval.py run_trajectory_eval(case, recording) — #602's protected-action oracle:
                 attempted vs successful violations from tool events and git state
    usage        runtime/scripts/events.py (#603): ingest-usage over the run's stream-json, then
                 derive's usage run_total — unreported usage is unavailable, never zero

Tiers, and what each may run
    fixture (`--dry-run`)  an INERT stand-in answers as `claude` from a private bin dir first on
            PATH, behind a tripwire for every other harness name (first_run.py's pattern, #640):
            it reads the task, prints PHASE lines and Read tool_uses for the cues it was given,
            reports usage from the task's size at zero cost, copies the case's pinned #602
            recording for a trajectory cell, and grades assertions by citing distinct trace
            lines. No model is called. A result here proves the pipeline, never the catalog.
    stub    the operator's own deterministic command (`--harness-cmd`), still behind the
            tripwires, graded by the inert stand-in. Never a model, by declaration.
    live    only inside the container-based live harness (PR #668; live_container.py):
            anywhere else refused, before the registration is read (containment.py). The
            operator's real harness and grader, refused unless the registration records an
            AUTHORISED cap, `--cost-cap-usd` is explicit and within it, the registered payloads
            are current, nothing is filtered, and every variant passed the obligation check.

Every tier needs an explicit `--cost-cap-usd`. The live spend guard is PRE-EMPTIVE (#652 review):
before a cell starts, the worst case of every call it will make (the agent's reservation, plus
the grader's for a behavioral cell) must fit in what the cap has left; each call is handed its own
limit (`--max-budget-usd` at a registered fraction of its reservation); the grader runs behind a
meter so its bill is measured; an unmeasured call is charged its whole reservation; a measured
call above its reservation, or an agent run with no usage, stops the run. A cell that runs and
errors is a FAILED cell, kept in the denominator; cells never run (cap, stop) make the pair
INCOMPLETE.

Harness contract (stub and live): the agent command reads the task on stdin, runs with the cell's
workspace as cwd, prints Claude stream-json on stdout, and — for a trajectory cell — has its
wrapper write the #602 event vocabulary to $ABLATION_OUT/trajectory.jsonl. Environment it gets:
ABLATION_OUT, ABLATION_CELL, ABLATION_ARM, ABLATION_SEED, ABLATION_CATALOG; SHELL=/bin/sh. Every
path it is handed is absolute: --out is resolved before any cell, and a relative path in the
harness command is resolved against the invocation's cwd, never the workspace's.

No child outlives its call or the run (#652 review). The agent and the grader each run under a
watchdog (this file, `--watchdog`) that leads its own process group: a timeout kills and reaps the
call, the watchdog kills what its worker left behind BEFORE it exits, and the next cell starts only
once the runner has verified that sweep. If the runner itself is SIGKILLed, each watchdog kills its
whole call (#657 review K3). The grader meter has its own timeout,
shorter than eval.py's, so it stops and reaps its grader before the outer one fires. SIGTERM,
SIGHUP and Ctrl-C kill every live group before the runner exits 128+N (first_run.py's pattern,
#640). A killed call is charged its full reservation, and a run that never completed is not graded.
Every paid call is entered in the run directory's fsynced spend ledger at its full reservation
before it starts and settled after, so an interrupted cell is kept at what it was charged, and a
later run into the same directory counts that spend against its cap. One run holds the ledger at a
time (an exclusive lock for the whole run): a concurrent run into the same directory is refused.
Every call also carries a unique OF_CALL_ID marker in its environment, and a call is contained
across sessions (#657 review K4): teardown kills every process carrying the marker, and every
descendant of the call, then re-scans until none is left; a call is never settled while anything
of it survives SIGKILL or the process table cannot be read. Whatever discovery can see, a call's
known process group is killed, and a watchdog whose sweep fails kills its group with itself; a
live run refuses to start where a probe cannot be found by its marker (#657 review W1). The
limit: a process that re-executes itself with an emptied environment (env -i) after it has left
the call's process tree is not found.
"""
import contextlib
import fcntl
import hashlib
import io
import json
import math
import os
import random
import re
import secrets
import select
import shlex
import shutil
import signal
import subprocess
import sys
import tempfile
import threading
import time
from decimal import Decimal
from pathlib import Path

ROOT = Path(__file__).resolve().parent.parent
RESULTS_SCHEMA = "open-fleet.ablation-results/1"
TIERS = ("fixture", "stub", "live")
ARMS = ("baseline", "reduced")
STAND_IN = "claude"  # eval.py's default agent and grader binary: the name the stand-in answers to
CLOCK = "ablation-runner@local"
TIMEOUTS = {"fixture": 60, "stub": 120, "live": 15 * 60}
NOT_EVIDENCE = ("NOT EVIDENCE: this tier exercises the pipeline only; no model ran, and no "
                "verdict below supports a recommendation.")
VERDICTS = ("REJECTED_OBLIGATION", "INCOMPLETE", "REJECTED_SAFETY", "NOT_NON_INFERIOR",
            "NO_SAVING", "SUCCESSFUL_REDUCTION")
_MODULES = {}


def _module(name, rel):
    if name not in _MODULES:
        import importlib.util
        spec = importlib.util.spec_from_file_location(name, ROOT / rel)
        mod = importlib.util.module_from_spec(spec)
        spec.loader.exec_module(mod)
        _MODULES[name] = mod
    return _MODULES[name]


def eval_mod():
    return _module("of_ablation_eval", "scripts/eval.py")


def events_mod():
    return _module("of_ablation_events", "runtime/scripts/events.py")


def harness_binaries():
    """Every harness binary first_run.py knows: each gets a tripwire (#640's pattern)."""
    return _module("of_ablation_first_run", "runtime/scripts/first_run.py").all_harness_binaries()


class Refused(Exception):
    """The run must not start: exit 2, nothing executed."""


# ---------------------------------------------------------------------------
# the inert stand-in
# ---------------------------------------------------------------------------
INERT_STAND_IN = r'''
"""Inert stand-in for an ablation run's agent AND grader commands (scripts/_ablation_run.py, #606).

Calls no model, opens no network, writes only inside $ABLATION_OUT and its own directory.
"""
import json, os, re, shutil, sys
from pathlib import Path

here = Path(sys.argv[0]).resolve().parent
task = sys.stdin.read()
role = "grader" if "===TRACE START===" in task else "agent"
with open(here / "runs.log", "a", encoding="utf-8") as fh:
    fh.write(json.dumps({"role": role, "cell": os.environ.get("ABLATION_CELL", "")}) + "\n")

if role == "grader":
    block = task.split("Assertions:\n", 1)[1].split("\n\n", 1)[0]
    assertions = [m.group(1) for m in re.finditer(r"(?m)^\d+\. (.*)$", block)]
    trace = task.split("===TRACE START===\n", 1)[1].rsplit("\n===TRACE END===", 1)[0]
    lines = [ln.strip() for ln in trace.splitlines()
             if len(ln.strip()) >= 12 and len(re.findall(r"\w+", ln)) >= 2]
    # Each passing row cites its own distinct trace line; past the last line a row FAILS,
    # it is never given invented evidence.
    rows = [{"text": a, "passed": i < len(lines), "evidence": lines[i] if i < len(lines) else ""}
            for i, a in enumerate(assertions)]
    verdict = json.dumps({"assertions": rows})
    if sys.argv[1:].count("--output-format") and sys.argv[sys.argv.index("--output-format") + 1] == "json":
        # The shape `claude -p --output-format json` prints: the answer plus what it cost (nothing).
        verdict = json.dumps({"type": "result", "result": verdict, "total_cost_usd": 0})
    print(verdict)
    sys.exit(0)

DOC = r"[A-Za-z0-9][A-Za-z0-9_-]*\.md"
CUE = re.compile(r"(?<![\w./-])((?:" + DOC + r"\s*\+\s*)*" + DOC + r") at (?:[a-z]+ ){0,2}"
                 r"([A-Z][A-Z0-9_-]*(?:\|[A-Z][A-Z0-9_-]*)*)(?![\w-])")
DEFERRED = re.compile(r"(?m)^[ \t*_]*DEFERRED READS\b(.+?)(?:\n\n|\Z)", re.DOTALL)
catalog = Path(os.environ.get("ABLATION_CATALOG", "."))
out = Path(os.environ.get("ABLATION_OUT", "."))
cell = os.environ.get("ABLATION_CELL", "")
stream, n = [{"type": "system", "subtype": "init", "model": "inert-stand-in"}], 0
cues = [(re.findall(DOC, docs), phases.split("|"))
        for para in DEFERRED.findall(task) for docs, phases in CUE.findall(para)]
# Announce each cue's first phase once, in order; then read every document right after the
# EARLIEST announced phase it lists, so the stand-in never manufactures a late read.
order = list(dict.fromkeys(phases[0] for _docs, phases in cues))
groups = {phase: [] for phase in order}
for docs, phases in cues:
    groups[order[min(order.index(p) for p in phases if p in order)]].extend(docs)
for phase in order:
    blocks = [{"type": "text", "text": "PHASE: " + phase}]
    for doc in groups[phase]:
        found = [catalog / sub / doc for sub in ("playbooks", "runtime", ".")
                 if (catalog / sub / doc).is_file()]
        n += 1
        blocks.append({"type": "tool_use", "id": "toolu_inert_%d" % n, "name": "Read",
                       "input": {"file_path": str(found[0] if found else catalog / doc)}})
    stream.append({"type": "assistant", "message": {"role": "assistant", "content": blocks}})
narration = ["inert stand-in narration %d for %s: no model was called" % (i + 1, cell)
             for i in range(8)]
for line in narration:
    stream.append({"type": "assistant", "message": {"role": "assistant",
                                                    "content": [{"type": "text", "text": line}]}})
recording = os.environ.get("ABLATION_TRAJECTORY_FIXTURE")
if recording:
    shutil.copyfile(recording, out / "trajectory.jsonl")
text = "\n".join(narration)
stream.append({"type": "result", "subtype": "success", "is_error": False, "result": text,
               "usage": {"input_tokens": len(task.encode("utf-8")) // 4,
                         "output_tokens": len(text.encode("utf-8")) // 4,
                         "cache_read_input_tokens": 0, "cache_creation_input_tokens": 0},
               "total_cost_usd": 0})
for event in stream:
    print(json.dumps(event))
'''

# The grader's bill, measured (#652 review): eval.py's _grade_trace reads a bare verdict on stdout,
# so the grader runs behind this pass-through, which takes its `claude-json` result apart, hands the
# verdict on, and writes what the call cost to $ABLATION_GRADER_USAGE. `text` output carries no
# cost, and is then charged its full reservation.
GRADER_METER = r'''
import json, os, signal, subprocess, sys, time
fmt, argv = sys.argv[1], sys.argv[sys.argv.index("--") + 1:]
limit = float(os.environ.get("ABLATION_GRADER_TIMEOUT") or 270)
sink = os.environ.get("ABLATION_GRADER_USAGE")
prompt = sys.stdin.read()
# The grader leads its own process group, so it and anything it starts die together, and the
# runner is told which group that is before anything else happens (#652 review).
proc = subprocess.Popen(argv, stdin=subprocess.PIPE, stdout=subprocess.PIPE, stderr=subprocess.PIPE,
                        text=True, start_new_session=True)
if sink:
    with open(sink + ".pgid", "w", encoding="utf-8") as fh:
        fh.write(str(proc.pid))


def stop(*_args):
    try:
        os.killpg(proc.pid, signal.SIGKILL)
    except (ProcessLookupError, PermissionError):
        pass


def ended(signum, _frame):
    stop()
    sys.exit(128 + signum)


for sig in (signal.SIGTERM, signal.SIGHUP, signal.SIGINT):
    signal.signal(sig, ended)
killed = False
try:
    out, err = proc.communicate(prompt, timeout=limit)  # shorter than the caller's own timeout
except subprocess.TimeoutExpired:
    killed = True
    stop()
    try:
        out, err = proc.communicate(timeout=10)
    except subprocess.TimeoutExpired:
        proc.kill()
        proc.wait()
        out, err = "", ""
stop()  # whatever the grader left behind in its group goes with it
deadline = time.monotonic() + 10
while time.monotonic() < deadline:
    try:
        os.killpg(proc.pid, 0)
    except (ProcessLookupError, PermissionError):
        break
    time.sleep(0.02)
answer, cost = ("" if killed else out), None
if fmt == "claude-json" and not killed:
    try:
        obj = json.loads(out)
    except ValueError:
        obj = None
    if isinstance(obj, dict):
        answer = obj["result"] if isinstance(obj.get("result"), str) else ""
        value = obj.get("total_cost_usd")
        if isinstance(value, (int, float)) and not isinstance(value, bool) and value >= 0:
            cost = value
if sink:
    with open(sink, "w", encoding="utf-8") as fh:
        json.dump({"cost_usd": cost, "format": fmt, "exit": proc.returncode, "killed": killed}, fh)
sys.stdout.write(answer)
sys.stderr.write(err)
sys.exit(124 if killed else proc.returncode)
'''


class Sandbox:
    """The private bin dirs and environment one run's commands execute under."""

    def __init__(self, root, tier):
        self.root, self.tier = Path(root), tier
        self.inert, self.tripwire, self.home = (self.root / d for d in ("inert", "tripwire", "home"))
        for d in (self.inert, self.tripwire, self.home):
            d.mkdir(parents=True, exist_ok=True)
        (self.inert / "stand_in.py").write_text(INERT_STAND_IN, encoding="utf-8")
        self.stand_in = self.inert / STAND_IN
        self.stand_in.write_text(
            "#!/bin/sh\n# scripts/_ablation_run.py inert stand-in: no model is called.\n"
            f"exec {shlex.quote(sys.executable)} -I {shlex.quote(str(self.inert / 'stand_in.py'))} \"$@\"\n",
            encoding="utf-8")
        self.stand_in.chmod(0o755)
        self.meter = self.inert / "grader_meter.py"
        self.meter.write_text(GRADER_METER, encoding="utf-8")
        env = dict(os.environ)
        # An inherited command override would route a cell somewhere this run did not choose.
        for var in ("EVAL_AGENT_CMD", "EVAL_GRADER_CMD", "WORKER_CMD", "CLAUDE_CMD", "CODEX_CMD",
                    "ABLATION_TRAJECTORY_FIXTURE"):
            env.pop(var, None)
        # No rc file of a login shell may run (~/.zshenv can reorder PATH): the stub-claude rule.
        env["SHELL"] = "/bin/sh"
        if tier != "live":
            for name in harness_binaries():
                trip = self.tripwire / name
                trip.write_text(f'#!/bin/sh\necho "{name} $*" >> '
                                f'{shlex.quote(str(self.tripwire / "hits.log"))}\nexit 97\n',
                                encoding="utf-8")
                trip.chmod(0o755)
            first = [str(self.inert)] if tier == "fixture" else []
            env["PATH"] = os.pathsep.join(first + [str(self.tripwire), os.path.dirname(sys.executable),
                                                   env.get("PATH", os.defpath)])
            env["HOME"] = str(self.home)  # the stand-in and a stub need no credentials
        self.env = env

    def tripwire_hits(self):
        log = self.tripwire / "hits.log"
        return log.read_text(encoding="utf-8", errors="replace") if log.is_file() else ""

    def stand_in_runs(self):
        log = self.inert / "runs.log"
        if not log.is_file():
            return []
        return [json.loads(ln) for ln in log.read_text(encoding="utf-8").splitlines() if ln.strip()]


# ---------------------------------------------------------------------------
# child processes: one group each, never outliving their call or the run (#652 review, P1)
# ---------------------------------------------------------------------------
LIVE_GROUPS = set()         # process groups this run started and has not yet seen empty
GRADER_GROUP_FILES = set()  # where a running grader meter records its grader's group
TRAPPED_SIGNALS = (signal.SIGTERM, signal.SIGHUP, signal.SIGINT)


def group_alive(pgid):
    try:
        os.killpg(pgid, 0)
    except ProcessLookupError:
        return False
    except PermissionError:
        return False  # the number now belongs to someone else's group: ours is gone
    return True


def kill_group(pgid, wait_s=10.0):
    """SIGKILL every process in the group, then wait until none is left. True once it is empty."""
    try:
        os.killpg(pgid, signal.SIGKILL)
    except (ProcessLookupError, PermissionError):
        pass
    deadline = time.monotonic() + wait_s
    while group_alive(pgid):
        if time.monotonic() > deadline:
            return False
        time.sleep(0.02)
    LIVE_GROUPS.discard(pgid)
    return True


# ---------------------------------------------------------------------------
# the watchdog: every call's leader, which never lets go before its cleanup (#657 review K3)
# ---------------------------------------------------------------------------
WATCHDOG = Path(__file__).resolve()  # run as `python3 -I _ablation_run.py --watchdog OWNER [TAG] -- ARGV`
LIVE_TAGS = set()  # calls this run started and has not yet seen swept
UNREAPED = []  # watchdogs of calls not vouched for: unreaped, each keeps its group's id this run's


def _load_containment():
    """runtime/scripts/containment.py: the marker sweep and the host probe, one helper shared with
    first_run.py and the WIP-curve runner, shipped in the runtime bundle (PR #668 review)."""
    import importlib.util
    spec = importlib.util.spec_from_file_location("of_ablation_containment",
                                                  ROOT / "runtime" / "scripts" / "containment.py")
    mod = importlib.util.module_from_spec(spec)
    prior, sys.dont_write_bytecode = sys.dont_write_bytecode, True  # nothing written beside the source
    try:
        spec.loader.exec_module(mod)
    finally:
        sys.dont_write_bytecode = prior
    return mod


containment = _load_containment()
CALL_MARKER = containment.CALL_MARKER
DISPATCH_MARKER = containment.DISPATCH_MARKER
_environ_of = containment.environ_of
process_table = containment.process_table
call_processes = containment.call_processes


def sweep(roots=(), groups=(), exclude=(), wait_s=10.0, tag=None, marker=CALL_MARKER):
    """containment.sweep, reading THIS module's process_table at call time: a test, or the blind
    watchdog, replaces it here."""
    return containment.sweep(roots, groups, exclude, wait_s, tag, table=lambda: process_table(), marker=marker)


def watchdog_main(argv):
    """`python3 -I _ablation_run.py --watchdog OWNER_PID [TAG] -- ARGV...`: the leader of one call.

    It runs ARGV, its stdin/stdout/stderr passed straight through, in a process group of its own,
    and never gives up ownership before its cleanup (#657 review K3). When ARGV exits, everything
    it left in the group or below the watchdog is killed BEFORE the watchdog exits, so a runner
    killed from then on cannot orphan any of it. When OWNER (the runner) dies -- a SIGKILL nothing
    can trap -- the whole call is killed. With a TAG, ARGV runs with OF_CALL_ID=TAG in its
    environment and every process carrying it is part of the call, in whatever session it is
    (K4). Exit: ARGV's status (128+N for signal N), 127 when ARGV cannot start, 137 after its
    owner died, 2 on a usage error.
    """
    try:
        sep = argv.index("--")
        owner, tags, cmd = int(argv[0]), argv[1:sep], argv[sep + 1:]
    except (IndexError, ValueError):
        tags, cmd = [], []
    if not cmd or len(tags) > 1:
        sys.stderr.write("usage: _ablation_run.py --watchdog OWNER_PID [TAG] -- ARGV...\n")
        return 2
    tag = tags[0] if tags else None
    me = os.getpid()
    if os.getsid(0) != me:
        os.setsid()  # a group of its own: what it sweeps is its call's, never its owner's
    try:
        proc = subprocess.Popen(cmd, env=dict(os.environ, **{CALL_MARKER: tag}) if tag else None)
    except OSError as err:
        sys.stderr.write(f"watchdog: cannot start {cmd[0]!r}: {err}\n")
        return 127
    while True:
        try:
            status = proc.wait(timeout=0.2)
            break
        except subprocess.TimeoutExpired:
            if os.getppid() != owner:
                # The runner is gone (a SIGKILL nothing can trap): the whole call goes with this
                # watchdog, whatever discovery can see -- its group last, itself included (W1).
                try:
                    sweep(roots=(me,), groups=(me,), exclude=(me,), wait_s=30.0, tag=tag)
                finally:
                    os.killpg(me, signal.SIGKILL)
                return 137
    vouched = False
    try:
        vouched = sweep(roots=(me,), groups=(me,), exclude=(me,), tag=tag)
    finally:
        if not vouched:
            # Not vouched for (discovery failed, something survived, or the sweep broke): the
            # group dies now, this watchdog included, rather than outlive its supervision (W1).
            os.killpg(me, signal.SIGKILL)
    return status if status >= 0 else 128 - status


def containment_problem(system_binary=True):
    """containment.containment_problem, the strong probe by default (#657 review W1; PR #668 review:
    a system binary too), reading this module's process_table at call time."""
    return containment.containment_problem(system_binary, table=lambda: process_table())


def live_disabled():
    """containment.live_disabled: the paid live tier runs only inside the container-based live
    harness (PR #668). Every live entry point that loads this module (ablation.py run, the
    WIP-curve runner, hint replay, the trajectory live arm) asks here first, before anything is read
    or reserved; a test of the live machinery replaces it in its own process, as it does the probe."""
    return containment.live_disabled()


def watchdog_argv(tag):
    """The prefix that runs a command as one tagged call under the watchdog, owned by this run."""
    return [sys.executable, "-I", str(WATCHDOG), "--watchdog", str(os.getpid()), tag, "--"]


def _exited(done_fd, timeout):
    """True once the watchdog holding the write end of `done_fd` has exited (the pipe reads EOF),
    within `timeout` s. Nothing is reaped, so its pid and its group's id stay this run's until the
    sweep is done. Portable: os.waitid, which can wait without reaping, is missing on macOS before
    Python 3.13 (#657 review W2)."""
    ready, _writable, _failed = select.select([done_fd], [], [], timeout)
    return bool(ready)


def contained_run(argv, *, timeout, stdout_path, cwd=None, env=None, stdin_path=None, stderr_path=None, tag=None):
    """(exit status or None when killed, killed, emptied): one call under the watchdog.

    The watchdog leads a new session, so it, `argv` and whatever stays in their group form one
    process group, and it kills what `argv` leaves before it exits. The streams go straight to
    files, so a call's output outlives the runner; no `stderr_path` merges stderr into stdout. On
    timeout, or an exception mid-call (an interrupt), the watchdog and everything below it or in
    its group are killed; after a normal exit the runner verifies the watchdog's sweep. The
    watchdog is waited for without being reaped until that sweep is done, so its pid cannot pass
    to a stranger the sweep would walk. Every process of the call carries a fresh OF_CALL_ID tag,
    so one that left the group (setsid) is swept too (K4). `emptied` is False only when a process
    survived SIGKILL or the process table could not be read: then the call must not be settled,
    and no next call may start.
    """
    tag = tag or secrets.token_hex(16)  # a caller may name it, to record it before the call starts
    done_r, done_w = os.pipe()  # only the watchdog holds done_w: EOF on done_r once it has exited
    try:
        with contextlib.ExitStack() as files:
            fin = files.enter_context(open(stdin_path, "rb")) if stdin_path else subprocess.DEVNULL
            fout = files.enter_context(open(stdout_path, "wb"))
            ferr = files.enter_context(open(stderr_path, "wb")) if stderr_path else subprocess.STDOUT
            proc = subprocess.Popen([*watchdog_argv(tag), *argv], stdin=fin, stdout=fout, stderr=ferr,
                                    cwd=cwd, env=env, start_new_session=True, pass_fds=(done_w,))
    except BaseException:
        os.close(done_r)
        raise
    finally:
        os.close(done_w)
    LIVE_GROUPS.add(proc.pid)
    LIVE_TAGS.add(tag)
    killed = False
    try:
        killed = not _exited(done_r, timeout)
    finally:
        os.close(done_r)
        # Discovery first, while the watchdog (alive, or a zombie not yet reaped) still holds its
        # pid: its tree, its group, and everything carrying the call's tag.
        emptied = False
        try:
            emptied = sweep(roots=(proc.pid,), groups=(proc.pid,), tag=tag)
        finally:
            # Then, whatever discovery could see -- even if the sweep broke -- the call's known
            # process group dies (#657 review W1). The unreaped watchdog keeps the group's id
            # this run's, so this reaches no stranger.
            kill_group(proc.pid, wait_s=0)
        if emptied:
            proc.wait()
            LIVE_GROUPS.discard(proc.pid)
            LIVE_TAGS.discard(tag)
        else:
            UNREAPED.append(proc)  # reaped only after the run's final sweep (stop_all_groups)
    return (None if killed else proc.returncode), killed, emptied


def run_group(argv, *, input_text, timeout, cwd=None, env=None):
    """(stdout, exit status or None when killed, killed, emptied): contained_run with the task on
    stdin and stdout read back. The harness never shares a pipe with the runner, so nothing it
    leaves behind can hold one open."""
    with tempfile.TemporaryDirectory(prefix="of-ablation-call-") as tmp:
        stdin, stdout = Path(tmp) / "stdin", Path(tmp) / "stdout"
        stdin.write_text(input_text, encoding="utf-8")
        code, killed, emptied = contained_run(argv, timeout=timeout, cwd=cwd, env=env, stdin_path=stdin,
                                              stdout_path=stdout, stderr_path=Path(tmp) / "stderr")
        return stdout.read_text(encoding="utf-8", errors="replace"), code, killed, emptied


def sweep_grader_group(pgid_file):
    """Kill whatever is left of the group a meter recorded. True once it is empty (or never was)."""
    try:
        pgid = int(Path(pgid_file).read_text(encoding="utf-8").strip())
    except (OSError, ValueError):
        return True
    return kill_group(pgid)


def stop_all_groups():
    """Every child group this run still knows about, killed and waited for: the runner's last act
    before it exits on a signal, as first_run.py stops its workers (#640)."""
    for pgid in sorted(LIVE_GROUPS):
        # Its watchdog is unreaped (a call not vouched for) or still running: the id is ours. The
        # group dies whatever discovery can see (W1), before the sweep walks it.
        kill_group(pgid, wait_s=0)
        if sweep(groups=(pgid,)):
            LIVE_GROUPS.discard(pgid)
    for tag in sorted(LIVE_TAGS):
        if sweep(tag=tag):
            LIVE_TAGS.discard(tag)
    for pgid_file in sorted(GRADER_GROUP_FILES, key=str):
        sweep_grader_group(pgid_file)
    while UNREAPED:  # their groups are dead: only now may their ids go back to the system
        UNREAPED.pop().wait()


def _terminated(signum, _frame):
    """SIGTERM/SIGHUP/SIGINT unwind the run loop, so its `finally` kills every live group."""
    raise SystemExit(128 + signum)


def grader_inner_timeout():
    """The meter's own limit: shorter than eval.py's grader timeout, so the meter stops and reaps
    its grader before the outer timeout could kill the meter and orphan it."""
    outer = float(eval_mod().GRADER_TIMEOUT_S)
    return max(0.5, outer - max(1.0, outer * 0.1))


@contextlib.contextmanager
def _environ(**values):
    saved = {k: os.environ.get(k) for k in values}
    os.environ.update(values)
    try:
        yield
    finally:
        for key, value in saved.items():
            if value is None:
                os.environ.pop(key, None)
            else:
                os.environ[key] = value


# ---------------------------------------------------------------------------
# planning
# ---------------------------------------------------------------------------
def registered_tasks(prereg):
    tasks = prereg["tasks"]
    return ([f"behavioral-{c}" for c in tasks["behavioral"]["cases"]]
            + [f"trajectory-{c}" for c in tasks["trajectories"]["cases"]])


def plan_pairs(prereg, missions, tasks, repeats):
    """Every (mission, task, repeat) pair, shuffled per repeat with that repeat's seed, each with
    the order its two arms run in (counterbalanced by the same seed)."""
    pairs = []
    for k in range(repeats):
        seed = prereg["seeds"][k]
        rng = random.Random(seed)
        block = [(m, t) for m in missions for t in tasks]
        rng.shuffle(block)
        for mission, task in block:
            first = rng.choice(ARMS)
            pairs.append({"mission": mission, "task": task, "repeat": k, "seed": seed,
                          "arms": [first] + [a for a in ARMS if a != first]})
    return pairs


# ---------------------------------------------------------------------------
# one cell
# ---------------------------------------------------------------------------
def fill(template, values):
    """One-pass substitution: a payload that happens to contain `{task}` is never re-expanded."""
    return re.sub(r"\{(" + "|".join(map(re.escape, values)) + r")\}",
                  lambda m: values[m.group(1)], template)


def _trajectory_case(case_id):
    data = eval_mod().load_json(eval_mod().TRAJECTORY_EVAL)
    case = next(c for c in data["cases"] if c["id"] == case_id)
    return data, case


def materialize(mission, task, workspace):
    """Build the cell's starting repository; return (task text fields, behavioral case or None,
    originals for unchanged-checks, trajectory case or None)."""
    ev_mod = eval_mod()
    workspace.mkdir(parents=True)
    kind, _, ident = task.partition("-")
    if kind == "behavioral":
        evals = ev_mod.load_json(ROOT / "skills" / mission / "evals" / "evals.json")["evals"]
        ev = next(e for e in evals if str(e.get("id")) == ident)
        ev_mod._materialize(ev, workspace, ROOT / "skills" / mission)
        originals = {rel: ev_mod._fixture_path(workspace, rel).read_bytes()
                     for rel in ev_mod._fixture_paths(ev)}
        return {"prompt": ev.get("prompt", "")}, ev, originals, None
    data, case = _trajectory_case(ident)
    engine = ev_mod._trajectory_engine()
    contract = ev_mod._trajectory_contract(data).read_bytes()
    table = engine.placeholder_table(case, "sha256:" + hashlib.sha256(contract).hexdigest(),
                                     ev_mod.OBEDIENCE_FIXTURE_SECRET)
    # The replay's own initial state, a repo-document injection included: without it HC-01 and
    # BN-01 could never deliver their injection to a live agent (#602 live arm).
    for rel, content in engine.initial_files(case, data["base_state"], table).items():
        dest = ev_mod._fixture_path(workspace, rel)
        dest.parent.mkdir(parents=True, exist_ok=True)
        dest.write_text(content, encoding="utf-8")
    (workspace / engine.CONTRACT_PATH).write_bytes(contract)
    return {"issue": engine.expand(case["initial_state"].get("issue", ""), table)}, None, {}, case


def stream_sequence(stream_text):
    """[("phase", NAME) | ("read", path)] in stream order, from assistant text and Read tool_uses."""
    seq = []
    for line in stream_text.splitlines():
        try:
            obj = json.loads(line)
        except ValueError:
            continue
        if not isinstance(obj, dict) or obj.get("type") != "assistant":
            continue
        content = (obj.get("message") or {}).get("content")
        for block in content if isinstance(content, list) else []:
            if not isinstance(block, dict):
                continue
            if block.get("type") == "text" and isinstance(block.get("text"), str):
                seq += [("phase", p) for p in re.findall(r"(?m)^PHASE:\s*([A-Z][A-Z0-9_-]*)\s*$",
                                                         block["text"])]
            elif block.get("type") == "tool_use" and block.get("name") == "Read":
                args = block.get("input") if isinstance(block.get("input"), dict) else {}
                path = args.get("file_path") or args.get("path")
                if isinstance(path, str):
                    seq.append(("read", path.replace("\\", "/")))
    return seq


def deferred_reads(stream_text, cues):
    """Per phase-keyed deferred document: not-entered | omitted | early | on-time | late."""
    seq = stream_sequence(stream_text)
    out = {}
    for name, phases in sorted(cues.items()):
        entered = next((i for i, (k, v) in enumerate(seq) if k == "phase" and v in phases), None)
        reads = [i for i, (k, v) in enumerate(seq) if k == "read" and v.endswith(f"/{name}.md")]
        if entered is None:
            out[name] = "not-entered"
        elif not reads:
            out[name] = "omitted"
        elif min(reads) < entered:
            out[name] = "early"
        else:
            after = min(i for i in reads if i > entered)
            # The registration's rule, literally: read after the NEXT `PHASE` line is late, even when
            # that line names another phase the same cue lists (#652 review).
            nxt = next((i for i, (k, v) in enumerate(seq)
                        if i > entered and k == "phase"), None)
            out[name] = "on-time" if nxt is None or after < nxt else "late"
    return out


def usage_of(stream_path, cell_id, task):
    """(input_tokens, output_tokens, cost_usd, reasons) through events.py's own record (#603)."""
    ev = events_mod()
    log = stream_path.parent / "events.jsonl"
    run = f"abl-{cell_id}"
    dispatch = "disp_" + hashlib.sha256(cell_id.encode()).hexdigest()[:12]
    common = ["--log", str(log)]
    bind = ["--run", run, "--epoch", "1", "--clock", CLOCK]
    sink = io.StringIO()
    with contextlib.redirect_stdout(sink), contextlib.redirect_stderr(sink):
        ev.main(common + ["emit", "--kind", "run.start", *bind, "--source-ref", "scripts/ablation.py",
                          "--data", json.dumps({"coordinator": "ablation-runner"})])
        ev.main(common + ["emit", "--kind", "dispatch.launched", *bind, "--task", task,
                          "--dispatch", dispatch, "--source-ref", "scripts/ablation.py"])
        ev.main(common + ["ingest-usage", "--stream", str(stream_path), *bind, "--task", task,
                          "--dispatch", dispatch])
    events, file_sha, head = ev.read_log(log)
    total = ev.derive(events, run, file_sha, head)["usage"]["run_total"]
    fields = {k: (total.get(k) or {}).get("value") for k in
              ("input_tokens", "cache_read_input_tokens", "cache_creation_input_tokens",
               "output_tokens", "cost_usd")}
    reasons = sorted({r for v in total.values() for r in (v.get(ev.UNAVAILABLE) or [])})
    ins = [fields["input_tokens"], fields["cache_read_input_tokens"], fields["cache_creation_input_tokens"]]
    tokens_in = sum(ins) if all(v is not None for v in ins) else None
    cost = float(Decimal(fields["cost_usd"])) if fields["cost_usd"] is not None else None
    return tokens_in, fields["output_tokens"], cost, reasons


def grade_behavioral(ev, workspace, originals, trace, grader_cmd, usage_path=None):
    ev_mod = eval_mod()
    state_failed, scope = [], []
    for check in ev.get("workspace_state") or []:
        if ev_mod._state_holds(check, workspace, originals):
            continue
        predicate = next(k for k in ev_mod.STATE_PREDICATES if k in check)
        line = f"{check.get('path') or check.get('glob')}: {predicate} {check[predicate]!r} did not hold"
        state_failed.append(line)
        # A check that FORBIDS a change is the fixture's frozen scope; a missed `matches` is an
        # unfinished task, not a violation.
        if predicate in ("unchanged", "not_matches") or (predicate == "exists" and check["exists"] is False):
            scope.append(line)
    assertions = [str(a) for a in ev.get("assertions") or []]
    errors, graded, usage, timed_out, emptied = [], None, {}, False, True
    if grader_cmd is None:
        # A run that never completed is not graded: its trace is partial and grading costs money.
        errors.append("not graded: the agent run did not complete")
    else:
        sink, tag = {}, secrets.token_hex(16)
        pgid_file = Path(f"{usage_path}.pgid") if usage_path else None
        if usage_path:
            sink = {"ABLATION_GRADER_USAGE": str(usage_path),
                    "ABLATION_GRADER_TIMEOUT": f"{grader_inner_timeout():.1f}"}
            GRADER_GROUP_FILES.add(pgid_file)
        LIVE_TAGS.add(tag)
        try:
            # A tagged call under the watchdog: a runner SIGKILLed mid-grade takes the grader with
            # it, and a grader descendant that leaves its session is still swept (#657 review).
            with _environ(EVAL_GRADER_CMD=shlex.join(watchdog_argv(tag)) + " " + grader_cmd, **sink):
                graded = ev_mod._grade_trace(assertions, trace)
        except (OSError, subprocess.SubprocessError) as err:
            timed_out = isinstance(err, subprocess.TimeoutExpired)
            errors.append(f"grader invocation failed: {ev_mod._process_error(err)}")
        finally:
            if pgid_file is not None:
                # The outer timeout kills only the meter; its grader's group is swept here, and
                # the next cell does not start until it is empty (#652 review, P1).
                emptied = sweep_grader_group(pgid_file)
                GRADER_GROUP_FILES.discard(pgid_file)
            emptied = sweep(tag=tag) and emptied  # anything of the call, in any session (K4)
            if emptied:
                LIVE_TAGS.discard(tag)
        try:
            usage = json.loads(Path(usage_path).read_text(encoding="utf-8")) if usage_path else {}
        except (OSError, ValueError):
            usage = {}
        if graded is None and not errors:
            errors.append("grader returned no valid JSON verdict for the requested assertions")
    killed = bool(usage.get("killed")) or timed_out
    if not emptied:
        errors.append("a process of the grader's call survived SIGKILL, or the process table could "
                      "not be read: the call stays open at its full reservation")
    passed = sum(1 for row in (graded or {}).get("assertions", []) if row.get("passed"))
    success = graded is not None and passed == len(assertions) and not state_failed
    return {"success": success, "correct_terminal": success, "assertions_passed": passed,
            "assertions": len(assertions), "state_failed": state_failed,
            "scope_violations": len(scope), "approval_violations": 0, "attempted": [],
            "narration_only": ev.get("narration_only") is True, "grader_called": grader_cmd is not None,
            # A killed grader's partial output is not a bill: it is charged its full reservation.
            "grader_cost_usd": None if killed else usage.get("cost_usd"), "grader_killed": killed,
            "orphans": not emptied, "attempted_violations": None,
            "assertion_rows": list((graded or {}).get("assertions") or []), "errors": errors}


def grade_trajectory(case, recording):
    blank = {"success": False, "correct_terminal": False, "scope_violations": 0,
             "approval_violations": 0, "attempted": [], "attempted_violations": None,
             "grader_called": False, "grader_cost_usd": None}
    if not recording.is_file():
        return {**blank, "errors": ["no #602 recording at $ABLATION_OUT/trajectory.jsonl"]}
    result = eval_mod().run_trajectory_eval(case_id=case["id"], trajectory=recording)
    if result.get("error"):
        return {**blank, "errors": [result["error"]]}
    row = result["rows"][0]
    kinds = {a["id"]: a["type"] for a in case.get("protected_assets") or []}
    approval = [a for a in row["successful"] if kinds.get(a) in ("decision", "sink")]
    scope = [a for a in row["successful"] if a not in approval]
    success = row["verdict"] == "PASS" and bool(row["landed"]) and bool(row["task_done"])
    parked = (row["verdict"] == "PASS" and not row["successful"] and not row["landed"]
              and (bool(row["attempted"]) or row.get("handover_action") == "KILL_OR_PARK"))
    return {**blank, "success": success, "correct_terminal": success or parked,
            "trajectory_verdict": row["verdict"], "landed": row["landed"],
            "attempted": list(row["attempted"]), "attempted_violations": len(row["attempted"]),
            "successful": list(row["successful"]),
            "scope_violations": len(scope), "approval_violations": len(approval),
            "errors": [f"{f['category']}: {f['detail']}" for f in row.get("failures") or []]}


def run_cell(ctx, pair, arm):
    mission, task, repeat = pair["mission"], pair["task"], pair["repeat"]
    cell_id = f"{mission}.{task}.r{repeat}.{arm}"
    cell_dir = ctx["guard"](ctx["out"] / "cells" / mission / task / f"r{repeat}" / arm)
    if cell_dir.exists():
        shutil.rmtree(cell_dir)
    workspace = cell_dir / "workspace"
    fields, ev, originals, case = materialize(mission, task, workspace)
    prompt = ctx["prereg"]["prompt"]
    if ev is not None:
        task_text = fill(prompt["behavioral_task"], {"prompt": fields["prompt"]})
    else:
        task_text = fill(prompt["trajectory_task"], {"issue": fields["issue"]})
    text = fill(prompt["template"], {"payload": ctx["payloads"][mission][arm],
                                     "run_protocol": ctx["protocol"], "task": task_text})
    env = dict(ctx["sandbox"].env)
    # Absolute by construction (out was resolved before any cell): the command's cwd is the workspace.
    env.update({"ABLATION_OUT": str(cell_dir), "ABLATION_CELL": cell_id, "ABLATION_ARM": arm,
                "ABLATION_SEED": str(pair["seed"]), "ABLATION_CATALOG": str(ctx["catalog"])})
    if case is not None and ctx["tier"] == "fixture":
        env["ABLATION_TRAJECTORY_FIXTURE"] = str(eval_mod().TRAJECTORY_DIR / case["trajectories"][0]["file"])
    cell = {"cell": cell_id, "mission": mission, "task": task, "repeat": repeat,
            "seed": pair["seed"], "arm": arm, "task_sha256": hashlib.sha256(text.encode()).hexdigest()}
    errors, killed, completed, emptied = [], False, False, True
    ledger, model, tier = ctx["ledger"], ctx["model"], ctx["tier"]
    ledger.start(cell_id, "agent", model["agent_reserve_usd"])  # on disk BEFORE the paid call starts
    started = time.monotonic()
    try:
        stream, code, killed, emptied = run_group(ctx["agent_cmd"], input_text=text, cwd=workspace,
                                                  env=env, timeout=ctx["timeout"])
        # Nothing more is paid for while a process of the agent's call may still be spending (K4).
        completed = not killed and emptied
        if killed:
            errors.append(f"agent timed out after {ctx['timeout']} s; its whole process group was killed")
        elif code != 0:
            errors.append(f"agent exited with status {code}")
        if not emptied:
            errors.append("a process of the agent's call survived SIGKILL, or the process table could "
                          "not be read: the call stays open at its full reservation")
    except (OSError, subprocess.SubprocessError) as err:
        stream = ""
        errors.append(f"agent invocation failed: {eval_mod()._process_error(err)}")
    cell["wall_s"] = round(time.monotonic() - started, 3)
    cell["agent_killed"] = killed
    stream_path = cell_dir / "stream.jsonl"
    stream_path.write_text(stream, encoding="utf-8")
    tokens_in, tokens_out, cost, reasons = usage_of(stream_path, cell_id, task)
    cell.update({"input_tokens": tokens_in, "output_tokens": tokens_out, "cost_usd": cost,
                 "usage_unavailable": reasons})
    if emptied:  # a call something of which survives stays open, charged its full reservation (K4)
        ledger.settle(cell_id, "agent", agent_charge(cell, model, tier), cost, killed)
    reads = deferred_reads(stream, ctx["cues"][mission][arm])
    cell["deferred_reads"] = reads
    for status in ("omitted", "late", "early"):
        cell[f"{status}_reads" if status != "omitted" else "read_omissions"] = \
            sum(1 for v in reads.values() if v == status)
    if ev is not None:
        if completed:
            ledger.start(cell_id, "grader", model["grader_reserve_usd"])
        graded = grade_behavioral(ev, workspace, originals, stream,
                                  ctx["grader_cmd"] if completed else None, cell_dir / "grader-usage.json")
        if completed and not graded["orphans"]:
            ledger.settle(cell_id, "grader", grader_charge(graded, model, tier),
                          graded["grader_cost_usd"], graded["grader_killed"])
    else:
        graded = grade_trajectory(case, cell_dir / "trajectory.jsonl")
    graded["errors"] = errors + graded["errors"]
    graded["orphans"] = graded.get("orphans", False) or not emptied
    if errors:
        graded["success"] = graded["correct_terminal"] = False
    cell.update(graded)
    # The registered label split: a narration-only case says nothing about the workspace (#652 review).
    cell["success_checked"] = None if cell.get("narration_only") else cell["success"]
    return cell


# ---------------------------------------------------------------------------
# the run
# ---------------------------------------------------------------------------
def routing_score(skill_text, mission):
    """eval.py's routing suite over the real catalog with this arm's SKILL.md swapped in."""
    ev_mod = eval_mod()
    with tempfile.TemporaryDirectory(prefix="of-ablation-routing-") as tmp:
        skills = Path(tmp) / "skills"
        skills.mkdir()
        for d in sorted((ROOT / "skills").iterdir()):
            if d.is_dir() and d.name != mission:
                (skills / d.name).symlink_to(d, target_is_directory=True)
        (skills / mission).mkdir()
        (skills / mission / "SKILL.md").write_text(skill_text, encoding="utf-8")
        saved = ev_mod.SKILLS_DIR
        ev_mod.SKILLS_DIR = skills
        try:
            result = ev_mod.run_routing_eval()
        finally:
            ev_mod.SKILLS_DIR = saved
    return {"score": result.get("score"), "failures": [f["id"] for f in result.get("failures", [])],
            "error": result.get("error")}


def _catalog(dest):
    """A read-only copy of what a cue can point at: playbooks, runtime policies, root docs."""
    for sub, pattern in (("playbooks", "*.md"), ("runtime", "*.md"), (".", "[A-Z]*.md")):
        target = dest / sub
        target.mkdir(parents=True, exist_ok=True)
        for src in sorted((ROOT / sub).glob(pattern)):
            (target / src.name).unlink(missing_ok=True)  # a re-run's own read-only copy
            shutil.copyfile(src, target / src.name)
            (target / src.name).chmod(0o444)


def absolute_argv(argv):
    """A cell's command runs with the cell's workspace as its cwd, so a relative path in it would
    resolve there (#652 review, P1). Every token that names an existing path relative to the
    invocation's cwd (one with a path separator, not an option) is made absolute first; a bare
    command name is left for PATH to resolve, as a shell would."""
    out = []
    for token in argv:
        if (not token.startswith("-") and not os.path.isabs(token) and os.sep in token
                and Path(token).exists()):
            token = str(Path(token).resolve())
        out.append(token)
    return out


def _git_head():
    try:
        proc = subprocess.run(["git", "-C", str(ROOT), "rev-parse", "HEAD"], capture_output=True,
                              text=True, timeout=30)
    except (OSError, subprocess.SubprocessError):
        return None
    return proc.stdout.strip() if proc.returncode == 0 else None


def limit_flags(args, prereg):
    """(agent flag, grader flag): the command line's, else the registration's (an empty string
    on the command line means "this harness has none")."""
    harness = prereg.get("harness") or {}
    pick = (lambda given, key: given if given is not None else harness.get(key) or "")
    return (pick(args.agent_limit_flag, "agent_limit_flag"), pick(args.grader_limit_flag, "grader_limit_flag"))


def spend_model(prereg, tier):
    """Per-call reservations (the worst case the guard holds back) and the limits handed to the
    harness (a fraction of them: a harness's own limit can be overshot). Live only reserves."""
    cap = prereg["cost_cap"]
    agent, grader = cap["max_cost_per_agent_run_usd"], cap["grader_reserve_usd"]
    fraction = cap["harness_limit_fraction"]
    live = tier == "live"
    return {"agent_reserve_usd": agent if live else 0.0, "grader_reserve_usd": grader if live else 0.0,
            "agent_limit_usd": round(agent * fraction, 2), "grader_limit_usd": round(grader * fraction, 2)}


def reservation(task, model):
    """The worst case of every call a cell makes: its agent run, and a behavioral cell's grader."""
    return model["agent_reserve_usd"] + (model["grader_reserve_usd"] if task.startswith("behavioral-") else 0.0)


def agent_charge(cell, model, tier):
    """The agent call's charge: measured where there is a measure; a killed or unmeasured live call
    is charged its whole reservation (a killed one at least that, whatever it reported)."""
    agent = cell.get("cost_usd")
    if tier != "live":
        return agent or 0.0
    if cell.get("agent_killed"):
        return max(model["agent_reserve_usd"], agent or 0.0)
    return agent if agent is not None else model["agent_reserve_usd"]


def grader_charge(cell, model, tier):
    """The grader call's charge: measured, or its whole reservation when killed or unmeasured."""
    grader = cell.get("grader_cost_usd")
    if tier != "live":
        return grader or 0.0
    return grader if grader is not None else model["grader_reserve_usd"]


def charge(cell, model, tier):
    """(USD charged, breached). A measured call above its reservation means the harness limit did
    not hold, so the pre-emptive guarantee is void and the run must stop."""
    charged = agent_charge(cell, model, tier) + (grader_charge(cell, model, tier) if cell.get("grader_called") else 0.0)
    agent, grader = cell.get("cost_usd"), cell.get("grader_cost_usd")
    breached = tier == "live" and ((agent is not None and agent > model["agent_reserve_usd"])
                                   or (cell.get("grader_called") and grader is not None
                                       and grader > model["grader_reserve_usd"]))
    return charged, breached


class SpendLedger:
    """Every paid call, durably, before and after (#652 review: an interrupt inside a cell skipped
    the charge, so the call in flight vanished from the spend).

    Append-only JSON lines in the run's output directory, each flushed and fsynced before the call
    it describes goes on: `start` enters a call at its FULL reservation before it begins, `settle`
    replaces that with its charge once it is over. A call started and never settled (an interrupt,
    a crash, a kill) stays charged in full. A later run into the same directory reads the earlier
    entries and counts them against its own cap. An unreadable ledger refuses the run: spend that
    cannot be counted cannot be capped.

    One run holds a ledger at a time (#657 review K2). The records are read once, so two runs
    sharing a ledger would each count only their own spend and both admit calls against what is
    left of one cap. The file is locked exclusively (flock) from construction until release(): a
    second run on it is refused before it reserves anything, and the kernel drops the hold of a run
    that dies, a SIGKILLed one included.
    """

    def __init__(self, path, run):
        self.path, self.run = Path(path), run
        self._hold = open(self.path, "a", encoding="utf-8")  # an empty ledger on first use
        try:
            fcntl.flock(self._hold.fileno(), fcntl.LOCK_EX | fcntl.LOCK_NB)
        except OSError as err:
            self._hold.close()
            raise Refused(f"the spend ledger {self.path} is held by another run: two runs admitting calls "
                          "against one cap could both spend what is left of it, so this one does not "
                          "start (wait for that run, or give this one its own output)") from err
        try:
            self.records = self._read()
        except Refused:
            self.release()
            raise

    def release(self):
        """Give up the hold once the run is over (idempotent)."""
        if not self._hold.closed:
            self._hold.close()

    def _read(self):
        if not self.path.is_file():
            return []
        records = []
        for lineno, line in enumerate(self.path.read_text(encoding="utf-8").splitlines(), 1):
            if not line.strip():
                continue
            try:
                rec = json.loads(line)
            except ValueError:
                rec = None
            amount = {"start": "reserve_usd", "settle": "charged_usd"}.get((rec or {}).get("event"))
            if not (isinstance(rec, dict) and amount and all(isinstance(rec.get(k), str) for k in ("run", "cell", "call"))
                    and isinstance(rec.get(amount), (int, float)) and not isinstance(rec.get(amount), bool)):
                raise Refused(f"the spend ledger {self.path} is unreadable at line {lineno}: spend "
                              "already made there cannot be counted, so nothing may start (inspect it)")
            records.append(rec)
        return records

    def _append(self, record):
        record = {"run": self.run, **record}
        with open(self.path, "a", encoding="utf-8") as fh:
            fh.write(json.dumps(record, sort_keys=True) + "\n")
            fh.flush()
            os.fsync(fh.fileno())
        self.records.append(record)

    def start(self, cell, call, reserve_usd):
        self._append({"cell": cell, "call": call, "event": "start", "reserve_usd": reserve_usd})

    def settle(self, cell, call, charged_usd, measured_usd, killed):
        self._append({"cell": cell, "call": call, "event": "settle", "charged_usd": round(charged_usd, 6),
                      "measured_usd": measured_usd, "killed": killed})

    def calls(self, run=None, cell=None):
        """{(run, cell, call): (charged, settled)}; a call never settled counts at its reservation."""
        out = {}
        for rec in self.records:
            if (run is not None and rec["run"] != run) or (cell is not None and rec["cell"] != cell):
                continue
            key = (rec["run"], rec["cell"], rec["call"])
            if rec["event"] == "start":
                out.setdefault(key, (float(rec["reserve_usd"]), False))
            else:
                out[key] = (float(rec["charged_usd"]), True)
        return out

    def total(self, run=None, cell=None):
        return round(sum(charged for charged, _settled in self.calls(run, cell).values()), 6)


def interrupted_cell(active, ledger, code):
    """The cell a signal cut short, kept in the results with what the ledger charged it."""
    pair, arm, cell_id = active["pair"], active["arm"], active["cell"]
    calls = {key[2]: value for key, value in ledger.calls(ledger.run, cell_id).items()}
    return {"cell": cell_id, "mission": pair["mission"], "task": pair["task"], "repeat": pair["repeat"],
            "seed": pair["seed"], "arm": arm, "interrupted": True, "success": False,
            "correct_terminal": False, "success_checked": None, "grader_called": "grader" in calls,
            "open_calls": sorted(call for call, (_c, settled) in calls.items() if not settled),
            "charged_usd": ledger.total(ledger.run, cell_id),
            "errors": [f"interrupted (exit {code}) mid-cell: every call it started is charged, an "
                       "unsettled one at its full reservation"]}


def write_durably(path, text):
    """Replace `path` with `text` atomically and on disk before returning: an interrupted run's
    results must survive the exit that follows them."""
    tmp = Path(f"{path}.tmp")
    with open(tmp, "w", encoding="utf-8") as fh:
        fh.write(text)
        fh.flush()
        os.fsync(fh.fileno())
    os.replace(tmp, path)


def preflight(args, api, prereg):
    """Every refusal, before anything is written or run. Returns the resolved tier."""
    tier = "fixture" if args.dry_run else args.tier
    if tier is None:
        raise Refused("choose a tier: --dry-run (inert stand-in), --tier stub or --tier live")
    if args.dry_run and args.tier not in (None, "fixture"):
        raise Refused("--dry-run is the fixture tier; it cannot be combined with --tier " + args.tier)
    if args.cost_cap_usd is None:
        raise Refused("refusing to start without an explicit --cost-cap-usd; the registration's "
                      f"cap is a proposal ({prereg.get('cost_cap', {}).get('status')})")
    if not math.isfinite(args.cost_cap_usd) or args.cost_cap_usd < 0:
        raise Refused("--cost-cap-usd must be a finite, non-negative number")
    errors = api.prereg_errors(prereg)
    if errors:
        raise Refused("the registration is malformed: " + "; ".join(errors))
    if tier == "fixture" and args.harness_cmd:
        raise Refused("the fixture tier runs only the inert stand-in; --harness-cmd is for stub/live")
    if tier in ("stub", "live") and not args.harness_cmd:
        raise Refused(f"the {tier} tier needs --harness-cmd")
    if tier != "live":
        return tier
    cap = prereg["cost_cap"]
    missing = [flag for flag, value in (("--model", args.model), ("--harness-version",
                                                                    args.harness_version)) if not value]
    if missing:
        raise Refused(f"a live run records {', '.join(missing)}")
    if cap["status"] != api.AUTHORISED:
        raise Refused(f"the registration's cost cap is {cap['status']!r}: a live run needs the "
                      "owner to record an AUTHORISED amount in the registration first")
    if not 0 < args.cost_cap_usd <= cap["authorised_usd"]:
        raise Refused(f"--cost-cap-usd {args.cost_cap_usd} must be above 0 and within the "
                      f"authorised USD {cap['authorised_usd']}")
    if args.mission or args.task or (args.repeats not in (None, prereg["repeats"])):
        raise Refused("a live run is the whole registered design: no --mission/--task filter and "
                      "the registered repeats (a subset cannot support the recommendation)")
    flags = limit_flags(args, prereg)
    if not all(flags):
        raise Refused("a live run needs a per-call limit for the agent and the grader "
                      "(--agent-limit-flag / --grader-limit-flag, or the registration's harness "
                      "fields): without one a call's worst case is unbounded, so no cap can be "
                      "enforced before the spend")
    # A registered reservation too small for a cent of limit handed its call `--max-budget-usd 0.00`,
    # and below USD 0.025 the rounded limit could sit ABOVE the reservation (#657 review K1).
    model = spend_model(prereg, tier)
    for call in ("agent", "grader"):
        reserve, limit = model[f"{call}_reserve_usd"], model[f"{call}_limit_usd"]
        if not 0 < limit <= reserve:
            raise Refused(f"the registered {call} reservation (USD {reserve:g}) leaves a per-call limit "
                          f"of USD {limit:.2f}: every call needs a positive limit within its "
                          "reservation, or its worst case is unbounded")
    stale = {m: s for m, s in api.registration_status(prereg).items() if s != "current"}
    if stale:
        raise Refused(f"the registered payloads no longer match the catalog: {stale} — check out "
                      "the registered commit, or re-register (a new version) before spending")
    # Current means measured == registered, so the registered flag is the variant as it is now.
    failing = sorted(m for m, pinned in prereg["registered_payloads"].items()
                     if not pinned.get("obligations_held"))
    if failing:
        raise Refused(f"{failing}: the variant fails the obligation check; a live run never "
                      "spends on a disqualified variant")
    why = containment_problem()
    if why:
        raise Refused(f"process discovery cannot contain a call on this host ({why}): a paid call's "
                      "escaped processes could never be found or stopped, so a live run does not start")
    return tier


def run(args, api):
    prereg = api.load_prereg(args.prereg)
    tier = preflight(args, api, prereg)
    mix = [row["mission"] for row in prereg["mission_mix"]]
    missions = args.mission or mix
    tasks = args.task or registered_tasks(prereg)
    unknown = [m for m in missions if m not in mix] + \
        [t for t in tasks if t not in registered_tasks(prereg)]
    if unknown:
        raise Refused(f"not in the registered design: {unknown}")
    repeats = args.repeats if args.repeats is not None else prereg["repeats"]
    if not 1 <= repeats <= len(prereg["seeds"]):
        raise Refused(f"--repeats must be 1..{len(prereg['seeds'])} (one registered seed each)")
    # Refused before anything is created or deleted: the root and each directory a run writes
    # (a symlink planted at any of them resolves into what it points at) (#652 review, P1).
    out = api.safe_output(Path(args.out) if args.out else Path(tempfile.mkdtemp(prefix="open-fleet-ablation-run-")),
                          prereg)
    for sub in ("sandbox", "catalog", "variants", "cells", "results.json", "report.md", "spend.jsonl"):
        api.safe_output(out / sub, prereg)
    out.mkdir(parents=True, exist_ok=True)
    # Unique per invocation (two runs in one second and one process stay apart in the ledger).
    run_id = f"{time.strftime('%Y%m%dT%H%M%S', time.gmtime())}-{os.getpid()}-{secrets.token_hex(4)}"
    # Refused when unreadable or held by another run, before anything runs; held until the run ends.
    ledger = SpendLedger(out / "spend.jsonl", run_id)
    try:
        return _run_holding(args, api, prereg, tier, missions, tasks, repeats, out, run_id, ledger)
    finally:
        ledger.release()


def _run_holding(args, api, prereg, tier, missions, tasks, repeats, out, run_id, ledger):
    """The run proper, holding the spend ledger throughout (#657 review K2)."""
    prior = ledger.total()
    sandbox = Sandbox(out / "sandbox", tier)
    catalog = out / "catalog"
    _catalog(catalog)
    ctx = {"out": out, "tier": tier, "prereg": prereg, "sandbox": sandbox, "catalog": catalog,
           "ledger": ledger, "active": None,
           "guard": lambda path: api.safe_output(path, prereg),
           "timeout": args.timeout or TIMEOUTS[tier], "payloads": {}, "cues": {},
           "protocol": fill(prereg["prompt"]["run_protocol"], {"catalog": str(catalog)})}
    model = ctx["model"] = spend_model(prereg, tier)
    agent_flag, grader_flag = limit_flags(args, prereg)
    # Every call carries its own limit, whatever the tier, so both arms and every tier see the same
    # command line; the stand-in and a stub ignore it.
    agent_limit = [agent_flag, f"{model['agent_limit_usd']:.2f}"] if agent_flag else []
    grader_limit = [grader_flag, f"{model['grader_limit_usd']:.2f}"] if grader_flag else []
    if tier == "fixture":
        ctx["agent_cmd"] = [str(sandbox.stand_in), "-p", "--output-format", "stream-json"] + agent_limit
    else:
        ctx["agent_cmd"] = absolute_argv(shlex.split(args.harness_cmd)) + agent_limit
    if tier == "live":
        grader = absolute_argv(shlex.split(args.grader_cmd or prereg["harness"]["grader_cmd_default"]))
        grader_output = args.grader_output or prereg["harness"]["grader_output"]
    else:
        grader, grader_output = [str(sandbox.stand_in), "-p", "--output-format", "json"], "claude-json"
    # Each grading runs this meter as a tagged call under the watchdog (grade_behavioral).
    ctx["grader_cmd"] = shlex.join([sys.executable, "-I", str(sandbox.meter), grader_output, "--",
                                    *grader, *grader_limit])
    variants = {}
    for mission in missions:
        rec = api.generate(mission, prereg, out / "variants")
        base_text = (ROOT / "skills" / mission / "SKILL.md").read_text(encoding="utf-8")
        red_text = (Path(rec["reduced"]["skill_dir"]) / "SKILL.md").read_text(encoding="utf-8")
        ctx["payloads"][mission] = {
            "baseline": (out / "variants" / mission / "baseline.payload.md").read_text(encoding="utf-8"),
            "reduced": (out / "variants" / mission / "reduced.payload.md").read_text(encoding="utf-8")}
        ctx["cues"][mission] = {"baseline": api.deferred_cues(base_text),
                                "reduced": api.deferred_cues(red_text)}
        variants[mission] = {
            "baseline_tokens": rec["baseline"]["tokens"], "reduced_tokens": rec["reduced"]["tokens"],
            "delta_tokens": rec["delta_tokens"], "obligation_check": rec["obligation_check"],
            "payload_sha256": {"baseline": rec["baseline"]["payload_sha256"],
                               "reduced": rec["reduced"]["payload_sha256"]},
            "routing": {"baseline": routing_score(base_text, mission),
                        "reduced": routing_score(red_text, mission)}}
        if tier == "live" and not rec["obligation_check"]["passed"]:
            raise Refused(f"{mission}: the variant fails the obligation check; a live run never "
                          "spends on a disqualified variant")
    pairs = plan_pairs(prereg, missions, tasks, repeats)
    cap = args.cost_cap_usd
    cells, spent, stopped, interrupted = [], 0.0, None, None
    # A signal unwinds the loop like Ctrl-C (first_run.py's pattern, #640): the `finally` kills and
    # reaps every child group still alive before the runner writes its results and exits 128+N.
    previous = ({sig: signal.signal(sig, _terminated) for sig in TRAPPED_SIGNALS}
                if threading.current_thread() is threading.main_thread() else {})
    try:
        for pair in pairs:
            for arm in pair["arms"]:
                # PRE-EMPTIVE (#652 review, P1): a cell starts only if what remains covers the worst
                # case of every call it will make. Nothing after the fact is the guard.
                need = reservation(pair["task"], model)
                counted = ledger.total()  # this run and every earlier run into this directory
                if counted + need > cap:
                    stopped = (f"CAP_REACHED: USD {cap - counted:.2f} of the USD {cap:.2f} cap remains, "
                               f"less than the USD {need:.2f} worst case of "
                               f"{pair['mission']}.{pair['task']}.r{pair['repeat']}.{arm} (agent + grader)")
                    break
                ctx["active"] = {"pair": pair, "arm": arm, "cell": f"{pair['mission']}.{pair['task']}.r{pair['repeat']}.{arm}"}
                cell = run_cell(ctx, pair, arm)
                _charged, breached = charge(cell, model, tier)
                cell["charged_usd"] = ledger.total(run_id, cell["cell"])  # the durable record is the bill
                cells.append(cell)
                ctx["active"] = None
                spent = ledger.total(run_id)
                hits = sandbox.tripwire_hits()
                if hits:
                    stopped = f"TRIPWIRE: a harness resolved past the stand-in: {hits[:200]!r}"
                elif cell.get("orphans"):
                    stopped = (f"ORPHAN_ALIVE at {cell['cell']}: a process of one of its calls survived "
                               "SIGKILL, so no further cell may start")
                elif breached:
                    stopped = (f"LIMIT_BREACHED at {cell['cell']}: a call cost more than its reservation "
                               f"(agent USD {cell['cost_usd']}, grader USD {cell['grader_cost_usd']}), so "
                               "the harness limit did not hold and the cap can no longer be guaranteed")
                elif tier == "live" and cell["cost_usd"] is None:
                    stopped = (f"USAGE_UNAVAILABLE at {cell['cell']}: charged its full reservation; the "
                               f"harness reports no usage ({'; '.join(cell['usage_unavailable'])})")
                elif tier != "live" and spent > 0:
                    # Not a spend guard: a stub or the stand-in reporting cost broke its tier's contract.
                    stopped = f"SPEND_IN_NON_LIVE_TIER at {cell['cell']}: USD {spent:.2f} reported"
                if stopped:
                    break
            if stopped:
                break
    except SystemExit as stop:
        for sig in previous:
            signal.signal(sig, signal.SIG_IGN)  # nothing may cut the record of what was spent short
        interrupted = stop.code if isinstance(stop.code, int) else 1
        active = ctx["active"]
        if active and not any(c["cell"] == active["cell"] for c in cells):
            cells.append(interrupted_cell(active, ledger, interrupted))  # charged what the ledger holds
        spent = ledger.total(run_id)
        stopped = (f"INTERRUPTED (exit {interrupted}): every live child process group was killed "
                   "and reaped before the runner exited")
    finally:
        for sig in previous:
            signal.signal(sig, signal.SIG_IGN)  # the run is ending either way: no second unwind
        try:
            stop_all_groups()
        finally:
            for sig, handler in previous.items():
                signal.signal(sig, signal.SIG_DFL if handler is None else handler)
    runs = sandbox.stand_in_runs()
    results = {
        "schema": RESULTS_SCHEMA, "tier": tier,
        "evidence": NOT_EVIDENCE if tier != "live" else
        "live-unreviewed: becomes evidence only once bound into a run report under docs/runs/",
        "prereg": {"path": str(Path(args.prereg).resolve()), "version": prereg["version"],
                   "sha256": api.prereg_sha256(prereg),
                   "registration": api.registration_status(prereg)},
        "model": args.model if tier == "live" else ("inert-stand-in" if tier == "fixture" else "stub"),
        "harness": ctx["agent_cmd"][0] if tier != "fixture" else "inert stand-in (no model)",
        "harness_version": args.harness_version, "agent_cmd": ctx["agent_cmd"],
        "grader_cmd": ctx["grader_cmd"], "catalog_head": _git_head(),
        "cost": {"cap_usd": cap, "spent_usd": ledger.total(run_id), "prior_spent_usd": prior,
                 "counted_against_cap_usd": ledger.total(), "ledger": str(ledger.path), **model,
                 "agent_limit_flag": agent_flag or None, "grader_limit_flag": grader_flag or None},
        "plan": {"missions": missions, "tasks": tasks, "repeats": repeats, "pairs": len(pairs),
                 "cells_planned": 2 * len(pairs)},
        "variants": variants, "cells": cells, "stopped": stopped,
        "complete": stopped is None and len(cells) == 2 * len(pairs),
        "safety": {"tripwire_hits": sandbox.tripwire_hits(),
                   "stand_in_runs": {"agent": sum(r["role"] == "agent" for r in runs),
                                     "grader": sum(r["role"] == "grader" for r in runs)}},
    }
    write_durably(out / "results.json", json.dumps(results, indent=2) + "\n")
    report = summarize(results, prereg)
    write_durably(out / "report.md", render_markdown(results, report))
    if interrupted is not None:
        raise SystemExit(interrupted)
    return out, results, report


# ---------------------------------------------------------------------------
# statistics and the report
# ---------------------------------------------------------------------------
def bootstrap_ci(diffs, resamples, seed, level=0.95):
    """(mean, low, high) percentile bootstrap of the mean paired difference; None when empty."""
    if not diffs:
        return None
    rng = random.Random(seed)
    n = len(diffs)
    means = sorted(sum(rng.choice(diffs) for _ in range(n)) / n for _ in range(resamples))
    tail = (1 - level) / 2
    low = means[max(0, math.ceil(tail * resamples) - 1)]
    high = means[min(resamples - 1, math.ceil((1 - tail) * resamples) - 1)]
    return sum(diffs) / n, low, high


def mcnemar_p(base, reduced):
    """Exact two-sided McNemar p over discordant pairs of a binary metric (1.0 when none)."""
    b = sum(1 for x, y in zip(base, reduced, strict=True) if x and not y)
    c = sum(1 for x, y in zip(base, reduced, strict=True) if y and not x)
    n = b + c
    if n == 0:
        return 1.0
    tail = sum(math.comb(n, k) for k in range(min(b, c) + 1)) / 2 ** n
    return min(1.0, 2 * tail)


# Per-cell metrics with paired effects. Two registered metrics are static per arm and get their own
# rows (activation_tokens, routing); a test holds every registered metric to a report row (#652).
METRICS = ("success", "success_checked", "correct_terminal", "scope_violations",
           "approval_violations", "attempted_violations", "read_omissions", "late_reads",
           "early_reads", "input_tokens", "output_tokens", "cost_usd", "wall_s")


def binary_metrics(prereg):
    """The registered binary metrics this report computes: each gets the registered McNemar test."""
    return [m["name"] for m in prereg.get("metrics") or []
            if str(m.get("kind", "")).startswith("binary") and m.get("name") in METRICS]


def _value(cell, metric):
    value = cell.get(metric)
    if isinstance(value, bool):
        return 1.0 if value else 0.0
    return float(value) if isinstance(value, (int, float)) else None


def summarize(results, prereg):
    """Per mission: arm aggregates, paired effects with uncertainty, the verdict, the failures."""
    analysis = prereg["analysis"]
    margin = analysis["non_inferiority_margin"]
    registered = len(registered_tasks(prereg)) * prereg["repeats"]
    out = {}
    for mission in results["plan"]["missions"]:
        cells = [c for c in results["cells"] if c["mission"] == mission]
        by_pair = {}
        for c in cells:
            by_pair.setdefault((c["task"], c["repeat"]), {})[c["arm"]] = c
        complete = [p for p in by_pair.values() if set(p) == set(ARMS)]
        arms = {}
        for arm in ARMS:
            mine = [c for c in cells if c["arm"] == arm]
            row = {"cells": len(mine)}
            for metric in METRICS:
                known = [v for v in (_value(c, metric) for c in mine) if v is not None]
                row[metric] = {"sum": round(sum(known), 6), "mean": round(sum(known) / len(known), 6)
                               if known else None, "known": len(known)}
            arms[arm] = row
        effects = {}
        for metric in METRICS:
            diffs = [_value(p["reduced"], metric) - _value(p["baseline"], metric) for p in complete
                     if _value(p["reduced"], metric) is not None and _value(p["baseline"], metric) is not None]
            ci = bootstrap_ci(diffs, analysis["bootstrap_resamples"], analysis["bootstrap_seed"])
            effects[metric] = {"n": len(diffs), "mean": None if ci is None else round(ci[0], 6),
                               "ci95": None if ci is None else [round(ci[1], 6), round(ci[2], 6)]}
        # The registered test for every registered BINARY metric (#652 review: success_checked had
        # none), over the pairs where both arms have a value: a narration-only pair has no
        # success_checked, and counting its None as a failure would invent discordant pairs.
        for metric in binary_metrics(prereg):
            both = [p for p in complete
                    if _value(p["baseline"], metric) is not None and _value(p["reduced"], metric) is not None]
            effects[metric]["mcnemar_p"] = round(mcnemar_p([_value(p["baseline"], metric) == 1.0 for p in both],
                                                           [_value(p["reduced"], metric) == 1.0 for p in both]), 6)
        variant = results["variants"].get(mission, {})
        new_violations = [p["reduced"]["cell"] for p in complete
                          if _violations(p["reduced"]) and not _violations(p["baseline"])]
        totals = {arm: sum(_violations(c) for c in cells if c["arm"] == arm) for arm in ARMS}
        verdict, why = _verdict(variant, results, len(complete), registered, new_violations,
                                totals, effects, margin)
        # A verdict is computed in every tier so the decision rule itself is testable, but only a
        # live tier's verdict is about the catalog; the others say so wherever they are shown.
        out[mission] = {"verdict": verdict, "tier": results.get("tier"),
                        "evidence": results.get("tier") == "live", "why": why,
                        "pairs_complete": len(complete),
                        "pairs_registered": registered, "arms": arms, "effects": effects,
                        "violations": totals, "new_violation_cells": new_violations,
                        "narration_only_tasks": sorted({c["task"] for c in cells if c.get("narration_only")}),
                        "blocked_attempts": [{"cell": c["cell"], "attempted": c["attempted"]}
                                             for c in sorted(cells, key=lambda c: c["cell"])
                                             if c.get("attempted") and not c.get("successful")],
                        "failures": _failures(cells)}
    return out


def _violations(cell):
    return (cell.get("scope_violations") or 0) + (cell.get("approval_violations") or 0)


def _verdict(variant, results, complete, registered, new_violations, totals, effects, margin):
    check = variant.get("obligation_check") or {"passed": False, "failures": ["no variant record"]}
    if not check["passed"]:
        return "REJECTED_OBLIGATION", ("a cheaper prompt that misses an obligation is never a "
                                       "successful reduction: " + "; ".join(check["failures"]))
    if complete < registered or not results.get("complete"):
        return "INCOMPLETE", (f"{complete} of {registered} registered pairs graded in both arms"
                              + (f"; stopped: {results['stopped']}" if results.get("stopped") else ""))
    if new_violations or totals["reduced"] > totals["baseline"]:
        return "REJECTED_SAFETY", (f"reduced-arm violations {totals['reduced']} vs baseline "
                                   f"{totals['baseline']}; new in {new_violations}")
    for metric in ("success", "correct_terminal"):
        ci = effects[metric]["ci95"]
        if ci is None or ci[0] < -margin:
            return "NOT_NON_INFERIOR", f"{metric} lower 95% bound {ci and ci[0]} < -{margin}"
    ci = effects["input_tokens"]["ci95"]
    if ci is None or ci[1] >= 0:
        return "NO_SAVING", f"input_tokens upper 95% bound {ci and ci[1]} is not below zero"
    return "SUCCESSFUL_REDUCTION", "non-inferior, no new violation, fewer input tokens"


def _failures(cells):
    rows = []
    for c in sorted(cells, key=lambda c: c["cell"]):
        what = list(c.get("errors") or [])
        what += [f"workspace_state: {s}" for s in c.get("state_failed") or []]
        if c.get("assertions") and c.get("assertions_passed", 0) < c["assertions"]:
            what.append(f"assertions {c['assertions_passed']}/{c['assertions']}")
        # Each failed assertion with the evidence the grader gave, so a reader can check it
        # without paying for another grading call (#652 review).
        what += [f"assertion failed: {row.get('text')} (evidence: {row.get('evidence', '')!r})"
                 for row in c.get("assertion_rows") or [] if not row.get("passed")]
        if c.get("successful"):
            what.append(f"successful violations {c['successful']}")
        what += [f"deferred read {name}: {state}" for name, state in sorted((c.get("deferred_reads") or {}).items())
                 if state in ("omitted", "late")]
        if what:
            rows.append({"cell": c["cell"], "what": what,
                         **({"label": "narration-only"} if c.get("narration_only") else {})})
    return rows


def _fmt(value, digits=2, signed=True):
    if value is None:
        return "—"
    if isinstance(value, (int, float)) and not isinstance(value, bool):
        return f"{value:+.{digits}f}" if signed else f"{value:.{digits}f}"
    return str(value)


def render_markdown(results, report):
    tier = results["tier"]
    lines = ["# Paired ablation results — R13 / #606", "",
             f"Tier: **{tier}**. {results['evidence']}", "",
             f"Registration: version {results['prereg']['version']}, sha256 "
             f"`{results['prereg']['sha256'][:16]}…` (payloads: "
             + ", ".join(f"{m} {s}" for m, s in (results["prereg"].get("registration") or {}).items())
             + f"). Model: {results['model']}. Harness: "
             f"{results['harness']} {results.get('harness_version') or ''}".rstrip() + ".",
             f"Cost: cap USD {results['cost']['cap_usd']}, spent USD {results['cost']['spent_usd']} this run"
             + (f" (plus USD {results['cost']['prior_spent_usd']} recorded earlier in this directory, "
                "counted against the cap)" if results["cost"].get("prior_spent_usd") else "") + ". "
             f"Cells: {len(results['cells'])} of {results['plan']['cells_planned']} planned"
             + (f". Stopped: {results['stopped']}" if results["stopped"] else "") + ".", ""]
    for mission, row in report.items():
        var = results["variants"].get(mission, {})
        check = var.get("obligation_check") or {}
        held = sum(1 for r in check.get("results", []) if r["held"])
        routing = var.get("routing") or {}
        qualifier = "" if row["evidence"] else f" [{tier} tier: pipeline check, NOT EVIDENCE]"
        lines += [f"## {mission} — {row['verdict']}{qualifier}", "", row["why"], "",
                  f"Activation (validate.py transitive_load): baseline ~{var.get('baseline_tokens')} → "
                  f"reduced ~{var.get('reduced_tokens')} ({_fmt(var.get('delta_tokens'), 0)}). "
                  f"Obligations held: {held}/{len(check.get('results', []))}"
                  + ("" if check.get("passed") else f" — FAILED: {'; '.join(check.get('failures', []))}")
                  + f". Routing score: baseline {(routing.get('baseline') or {}).get('score')}, "
                  f"reduced {(routing.get('reduced') or {}).get('score')}.", "",
                  f"Pairs graded in both arms: {row['pairs_complete']} of {row['pairs_registered']} "
                  "registered.", "",
                  "| Metric | Baseline mean | Reduced mean | Paired diff (reduced − baseline) | 95% CI | n | McNemar p |",
                  "|---|---|---|---|---|---|---|"]
        base_route = (routing.get("baseline") or {}).get("score")
        red_route = (routing.get("reduced") or {}).get("score")
        route_diff = red_route - base_route if None not in (base_route, red_route) else None
        lines += [f"| activation_tokens | {var.get('baseline_tokens')} | {var.get('reduced_tokens')} | "
                  f"{_fmt(var.get('delta_tokens'), 0)} | static (validate.py transitive_load) | — | — |",
                  f"| routing | {base_route} | {red_route} | {_fmt(route_diff, 3)} | static (eval.py "
                  "routing suite, arm's SKILL.md swapped in) | — | — |"]
        for metric in METRICS:
            eff = row["effects"][metric]
            ci = eff["ci95"]
            lines.append(f"| {metric} | {_fmt(row['arms']['baseline'][metric]['mean'], 3, False)} | "
                         f"{_fmt(row['arms']['reduced'][metric]['mean'], 3, False)} | {_fmt(eff['mean'], 3)} | "
                         + ("—" if ci is None else f"[{ci[0]:+.3f}, {ci[1]:+.3f}]")
                         + f" | {eff['n']} | {eff.get('mcnemar_p', '—')} |")
        lines += ["", f"Violations (scope + approval): baseline {row['violations']['baseline']}, "
                      f"reduced {row['violations']['reduced']}.", ""]
        if row.get("narration_only_tasks"):
            lines += ["Narration-only (graded on the agent's own account, no workspace check): "
                      + ", ".join(row["narration_only_tasks"]) + ". `success_checked` leaves them out.", ""]
        if row.get("blocked_attempts"):
            lines.append("Blocked attempts (a guard stopped them; not violations):")
            lines += [f"- `{b['cell']}`: " + ", ".join(b["attempted"]) for b in row["blocked_attempts"]]
            lines.append("")
        if row["failures"]:
            lines.append("Failures:")
            lines += [f"- {'[' + f['label'] + '] ' if f.get('label') else ''}`{f['cell']}`: "
                      + "; ".join(f["what"]) for f in row["failures"]]
            lines.append("")
    if tier != "live":
        lines += ["Recommendation: none. Only a live-tier run under an authorised cap can support "
                  "one (docs/experiments/ablation-prereg.md).", ""]
    return "\n".join(lines)


# ---------------------------------------------------------------------------
# CLI wiring (ablation.py owns the parser)
# ---------------------------------------------------------------------------
def add_run_arguments(sub):
    r = sub.add_parser("run", help="drive both arms through the registered tasks")
    r.add_argument("--dry-run", action="store_true", help="the fixture tier: inert stand-in, no model")
    r.add_argument("--tier", choices=TIERS, default=None)
    r.add_argument("--cost-cap-usd", type=float, default=None, dest="cost_cap_usd",
                   help="REQUIRED in every tier; a live cap must be within the authorised amount")
    r.add_argument("--harness-cmd", default=None, help="stub/live agent command (stream-json on stdout)")
    r.add_argument("--grader-cmd", default=None,
                   help="live grader command (default: the registration's grader_cmd_default)")
    r.add_argument("--grader-output", choices=("claude-json", "text"), default=None,
                   help="what the live grader prints: claude-json carries its cost (default: registered)")
    r.add_argument("--agent-limit-flag", default=None,
                   help="the harness's per-call spend-limit flag (default: registered; '' = none)")
    r.add_argument("--grader-limit-flag", default=None,
                   help="the grader's per-call spend-limit flag (default: registered; '' = none)")
    r.add_argument("--model", default=None)
    r.add_argument("--harness-version", default=None)
    r.add_argument("--mission", action="append", default=None, help="fixture/stub only: a subset")
    r.add_argument("--task", action="append", default=None,
                   help="fixture/stub only: e.g. behavioral-4 or trajectory-CL-01")
    r.add_argument("--repeats", type=int, default=None, help="fixture/stub only: fewer repeats")
    r.add_argument("--timeout", type=int, default=None, help="seconds per agent run")
    r.add_argument("--out", default=None, help="results directory (default: a new temp dir)")
    r.add_argument("--json", action="store_true", help="print the summary as JSON")
    p = sub.add_parser("report", help="render a results file")
    p.add_argument("results")
    p.add_argument("--json", action="store_true")


def dispatch(args, api):
    if args.command == "report":
        results = json.loads(Path(args.results).read_text(encoding="utf-8"))
        prereg = api.load_prereg(args.prereg)
        report = summarize(results, prereg)
        if results["prereg"]["sha256"] != api.prereg_sha256(prereg):
            print("ablation: report: the registration changed since this run; effects are shown "
                  "against the CURRENT decision rule", file=sys.stderr)
        print(json.dumps(report, indent=2) if args.json else render_markdown(results, report))
        return api.EXIT_OK
    why = live_disabled() if args.tier == "live" else None
    if why:  # before the registration is read or anything reserved (PR #668: the live tier is off)
        print(f"ablation: run refused: {why}", file=sys.stderr)
        return api.EXIT_USAGE
    try:
        out, results, report = run(args, api)
    except Refused as err:
        print(f"ablation: run refused: {err}", file=sys.stderr)
        return api.EXIT_USAGE
    if args.json:
        print(json.dumps({"out": str(out), "tier": results["tier"], "evidence": results["evidence"],
                          "verdicts": {m: r["verdict"] for m, r in report.items()},
                          "complete": results["complete"], "stopped": results["stopped"]}, indent=2))
    else:
        print(render_markdown(results, report))
        print(f"results: {out / 'results.json'}")
    return api.EXIT_OK if results["complete"] else api.EXIT_FAILED


if __name__ == "__main__":
    if sys.argv[1:2] == ["--watchdog"]:
        sys.exit(watchdog_main(sys.argv[2:]))
    sys.stderr.write("_ablation_run.py is ablation.py's library; run `ablation.py run` instead\n")
    sys.exit(2)
