# Testing

Rules about how tests are registered, what they may assume, and the ways a test
suite in this repository has previously reported a defect as something else.

Read this before adding a script-driven test, a test that needs a port, or any
test that waits on another process or thread.

The rule that costs the most when broken: **every wait is bounded**. A helper that
spins on a condition a regression never satisfies hangs instead of failing, and a
900-second ctest timeout naming nothing is the least useful way CI can report a
defect — this repository has already paid for that once
(`dist-compile-e2e ***Timeout 900.10 sec`).

And the next clause of the same rule: **a bound is an assumption about the
machine.** A budget that passes on a warm developer laptop encodes that laptop — a
cold two-core runner doing the same work is the machine the test actually has to
survive. Write the budget for the slower machine, and make the wait name **which**
participant it is waiting for, because "saw 1 of 3" says the fleet is short without
saying which process never came up.

`node-scratch-isolation-e2e` cost a CI cycle proving it. It started two compile
nodes at once, each given a bare `--toolchain` — which makes a node compute a
fingerprint by walking the compiler's entire include tree. Warm, that is seconds and
the fixture passed every local run. Cold, on a two-core runner, two of those racing
did not both finish inside 90 seconds, and the fixture failed having never reached a
compile. The one node that did register was the scheduler, because
`--toolchain=scheduler-only=<cc>` names its fingerprint explicitly and is therefore
never probed — and *that* asymmetry, visible only in the log, is what identified the
cause. (That trick is gone since #206: a scheduler kept out of the work is
`--slots=0`, which surveys and registers nothing.) The budget was not careless; it
was measured on the wrong machine.

Two things fixed it, and the second is the one that generalises: the nodes are
started one at a time, and each wait names the node it is waiting for and dumps that
node's log when it expires. Serialising cost the fixture nothing, because what it
exists to catch happens when two workers *compile* at once, not when they start.

One corollary, because reorganising a fixture is how its teeth get quietly pulled:
**a fixture that has been restructured and not re-falsified is a fixture nobody has
checked.** After that change the defect was reintroduced and the fixture confirmed to
still fail for its original reason before the change was believed.

## A wall clock is not a duration, because it can be STEPPED

<!-- agent-tripwire: A wall clock is not a duration -->

`SECONDS`, `TIMEFORMAT='%3R'` and `date +%s.%N` all read CLOCK_REALTIME, and a VM
guest's host time sync moves that in both directions. An interval computed from
two readings of it is therefore not a lower bound, not an upper bound, and can be
**negative**.

### And a negative interval does not read as an error, it reads as the BEST answer

That is the half that costs something, and it is not about clocks at all: it is
about what the negative is then handed to.

`scripts/check-sccache-backend-caveat.cmake` classifies a scan's cost by looking
its per-file figure up in a table of ascending ceilings, first match wins
(`msPerFile LESS_EQUAL ${bandCeiling}`). **Every negative number is LESS_EQUAL the
first row's ceiling**, so a backward step does not produce a refusal or an
obviously broken figure — it produces the FASTEST band. Measured by injecting a
100 s backward step on 2026-09-12: `-100s wall in total, about -93 ms/file. That
is the 'native' band: A filesystem reached directly -- ext4, or NTFS from a
Windows cmake`, on a run that was on neither, **exit 0**. The instrument whose one
job is to say which filesystem condition the scan ran under answered confidently,
wrongly, and passed.

The same cause reaches a second consumer and fails it the OTHER way: a narration
line appended only when `runSeconds GREATER_EQUAL` a threshold, which a negative
never is, so a required line goes missing and the check goes **red** with `did not
say: narrated nothing`. Both failures, one step. **The loud one is what got filed
(#1313) and the silent one is what was worth fixing** — which is the general
shape: a wrong answer that passes outranks a true observation that reddens.

What is worth carrying past this check:

* **The fix is a third outcome, never a clamp.** Clamping a negative to zero
  restores the fastest-band answer by the front door, and it looks like
  defensiveness while doing it. A mutation that clamped instead of reporting was
  caught by the new case only because the case asserts the band is ABSENT rather
  than asserting the number.
* **Intervals over one clock disagree, so the outcome is recorded where the
  SUBTRACTION happens** — never rebuilt at the sites the report happens to hold
  variables for. A step landing inside a sub-interval leaves the enclosing one
  positive; consulting only the enclosing interval passed both of the first two
  regression cases, and was caught by a third that places the step inside the
  inner one (`100,200,150`). Fixing *that* by OR-ing the two intervals the cost
  line names is the same defect one step along: this check takes **four** — the
  whole run, the directory walk, one per root at the walk's narration point and
  one per progress checkpoint — and a step landing in the READ phase, which is
  where nearly all the wall time is, shows up only in a checkpoint's. Measured
  with `1000×10,900,1100`: the walk measured `0s`, the run `+100s`, a checkpoint
  `-100s`, and the check reported `93 ms/file. That is the 'bridged and
  contended' band` at exit 0 — a band across a clock it had already watched move.
  So `pace_scan_interval` takes a LABEL and files every backward step
  itself, and the reporting arm reads that record rather than enumerating its
  sources. An arm that enumerates them is an arm that goes silent about the next
  interval somebody adds.
* **And silencing is per INTERVAL, not per run**, so the refusal says what
  narration DID rather than asserting it is off: a step in the walk leaves every
  later checkpoint free to fire, and a blanket *"progress narration is off"*
  printed beside `still scanning` lines the same run emitted is exactly the
  confident wrong detail a "cost NOT MEASURED" message exists to avoid.
* **Adding an OUTCOME changes what an old condition does to every case that
  tolerated the wrong answer.** This is the half that nearly shipped, and it is
  not about clocks.

  Before the third outcome existed, a backward step made this check print
  `-93 ms/file / 'native' band` -- wrong, but *shaped like an answer*, so every
  assertion about `ms/file. That is the '`, the headroom line, `still scanning` and
  `narrated nothing` was still satisfied and the cases passed. The third outcome
  replaces all of that with one refusal sentence, so the same step now fails any
  case that reads the host clock. **Four default-set `hygiene` cases were made
  flaky by a fix for flakiness**, in the direction that reads as *my branch is
  bad*, and the author had just finished writing the paragraph explaining why that
  direction is the expensive one.

  Nothing in the change touched those cases, which is why a diff review does not
  find it: they were relying on a wrong answer being well-formed. So when a change
  adds a refusal, an `unknown`, or any arm that REPLACES a previously-plausible
  output, enumerate what used to be asserted about that output and ask which of
  those assertions the new arm removes. Measured both ways here -- pinned, the four
  are green; given a stepping clock, all four go red by name.

  The seam the change itself adds is usually the fix: pin the input so the host
  cannot take the case away.

* **A clock is a seam like any other.** There is no arrangement of real sleeps
  that makes a backward step happen on demand, so this was untestable until the
  clock could be injected — and `string(TIMESTAMP)` is the only clock a `cmake -P`
  script has, which rules out switching to something monotonic. The readings
  repeat their last value rather than running out, because a list that exhausts
  into the host clock would measure an environment nobody chose, which is the
  defect reappearing inside its own fix.

Measured on a contended WSL2 host (`clocksource: tsc`), twenty `sleep 0.2` calls
with no fixture around them, timed by three clocks at once:

```
run   time %3R   date +%s.%N   /proc/uptime
6     4.020      4.021         4.020
7     2.761      2.763         4.030      <- both realtime readers lose 1.27s
8     4.023      4.026         4.030
```

**The variable is the ENVIRONMENT, not the load.** Two step detectors run
concurrently on one box, over one 240-second window:

```
WSL2                 samples=502   min=-1466ms   max=552ms   negative=8
Git Bash (Windows)   samples=429   min= +545ms   max=592ms   negative=0
```

WSL2 stepped backwards eight times in four minutes, to **-1.466 s** — inside the
1.27-1.68 s band the three sessions above measured independently. The Git Bash
side read 545-592 ms against a 500 ms sleep across that same window, and *that* is
what says the box was near-idle: a measured overhead of 45-92 ms rather than a load
average nobody wrote down. **So the step does not need a busy host.**

Two consequences, and the second is the one that costs a session:

* **The magnitude is not portable.** These are WSL2 readings, taken through
  `wsl.exe` — which is how every ctest-driven figure in this ticket and its
  neighbours was taken. Do not read them as a property of Linux, of macOS or of a
  CI runner. And Git Bash producing no backward step in **429 samples** is *not
  observed under these conditions*, never *cannot step*.
* **A clean run in the other environment is not weak evidence, it is none.** A
  lane's 120 clean runs under Git Bash said nothing about a WSL2 defect, the
  precondition being absent by construction. So a clean run cited against a
  clock-step ticket states which environment produced it, or it is unreadable.

A 965-sample, zero-backward-step reading was once cited here as evidence that an
idle host does not step. **The lane that took it reports it ran under Git Bash** —
120 runs, 60 on master and 60 on the branch, across both idle and 48-burner
contention, in that environment throughout, with the detector running alongside
them. So it is a **third corroboration of the pairing** rather than a caveat
against it: zero backward steps in the environment where the precondition is
absent by construction. It was never a reading about load. Recorded as REPORTED by
that lane rather than as measured here, which is the distinction the whole section
turns on.

Load remains a real and subordinate caveat: the readings in this section were
taken on a contended host, so the RATE here says nothing about the rate on a quiet
one. What it no longer supports is the inference that a quiet host is a safe one.

Confirmed independently on the same host by a second session with a different
reader (`date +%s%N` against `/proc/uptime`, run 8: realtime 2828 ms, monotonic
4110 ms, delta **-1282 ms**, the other thirteen runs inside 8 ms), and by a third
measuring `read -t 5` on a FIFO nobody writes to. The three numbers agree, and the
third session's reads all carried status **142** — a genuine full-bound timeout —
which is the reconciliation: **the reads did not return early, the reading lost a
second.**

The cost was #1058: a 23% flake in the DEFAULT `ctest` set, `macOS-clang-release`
red in a merge group, and a pull request ejected from the queue. Three cases in one
fixture, three shapes, one cause — a staged 4058 ms defect reading 2966 ms and
failing a 3000 ms floor; a `read -t 5` that consumed its whole bound measuring
`SECONDS`-elapsed of **4** in 7 of 45 reads; and `%3R` rendering one interval as
**`/.044`**, which is how bash prints a negative second, `'0' - 1` being `/`.

**A shape guard does not save you, and this is the reading that proves it.** After
the fix, a *healthy* fast path that had requested 200 ms of pause reported its
elapsed time as **6 ms** — the clock had stepped back by very nearly the whole
interval being measured. That reading is **well formed**. It is not negative, not
absurd, and it passes every predicate that exists to refuse a malformed one;
`/.044` was the same event overshooting past zero and was caught *only because* it
came out malformed. A guard on the SHAPE of a reading cannot help here, because
nothing about the reading is the wrong shape. The reading has to be structurally
incapable of being a duration — which is what asserting the requested pause
achieves — or it will be believed.

**The defect is BIDIRECTIONAL, and only one direction had been seen.** Every
reading above is a backward step, which presents as work that took less time than
it did: a bound overrunning, a defect coming in short. A **forward** step is the
mirror — it shortens a bound, so a healthy wait gives up early and presents as a
premature failure. Observed on a fourth tree: PR #1081, whose change touches none
of this, went red on `macOS-clang-release` with `FAIL wait-for-log: exited 1,
expected 0`, from `wait_until` bounding on `SECONDS`. A reader who has only met the
backward form will diagnose that as a slow runner and raise the budget, which is
the one remedy that cannot work.

- **Prefer asserting the DECISION over the measurement.** What a bounded helper
  *asked for* is exact and host-independent; what it *cost* is a reading. Where the
  property under test is pacing, record the requested pauses and assert on those.
  It is also strictly stronger than the timing proxy, since it counts the ticks as
  well as their length.
- **Where a duration is genuinely needed, take it from something monotonic.**
  `sleep` is `nanosleep` against CLOCK_MONOTONIC on Linux and macOS and cannot be
  stepped — measured, it took its full 4.11 s in the run where realtime read
  2.83 s — so a co-timer is the portable monotonic clock bash 3.2 does not
  otherwise have. `/proc/uptime` is Linux-only, `EPOCHREALTIME` is bash 5, and
  `date +%s%N` is GNU-only.
- **A derivation is only as sound as the premise it does not state.** The algebra
  `floor(a + BOUND) - floor(a) == BOUND` is correct, was written down, was defended
  over 200k simulated placements, and was used to conclude that the silent error
  *"cannot happen here"*. It assumes the clock does not move, and never says so.
  **A census cannot falsify a premise** — those placements validated the arithmetic
  *given* the premise and never tested it. Three readers passed over that paragraph;
  the tell nobody looked at is that a duration cannot come in short.
- **#678 was the same clock one property earlier** — its one-second QUANTISATION
  wrecking readings in these same two files — and it was closed by keeping the clock
  and improving the resolution, which is why the surrounding comments all argue
  about resolution. Resolution was never the whole defect.

## A fixed port needs a reaper, and a leftover listener is refused rather than adopted

<!-- agent-tripwire: A fixed one needs a reaper -->

`run-launcher-e2e.ps1` bound the constant `21714` and nothing reaped the daemon when
a run did not reach its cleanup — a ctest interrupted, a test killed by a timeout, a
build cancelled mid-suite. `pace-kv.exe` then listened for as long as the machine
was up and **every later run** failed at

```
pace-kv exited immediately (exit 1)
```

which names neither the port nor the process and reads exactly like a daemon that
cannot start. It was diagnosed by hand from `Get-NetTCPConnection -LocalPort 21714`,
after surviving a rebase and presenting as a regression the rebase had caused (#220).

**The reason offered for the constant was true and did not support it.** The launcher
under test reads `PACE_ADDR` from the environment and several child processes
inherit it, so the port has to be decided BEFORE the daemon starts — which is an
argument for deciding it early, and drawing does that. The fixture draws from
20000..32000 like every sibling now, and the four were CHECKED rather than assumed:
`compile-cache-e2e.sh` and `dist-compile-e2e.sh` call `free_port`; `sccache-smoke.sh`
does too, and `PACE_SMOKE_PORT` defaults to EMPTY so the registration passes no
`--port` at all, on either platform since `sccache-smoke.ps1` drew too (#183). The
CMake half is worth naming separately from the script half, because for a while the
script drew and the registration passed `--port 11611` unconditionally: the draw was
live, unreachable from the only caller there is, and the diff showed a converted
fixture.

**And the same shape survives OUTSIDE CMake, which is the half that survey missed.**
`.github/workflows/build.yml` invokes three fixtures directly with an explicit
`--port`, so those legs exercise the fixed-port path and never the draw. Measured on
`08c68bdb`: three `sccache-smoke.sh` steps at `--port 11611`, and two
`compile-cache-e2e.sh` steps at `11611` and `21713`. A per-job runner makes the
constant harmless *there*, which is exactly why it reads as fine and stays: the cost
is that the code path CI proves is not the one a developer runs.

Three things worth keeping:

- **A probe that NAMES the holder turns a twenty-minute diagnosis into a sentence**,
  and it is the cheapest half. It is only reached for an explicitly passed port,
  since a drawn one was proved free a moment earlier.
- **Refused, never adopted.** A leftover listener is of an unknown vintage and may
  hold a store from a different build, which is the class of confusion the fixture
  exists to DETECT rather than reproduce. The one exception is a listener whose image
  path is byte-for-byte the daemon this run would start: that is REAPED, which is not
  adoption but the manual `Stop-Process` somebody already does — and a holder whose
  path could not be read is refused, because an unreadable path reaching the reap arm
  would kill a process the fixture knows nothing about.
- **The DECISION is what can be wrong, so it is what gets tested.** It was reachable
  only by running the whole fixture, which needs a built daemon, a built launcher and
  an MSVC toolchain — so on every machine and every CI leg without those it was
  asserted by nothing. `-SelfTestPorts` drives it over staged holder records and
  against real listeners, needs none of the three, and is registered as
  `launcher-e2e-ports-selftest`. Where `pwsh` is absent the row is REGISTERED and
  SKIPPED rather than dropped, because absent and skipped are two states.

Shown red and only where expected: with the classifier neutered to `return 'free'`,
exactly the six decision-dependent cases fail — the five staged records and the real
end-to-end refusal — while the accepting case, the three acquisition cases and the
two holder-detection cases stay green. The accepting case staying green under the
mutation is the reason it cannot stand alone.

### That fix was private to one fixture, so it fixed one fixture

`tls-smoke.ps1` and `run-crossdepth.ps1` went on binding a constant and reaping
nothing for as long as the three helpers lived inside `run-launcher-e2e.ps1` —
#220's defect verbatim, with no failure history for the reason this file already
gives: *a first failure MASKS its identical siblings*, and that one was simply the
fixture that ran often enough to be observed. `scripts/lib/E2EPorts.psm1` is where
they live now, and `tls-smoke.sh` — the arm Linux CI runs — drew the **same
constant 11811**, so the two halves of one fixture could not run side by side
(#1284).

Three things the extraction turned up, and the first two are about the TEST rather
than the port:

- **The refusal named neither the port nor the holder, and had not since #220.**
  PowerShell binds `-f` TIGHTER than `+`, so

  ```powershell
  ("port $p is held by {0} (pid {1})" + " and will not be adopted" -f $name, $id)
  ```

  formats the second fragment — which has no placeholders — and concatenates the
  first with its `{0} {1}` intact. Measured on 7.6.6: `"a {0}" + "b" -f 1` is
  `a {0}b`. The case covering it asserted **that a throw happened**, which is what
  BOTH states produce, so it was green from the day it was written — inside the
  very fix whose whole point was a message that names the holder.
- **A test that builds its expectation from the same template it asserts is blind
  to the template.** Routing both ends through one `Get-E2EPortRefusal` made the
  site cases agree perfectly while the sentence was wrong; measured, restoring the
  defect left all three green. So the RENDER has cases of its own, asserted against
  the facts — port, name, pid, path — plus *no `{N}` survives*, which states the
  defect class directly.
- **The guard written to catch it was BACKWARDS and reported clean.** Tighter
  binding means the `Format` node is the INNER one: the tree is
  `Plus(left, Format(b, args))`, not `Format(Plus(a, b), args)`. Written as the
  precedence reads when spoken, the predicate matched nothing, said the module was
  clean, and was caught only by its own positive control. Reading the tree confirms
  it in one line; reasoning about it produced the wrong answer.

And the sites are proved rather than argued: `Invoke-E2EPortSelfTest` holds a real
listener, drives **every** consuming fixture as a child process against that port,
and requires the refusal sentence back — because a fixture that never meets a
holder passes identically with the reaper deleted. Shown red: the decision neutered
to `free` reddens the five staged records, the real refusal and all three site
cases; `tls-smoke.ps1` alone made to skip its pre-flight reddens that one row and
no other. The two weaker claims beside it — *exited non-zero* and *named the port* —
both stayed GREEN under the neuter, because a fixture that proceeds fails downstream
and announces its port on the accepting path too.

### A teardown confirms EXIT, and what runs next shares nothing with it

`dist-compile-e2e.ps1` killed each process and waited five seconds, but it threw the
answer away. Its two COFF drivers shared one scratch directory and one port block, so a
killed isolation worker that outlived the wait was still holding `iso-worker.log` when the
next driver's `Remove-Item` reached it. The run failed with "being used by another
process", which read as a fault of the case that ran next, and nothing named the process.
Reproduced by making the kill land 8 s late. With every kill late, the same removal met
the isolation scheduler's `raft-log` first, so the fix could not be a per-driver LOG name.

Two halves, and neither is a longer wait:
- The FIXTURE shares no directory and no port between phases: per driver in
  `dist-compile-e2e.ps1`, and per phase in `node-scratch-isolation-e2e.ps1`, which
  already did. It shares none between RUNS either. With one root cleared at each start,
  an immediate rerun died in 0 s on `raft-log`, naming the file while the holders' PIDs
  sat in the previous run's log. So `New-E2ERunRoot` claims a root no run reuses: an
  exclusive `CreateNew` of `.claim`, held open for the run. `Clear-E2EStaleRoots`
  sweeps old roots, leaves a claimed one alone, and names the processes whose command
  line mentions any root that will not go. It never fails the run.
  - **A pipe HIDES this overlap.** The survivors inherit the caller's pipe, so the
    caller waits for them and the next run cannot start early. To reproduce it, run each
    fixture in its own console with no pipe (ShellExecute, output via a transcript).
  - The sweep names only holders whose command line mentions the root. A daemon given
    no path of the root on its command line holds files there anonymously.
- The teardown is `scripts/lib/E2EProcesses.psm1`'s `Stop-E2EProcesses`. It kills
  everything, then confirms each process EXITED within ONE shared bound, and returns a
  line naming the PID and the recorded command line of each that did not.
  - It has three answers, not two: still running is not "could not be asked".
  - PowerShell turns a property getter's exception into `$null` rather than throwing.
    On a Process with no handle, `HasExited` AND `Id` both read `$null`, and a `$null`
    key makes `ContainsKey` throw from inside a `finally`.
  - Its cases live beside it (`Invoke-E2EProcessesSelfTest`), and every importing
    fixture runs them from its own `-SelfTest`.

## A bounded wait must also say WHICH KIND of failure it was

<!-- agent-tripwire: when it times out, which KIND of failure it was -->

"Every wait is bounded" is the rule above, and it is not enough on its own. A wait
that reports only `waited 300s for worker A` cannot tell a loaded machine from a
wedged process, and those are fixed in completely different places -- one is a
budget, the other is a bug. Reading such a failure, nobody can responsibly choose
between raising the timeout and opening a defect, so the timeout gets raised,
because that is the action that makes the red go away.

`node-scratch-isolation-e2e` failed exactly that way on a Windows leg: worker A had
logged `computing the toolchain fingerprint` and nothing further inside its 300s
budget. The artefacts could not distinguish a cold include walk on a contended
runner from a deadlock, and the test's own history made both plausible -- it had
already been re-shaped once, within hours, because two nodes computing fingerprints
at the same time blew the budget.

So a wait that can time out records what it would need to tell them apart:

- **On success, what it actually cost.** Nothing recorded this, so no budget in the
  fixture could be set from data -- every number was a guess that survived by being
  generous. A green run now measures itself, and the next budget argument has
  evidence behind it.
- **Whether the process is still alive**, and its exit code if not. A process that
  DIED is a third case, diagnosed in one line, and it should never be reported as a
  timeout -- it is reported the moment it is noticed, rather than after the budget.
- **Whether the log grew**, and how long ago.
- **How much CPU it consumed during the wait**, and this is the half that is easy to
  miss. The operation this wait covers -- walking a compiler's include tree -- logs
  NOTHING while it runs, so a slow walk and a wedge produce *identical* logs. A
  log-growth heuristic alone would have diagnosed that failure confidently and
  wrongly. Work burns CPU; a block does not.

And where the signals disagree, say **INCONCLUSIVE** and name what is missing. A
confident wrong diagnosis costs more than an honest missing one -- that is the whole
lesson of this rulebook, applied to the reporting rather than to the code.

**And an INCONCLUSIVE verdict is a place to ask somebody ELSE, not the end of the
matter.** `launchctl kickstart` timing out at 60 s having burned almost no CPU is
`LaunchctlFindingOf`'s `Waiting`, reported honestly as *"this does not say whether that
was a busy host or a stall"* -- correct, and the end of what the CALLER's own readings
can establish, because from outside the two causes look identical
([#965](https://github.com/LASTRADA-Software/fastcached/issues/965)).

What separates them is whether launchd ever moved the job out of pending, and only
launchd knows. So the fixture asks it, on the FAILURE PATH: `launchctl print` shows
`state = running` or a non-zero last exit code for a job that started and then went
wrong, a still-pending job for a host that never got to it, and *no such job* for a
registration that wrote a plist launchd never took -- a third state neither of the first
two, and none of the three inferable from the timeout.

Failure path only, every command `|| true`: a diagnostic on an already-failed case must
be able to EXPLAIN the verdict and never to change it. The Windows spawn bracket (#966)
follows the same rule from the other side, and the general form is worth stating once --
**when an instrument correctly reports INCONCLUSIVE, the next move is a different
instrument, not a better reading of the same one.**

## What that classifier then got wrong, which is worth more than what it got right

<!-- agent-tripwire: A cumulative figure cannot answer a question about now -->

The first version of it shipped, fired on its fifth occurrence, and was wrong:

```
waited 300s for worker A to compute its toolchain fingerprint and bind
  evidence: alive=True logGrew=True lastGrowth=300s ago cpuDuringWait=3.4s
VERDICT: the process was still WORKING when the budget ran out (it consumed CPU
throughout). That is a budget or contention problem, not a hang -- raise the
budget or reduce what runs beside it.
```

Three separate errors, and only the first is about this fixture.

- **When a test binary dies mid-run the DENOMINATOR moves, and the ratio still looks
  healthy.** `AGENT.md` says a count cannot carry a verdict -- "25 of 26 green is
  arithmetic that is true and useless" -- and this is its sharper form: a crash does
  not report as a crash, it reports as a *smaller suite that mostly passed*. Measured
  while deleting a flag in #290 stage 3: removing a row from a `std::array<Row, 4>`
  left the fourth value-initialized to null pointers, the segfault took the rest of
  the run with it, and the summary read `171 cases | 170 passed | 1 failed` for a
  binary holding **276**. Every instinct trained on ratios says that is fine.

  The only signal was that 171 was not 276, which is a number you have to already
  know -- so do not rely on noticing it. **Compare the case count against the previous
  run whenever a change deletes anything**, and treat a drop as a crash until proven
  otherwise. A shrinking suite and a passing suite look identical in the one line most
  people read.

  It is also the project's own table rule arriving in a test file: an extent written
  as a literal outlived its rows. `std::to_array` derives it and the shape becomes
  unrepresentable, which is why the production tables use it.

- **A refusal's wire CODE is not its reason, so a test asserting the code is asserting
  something weaker than it looks.** The production side of this is already written down
  in [`metrics-and-observability.md`](metrics-and-observability.md): *the row is the
  refusal, not the code* -- two refusals share `MalformedFrame` and must not share a
  counter, so a table keyed on the code cannot hold them. The test-side consequence is
  the same fact read backwards: **where two refusals may legitimately answer one code,
  the counter is the reason and the code is not.**

  It is not hypothetical here. #290 merged the cache and compile surfaces onto one
  listener, and that listener now carries two refusals answering `ErrorCode::NotAMember`
  by deliberate design -- `CacheResponder::RefusePeer` refusing a caller that is not
  this machine (`NodeCacheRequestsRefusedNotLocal`), and `RefuseUnlessMember` refusing
  a caller with no claim on this machine's CPU (`WorkerJobsRefusedNotAMember`). One
  code, because a launcher steps over both identically; two counters, because an
  operator does not. A case asserting only the code cannot tell them apart, and after
  the merge they arrive on the same socket.

  Measured on #290's acceptance case, whose whole point is that those two rules
  disagree about one peer: delete the `Increment` from the locality refusal, changing
  nothing else, and the run reads **6 passed, 1 failed** -- the wire code assertion
  **passes**, and the only thing that goes red is
  `NodeCacheRequestsRefusedNotLocal == 1`. The refusal was still correct; what was
  lost was any way for the test, or an operator, to say WHICH rule produced it.

  So on a surface where codes are shared, **assert the counter as well as the code**,
  and read a green code assertion as evidence of very little on its own.

- **A cumulative figure cannot answer a question about now.** `cpuDuringWait` was
  the total over the whole wait and was read as a claim about the process's state
  **at the deadline**. 3.4s spread evenly over 300 seconds and 3.4s burned in the
  first ten seconds followed by a wedge are the same number and opposite
  diagnoses. A *duty cycle* over that same window is the identical mistake with a
  percent sign -- it is the same number divided by the same 300. Only a **recent**
  window can answer a question about now, so that is what the verdict is drawn
  from and the totals are printed as evidence only.
- **No magnitude bar can be calibrated when the healthy range spans orders of
  magnitude.** The whole Windows SDK include tree is 9,487 files and walks warm in
  0.1s at 88% duty; the same walk cold, virus-scanned and contended is I/O bound
  and burns a tiny fraction of that. A bar set high enough to exclude an idle
  runtime's own timer threads would call a genuinely working cold walk BLOCKED,
  which is the opposite error and the worse one -- it sends somebody hunting a hang
  that is not there. **What does not vary is zero**: a blocked thread accrues no CPU
  at any temperature. So the test is *presence* in a recent window rather than
  magnitude, and everything between "idle" and "clearly working" is reported as
  neither.
- **An `-or` is right for two independent CONFIRMATIONS and wrong for two competing
  READINGS.** `$progressing` was False -- the log had not grown in 300 seconds --
  and `$busy` was True, and the disjunction let the weaker one win unopposed. The
  two signals *contradicted each other* and the code combined them as though they
  agreed. This is a reasoning error rather than a scripting one, and reaching for
  `-or` is the reflex. Where two signals can disagree, the disagreement is the
  finding.

`logGrew=True` is the same family from the other side: it was true, and it counted
the two startup lines landing in different polls. **A signal that cannot be false in
the failing case is not evidence**, and printing it beside a conclusion lends it
authority it has not earned.

Two things follow for anything shaped like this.

**Measure the process TREE, not the process.** A step that spawns a compiler sits in
a kernel wait at zero own-CPU while the child does the work, so recent-window
own-CPU alone reports BLOCKED for a healthy compile. The first version documented
that limitation in prose and told the reader to run `Get-Process cl` by hand; a
limitation you can describe is one the instrument can apply.

**An instrument that prints a remedy has to know when the remedy is under dispute,
and it cannot.** "Raise the budget" is sound general advice, was printed by the
branch that fires most often, and is exactly what [#354](https://github.com/LASTRADA-Software/fastcached/issues/354)
refuses -- that budget has been raised twice already. State the finding and stop.

And it is tested, by `ctest -R node-scratch-isolation-e2e-selftest`. **A classifier
that cannot be made to say BLOCKED cannot report a hang**, and the original could
not.

**That selftest is in the DEFAULT `ctest` set**, labelled `hygiene` rather than `smoke`, because
it needs no daemon, no socket and no compiler -- the whole point of splitting the decision out
of the acquisition is that the decision can be exercised anywhere. Where no `pwsh` is found the
row is REGISTERED and SKIPPED rather than omitted, for the reason `launcher-e2e-ports-selftest`
is: absent and skipped are two states, and a classifier nobody ran reads exactly like one that
had nothing to say.

## A fixture waits on what a line MEANS, and a rename is not what changes it

<!-- agent-tripwire: A fixture waits on what a line MEANS, not on its wording -->

`node-scratch-isolation-e2e` starts three nodes one at a time, and the paragraph
explaining why has been in the file since it was written: two include-tree walks
racing on a two-core runner exceeded the budget and the fixture failed having never
reached a compile. The serialisation rested on waiting for `compile node ready`
before starting the next node, which at the time meant **surveyed** -- a node
fingerprinted before it bound.

[#365](https://github.com/LASTRADA-Software/fastcached/issues/365) made a node bind
and serve first and survey afterwards, for good reasons of its own. The log line was
not renamed, not moved and not reworded; it simply stopped carrying the fact the
fixture was reading out of it. Every node now reached it in about a second, all three
walked at once, and the measured rate on the `clangcl` runner fell to **2-5 file/s**
against the ~30 file/s [#354](https://github.com/LASTRADA-Software/fastcached/issues/354)
measured with a single walker. 5136 files did not fit in the 600 s that
[#428](https://github.com/LASTRADA-Software/fastcached/issues/428) had just moved
onto the registration wait, and an unrelated pull request was ejected from the merge
queue for it.

Three things follow.

**The budget was the symptom and raising it would have buried the cause.** The
fixture asked the machine for three times the concurrent I/O it was written to ask
for; a budget that accommodated that would have made every later run three times
slower and left the next reader with no way to see why.

**Wait on the stage, not on a line that currently coincides with it.** The two
stages now have two waits -- `compile node ready` for **serving**, `serving <compiler>
as <fingerprint>` for the survey -- and they are kept separate rather than folded,
because a stall in one has different costs and different fixes from a stall in the
other, and a fixture that folds them cannot say which one happened.

**And `compile node ready` is not the bind.** This file said "for the bind" and
`AGENT.md` said #365 made the line mean *bound*; both were a shorthand and both were
wrong in the same direction
([#652](https://github.com/LASTRADA-Software/fastcached/issues/652)). Measured: the
accept loop starts at `main.cpp:1128` and the line is logged at `:1454`, with the
credential, the registrars, the startup toolchain count and the heartbeat thread in
between --

```
bound  <  accepting  <  READY (serving)  <  surveyed
```

Relative to the survey the marker is early; relative to the bind it is **late**. The
cost of the shorthand was not theoretical: `node-scratch-isolation-e2e.ps1` waited on
this marker and reported *"did not bind its compile port"*, so a node that bound,
accepted and then stalled in heartbeat setup sent its reader to check a port that was
open and answering -- the one part that was working. The marker and the fact it names
are now a row of `Core/ReadinessMarker.hpp`, whose `ReadinessFact` has **no `Bound`
enumerator**, so the mistake cannot be spelled there
([#654](https://github.com/LASTRADA-Software/fastcached/issues/654)).

**A comment stating the intent did not protect it.** The serialisation paragraph was
correct, prominent and three lines above the wait that stopped implementing it. What
a fixture depends on has to be in what it *does*.

## Do not measure a stand-in through an instrument as costly as the thing measured

<!-- agent-tripwire: A stand-in built to exhibit a MAGNITUDE must not be measured through an instrument -->

The first version of that test drove real processes. Six stand-ins, each arranged
to exhibit one reading -- a growing log, a self-spinner, a quiet parent with a
spinning child, a sleeper, a trickle-then-silence, one that dies -- and it read the
classifier's answer back. Five of the six were robust, because they target a
*presence*, an *absence* or a *death*, and those do not depend on how fast the box
is.

The sixth had to land a **magnitude** strictly inside the classifier's
`(0.15s, 0.50s)` band. It burned until its own consumed process CPU had risen by
250 ms -- already closing the loop on the right quantity rather than spinning for a
duration -- and it still could not be made reliable:

- it passed three consecutive local runs and failed on `Windows-clangcl-release` at
  **0.52s against a 0.50s bound**, because leftover interpreter startup landed
  inside the measured window;
- tightened, it then put the deliberate burn at the recent window's cutoff edge,
  where **0.16s of a measured 0.25s** counted.

Neither was a bound being wrong. **The band is 0.35s wide and a PowerShell
process's own startup costs 0.2-0.5s** -- the instrument's overhead and the
quantity under test were the same magnitude, so there is no stand-in construction
that fixes it. The noise *is* the interpreter the stand-in is made of.

The fix is a seam, not a stand-in. `Get-WaitVerdict` is now pure -- it takes a
record of readings (own recent CPU, descendant recent CPU, counts, log growth and
stall age, alive, exit code, both bounds) and returns the lines to print. It opens
no socket, reads no clock, spawns nothing. Acquisition keeps doing exactly what it
did.

Three things follow, and they are the reason to reach for this shape early rather
than after a red CI leg:

- **Branches that could not be staged become one line each.** The
  could-not-sample-CPU verdict needs a live process whose CPU the script may not
  read, which cannot be arranged; as a record it is `OwnRecent = $null`.
- **Every bound gets pinned on both sides**, not demonstrated once from the middle
  -- at the floor and just above it, at the working bound and just below it. That
  is where an `-and`/`-or` mistake actually lives.
- **It is instant**, so the sweep that proves each branch load-bearing is cheap
  enough to actually run. Mutating each of the seven verdicts and each of the five
  comparisons turns exactly the expected cases red; `EverGrew -and` weakened to
  `-or` -- the original defect's own shape -- turns 14 of 17 red. 53 seconds and a
  `RUN_SERIAL` became 0.3 seconds and neither.

What deliberately stayed untested is **acquisition**: `Win32_Process`, the
parentage walk, the pid-reuse guard by creation time, the locked-log read. All
three real defects here were in that half, and it is exactly as hard to exercise
wherever it lives -- but it now contains no decisions, so nothing silently right or
wrong is hiding in it.

The general rule, which is not about PowerShell: **a decision worth several named
outcomes is worth separating from the ambient facts it reads**, and a fixture that
must exhibit a magnitude must not be measured through machinery whose own cost is
comparable to that magnitude. Both halves of this file got that wrong once, in the
same direction -- towards a confident wrong answer.

## A case name is an ARGUMENT, so it may not begin with `-`

<!-- agent-tripwire: A Catch2 case name is an ARGUMENT, and that one fact has three consequences -->

`catch_discover_tests` registers each case as
`add_test(NAME <case> COMMAND <exe> <case>)`. The name therefore reaches Catch2 on
its command line, and Catch2 parses arguments before it parses test specs — so a
leading dash is read as an option. The two halves fail differently and the quiet
one is worse:

- **A recognised flag.** `TEST_CASE("--help wins over whatever follows it")` made
  the runner print its usage and exit 0, so CTest recorded a **pass for a case that
  had never run**. It had been doing that since the day it was written, which is
  the shape this whole file is about: nothing fails, and the thing somebody was
  told is covered is not. `TEST_CASE("--help works with and without a
  sub-command")` in the test client was the same case, one target over.
- **An unrecognised one.** `TEST_CASE("--cache-dir gives the node an on-disk
  tier")` made Catch2 print `Unrecognised token` and exit non-zero, so CTest
  reported a failure the case did not have — and it passed when run by hand. That
  is how the first half was found.

`ctest -R test-name-hygiene` scans for the pattern and refuses a third. It scans
rather than listing the two known names, for the reason every other table here
does: a list of what is wrong today is maintained by the same person who
introduces the next one. Put the flag anywhere but first — "Naming `--cache-dir`
gives the node an on-disk tier" reads no worse and runs.

### A COMMA splits the spec, so such a name cannot select itself — and the miss is a RED

The dash is one instance of the rule; the comma is the next, and **the rule is
that the name is an argument, not that these two characters are bad.** Whatever
Catch2 adds to its spec grammar joins this list, so read the general form first:
**a filter that matched nothing must never be read as a subject that failed.**

Catch2 parses a test spec as a **comma-separated list of specs**. So

```
The endpoint arms the responder's deadline, not its own
```

splits into two fragments, neither of which names a case, and the run reports
`No test cases matched ...` twice and `No tests ran`. **`No tests ran` exits
non-zero**, so the miss does not present as an empty result — it presents as a
**deterministic red**, identical on every iteration, which is exactly what a real
reproducible failure looks like.

Re-measured against a built `PaceTest` rather than taken from the tickets,
both directions, because a subject with no control cannot tell *this name matches
nothing* from *my quoting is broken* — the first attempt's control picked the
`--list-tests` header instead of a case and reported `No tests ran` for the
control too, which would have proved nothing:

```
"A push while the consumer is parked does not resume it inline"   exit 0
                              All tests passed (8 assertions in 1 test case)
"A deadline fires exactly once, on the reactor"                   exit 2
    No test cases matched '"A deadline fires exactly once"'
    No test cases matched '"on the reactor"'
    No tests ran
``` A lane stress-checking a timing-sensitive case
got five runs and five "failures" for a case that had just passed inside the full
suite (#636). Another, measuring an abort rate, selected its case by name and read
`0 failed` over **zero cases executed** — for a measurement whose expected result
was 20/20, that is indistinguishable from a clean pass (#895).

**Both readings of that output are wrong in the direction you were hoping for**,
which is what makes it worth a rule rather than a footnote.

Measured 2026-09-10 on this tree — pattern stated because three tickets quote
three different figures and those are **different questions asked of earlier
trees, not drift**: over `src/**/*_test.cpp`, the four case macros, the name taken
as the first string literal on the line, **529 of 3503 names (15.1%) contain a
comma**. #895 recorded 455 of 3263, #636 418 of 3074, #729 3166 names.

**This is not a reason to rename them.** The names are sentences stating what the
case establishes, that convention is deliberate and good, and 15% is not a corner
to be tidied away — the filter is what cannot express the convention, and
`test-name-hygiene` therefore does **not** refuse a comma. What to do instead:

- **`ctest -R` is unaffected.** `catch_discover_tests` registers each case under
  its full name and CTest matches by regex, so CI and `scripts/local-gate.sh`
  never meet this. It bites the person narrowing a failure by hand, which is the
  worst moment for it.
- **Select by TAG**, or by a comma-free substring, wherever tooling picks a case —
  rate measurements, reproductions, bisects.
- **Anything selecting a subset asserts HOW MANY CASES RAN**, not only how many
  failed. A run that executed nothing and a run that passed are one number today,
  and the assertion is what separates them. That is the positive control that
  caught #895 in the first place.

**That last obligation is the CALLER's, and `flake-rate.sh` is where this is easy
to misplace.** It counts exit statuses of an arbitrary `"$@"` and never selects a
case itself, so its `ran=` is a count of ITERATIONS, not of cases executed — a
comma-bearing name handed to it yields `ran=200 pass=0 fail=200`, which is a
perfect deterministic red produced by a filter that matched nothing. The script
cannot fix that for you without assuming its command is Catch2, and `--quiet`
discards the `No tests ran` that would have said so. So the caller selects by tag
and checks the case actually ran, before reading any rate off it.

### A DUPLICATED name registers two entries that each run BOTH cases

A different mechanism, same subject. `catch_discover_tests` registers one entry
per NAME, so two cases sharing one name produce two ctest entries that each run
the binary filtered by that name — and Catch2 matches **both** cases for either
entry, tolerating names that differ only in tags.

**Nothing is skipped, and that is why it reads as harmless.** It is the mirror of
this tree's usual disease: work done twice under a name that cannot say which case
it was, rather than work skipped. What breaks is attribution — one defect surfaces
as two red entries and neither names the failing case, `ctest -R "^<name>$"` cannot
select one of the pair, and per-case timings and `--repeat` flake hunts are filed
under an ambiguous name.

`test-name-hygiene` refuses duplicates. Its exemption table carries a **reason**
per row, so an allowed duplicate cannot be spelled the same way as a forgotten one
— and a row that has **stopped** describing a duplicate is refused as stale,
because an exemption nobody must keep true is a licence that outlives its argument
and would wave through the next duplicate of that name. There is one row: the
Epoll and Kqueue reactor tests are wholly inside `#if defined(__linux__)` and
`#if defined(__APPLE__)`, so they never co-exist in one build, and the parallel
naming is what makes one property greppable across the two platform reactors.

The check also refuses a scan that matched **no file or no case**. Every verdict
in it is drawn from an accumulated list, so an empty scan and a clean tree produced
byte-identical output — two empty lists agree perfectly (#729).

## A failing `REQUIRE` above an explicit `Stop()` turns a RED into a HANG

<!-- agent-tripwire: A failing `REQUIRE` above an explicit `Stop()` turns a RED into a HANG -->

A test starts something that needs an explicit stop — a reactor on a `jthread`, a
server, a loop — and puts its `REQUIRE`s above the `Stop()`. **Catch2 unwinds on a
failed `REQUIRE`**, so the failure skips the stop, and `~jthread` then joins a loop
nobody asked to end.

The test hangs instead of reporting, and that is strictly worse than a plain
failure three ways:

- **The timeout does not name the assertion.** The one thing the test existed to
  produce is the thing that is lost.
- **A timeout and a wedge look identical**, so the reader's first hypothesis is
  infrastructure rather than the subject — the wrong investigation, by the wrong
  person, usually on the wrong machine.
- **It is silent until something fails.** A green suite says nothing about it, so
  it can only be found by breaking the thing under test, which is exactly when you
  least want a second puzzle.

**It concentrates in teardown tests, and that is not coincidence.** A test whose
subject is orderly shutdown is by construction one that starts a thing and must
stop it, written by somebody thinking about the *subject's* ordering rather than
the *harness's*. Same species as the entry elsewhere here that a state-collapsing
bug is likeliest in the tool whose job is that state distinction.

**`CHECK` does not unwind.** Only the `REQUIRE` family, `FAIL` and `SKIP` throw, so
a `CHECK` above a stop is not this hazard — and counting it as one buries the real
ones.

### The two fixes, and the second half is the one that gets forgotten

**Stop before you assert**, where the diagnosis does not need the thing running —
`HealthProbe_test.cpp` calls `server.Shutdown()` *before* its `FAIL`, having
already taken the diagnosis into locals, precisely because `AdminHttpServer::Run`
leaves only on the shutdown flag and its lambda takes no stop token for
`~jthread`'s `request_stop` to reach.

Or **RAII** — a guard whose destructor stops the thing, so the stop runs on the
unwind path too. **Declaration order is half of the fix**: the fake being closed
must be declared *before* the guard, so it outlives the thread still touching it.
Get the guard right and the order wrong and the hang becomes a use-after-free,
which is worse. `ThreadedAddressResolver_test.cpp` spells it with the order stated
on the line itself (`// after 'stopper', so destroyed before it`), and
`RaftPeerServer_test.cpp` states the whole reverse-destruction argument.

**A `jthread` whose lambda takes a `std::stop_token` and loops on
`stop_requested()` is not exposed at all** — `~jthread` requests the stop and the
thread ends unaided. That is the cheapest fix where the body can be written that
way, and it is what makes the census below discriminating rather than a file count.

### Is it mechanizable? Not soundly — and the tractable form is a DIFFERENT check

Stated rather than left open, because an unstated *"we could not check this"*
reads as *"this is checked"*.

The hazard is *"termination depends on a statement a throwing macro can skip"*.
Deciding that needs to know which paths reach the stop — **dataflow, not a
regex**. Anything textual is approximate in **both** directions: it cannot see RAII
that is already correct, and it cannot see a stop reached through a helper. Both
misreadings were observed while triaging this: a scan flagged
`HealthProbe_test.cpp` because a *later* stop existed, missing the correctly-placed
earlier one, and flagged an `IocpSocket` case by running past the case boundary
into the next block.

So: **not soundly mechanizable; mechanizable as a helper-usage scan — a raw thread
in a test file refused by name, with the RAII holder in `src/tests/` — at the cost
of an exemption list, since a thread that ends unaided is legitimate.** That
converts an undecidable check into a decidable one over a different property, which
is the move that worked for `ClaimReadSlot` and for `SigningDomain`.

**It is deliberately not written.** With the tree measured clean below, such a scan
would refuse the 18 legitimate raw threads on day one and arrive needing an
exemption list longer than its findings — and a check that fails on arrival is a
check somebody disables. That is a decision recorded here, not a residual: if a
third instance turns up, the scan is the shape to reach for, and the exemption
list is what it costs.

### The tree was clean when this rule was written, and how that was established

Measured 2026-09-10, patterns stated so the next reader can re-run them rather
than trust the number:

- **24** files under `src/**/*_test.cpp` match `std::jthread|std::thread`
  (positive control: it finds both files the ticket names). **11** of those also
  carry an explicit `.Stop()` / `request_stop()` / `.Shutdown()`.
- **20** `std::jthread` declarations; **2** take a `std::stop_token`, **18** do not
  and so depend on something else stopping their subject.
- Every one of the resulting candidates was read **by hand**, and all were already
  correct — stop-before-assert, an RAII guard, a bounded self-terminating body, or
  a scoped join.

**Zero is a finding only with a control**, so the triage was run against a planted
hazard and named it, and against a `stop_token` case and correctly excluded it. The
instances that motivated the ticket were fixed by hand as they were found; what was
missing was the rule, which is why this section exists with no accompanying code
change.

## The shared helpers: `Unwrap`, `ScratchPath` and `ScriptedSocket`

<!-- agent-tripwire: `Unwrap(x)` after `REQUIRE(x.has_value())` for `std::optional`; a bare `*x` is a build failure -->

`src/tests/` holds the helpers every test target shares -- `Unwrap.hpp` and
`ScratchPath.hpp` -- and they are there rather than beside one caller for the same
reason, which the second one learnt the hard way (see below).
clang-tidy's `bugprone-unchecked-optional-access` cannot see a `has_value()`
guard through Catch2's `REQUIRE`, so a plain `*x` after one is a **build failure**
under `WarningsAsErrors` — `Unwrap(x)` goes through `value_or`, which is provably
safe, and the preceding `REQUIRE` still fails first when the optional is empty.
It replaced eleven copies that were *near*-identical rather than identical: each
carried its own abbreviation of that reasoning, so why the idiom exists was
reconstructible from some and not from others, and an author who found a terse
copy had nothing telling them a plain dereference was not simply better. It is
header-only and includes only `<optional>`, so the launcher's and worker's test
binaries can use it without linking `Pace`. `std::expected` is **not**
covered by that check, so a `*result` after `REQUIRE(result.has_value())` stays as
it is — routing it through `Unwrap` does not even compile.

**A per-process counter is not unique, because every `TEST_CASE` is a process.**
`catch_discover_tests` registers each case as its own ctest test, so a fixture that
names a scratch directory from a `static` counter hands the same path to every
concurrent case -- and a name that gets cleared before it is used turns a collision
into **deleted data**: the second case wipes the files the first is still reading.
`tests/ScratchPath.hpp` is the one definition now -- `UniqueScratchPath` (pid +
counter, cleared before it is handed out) and the RAII `ScratchDirectory` over it --
and what got it there is worth keeping:

- **It has been written SIX times.** The first fix was private to
  `Stats_test.cpp`; three later files reintroduced it; the fifth,
  `RaftStorage_test.cpp`, failed ten cases under `ctest -j 8` -- its class comment
  claimed exactly the guarantee it had, "two cases running in one binary cannot
  collide", and that scope is the bug.
- **The sixth got it wrong in a NEW way, and that is the one worth reading**
  ([#1507](https://github.com/LASTRADA-Software/fastcached/issues/1507)). Five copies
  used a counter and were beaten by the pid; `StorageTestUtils.hpp`'s `TempFile` reached
  for `std::mt19937_64 { std::random_device {}() }()` instead -- which *looks* stronger
  than a counter and is not a counter at all, so none of the reasoning above applied to
  it and review had nothing to catch. **`std::random_device` is not a uniqueness source.**
  Measured on the WSL2/libstdc++ host this was reproduced on: 2880 draws across 32
  concurrent processes returned **1652 seeds of zero**, and `mt19937_64 { 0 }()` is
  always `2947667278772165694` -- so 31 of 32 processes agreed on one filename. Four
  more copies of the idiom had spread by then, in `FilePageStore_test`,
  `LayeredStorage_test`, `CowTreeStorage_test` and `DefaultConfigPath_test`, the last of
  which said in its own comment that it followed `Testing::TempFile`'s reasoning. It
  did.
  - **The symptom named the wrong subject, which is why it cost a ticket.** The store's
    `flock` refused the second opener `InUse` -- doing exactly what `FilePageStore`'s
    comment says it will -- so the failure read as a storage concurrency defect and was
    filed as one. What identified it was printing `(dev, ino, pid, path)` at the refusal
    and finding **one path held by nine of thirty-two processes while all 2582 others
    were private to one**. A shared path is not a collision; it is a constant.
  - And the fix is the seam, so the guard is a SCAN: nothing in the type system makes a
    test reach for `UniqueScratchPath`, and a seventh author will reach for whatever
    looks random. `ctest -R unique-temp-paths`.
- **The fifth one happened because the shared fix was somewhere it could not be
  included from.** `UniqueScratchPath` lived in `src/apps/pace-cc/`, which
  `PaceTest` does not have on its include path, so the one suite that could
  not reach it re-derived it. A helper is shared only if it sits where everything
  that needs it can include from; `src` is on all three test targets' paths, which
  is why this and `tests/Unwrap.hpp` live together.
- **`UniqueScratchPath` clears its own name before returning it**, safe only
  because the name carries the pid: what it can then reach is this process's own
  leftover or a dead process's -- never a live peer's. Removing something you did
  not create is the step that makes a collision destructive rather than merely
  confusing.
  - **The guarantee stops at the name it returned, and it fails SILENTLY there.**
    A sibling built by appending a suffix to that name, or a name reparented
    under a different directory, is a DIFFERENT path this clearing never
    reaches -- no error, no exception, just a leftover a caller who assumed the
    guarantee extended there will never see coming. Such a caller passes its
    own parent through `UniqueScratchPath`'s parent parameter, or clears what
    it builds itself.
  - **A caller that CREATES a directory at the returned name must use
    `ScratchDirectory`**, whose destructor removes it again. A raw
    `create_directories` call with no matching removal is a LEAK, and a leak is
    what turns pid reuse into a live process inheriting a dead one's state.
- **A caller-supplied name becomes a child of a unique parent, not the whole
  name.** `ScratchTree`/`ScopedTree` take names like `"cache-hit"` and one that is
  itself a nested path, and those names are what a reader recognises; they hang
  under `UniqueScratchPath(prefix)` now, and the destructor removes the *parent*
  so the unique level cannot leak.

**And both CI and the gate run the tests in parallel now, because until this
change nothing did.** `ctest` was invoked bare in every CI job, no preset set a
job count, and `scripts/local-gate.sh` did not either -- which is why five
separate authors could write this bug and no run anywhere would show it. CI sets
`CTEST_PARALLEL_LEVEL` once in the workflow's `env:` rather than adding
`--parallel` to each of the four `run:` lines, so an invocation added later is
covered by construction; the gate passes `--parallel` explicitly (`getconf
_NPROCESSORS_ONLN`, since it runs on macOS too; `PACE_GATE_JOBS` overrides).
Tests that genuinely cannot share -- a daemon, a fixed port -- carry `RUN_SERIAL`,
which `tls-smoke` was missing while every one of its neighbours had it. Measured
on the full suite: 649s serial, 131s at `--parallel 8`, same 1965 tests; Windows
65s to 37s.

**A fake is a shared helper too, and the same rule caught it a third time.**
`tests/ScriptedSocket.hpp` -- an `ISocket` replaying canned reply bytes, plus
`Replies` and an all-paths-fail `FailingSocket` -- existed as three near-identical
private copies, and **two of them carried the same defect**: `WriteVectored`
answering `0`, a short write, which `SendAll` correctly reads as a failure. Nothing
had tripped on it because `CacheProtocol::Exchange` is the first caller to send a
vectored write and no case reached one. The second copy was found while writing
#340; the first was still carrying it a day later and was found only by reading the
three side by side (#362).

Two of the arguments *for* keeping them separate had been written down, and both
were wrong in an instructive way:

- "Sharing would mean moving ninety lines to reuse thirty." That trades lines
  against a bug fixed in one copy staying live in the others, which is what
  happened. The trace machinery moved **with** the class rather than being dropped,
  so the case that needs it still has it and the two that do not simply never call
  it.
- "These two binaries share nothing but the wire, so a fixture reaching across
  would be the coupling the test denies." That is right about the two **binaries**
  and does not reach the helper: `src/tests/` is neither binary's, includes nothing
  from either app, and is already how both reach `Unwrap`.

The general form is the one `ScratchPath` taught: a helper is shared only if it
sits where everything needing it can include from -- and a fake nobody exercises
does not report its own bugs, so copies of one drift silently and the drift is
found by whichever case walks into it.

### A fourth time, and what it adds is that the COST OF A COPY GROWS

`tests/MembershipFakes.hpp` -- `ListedMembership` (admits the hosts it lists, and
`Remove` stops admitting one mid-case) and `FixedMembership` (one verdict whatever it
is asked, which is the only way to spell `Forgotten`, since no host list can). It was
**six** copies across six test files, four of them byte-identical (#1497).

Everything above applies unchanged. Two things are new, and the second is the reason
this one is worth its own entry.

**The direction a fake's bugs point.** Duplicated production code is found when it
breaks. A duplicated FAKE cannot break its cases -- a fake that is wrong makes them
**pass**, because a case asserts what the fake was built to produce. So the green
suite says nothing, an assertion review says nothing, and the copy is found only when
somebody happens to read it. Three of the four instances in this file were found by
reading, one by a second copy being written; none by a failure.

**A copy's cost is the number of FACTS it must get right, and that number is not
fixed.** These six copies were free for as long as the seam had nothing to decide:
`Classify` returned a verdict, every copy returned it the same way, and a wrong copy
was not expressible. #1471 made `Explain` the one virtual and gave every answer an
attributed ROUTE -- so each copy acquired a fact, *which participant do I stand for*,
and each became a separate chance to name the wrong one. Naming the wrong route makes
a case assert attribution it never established, which is a green test over a defect.

The consequence for the fix: **the shared fake takes the participant as a REQUIRED,
undefaulted argument.** Consolidating a fake must not consolidate the fact each case
states about it, and a default is the tempting shape precisely because eleven of the
twelve call sites want the same value. That is the type system used for the half of
the rule it is right for -- the obligation is *supply a value*, so make the right
answer the only reachable one -- while the ONE reason a fixture had for using a host
list rather than an open oracle stays at that fixture's construction site, in its own
words. Those reasons differed across all four copies and were the only part that did.

**And a host-answering fake may stand only for a route production answers by HOST** (W-15):
Loopback for this machine and OpenPolicy for any caller, which `HostLabels` (`MembershipFakes.hpp`,
an `EnumTable` over `MembershipParticipant`) says row by row, refusing the rest by exception at
construction. A ticket, a proof or a revoked key is never derived from a host in production, so a
host list labelled `MachineTicket` admitted an address that presented no ticket at all -- a route
production does not have, and so a green case over it. Those routes are the production fold,
`Testing::RosterFold` (loopback plus a key roster, with the voters a case about operators names),
and the case PRESENTS the key or ticket on the connection.

`ctest -R membership-fakes` enforces it, over every `*_test.cpp`, and the enforcement
is a `class`/`struct` whose base clause names `IMembershipOracle` -- bounded by
`[^;{]*`, so a declaration WRAPPED across lines is still one match. That bound is the
point rather than an optimisation: a line-based reader fails **open** on exactly the
shape a formatter produces once a class name grows, which is the residual that would
have let copy seven through. Its self-test watches it accept a mention in prose and a
parameter of the interface type, because a pattern that has gone greedy passes the
refusing cases and only the accepting ones can see it.

### A fake that RESOLVES what production SUSPENDS on makes every test over it vacuous

The entry above is about a fake carrying its own bugs into every consumer. This one is
worse and has the opposite tell: **there is nothing wrong with the fake.** #778.

`InMemorySocket::WaitReadable` resolves immediately in all three directions -- error when
closed, `0` at EOF, `1` otherwise -- and its header says why, in as many words: *"so no
caller gains a suspension point it did not have"*. That is a correct in-memory transport
and a deliberate decision. It simply never enters the state the protocol under test is
DEFINED by, so every assertion written over it holds for a reason unrelated to the
property being claimed, **and the suite is green whether the protocol is implemented or
not.** #710 (`RunBlockingRead` re-arming per iteration) and #755 (a watcher surviving the
transition out of subscribe mode) both sat behind exactly that green.

So the question to ask of a fake is not *is it correct* but **can it reach the state the
case is about**. Where it cannot, the case needs a real socket -- `PlatformReactor` /
`PlatformListener`, cross-platform rather than three copies under three `#if`s, because a
per-platform test is the shape that cannot see the platforms disagreeing.

**Checked-and-present must not render the same as not-checked**, so the survey records
both. Suspension-defined properties, and where each is exercised:

<!-- table-total: none -->
| Property | Real-socket case |
|---|---|
| `WaitReadable`: EOF vs data vs error | `Net/WaitReadable_test.cpp`, `PlatformReactor` |
| Read-slot exclusivity (#663) | `tests/ReadSlotGuardCanary.cpp`, must-die |
| Reactor frees parked frames at `Stop` | `Async/ParkedWork_test.cpp` |
| Teardown serialised with dispatch | `tests/ReactorTeardownCanary.cpp` |
| `Read` refuses an empty buffer (#838) | **deliberately `InMemorySocket`** -- a canary aborts at the FIRST violation, so the other five sites are covered by the `read-buffer-guard` scan instead |
| `CancelRead` retrieves a parked read | `Net/CancelRead_test.cpp` -- **added by #778; before it, Windows only** |

The last row is what the survey was for. `EpollSocket::CancelRead` and
`KqueueSocket::CancelRead` are real overrides sharing one `Detail::RetireParkedRead`, and
their only coverage was `Net/IocpSocket_test.cpp` (Windows) and `Testing::ParkingReadableSocket`
-- a fake built precisely because the shared one will not park. Neither runs on the legs the
local gate runs.

**And the fake being more permissive is not the only way this bites -- the real transport can
be less predictable than the contract's wording.** `CancelRead` is documented *idempotent*,
which invites *call it twice, the second does nothing*. On epoll and kqueue a completion
resumes the awaiting coroutine INLINE, so the first call's resumption runs that coroutine on
to its next `Read` and arms it before the second call executes -- and the second cancels the
new read. Measured while writing the case above: the read after a double cancel came back
`Cancelled` rather than its bytes. On IOCP the completion is marshalled to a later turn, so
the same two lines behave differently again. What is idempotent is a cancel with **nothing
parked**, which is the arrangement the contract is about.

### A fake's CLOSED states are one table, pinned against a real pair

#1553. `InMemorySocket` accepted a write to a peer that had closed, so a session the OTHER end
ended was invisible to every in-memory case: session teardown, revocation, a leader deposed
mid-send, a worker that went away. #178's revocation tests found it by having to force the
redial through a readdress, because the dialler's writes kept succeeding. The rule it broke is
the one above -- *a fake more permissive than the thing it stands for* -- in its purest form:
nothing was wrong with any case, and every case over the gap passed.

Every closed state is now a row, and `Net/SocketClosedStates_test.cpp` drives each sequence of
rows twice -- over `InMemorySocketPair`, and over a `PlatformListener` socket facing a blocking
client -- asserting that the fake answered the table and that the real pair answered it too:

- the peer CLOSED with nothing unread: reads drain then EOF; the FIRST write after it is
  accepted and lost and draws the reset; every later write and read fails `SystemError`
  (`EPIPE`, `WSAECONNABORTED`);
- the peer closed with bytes of ours UNREAD: a reset at once, so every write and read fails
  `ConnReset` (`ECONNRESET`, `WSAECONNRESET`);
- the peer HALF-closed: reads reach EOF, writes still succeed;
- THIS end closed: `BadFileHandle` from every operation that can report one, as all four
  platform sockets answer. `ShutdownWrite` returns `void` on `ISocket` and every platform
  socket ignores it after a close, so the fake does too: making it report is an interface
  change across every transport, not a property of the fake;
- this end half-closed: writes fail `SystemError` (`EPIPE`, `WSAESHUTDOWN`) -- the fake used to
  answer `WouldBlock`, the one failure a caller is entitled to retry.

Every code is the one `ISocket` maps the platform's error to, and each failing row of the table
names it.

**Where the platforms disagree, the model takes the stricter answer, and it is Windows's.**
Measured on loopback on Windows 11, Windows Server 2025, Linux under WSL2 and on
`ubuntu-24.04`, and macOS 14: after a reset, Linux and macOS hand over bytes already buffered and
then report EOF again; Windows fails every read and drops what was buffered. And POSIX reports
a pending reset to whichever call comes first, so the code a later call meets depends on the
order. A row that lets Linux and macOS fail under another code, or answer where the model fails,
says so, and **on Windows no row grants anything** -- the model IS Windows, error codes
included, so a Windows run that differs means the justification has stopped being true.

- **The pin's first finding was not about the fake.** Driving `ShutdownWrite` over a real
  accepted socket showed Windows writing on after the half-close: `IocpListener` never set
  `SO_UPDATE_ACCEPT_CONTEXT`, so `shutdown` failed `WSAENOTCONN` on every socket it accepted and
  the failure was ignored (#1556). No in-memory case could see that and no Linux gate runs IOCP.
  A pin against a real pair tests BOTH sides of its comparison.
- **The cases that passed only because of the gap were right, and production was wrong.** Three
  (`RedisResp_test` "a value exceeding the cap gets a protocol error reply, not a bare reset",
  and the admin surface's `408` dribble and `431` byte-cap cases) asserted a refusal the client
  read after the server closed over a request it had not finished reading. Over a real socket
  that close is a reset, and on Windows the reset destroys the refusal. They were fixed at their
  subject -- production closes through `CloseLingering` now (#1554,
  [`wire-and-protocol.md`](wire-and-protocol.md)) -- and each fixture closes the way production
  does, beside a case through `Server::Run` or `AdminHttpServer::Run` that guards the call site
  itself. Relaxing the model to keep them green would have re-asserted a claim that is false for
  every Windows client.
- **An in-process pair has no clock**, so a fixture whose server lingers half-closes its client;
  a real socket's linger ends at a deadline the pair cannot reach, and a parked `SyncRun` is a
  thrown `logic_error` over a frame the fake still points at.

### A value from another generation is BUILT by the shared helper, never by hand

`tests/ForeignGenerationValue.hpp` (#649). Four cases across two test binaries need a
stored value carrying a generation this build does not implement, and all four built one
the same way and separately: encode through the real encoder, assert the leading byte is
`CompileValueVersion`, write `CompileValueVersion + 1` over it. Three lines, no
collaborator, nothing that looks like it wants a helper -- which is why it spread.

**What makes it worth consolidating is that the copies fail SILENTLY.** Every one of those
cases asserts a REFUSAL, and a value damaged in some other way is refused too. So a
generation that moves off byte 0 leaves each copy stamping a different field: the value
stops being a foreign generation, the case goes on passing, and the name still says what
it no longer builds. That is the shape `Assert what DISTINGUISHES` describes, arriving
through a construction rather than through an assertion -- and an assertion review does
not find it, because every assertion is correct.

Two facts live in the helper and nowhere else:

- **Which byte carries the generation.** `StampGeneration` refuses bytes whose leading
  byte is not `CompileValueVersion`, so a moved generation is a thrown `logic_error`
  naming the two numbers rather than four cases quietly testing something else. A
  precondition violation is the one thing this project throws for.
- **Which generation is foreign.** `ForeignGeneration` is DERIVED, not spelled
  `CompileValueVersion + 1`. That arithmetic stops being right at the top of the reserved
  range: a leading byte outside `[1, MaxCompileValueGeneration]` is not a compile value of
  any generation (#552), so at version 15 all four copies would have built a
  `NotACompileValue` -- a different outcome under a different policy, in cases named for
  the one they no longer build. A `static_assert` proves the derived byte stays inside the
  range, so the failure is a build error rather than four confusing reds.

The guard is proved in both directions by
`The shared foreign-generation helper refuses to stamp a value it does not recognise`, in
`CompileValue_test.cpp` -- a `CHECK_NOTHROW` on the ordinary path beside the two refusals,
because a guard nobody has watched ACCEPT is not known to work and a helper that threw
unconditionally would satisfy the refusing half alone. Neutering the precondition reddens
that one arm and nothing else: measured, the empty-vector arm, the `CHECK_NOTHROW`, and
both neighbouring cases stay green.

**A hand-built frame is NOT this helper's job and must not be routed through it.**
`CompileValue_test`'s `futureFramed` synthesises a value whose FRAMING this build cannot
parse -- a generation byte followed by a field that does not exist here -- which is #552's
subject and cannot come out of this build's encoder at all. The helper takes an encoder
output; a frame this build could not have written is a different thing that happens to
share a leading byte.

### A C++ test waits through `BoundedWait.hpp`, on the thread the wait belongs to

`src/tests/BoundedWait.hpp` is the tree's one test wait (#1446), over `DrainWithin`, so its
bound is real time on a monotonic clock and never a count of sleeps. Before it, #1446's census
found tests waiting on other threads by counting (`2000 x 1 ms`, `2000 x 5 ms`), by six
hand-rolled deadline loops, and -- twice -- not bounding at all.

- **`WaitUntil` on the case's own thread.** When it runs out it attaches an account to the
  next assertion: what it waited for, the real time and polls spent, the state at the end, and
  whether that state was MOVING, STALLED or cannot be told apart (`ReadWait`, a pure function
  with a case per reading). Catch2 clears that message at the next assertion, pass or fail, so
  **assert the wait that ran out first**.
- **`OffThreadWaits` on a helper thread, never `WaitUntil`.** Catch2's assertions and messages
  belong to the thread running the case; a message from another thread races its state. The
  helper keeps the account and the case asserts `AllReached()` as its first assertion after the
  join.
- **That race is NOT a reported race, inside the TSan scope or out of it, and this bullet said
  it was until #1211.** Catch2 is built without the sanitizer here -- measured: a clang-tsan
  build's `libCatch2d.a` references no `__tsan_func_entry` in any of its 106 objects -- so the
  race is in code TSan never observes, and the TSan gate stayed clean over the binary that had
  it. What it did instead: `FrameEndpoint_test`'s `Exchange` asserted on three `std::async`
  threads, the cumulative JUnit reporter's node for that case was damaged, and the damage
  surfaced at run end as a SIGSEGV in `JunitReporter::writeAssertion`, a `free(): invalid
  pointer`, or glibc printing `malloc(): invalid size (unsorted)` and wedging inside `abort` --
  5 of 18 `[frame]` runs on Linux and 10 of 20 on Windows, under JUnit only, and never under
  the console reporter or ctest's one-case-per-process registration, which is how every gate
  ran it. **So the rule is ENFORCED at run time now, not by the sanitizer:**
  `src/tests/OffThreadAssertionGuard.cpp` is an INTERFACE source of the Catch2 target, so every
  test binary compiles it through its link, and it ends the process at an assertion made off
  the case's thread -- every run, every reporter, naming the line. Return what the helper
  observed, or keep it with `OffThreadWaits::Keep`, and assert after `.get()` or `.join()`.
  `ctest -R off-thread-assertion` watches it accept and refuse, and reads the link lines. **It
  sees ASSERTIONS only**: `INFO`, `CAPTURE`, `UNSCOPED_INFO` and `SECTION` off the case's thread
  race the same state through entry points it never hears, so its silence clears none of them.
- **Two waits that give up together report the symptom, not the cause.** Measured on
  `DashboardSampler_test`: the pool thread's one-guard wait for a release and the case's
  one-guard wait for the frame ended within a millisecond, and the frame's won. The outer wait
  is twice the guard, so the inner one gives up first and names the release.
- **A wait that can now fail exposes the teardown behind it.** A neuter that failed one wait in
  `ThreadedAddressResolver_test` hung the case until it was killed: the `REQUIRE` unwound into a
  join on a worker the case held. `ShardedStorage_test`'s parked-thread cases unwound through a
  joinable `std::thread` instead, which is `std::terminate` and takes the report with it. Both
  are the RED-into-HANG rule above, and both were only visible once the wait could be made to
  fail -- so neuter a new wait, and watch what the case does after it.

- **`AwaitUntil` in a coroutine on a reactor, and a wait that ran out STOPS the coroutine.** A
  coroutine cannot block its own reactor thread in `WaitUntil`, so it parks between looks and
  is bounded on the reactor's clock (#1453) -- a `ManualClock` reactor's bound is manual time,
  asserted exactly. Its outcome goes to `OffThreadWaits::Keep`, and where that answers false the
  coroutine `co_return`s or releases only what it holds: running on as if the wait had held
  asserts, writes or cancels against a state that never arrived, and the account then names the
  symptom rather than the wait. A test FAKE that waits inside an answer settles the reply it
  still owes (`FrameEndpoint_test`'s held responder returns a counted `Miss`) and asserts its
  accounts where every case using it reaches -- its destructor, skipped while a failure unwinds.

`ctest -R test-loops` refuses a `while` that polls an atomic, a coroutine `while` whose body
opens by parking on its reactor, and a C-style `for`; its header says what it does not cover,
and the coroutine rule reads only the one shape #1453's census found.

**Its scope is per RULE, and that is the scope rather than a refinement of it.** `loop` reaches
every C++ source under `src/` (#1452). `spin` and `poll` do not, and widening them was tried and
reverted inside one change: they fired 16 and 5 times, every hit in a PRODUCTION file -- reactor
shutdown checks, `FrameEndpoint`'s drain, the bench's workers -- and the wait they ask for is
`src/tests/BoundedWait.hpp`, which a production source cannot include. **A guard's remedy text is
part of the guard**, so a rule whose remedy does not exist for the files it refuses is not a
stricter rule, it is a broken one. The `rules` column of `PaceTestLoopScope` says which,
and a rule no scope row names is refused rather than left enumerated by nothing.

**The 148 sites the widening found were a RATCHET, and a backlog row is a different CLAIM from an
exemption row.** An exemption says *this site is right and must stay, here is why*. A row in
`scripts/check-test-loops-backlog.txt` says *nobody has decided about this yet, and the issue it
names will* -- the `RefuseUntriaged` distinction from
[`.agent/rules/metrics-and-observability.md`](metrics-and-observability.md), and safe for the
same single reason: the check TALLIES them and prints the total per issue on every run. Spelling
them as exemptions would have put 148 sites behind a word that means *decided*. #1452 decided all
of them and left the backlog EMPTY, which the check says in so many words (`backlog: empty`)
rather than by printing no tally -- a line that stops appearing reads the same as one that
stopped being computed.

It turns one way. A file with MORE sites than its row records is a new site and is refused, and
the answer is to convert it rather than raise the number; FEWER is a row that has stopped
describing the file and is refused as stale, so a conversion is recorded in the change that
makes it and the number it left behind is not room for the next arrival. Keyed on a count per
(rule, file) and deliberately not on a line, which churns on any edit above a site. **What that
leaves open is stated rather than engineered away**: one site removed and another added in the
same file under the same rule is a wash, and a key that could see it would have to be the header
text, which contains a `;`.

**And `AGENT.md`'s bullet deliberately states NO count.** That is the same rule as the row key,
read one level out: the backlog file owns the number, and a prose copy of a number a table owns
is the second source of truth `ctest -R table-totals` refuses everywhere else. Recorded as
history rather than as a figure to keep current -- the total has read 148, then 134, then 119,
then 56, then 0 while one prose sentence in `AGENT.md` stood still through all five. Any one of
those numbers would have been correct in `AGENT.md` for as long as it took the next conversion
to land, and wrong and unnoticed afterwards, which is why the bullet there names the FILE and
stops. Do not "helpfully" add the current figure back to it.

**The census in #1452's body is 45 and the tree holds 169.** Not a miscount -- the ticket's
pattern `\bfor \([^:)]*;[^;]*;` rejects any init containing a `:` or a `)`, so it misses every
`std::`-qualified declaration and every init that calls a function. Measured per line:
`for (int i = 0; ...)` matches, `for (std::size_t i = 0; ...)` does not, `for (auto i = c.begin(); ...)`
does not. **A census states its PATTERN, not only its number**, and this is the third instance of
that rule in this repository's history.

**clang-tidy cannot be the mechanism, and this was measured rather than assumed.**
`modernize-loop-convert` is the only candidate, it is already enabled with
`WarningsAsErrors: "*"`, and it fires only when the loop bound IS the container's own size:
`index < batch.items.size()` over a `std::array` is flagged, `index < batch.count` over the same
array with the same body and the same indexing is not. None of the 148 has that shape, which is
why an analyser that has been on the whole time has said nothing about them.

## The POSIX fixtures share one helper library, and a bound is read from a clock

<!-- agent-tripwire: The POSIX shell fixtures share `scripts/lib/e2e-common.sh` -->

`scripts/lib/e2e-common.sh` holds `fail`, `free_port`, `port_answers`,
`wait_until`, `wait_for_port`, `wait_for_log`, `stop_and_require_exit` and
`http_get`. It was seven copies, and every argument the C++ side of this file
makes about `ScriptedSocket` applies unchanged: a shared helper is a shared fake,
a fake nobody exercises does not report its own bugs, and copies drift silently
until whichever caller walks into the drift pays for it.

The drift had already happened, in three directions, and each one is a fixture
that could not report what it saw:

- `check-compile-cache-daemon-start.sh`'s `wait_for_port` checked **no liveness
  at all**, so a daemon that died at `bind()` was reported as `never answered on
  port N` after the full bound had burned — the slow-machine-versus-wedged-process
  confusion this file spends three sections on.
- `fleet-dashboard-e2e.sh`'s `http_get` learnt that `read` returns non-zero on a
  final chunk with no trailing newline, so a naive loop drops it — and the JSON
  document that route serves is one line with no newline at all. The fix was never
  carried back; in the other six copies it is latent by luck about which endpoints
  end in a newline.
- Two `free_port`s had no issued-port ledger.

The library is therefore the **union** of the correct behaviours, not their
intersection: preserving each caller's current behaviour would have preserved all
three defects under the name of compatibility.

**A bound is read from a clock, never counted in iterations.** Every copy said
things like "100 x 0.2s = 20s" and none of those equalities held: `sleep` is an
external command that forks and execs, and it overshoots on a busy machine, so the
product is a *lower* bound that drifts most exactly when a fixture is timing out.
`fleet-dashboard-e2e` had the pure form of it —

    fail "timed out after $((WAIT_TICKS / 10))s waiting for $what to listen on ${port}"

— a duration computed from the loop shape and **never observed**. Whatever the loop
took, the operator was told `WAIT_TICKS / 10`. That message is the one this file
requires to separate a slow machine from a wedged process, and it cannot, because
the reading that would show a slow machine is derived from assuming the machine was
fast. `SECONDS` bounds the loop and `SECONDS` is what gets reported; the sleep stays
as pacing. One second of resolution is the price and it is ample against budgets of
20s and 240s, because it is a measured second rather than an assumed one.

**A bespoke condition is a predicate, never a bespoke loop.** `wait_until` is public
for exactly that: `fleet-dashboard-e2e` had a hand-written poll for a worker to
appear in `/fleet.json`, with its own bound, its own message and no liveness check,
because neither `wait_for_port` nor `wait_for_log` covered it. That is how the next
copy gets written.

**`fail` signals the top-level shell unconditionally, and does not test `BASHPID`.**
`exit` inside `( ... )` ends the subshell only; the obvious guard is to compare
`BASHPID` with the top-level pid and signal only when they differ, and that guard is
correct on bash 4 and **silently inert on 3.2**, where `BASHPID` is unset and the
test reduces to comparing `$$` with itself. So there is no detection: the signal
goes out always and a `trap 'exit 1' TERM` turns it back into an ordinary exit with
the EXIT trap intact. This is not belt-and-braces reasoning — staging the `BASHPID`
guard back in and running the self-test on a bash 5 runner leaves every behavioural
case **green**, because on bash 5 the guard works. The bash-3.2 scan in
`check-e2e-helpers.sh` is the only check in the tree that can see it.

**And that scan reads every script under `scripts/`, not the library.** It read
one file for two tickets while `launcher-replay-e2e.sh` carried the exact guard
the rule bans by name, under a comment arguing it was correct — so the repository
had the rule written down, had a check enforcing it, and the check did not read
the file that broke it (#627). The set is WALKED rather than listed, because a
list is exact about the files it knows and silent about the ones it does not;
restricting the walk to `scripts/` is a scope choice, so a tracked `*.sh` outside
it is refused by name, the message states the pattern it searched, and where git
is absent that half reports as NOT CHECKED rather than as clean. It refuses on an
empty file list and on an emptied token table — two empty lists agree perfectly,
and this scan has two ways to become one.

**One enumeration serves all three scans in that file**, and folding them found a
second instance of the same defect: the `timeout` scan's own failure message says
*"use `run_bounded` from `scripts/lib/e2e-common.sh`"*, and its non-recursive glob
could not read the file that DEFINES `run_bounded`. Three copies of a file list
is three answers to one question, and the delta was exactly the worst file.

**A file exempts a REGION, not itself.** `check-e2e-helpers.sh` has to hold the
banned-token table and the canary's staged text, so it matches its own scan by
construction — and the first fix was an allowlist row for the whole file. That is
the wrong altitude by three orders of magnitude: the file is over 1700 lines, is
the heaviest array user under `scripts/`, and ctest runs it through `/bin/bash`,
so on macOS it is a bash 3.2 script like any other. It now marks those two blocks
with `# bash32-scan: data-begin` / `-end`, the scan reads everything else, an
unbalanced region is refused (an unclosed one would blank the rest of a file), and
every declared region is NAMED on each run — an exemption with a smaller blast
radius is still an exemption. Watched: a `local -n` planted outside a region is
caught, where under the whole-file row it was not. The markers a file has to
*write* are spelled `bash32-%s` through `printf`, or a heredoc holding them
verbatim closes the enclosing region early — which happened on the first run of
that block, and the scan reading its own source is what caught it.

**Whether a region is well formed is asked by a STATE MACHINE, not by counting the
two markers.** Counting is the obvious spelling and it fails in the hiding
direction: a `data-end` sitting above the first `data-begin` is a no-op for the
reader and leaves a region open to end of file, while the totals come out equal and
the file reads as balanced. Measured by staging exactly that into
`check-e2e-helpers.sh` with a `mapfile` below it — the whole run's output was
byte-identical to a clean one, census line included. A checker that does not ask its
question the way the reader asks it is answering a different question.

**`BASHPID` is one of at least three doors to the same room**, and the general
form belongs beside the fix: *inside a `want-fail` assertion, any failure to run
is indistinguishable from the rule firing.* #723 reached it through a mode bit (a
bare `"$0"` exited **126**, and eight cases passed because the SHELL refused);
`set -u` reaches it by expanding an empty array, which is an unbound variable
before 4.4 (`${1+"$@"}` is the remedy; #793, #794); `BASHPID` reaches it by making
the abort a no-op. The token table covers the first and the third and
**deliberately not the second** — measured, `"${x[@]}"` and `"$@"` occur about 110
times across the 22 scripts that set `-u`, essentially all of them arrays that
cannot be empty, and no regex over shell can tell a possibly-empty array from a
never-empty one. A row for it would be ~110 findings on a correct tree, and a
scan that reports noise is a scan somebody deletes — which would cost the eight
rows that do work. That is the decision, recorded so the next instance is not
missed for want of anyone having made one.

`ctest -R e2e-helpers-selftest` is the test, in the default set, POSIX-only. Its
decision half — which kind of failure a wait suffered — is `_e2e_verdict`, pure and
driven from staged records with both sides of every threshold pinned, for the reason
`Get-WaitVerdict` is. Its acquisition half is driven against real processes that
really die and real logs that really grow. Both halves were falsified: eleven staged
defects, each shown red at the case that names it. Two of the first drafts' cases
could **not** be made to fail and were rewritten — a forty-draw port test that a
deleted ledger passed fifteen runs in sixteen, and a `( fail )` subshell case that
`set -e` was quietly rescuing.

**A background process a fixture starts is bounded by TWO independent arms, and the
one that can be reopened by omission is the one that has to be structural.** #839
measured what a missing arm costs: **1368 orphan `perl` listeners holding loopback
ports, the oldest 30.5 hours old.** The ports were the expensive half rather than the
load — these fixtures draw from below the ephemeral range, so the next run meets a
port held by a process nobody knows about and fails somewhere else entirely, which is
the worst available shape. The arms are `exec` (so the pid a caller holds is the
PROGRAM and not the subshell bash forks for a backgrounded function — three
`kill "$listener"` calls here had never worked) and a self-imposed lifetime (because
no trap runs under `SIGKILL`, a `ctest --timeout` or a cancelled CI job, and this
fixture is in the DEFAULT set on every platform). **Each alone drives a survivor
count to zero, for a different reason, so a COUNT cannot tell you whether either
works** — ask the process tree.

`exec` fails LOUDLY when it is forgotten, since the existing `kill` stops working.
The lifetime does not, so it rides on the thing every stand-in must do anyway:
`_selftest_bounded_perl <seconds> '<program>' <args...>` owns both, injecting the
bound as its own `perl -e` chunk so the bodies stay textually distinct — they model
different things, and concatenating perl program text as strings is the hazard, not
the fix. There is no argument to pass an unbounded program to, and a bound of `0` is
refused by name because `alarm 0` is perl's spelling of *cancel*, which would be an
escape hatch wearing the shape of the guard. This is the `Refuse`-takes-a-row idiom
(#1214).

**Nothing makes a NEW stand-in go through that door, so the rule is a scan and not a
comment** (#843). That is #970's finding arriving here: a rule stated in the files
that obey it reaches no file that does not — and it is not hypothetical, since PR
#834 added an unbounded listener *while* the ticket about bounds was open with its
diagnosis written down. `perl-bounds-scan` walks every `*.sh` under `scripts/` and
refuses any `perl` command position outside the injector, unless the line states
`# perl-lifetime: <reason>`. Two spellings, two claims, and the marked ones are
TALLIED and printed on every run, or *decided* and *forgot* are one spelling again.
It refuses at zero as well: a scan whose subject has left the tree reports every file
clean, which reads identically to complete coverage. Do not write the naive version —
`alarm 30` appears in prose in that file, so a token grep is satisfied by a comment;
it reads through the same declared-region filter the `bash32` and `seconds` scans use,
and a file that matches its own scan by construction exempts a REGION, never itself.
And the DOOR is asserted behaviourally in both directions, by exit STATUS and never by
timing: a 60-second program under a 2-second bound must exit **142** (128 + SIGALRM),
and a short program under a 30-second bound must exit 0 with its `@ARGV` intact — a
door that armed nothing would pass the scan, and one that killed everything would pass
the refusing half alone.

**A cleanup reaps `jobs -pr`, never a pid ledger the call sites append to** (#845).
A ledger is per-site, so the next background site reopens the leak by forgetting one
line; there is nothing to forget in the shell's own job table. Two things a conversion
may not assume, and both are checked by ENUMERATING the background sites rather than
by argument: `jobs -pr` is per-shell and cannot see a process started *inside* a
`( ... )` subshell — a backgrounded subshell is itself a job and is fine, its
grandchildren are not, measured — and `$!` for a backgrounded shell FUNCTION is the
wrapper. A ledger may still exist for ADDRESSING (`cluster-e2e.sh` keeps a slot-indexed
one so a case can stop one named node); what it must stop being is the thing cleanup
depends on. The escalation those fixtures need stays: TERM every job, one shared grace,
then KILL the survivors. It must never call `fail` and never `wait` before the KILL —
`fail` re-enters the EXIT trap already firing, and a bare `wait` in cleanup is
unbounded against exactly the TERM-ignoring child these suites stage on purpose.

## An in-process fleet, and what a harness has to earn

<!-- agent-tripwire: A fleet property that spans two machines needs `src/tests/FleetHarness.hpp` -->

`tests/FleetHarness.hpp` runs a compile fleet in one process: N `SchedulerService`
instances addressed by endpoint, real `SchedulerProtocol` framing, the launcher's
own `Cc::ExchangeFramed` on the client side, and `Cc::Dispatch` running unmodified.
Time moves only in `Step`. It is the fleet's counterpart to
`Consensus/RaftClusterHarness`, and the argument for it is the one that header
makes: rules about a **sequence** across two machines are not reached by any amount
of single-transition testing.

Three things about it are load-bearing, and a fourth is what keeps the other three honest: **the
harness admits no caller a node would refuse** (W-8). A node given no oracle is decided by the fold
every node composes when it is not open -- loopback and a key roster of its own applied state --
never by "everybody is a proven member"; a password AUTH establishes nothing; and the roster is
adopted at a COMMIT, never per exchange. A harness more permissive than production lets a fold or
publish regression stay green, which is the defect a harness exists to catch.

**It is in `src/tests/`, not beside `RaftClusterHarness`.** That header lives in
`Consensus/` because everything it touches lives in `Consensus/`. A fleet spans
`Distributed/`, the node and the launcher's client sources, so the same placement
would make a **library directory include an app header**. `ctest -R net-boundary`
exists to stop the milder version of that; library-depending-on-app has no gate at
all, which is a reason to be careful rather than a licence.

**An interleaving has to be arrangeable, not hoped for.** `Cc::Dispatch` leases,
compiles and releases in one call, so a test cannot get between the grant and the
release from outside -- and that gap is exactly where leadership moving is
interesting. `OnCompile` fires inside the compile exchange, on the caller's thread.
This is the whole reason a script that spawns processes cannot assert these
properties: it can wait for an election, but it cannot place one.

**A harness earns its place by asserting something that can be shown red.** Per
#355 a test that cannot fail for the reason it exists is not evidence, and a
harness makes it easy to write a case that exercises a great deal and pins
nothing. The first property here -- the RELEASE goes to whoever ISSUED the lease --
was proven by pointing the release at the configured endpoint instead and watching
four assertions fail, **including a second client's live lease being freed**: two
schedulers number their leases independently and both start at one, so a misrouted
release matches somebody else's. The straight no-redirect case stayed green under
the same break, which is exactly why it is in the file: it cannot tell the two
rules apart, and a suite containing only cases like it would have looked like
coverage.

## Registering a script-driven test

<!-- agent-tripwire: A script-driven test naming more than one executable is registered in `src/tests` -->

Not every test is a Catch2 case. Script-driven tests are registered in
`src/tests/CMakeLists.txt`: the `smoke`-labelled ones start a real daemon or
invoke a real compiler and report a missing prerequisite as skipped (exit 77 with
`SKIP_RETURN_CODE`), while `repository-hygiene` runs
`scripts/check-repository-hygiene.cmake` through `cmake -P` and is deliberately
*not* labelled `smoke`, since it needs no daemon, socket or compiler and so belongs
in the default `ctest` set. It reports "not a git work tree" by printing `SKIP: `
and exiting 0, matched by `SKIP_REGULAR_EXPRESSION` — a `cmake -P` script cannot
choose its own exit code before CMake 3.29 (`cmake_language(EXIT)`) and this
project supports 3.28, so a `SKIP_RETURN_CODE` it could never return would be dead
configuration.

`net-boundary` is the second of those and takes the same shape, with one
difference worth stating: it has **no skip path at all**. `repository-hygiene`
asks the git index, which an exported source tarball does not have; this reads the
source tree, which such a tarball contains exactly as a checkout does. A skip
condition it could never meet would be the dead configuration the paragraph above
argues against.

**Which CMakeLists registers a script-driven test is load-bearing, not filing.**
`src/apps` walks its app table *in order*, so a test registered beside one binary
cannot name a binary that comes later in that table: at the point
`src/apps/pace-cc` is configured, `pace-node` is not a target
yet, and a `$<TARGET_FILE:>` guard on it does not fail — it silently skips the
test, forever, with one `message(STATUS)` in a configure log nobody reads.
`src/tests` is added *after* `src/apps`, so every target exists by the time it
runs. That is why `dist-compile-e2e` lives there, and the general rule is that a
script-driven test naming more than one executable belongs in `src/tests`
regardless of which binary it feels closest to. (`compile-cache-e2e` predates the
rule and names only `pace-kv`, which the table happens to reach first.)

`dist-compile-e2e` additionally allocates its ports per run rather than fixing
them. It needs four, and four more fixed ports is four more ways to collide with
whatever else a CI runner is doing — a failure that reads as "distribution is
broken" when it means "something else was listening". `cluster-e2e` does the same
with the twelve its four nodes need, and so does `compile-cache-e2e` with the two
its daemons need — which had a fixed port and failed under a parallel `ctest` as
"the first compile was not a MISS", i.e. as a defect in the launcher's key rather
than as a stranger answering. It also re-checks that the daemon still running is
the one it started, because a port that was free at `bind` time says nothing about
who holds it a second later.

**A drawn port is drawn from below the kernel's ephemeral range, and remembered.**
Both halves have now been a red CI run. The ledger came first: nothing is listening
on a port issued a moment ago whose server has not bound yet, and a fixture that
draws every port it needs before binding any of them can hand the same number out
twice. The range came second, and is the half a connect probe *cannot* answer at
all — a port may be the local endpoint of an **outbound** connection, ESTABLISHED
or TIME_WAIT, with nothing listening on it, so the probe says "free" and the
`bind()` still fails with `EADDRINUSE`. A draw of 20000–39999 overlapped Linux's
default `ip_local_port_range` of 32768–60999 by better than one number in three,
and `dist-compile-e2e` duly died at `bind(127.0.0.1:33174) failed: 98` in the case
that runs after five cases' worth of connections. `lib/e2e-common.sh`'s `free_port`
draws 20000–31999, below that floor and below macOS's 49152, and every fixture that
reaches it through the shared helper inherits that. `migrate-storage-e2e.sh` does
not: it spells the helper `port`, draws 40000–59999, and is therefore entirely
inside Linux's default ephemeral range
([#628](https://github.com/LASTRADA-Software/fastcached/issues/628)). A helper
reimplemented under a different name is invisible to `check-e2e-helpers.sh`'s
name-collision scan, which is what that scan's allowlist reasons are for.

A fixture that reports "free" from a probe is answering *"is anything answering
here"*, which is not the same question as *"can I bind here"* — and the gap between
the two is exactly where a smoke test fails for a reason that has nothing to do
with what it tests.

**A body of assertions with a prerequisite the host may lack becomes its own ctest
test**, not another case in an existing one. A script exits once, so a case inside a
suite can do no more than print a line and let the run go green, and skipped and
passed are then the same result. The better answer, where one exists, is to remove the
prerequisite: the #235 pair needed a non-loopback address of this host's own, and was
a script mode of its own for that reason until a relabelled socket gave every host one
in process — see *A fixture whose client is always local cannot test who is admitted*,
below.

## A shared failure message describes one caller, and lies to the others

<!-- agent-tripwire: untriaged: #1567 no AGENT.md bullet carries this rule -->

`cluster-e2e`'s `find_leader` ended with:

    fail "no node ever answered a cluster question; the cluster never elected a leader"

Correct where it was written -- the first formation -- and false everywhere else it
is called from. In [#388](https://github.com/LASTRADA-Software/fastcached/issues/388)
it fired in phase 6, *after* eight assertions had passed, one of which had printed
the endpoint the cluster was being led from. The cluster had elected; what it could
not do was elect **again**, which is a different defect with a different cause. The
sentence sent the first half hour of the investigation to the wrong place.

So the situation is a **parameter**, named by each caller, and the failure prints
who was asked and what each said. "Nobody answered" is the absence of a finding;
the finding is in the refusals, each of which names the endpoint that node believes
leads.

## A reproduction models the wiring as it is

<!-- agent-tripwire: untriaged: #1567 no AGENT.md bullet carries this rule -->

**A fix at a different layer invalidates the reproduction that found the bug — and
the failing test is the signal, not the nuisance.**

#279's reproduction ran two `CompileJobRunner`s over one scratch root, which is what
two node processes were: each has its own job counter starting at 1, so both derived
`job-1` and everything beneath it. It failed deterministically, which is exactly what
was wanted from it.

The fix claims the root a layer **above**, in the node. `CompileJobRunner` still does
not isolate anything — hand it a shared root and it still collides, because its
*caller* isolates and it does not. So the moment the fix landed, the reproduction
asserted a property the class does not have and never will, and could only ever fail.

The tempting response to a test that fails after a correct fix is to weaken the test.
The right one is to ask **which layer now carries the property**, and move the case
there: the same scenario now sits beside `ScratchClaim`, wired the way `main` wires
it — a claim per node, each runner handed the root its own claim covers, the same
barrier holding both inside the compiler at once. It still fails without the claim,
for the original reason.

A reproduction is therefore a statement about a *design*, not only about a defect.
When the design moves, the reproduction moves with it or it is deleted — never
relaxed until it passes.

## What `cluster-e2e` covers

<!-- agent-tripwire: assert leadership stability only after formation -->

`cluster-e2e` is the consensus counterpart, and what it covers is deliberately
disjoint from the unit tests rather than a slower repeat of them: three real
processes elect a leader and *keep* that leader for three seconds of polling, a
follower's refusal names an endpoint that a client then successfully dials, a
setting replicates, a member is removed, a fourth machine started with no cluster
at all is admitted and answers a question only the replicated state can answer, and
the cluster re-forms after its leader is killed. The stability half is not
padding: a cluster that re-elects on a timer has exactly one leader at almost every
instant, so a single poll passes against leadership that never settles. Every one
of those is a property of the wire, the transport, the timers and the command line
meeting at once — which `RaftClusterHarness` cannot reach precisely because it
replaces all four. It is POSIX-only for now: the properties are
platform-independent and the fixture is not, so a Windows counterpart would be a
translation rather than new coverage.

## The first real run of a fixture is where its defects are

<!-- agent-tripwire: A fixture that has never completed has told you nothing -->

`launcher-replay-e2e` was reviewed, reasoned about and merged into a CI job, and
its first execution anywhere died on the first line that starts a process. Four
defects sat behind that line, each hidden by the one in front of it. Three are
below; the fourth was a repository bug the fixture merely reached first, and has
its own section two below this one (#390). They are recorded together because the
shape repeats:
**a fixture that has never completed has told you nothing, however carefully it
was read.**

**A flag spelling is checked against the table -- `CliOptions()` in
[`platform-service-and-config.md`](platform-service-and-config.md)'s one flag table, which drives
parsing and help alike -- not remembered.** The daemon was
started with `--memory-limit 2048mb`. There is no such option — the only
occurrence of that spelling anywhere in the tree was the line that used it — and
the byte suffix is a single character, so `2048mb` would be an unknown unit under
the right name too. The daemon printed usage and exited, and the fixture reported
`the daemon never accepted a connection`: a true sentence about the wrong thing.
Two spellings of the same start-up already existed in `scripts/`; the one that
worked was the one nobody had invented.

**`exit` inside a subshell ends the subshell.** A `fail` helper called from a
`( ... )` group — here the control build, running in one so it can unset the
launcher environment — does not stop the script. It then reported two further
failures about the artefacts the first one explains, so a reader working upward
from the last line starts on the wrong question. Fixed at the helper, not the
call site, because the next subshell will not remember: **signal the top-level
shell unconditionally.** This paragraph used to end "and test with `BASHPID`
rather than `$$`", and that half was wrong for two tickets — see the rule above,
and #627. `$$` cannot detect a subshell, `BASHPID` can and is bash 4.0+, so on
macOS the guard degrades to exactly the `$$` comparison it was written to
replace. There is no detection that works on both; unconditional costs nothing.

**A guard that proves a fixture bites can itself fail to bite.** The canary
compiled a deliberately wrong object over the object of the first `_test.cpp` in
the compile database — a unit of a *different target*, which the binary under
test does not link. The suite passed with exactly the case count it had passed
with a minute earlier, and the fixture announced `the suite PASSED with a wrong
object linked in`. No wrong object was linked. The observation was true and the
claim attached to it was false, which is worse than either alone: it names the
subject as broken when the instrument is.

So an injection is **asserted**, in the artefact and again in the thing that
consumes it. Every way of poisoning nothing — a substitution that did not fire,
an output path this build does not use, a unit belonging to another target — now
stops with a sentence about the injection rather than a verdict about the cache.

## A canary reports on the guard AND on itself, and cannot say which

<!-- agent-tripwire: A guard written to prove a fixture bites can itself fail to bite -->

The `static_assert` that every cache refusal policy states a counter *or* a
rationale (#491) was watched refusing only on the **third** attempt. The first two
runs both printed *the guard does not bite*, and the guard was correct both times.

Once the canary ran the build as `cmake --build ... | tail -40` and read the
**pipeline's** status, which is `tail`'s zero — so a build that *had* failed on the
assertion was reported as one that succeeded. That is
[`build-and-toolchain.md`](build-and-toolchain.md)'s `producer | grep -q` entry
arriving through the other end of the same pipe, written by someone who had read
that entry the same evening.

Once the assertion **was not in the file at all**: a path-scoped `git checkout --`,
undoing an unrelated botched edit, had discarded it along with the mistake it was
aimed at. The canary correctly reported that a guard which does not exist does not
fire.

*Absent*, *present but toothless* and *the run could not tell* are three states.
A canary that answers in two collapses them, and the sentence it produces blames
the **subject** — which is the same shape as a fixture announcing a wrong object
was linked when none was. What separated them here was neither care nor rereading:
it was **asserting the object count**. Forty-eight units rebuilt, so "compiled
nothing" was excluded and every surviving explanation was about the code.

So a canary: asserts the poisoned edit actually **compiled** something; takes the
status from the **process**, never from a pipe; and confirms the failure is the
**intended** one by matching its text rather than by a non-zero exit — a build that
fails for another reason proves nothing about the guard. Where it cannot establish
those, it reports INCONCLUSIVE and names the reading it is missing.

## `--repeat until-fail` reports the last iteration, so a flake reads as a pass

<!-- agent-tripwire: `ctest --repeat until-fail:N` reports the LAST iteration, so a 1% flake reads as -->

`ctest --repeat until-fail:N` reports the **last** iteration's result, so a test that
fails a small fraction of the time is reported `100% tests passed` whenever the final
run happens to pass.

Measured: a ~1% flake survived **six consecutive full-suite runs** qualified that way,
every one printing `100% tests passed`. A loop that counted every outcome found it on
the first try — `ran=200 pass=198 fail=2` (#735).

It is the `| tail` trap with a loop counter instead of a pipe: **the wrong reading and
the right one agree on every input except a flake**, which is precisely what you were
using it to look for. And it is self-concealing in the worst direction — a tool used to
*hunt* flakes that reports the last iteration reports success in proportion to how RARE
the defect is, so the rarer it is the more confident the false clean.

Use `scripts/flake-rate.sh`, which keeps a tally. Two things it deliberately keeps:

- **The early stop.** `--until-fail` still halts at the first failure, because once you
  have a reproduction the remaining runs teach you nothing. It says so on the way out:
  a run that stopped early is not a rate, and must not be read as one.
- **The N, on every line.** "Did not reproduce in 120 runs" does not disprove a 1% rate,
  and a tool that printed only a verdict would invite exactly that inference. Even the
  clean line states how many runs it is about.

## Assert what DISTINGUISHES, not what both sides produce

<!-- agent-tripwire: Assert what DISTINGUISHES, not what both sides produce -->

In one evening four lanes found **five** tests that could not fail for the reason
they existed ([#355](https://github.com/LASTRADA-Software/fastcached/issues/355)).
Not the same mistake in the same place — the same mistake in five shapes, and every
one of them green.

Two, which are enough to see the shape:

- **[#286](https://github.com/LASTRADA-Software/fastcached/issues/286)'s acceptance
  did `REQUIRE(held)` on a bind** (implemented by pull request #348).
  `BlockingListener::Bind` returns a **non-null pointer in an errored state**, so a
  failed bind passes it. Both sections — a named port that must refuse, a defaulted
  one that must warn and continue — would then have passed on a `ParseTcpPort`
  refusal rather than on the port conflict they existed to prove.
- **#288's pinned raft test asserted that a refusal happened and that the message
  names `--listen-raft`.** *Both* the old cross-flag rule and the new grammar rule
  name that flag, so it pinned the flag rather than which rule answered — and a
  relocation could land, or be reversed, in silence.

The other three: a reproduction whose fixture **supplied its own refusal** and so
never drove the production validator; an acceptance that passes under a digest taken
at the **wrong layer**, so it would have blessed a fix that catches nothing; and a
progress check using **log growth**, where the include-tree walk logs nothing while
it runs and a slow walk is character-for-character identical to a wedge.

**The shared shape: each asserts something both the healthy and the broken state
produce.** The test is not weak — it is measuring a quantity that does not vary with
the defect. And because it passes in both states nothing ever draws attention to it,
so it reads as coverage forever. A refusal test asserts *which* refusal; a
relocation test asserts the message only the new site emits.

**Prove the test can fail.** Neuter the fix, run it, and check that the failures are
the ones you expect *and only those*. Two of the five were caught exactly that way.
The clearest demonstration of the technique is elsewhere — pull request #353, which is
**not** one of the five — where neutering made the two positive cases fail while three
negative ones correctly still passed: **the asymmetry is the evidence**, since an
all-red run would equally be a harness that had stopped working. A green test nobody
has watched fail is an untested test — the sentence `compile-cache.md` applies to a
guard, applied here to the thing the guard is made of.

**A neuter that turns a red into a HANG proves nothing**, so a case whose broken rule would
make the code under test LOOP must be built to end red. Two shapes, both measured in one
fix round on lane 2a (T19/T20): a case that let a reforming body reform at EVERY body grew
the test process past 69 GB under its neuter, and a lock probe that destroyed a
`std::async` future inside the call it was watching deadlocked under its own -- a
`std::async` future WAITS in its destructor. So a fixture asks for a repeat only once (a
reforming body reforms once, then the case asserts), and never lets such a future go out of
scope inside the call it observes. This is the *A failing `REQUIRE` above an explicit
`Stop()` turns a RED into a HANG* entry's sibling on the neuter side.

**Three of the five were acceptance criteria**, written by the person who understood
the defect best, at the moment they understood it best. That is not carelessness.
*What would prove this fixed* and *what would fail if it were not* are different
questions, and only the second one tests anything — so an acceptance criterion is a
hypothesis, and it is worth asking the second question separately before writing the
test that satisfies it.

An acceptance clause has a second failure mode that is not about the hypothesis at all:
it may name an operation the tree cannot perform, in which case no tree can show it red
and the ticket can be closed by nobody. That, and the wider rule it belongs to — **a
ticket is a claim about a tree and it decays, so a premise is CHECKED before it is built
on, never read** — live in `AGENT.md`'s *Issues and pull requests* section and are
deliberately not restated here, because two copies of a rule are two things to be wrong.

Three entries in this file are instances of it: a bounded wait that must say which
KIND of failure it was, a fixture that states which PATH it exercised, and `SUCCEED`
standing in for a skip. **A harness earns its place by asserting something that can be
shown red** above is a fourth, and it already cites this ticket — it is where the rule
was applied before it was stated, including the asymmetry (four assertions failed while
the straight case correctly stayed green). Each was found on its own; none stated the
general form, which is why the fifth still had to be found by whoever happened to be
careful that day.

`Unwrap(x)` after `REQUIRE(x.has_value())` is deliberately **not** in that list. It
looks like one and is not: it exists because clang-tidy cannot see the guard through
`REQUIRE`, so a bare `*x` fails the build. That is a build-guard rule, and folding it
in would put one rule under two headings — which is what the census entry below means
by an instance filed where nobody looking for it will read it.

### THREE more in one batch, and how each was actually found

[#405](https://github.com/LASTRADA-Software/fastcached/issues/405) produced three, all
in fixtures its own author had just written and believed, all green. The number is the
point: **one instance reads as bad luck, three read as the default outcome** — so the
question to ask of a new fixture is not *is this careful* but *what would make it fail*.

The pattern travels with the figure, because the three are not one mistake repeated:

<!-- table-total: none -->
| the fixture | why it could not fail | how it was found |
|---|---|---|
| re-asked `Oracle()` after each reload | production binds it ONCE, so the case watched an object no consumer holds | asking how production ACQUIRES the collaborator — the subsection below |
| used a `--raft-peer` candidate to pin a call ORDERING | `StartupPolicyRejection` refuses that candidate before either check runs, so it never reached the code under test | **neutering** — it passed with the fix and with the fix reverted |
| asserted `contains("--cluster-key-file")` to pin WHICH rule refused | *both* rules say that, so it asserted what both sides produce — this rule's own failure, inside the ticket applying it | **building the neighbouring case**, which made the shared string visible |

**None was found by reviewing the assertion**, which is the common factor and the only
actionable part: every one of the three has a correct-looking assertion, and two of
them are correct assertions about the wrong object or an unreached path. Reading harder
does not find these. What finds them is neutering the fix, or building the case next to
it, or asking how the production code acquires what the fixture acquires.

### A fixture that RE-ACQUIRES what production binds ONCE is testing a different object

The sixth shape, found in
[#405](https://github.com/LASTRADA-Software/fastcached/issues/405) and not by review:
its first `--fleet-open` case called `membership.Oracle()` fresh after each reload and
passed. Every production surface — `SchedulerTier::Start`, `CompileResponder` — takes an
`IMembershipOracle const&` at construction and holds it for its lifetime. Against an
`Oracle()` that still returned one of two owned objects chosen by a flag read once, the
fixture saw each new answer and the running node saw none: **the defect was live and the
case was green.**

That is not a weak assertion, which is what makes it worth its own entry. The assertion
was exactly right; the *acquisition* was wrong, so the case measured an object no
consumer ever holds. Bind the collaborator the way the call sites bind it, before the
mutation, and read back through that binding afterwards.

- **The general form covers any seam a consumer caches** — a reference, an iterator, a
  `shared_ptr` snapshot, a resolved endpoint, a `std::function` copied into a member. Ask
  what the production code does ONCE and make the fixture do it once too.
- **The tell is that the fixture is more convenient than the production code.** Re-asking
  a getter per assertion is what anybody writes first, and it is the version nobody
  re-reads, because it looks like the careful spelling rather than the lucky one.
- It is the mirror of *a fake more PERMISSIVE than the thing it stands for*: here the
  fake is the CALL PATTERN rather than the object, so no amount of reading the fake
  finds it. Same family as `check-catch-skip-return-code`'s selftest exercising the
  fallback while CI exercised git — **the mode under test was not the mode in use.**
- Neutering is what catches it, and only if the neuter is the one the fixture's shape
  hides: reverting `Oracle()` to the two-object form reddens the corrected case and
  nothing else, and reddened the original not at all.
- **A harness drives the production CHANNEL and SURFACE over a fake wire, never its own
  reimplementation of either** (lane 2a, T21): a copy cannot state a field the real one gets
  wrong. The formation harness's own `MachineChannel`/`MachineProbe` stayed green under the
  join defect 5ea99fa9f fixed; over production's `DialledEnrollChannel` the same neuter turns
  seven cases red (measured on that lane). Its sibling: **seed the harness where production
  seeds**. A body handed the WHOLE applied state up front made the adoption that follows the
  state deletable with nothing red, until a second learner joined a body that was not rebuilt
  -- the update path had never run.

## A query that FAILED is not an observation about the subject

<!-- agent-tripwire: Where the answer cannot be determined, report that as its own outcome rather than the nearest neighbour -->

A required-context checker was written for the shape
[#542](https://github.com/LASTRADA-Software/fastcached/issues/542) names: read the
required names, report each one's state, and keep ABSENT distinct from pending so a
context that was never created cannot hide. Its first version captured
`gh pr checks ... 2>/dev/null`. `gh` was not on `PATH` in that environment, so
`command not found` went to the null device, the capture was empty, and the checker
printed **ABSENT for all eleven required contexts** — while the data sat there,
retrievable, one working invocation away
([#557](https://github.com/LASTRADA-Software/fastcached/issues/557)).

*Eleven is what the instrument printed and what the required set held that day; it has
grown since (#408, #629). The live figure is `RequiredContexts` in
`scripts/check-merge-queue-contexts.sh`, which is the only place it is written down —
this paragraph is a record, not a count.*

Keep the output, because the rule is easy to nod at and the failure is what makes it
stick: **eleven absent required contexts is catastrophic, plausible and
actionable-looking.** Nothing in it resembles a tool error. A reader would have gone
hunting for a workflow that had stopped dispatching. The instrument reproduced, one
level up, the exact defect it was built to prevent.

**A tool invocation's own failure is a state of the instrument, never a reading of
the subject.** An instrument that cannot express *I could not tell* will express it
as whatever its empty case means — and the empty case is usually the alarming one,
because instruments are written to make absence visible.

### Anything neither 0 nor 1 is the instrument failing, and a throwaway probe needs that arm too

Second instance, and it is the cheaper shape: a probe written in four lines to
settle one question. It asked whether `check-rulebook-open-work.sh` accepts a
sub-bullet under an `## Open work` entry at two, four and eight spaces, and passed
the tree as a positional argument. That script takes `--rules-dir`. It printed
`unknown argument` and exited **2** — and the probe's verdict helper was
`[ "$rc" -eq 0 ] && echo CLEAN || echo REFUSED`, which maps every non-zero to a
finding.

So **four confident verdicts came out of an instrument that had never run**, and
three of them were wrong in the direction that contradicted the claim under test.
That direction is the hazard: refuting somebody feels like diligence, so a refutation
is the reading least likely to be re-checked. The rule the probe broke is one this
repository already states about `cmake -P` checks and about `gh` — **anything neither
0 nor 1 is the instrument failing** — and the reason it broke it is that nobody
applies a rule about instruments to four lines they are about to delete.

**What caught it was a control with no plausible failure, not care.** One arm of the
probe was a continuation line with no bullet marker, which the grammar plainly allows;
when *that* came back REFUSED alongside the others, the uniformity was the tell. A
result that is implausible for an arm you understand is the only signal available when
the instrument itself is what is broken — the subject cannot supply one, because the
instrument is not reading the subject at all.

So a probe gets three outcomes rather than two, and a positive control whose answer
you already know. Re-run with `--rules-dir` and a control that must come back clean,
the real answer is: **two spaces refused** (CommonMark reads 0–3 as top level, so it
is a sibling and `unparsed-entry` fires), four and eight clean, continuation clean —
which is the opposite of what the broken probe reported for two of the three.

So a checker that can report *absent* must be able to report *I could not tell*, and
must refuse to say anything about the subject while that state is set. Zero rows is
not a verdict; it is the absence of one, and the **shape** of a response is checked
before any conclusion is drawn from it.

**The aggravating pattern to grep for is `2>/dev/null` on a command whose absence is
plausible** — a tool missing from `PATH`, which this repository hits routinely. That
redirection converts a missing binary into a confident finding.

This is the third shape of one family, and the other two are recorded in
[`build-and-toolchain.md`](build-and-toolchain.md): `producer | grep -q` under
`pipefail` reports absence *because* the symbol is present, and `| tail` returns the
pipe's status so a failed build reads as a passing one. There the query ran and its
status was misread; here **the query never ran at all**.

**And a failed query does not only MISS a finding — it can invent one, which is the
worse direction and the one that gets acted on.** Measured on `gh issue view`, which a
rulebook-staleness checker would resolve entries with:

```
number resolves to nothing   exit=1  stdout=0B   stderr: Could not resolve to an issue ...
repository does not exist    exit=1  stdout=0B   stderr: Could not resolve to a Repository ...
not a number at all          exit=1  stdout=0B   stderr: invalid issue format: "not-a-number"
a real issue (control)       exit=0  stdout=29B  stderr: —
```

Three faults, one exit status, one empty stdout — and **two of the three are faults in
the checker's own invocation**: a wrong `--repo`, a network failure, an expired
credential. A checker reading `exit != 0` as *this entry names a dead issue* therefore
reports a stale rulebook entry when its own argument was wrong, and somebody then
**edits a correct entry to satisfy a broken check**. Missing a finding costs a defect;
inventing one costs a correct file.

So such a checker has **four** outcomes, not two — pass, stale, bad reference, and
*could not run* — which is *skipped, absent, unstarted and failed* arriving inside the
tool written to enforce this rulebook. Prefer a route whose transport separates them:
`gh api repos/{owner}/{repo}/issues/N` answers with an HTTP status and hands back the
`pull_request` key in the same call, which also settles *is this number an issue or a
pull request* without a second request. And the suite needs a case for it: **a
deliberately broken invocation that must report `could not run` and must NOT report a
stale entry.** Nothing else proves the checker does not blame its subject for its own
faults.

The same rule reaches a measurement, where its direction is worth stating because it
is not symmetric. A counted loop that reports *N failures out of N* may be measuring
a subject that was never invoked — a stale binary, a mistyped filter, a case that no
longer exists — and Catch2 exits non-zero for `No tests ran` exactly as it does for a
failure. **A result containing at least one success is self-controlled against that**,
since a subject that was never reached cannot produce a pass. An all-failing result
therefore proves nothing until a positive control says the subject exists — and an
all-*passing* one needs the same control for the mirror reason, because a filter that
silently matched nothing also passes everything.

## A path-scoped revert is scoped to the FILE, not to the mistake

<!-- agent-tripwire: untriaged: #1567 no AGENT.md bullet carries this rule; the only revert bullet is about ancestry after `git revert` -->

`git checkout -- <path>` took two completed review fixes with it — a `static_assert`
and a repaired documentation block — because they were uncommitted in the same file
as the botched scripted rewrite it was aimed at. Nothing reported the loss: the
revert succeeded, `git status` said *clean*, and *clean* was true.

It surfaced only because a canary written for an unrelated purpose then failed. Had
that canary passed for any other reason, the branch would have shipped without the
guard.

**Commit before running an experiment that edits the tree.** The red-proof scripts
here already refuse to start against a dirty tree, and this is the same rule
pointing at the recovery rather than at the setup. Where a revert cannot wait,
restore the specific hunks rather than the path. And afterwards check what came
**back**, not what went away: *validate the reverted tree* below is the same lesson,
and it did not fire here because the loss was in the file being reverted rather than
in the build describing it.

## Attribution by adjacency is a guess, and a guard built on one is a lottery

<!-- agent-tripwire: Attribute by asking the process, never by adjacency in interleaved output -->

The same fixture reported `115 hit(s), 106 miss(es)` on a build of identical
source and passed, on the strength of "something hit". Either reading of that
number was available and nothing could choose between them: over half a build
missing is alarming, and it is also exactly what a correct cache does when the
third-party sources live *inside* the build directory and the two build
directories differ. Attributed, all 106 were third-party and all 74 of this
project's own units hit. The total had buried the only column that meant
anything.

The attribution is the part worth remembering. Reading the `[n/m] Building CXX
object ...` line above each outcome is the obvious move and is unsound: ninja
interleaves the output of concurrent edges, and two runs of the same build split
one unit differently — 74/41 against 75/40. A guard resting on that fails a build
for a scheduling accident, and would have been believed the first time it did.

**Ask the process, do not infer from its neighbours.** A one-line wrapper that
writes the unit to the same stream, from the same process, inside the same edge,
and then `exec`s the real program cannot be separated from the output it
labels — and an outcome that arrives with no label is counted as *neither* and
refused by name, rather than folded into whichever bucket was adjacent.

## A registration names a binary that may not have been built

<!-- agent-tripwire: A `$<TARGET_FILE:x>` naming a target that was NOT built is a hard error at **generate** time -->

**`$<TARGET_FILE:x>` naming a target that was not built is not a test that gets
skipped. It is a hard error at GENERATE time**, so the whole configure fails:

```
CMake Error at src/tests/CMakeLists.txt:943 (add_test):
  Error evaluating generator expression: $<TARGET_FILE:pace-kv>
  No target "pace-kv"
```

That is #390. A block registering a test that starts a binary is guarded on
**`TARGET x`** as well as on whatever feature makes the test interesting; the two
conditions are independent, because a feature can be enabled while the binary it
needs is not built. `tls-smoke` asked only `PACE_ENABLE_TLS` and the sccache
smokes only `SCCACHE`, so `-DPACE_BUILD_DAEMON=OFF` could not be configured
at all.

**It was conditional on the developer's machine rather than on the tree**, which is
why it survived. The sccache rows are themselves gated on finding sccache, so a
checkout without sccache installed never reaches the broken reference and the flag
appears to work. The error then names CMake rather than the option, on some
machines and not others — so the natural conclusion is "my checkout is broken".

And the rule was already written down. `src/apps/pace-cc/CMakeLists.txt`
spells it out in four lines directly above the block that obeys it, while two
blocks one directory away did not. A rule one file explains and another ignores is
a rule that needs a check, not a better comment: `ctest -R target-file-guards`
(`scripts/check-target-file-guards.cmake`), in the default set. It reads which
targets are optional from `src/apps/CMakeLists.txt`'s app table rather than
restating them, so a new app comes under the guard by existing.

**The app table was not always the only place a target became optional**
([#1369](https://github.com/LASTRADA-Software/fastcached/issues/1369)). While the root added
`vendor/` only under `PACE_BUILD_TUI`, every target `vendor/CMakeLists.txt` declared was
as optional as an app, and an unguarded `$<TARGET_FILE:fastcache-tui-linkprobe>` planted in
`src/tests/CMakeLists.txt` passed: the check's source set had stopped describing the tree, and
a list is exact about the files it knows and silent about the ones it does not. #1369 added a
SECOND reader for directories the root gates that way, as a parallel derivation with its own
completeness argument -- never merged into the app table's counts, where a target found in
`vendor/` could have masked a row lost from the table. #1596 moved that code to core-cpp, the
gated directory went, and the reader and its floor went with it (its floor refused a tree that
gates no such directory, and said to remove it then). A directory gated that way again brings
it back from git history, not a hand-written variant.

The frame walker it shared with the reference scan stays, and so do the cases that pin it: a
review of the first version found ways a line-by-line `^if\((.*)\)$` goes blind -- `if(X)  #
why` pushed nothing and its `endif()` popped the frame enclosing it, a condition spelled across
lines was not a frame, `IF(` went unread -- and a walk that loses track now reports the line
where it did.

Three ways it refuses to pass vacuously, because each is how such a check reports
success for work it did not do: an app table it could not read, a scan that found
no reference at all, and a file whose `if` nesting it could not follow to the end.
All three are named failures.

## A fixture whose client is always local cannot test who is admitted

<!-- agent-tripwire: A fixture whose client is always LOCAL cannot test who is admitted -->

`scripts/dist-compile-e2e.sh` had twelve cases, three real processes each, and every
leg of every one of them was loopback. Admission asked loopback **before** it consulted
anything else — deliberately, because that is what makes an unconfigured node useful on
its own machine — and it still does: the fold's loopback participant answers first, so
every route behind it was reached by nothing. At #235 the route behind it was a host list:

```cpp
if (IsLoopbackHost(peerAddress))
    return Membership::Member;                            // every case in the suite
...
return any_of(_hosts, SameHost) ? Member : Outsider;      // nothing at all
```

Today it is a proven key and a verified ticket, and the shape of the trap is unchanged.

That is how [#235](https://github.com/LASTRADA-Software/fastcached/issues/235)
survived. A worker that admitted **only** its own machine — and therefore refused
every dispatched compile the documented setup sent it — passed the whole distributed
suite, because the suite only ever asked it to admit its own machine. The fixture
proved dispatch works and could not have noticed that dispatch works for nobody else.

**The cheap fix does not work, and it looks exactly like it does.** A second loopback
address is the obvious move and was the ticket's own first suggestion:
`IsLoopbackHost` answers for the whole of `127.0.0.0/8` rather than `127.0.0.1`, and says so in
its own comment, so a client on `127.0.0.2` takes the same early return. The fixture would
change, the addresses in the log would differ, and the test would go on proving what
it proved before — which is the shape of the defect, applied to its own repair.

**What reaches the branch is a peer that is not this machine**, and it needs neither a
second machine nor a second address: `src/tests/RelabelledPeerListener.hpp` hands the
endpoint real loopback sockets whose `peerAddress()` reports a fixed non-loopback host.
Every read, write, deadline and half-close is the kernel's, so the endpoint's own framing
and AUTH state machine run unchanged, and only the question admission starts from gets a
different answer. The pair lives in `FrameEndpoint_test.cpp` (*(#235, rebuilt)*); the
fleet-wide cases in `FleetTickets_test.cpp` reach the same branch through
`FleetHarness::SetCallerHost`, set FIRST in every case.

It replaced a mode of `dist-compile-e2e.sh`, since deleted, that bound a worker
on the host's own LAN address and was registered as a ctest test of its own because a
host without such an address had to report SKIPPED. The relabelled socket has no such
prerequisite, so nothing is skipped and the mode is gone rather than kept beside it.

Its three legs have three homes now, and two of them moved in meaning as well as place.

- **Leg 1's route is a ticket, not `--fleet-open`.** The mode opened its admitting worker
  with the flag because a caller presenting no key had no other way in; since #178 no
  address admits anybody, and the route a launcher on another machine takes is the ticket
  its own node minted, so that is what the rebuilt admitted leg presents.
- **Leg 2's launcher half lives in the Dispatch tests.** The node refusing `not-a-member`
  is the rebuilt pair's second leg; that the launcher then compiles LOCALLY is the
  launcher's decision, not the node's: a worker's refusal is `DispatchStatus::Declined`
  (`Dispatch_test.cpp`, *A worker refusing the job is a decline, not a compile*), and a
  declined dispatch is a local compile.
- **Leg 3 is the SERVED direction of #290**, and has a case of its own: *(#235, rebuilt)
  the same peer on the same listener is served the cache as this machine*. The node's
  locality oracle names the relabelled host, so the caller IS this machine: its FETCH
  returns the stored bytes with `NodeCacheRequestsRefusedNotLocal` flat, and its COMPILE
  on the same connection is refused by membership. The refusing direction needs a peer
  that is genuinely somebody else and stays `NodeFrameSurface_test`'s *(#290) one peer on
  one listener*.

Three things about the shape, and they generalise.

- **Assert both directions; only the pair proves anything.** A ticket for an admitted
  machine → the COMPILE is served. No ticket, same address → refused `not-a-member`,
  nothing compiled, and `WorkerJobsRefusedNotAMember` **moves** — the assertion #235
  needed and did not have. The admitted leg alone passes over loopback too, since
  loopback is admitted before any other route is asked, so it cannot show the peer ever
  reached the other routes; the refusing leg is what shows it, because a loopback peer
  would have been admitted there as well.
- **Keep a control on the SAME fixture that is not relabelled.** The refusing leg sent
  through a listener that is not relabelled is served as this machine's. Neutering the
  relabelling (`peerAddress()` forwarding the real peer) turns the refusal legs red and
  leaves the control green — the asymmetry that says the relabelling is live rather than
  assumed.
- **A refusal is asserted by the counter of the rule that refused, not by the code.**
  Several rules answer `not-a-member`; a revoked machine's verb, for one, is refused with
  that code and counted on `NodeRequestsRefusedKeyRevoked`, never on the door's stranger
  row, and the revoked-door case asserts both counters for that reason.

## A fixture must state which PATH it exercised

<!-- agent-tripwire: A fixture states which PATH it exercised. A synthetic tree is not a git repository -->

`check-catch-skip-return-code` derives the files it scans from `git ls-files`, and
falls back to a directory walk where there is no git index. Its selftest had six cases
and they all passed. CI then failed on a vendored registration the check should never
have seen — and there was no contradiction between those two facts:

> a synthetic tree is not a git repository, so all six cases exercised the **fallback**
> path while CI exercised the **git** path — the mode under test was not the mode in
> use.

**A guard that passes because it is testing something else.** Nothing about the suite
could have revealed it: every case was correct, every assertion was real, and none of
them ran the code that runs in production.

- **Any code with a primary path and a fallback needs its fixtures to say which one
  they exercised**, or the cheap-to-construct path silently becomes the only one
  tested. A synthetic tree with no git index is the easy fixture, so it is the one that
  gets written — and it is the one CI never runs.
- **The mode is therefore part of the output**, not an internal detail: the check
  prints `via git ls-files` or `via directory walk (no git index)`, and the fixtures
  assert it. Without that, a silent fall back to the walk passes for the wrong reason,
  which is the same failure one level down.
- **Assert it on BOTH sides.** Covering only the path that broke swaps which half is
  unexercised rather than fixing it. One case requires the walk and one requires git,
  so neither can quietly become the only one tested — and each is shown red by making
  the check misreport its mode.
- **The fallback is exercised where it is actually used, too.** A real `git archive`
  export has no `.git`, takes the walk, says so, and reaches the same verdict — which
  is what makes the fallback sound there and unsound in a working checkout, where a
  dependency cache lives inside the source tree.
- **A fixture that MAKES its tree a repository writes it through `scratch_git`, never bare
  `git`** (`scripts/lib/git-scrub.sh`; `pace_scratch_git` in `CheckCommon.cmake`). Every
  `git init`, `git add` and commit obeys `GIT_DIR`, `GIT_WORK_TREE` and the rest of
  `scripts/lib/git-scrub-variables.txt` when they are in the environment, and then writes the
  repository they NAME instead of the scratch tree: an exported `GIT_DIR` around a `ctest -L
  hygiene` run made every scratch `git init` write `core.worktree` into the configuration all
  of this repository's worktrees share (2026-10-02), which broke git in every one of them. The
  scrub is folded into the command, per command and in a subshell, and `ctest -R scratch-git`
  in the default set refuses a scratch write spelled any other way. A scratch READ is left
  alone on purpose: under a hijacked `GIT_DIR` it answers about the wrong index and fails the
  case loudly. And never EXPORT `GIT_DIR` around a harness at all; scope it to one command.

## A SKIP that ctest scores as a failure

<!-- agent-tripwire: A Catch2 `SKIP(...)` exits **4**, and ctest must be told what that means -->

A Catch2 case that calls `SKIP(...)` exits **4**, and ctest must be told what that
means or it scores the skip as a *failure*. None of the five `catch_discover_tests`
registrations told it, so the binary printed `1 skipped` and ctest printed `***Failed`
**for the very same run** (#499).

**The repair is `SKIP_RETURN_CODE 4`, and on Catch2 3.6.0 it opened #1128.** The exit
code was then the failed-assertion count (clamped at 255), so a case failing exactly
four assertions exited 4 and was scored *skipped* — a genuinely failing test reported
inside `100% tests passed`, in all five binaries. **The repair for one state collapse was
the site of the next, and it landed inside the mechanism chosen to prevent state
collapse.** No other status was free to move the signal to: every value in 1..255 was
reachable as a count, and moving 4 to 77 only relocated the collision to a case failing
77 assertions — rarer, therefore quieter, the wrong direction for a false GREEN.

**Catch2 3.7.1 closed it from the other side, and the property is now exact.** Catch2
standardised its exit codes, and since 3.9.0 they are Session API constants in
`catch2/catch_session.hpp`: a run whose every case skipped exits **4**
(`AllTestsSkippedExitCode`), ANY assertion failure exits **42** (`TestFailureExitCode`)
whatever the count, a run that ran nothing exits 2. So 4 means skipped-and-nothing-failed,
and a case that skips one `SECTION` and fails four assertions in another exits 42 and is
scored failed. Measured on 3.16.1 through the canary: every skip-only shape exits 4,
and one failure, four, three hundred and skip-beside-four-failures all exit 42.

- **The EXACT pin is part of the rule.** The contract is a property of the Catch2
  BUILD, and `CPMAddPackage`'s `find_package` takes any version-COMPATIBLE 3.x a machine
  has installed: it took Fedora's 3.13 over the 3.6.0 the tree named, and would as
  readily take an older 3.x where the collision returns, with no line of the tree
  changed. So the top-level CMakeLists names one release with `FIND_PACKAGE_ARGUMENTS
  "EXACT"`, and a bump is a deliberate edit.
- **`catch-skip-exit-contract` is the reader.** It runs every shape of
  `src/tests/CatchSkipCanary.cpp` in its own process against the Catch2 actually linked
  and asserts the contract: skip-only shapes exit 4, every failing shape exits ONE value
  that is neither 0 nor 4, a passing control exits 0. The canary `static_assert`s the 4
  against `AllTestsSkippedExitCode` as well. A red there is a discovery about the linked
  Catch2, never a reason to edit the check; `catch-skip-return-code`'s green says only
  that every registration carries the property.

What the 3.6.0 investigation measured about the other channels is still true, and is
why the mechanism is the exit code and never a pattern:

- **The output is shared with the SUBJECT.** `SKIP_REGULAR_EXPRESSION` is
  a substring search over the case's ENTIRE output — names, `INFO` messages,
  stringified expressions — none of which this project controls. A case that only
  **fails**, carrying the literal summary text in a message, is scored SKIPPED.
  Measured. Closing that needs a line-start anchor and both spellings are unavailable:
  `^` is `cmd.exe`'s escape character, and the value is passed on a COMMAND LINE by
  `catch_discover_tests` which cmd parses on Windows (a literal `|` there killed every
  Windows leg at the DISCOVERY step); and a literal newline **arrives EMPTY** through
  cmd — measured, the receiving script runs, exits **0**, argument `[]`. An empty
  `SKIP_REGULAR_EXPRESSION` matches every line, so **the remedy for the hole degrades
  into every failing test scoring as skipped, silently, at exit zero.** That is the
  most dangerous shape found in this whole investigation: worse than the defect it was
  repairing, and invisible to every check and every Linux gate.
- **Composing them does not exist.** `FAIL_REGULAR_EXPRESSION` does NOT outrank
  `SKIP_RETURN_CODE` — measured on 3.6.0; with both set a four-failure case was still
  `***Skipped`. That was the one repair needing no new mechanism and no new process.
- **Adding shapes cannot make a pattern safe**, and this is the argument that decides
  it rather than the constraint table. A decoy carrying the pattern's TAIL refutes a
  tail-only pattern and certifies a same-line pattern as safe; a decoy carrying a WHOLE
  summary line then refutes that one. **Every shape you add is one you thought of, and
  the channel is shared with an author who thinks of others.**
- **Two facts about the tool, kept because everyone assumes otherwise from other regex
  flavours.** CMake's `.` **matches a newline**, so `.*` reaches text on a later line;
  and CMake has **no POSIX character classes at all** — `[[:digit:]]` matches nothing,
  parsing as a literal character set.

- **Were a pattern ever needed: the SUMMARY line, never the `SKIPPED:` marker.**
  Measured over nine case shapes: a case that skips one `SECTION` and fails
  another **prints the marker and fails**, so keying on the marker scores it skipped —
  which is *wider* than #1128, hiding any number of failures in a case that also skips
  rather than exactly four. Catch2 already gets the verdict right there, printing
  `test cases: 1 | 1 failed` above the marker; nobody was reading the line where it
  says so. The marker says a skip happened SOMEWHERE; the summary says what the case
  WAS.
- **A `catch_discover_tests` property value is a WIRE FORMAT with three parsers in it**,
  and the third is `cmd.exe`. The value is not kept inside CMake: it is written into a
  generated file and passed on a COMMAND LINE, so on Windows it is parsed by CMake, then
  ninja, then cmd. A literal `|` is a PIPE there whatever it is quoted with, because the
  quoting is stripped by the layers in between. Measured (#1146): with `\|` in the
  pattern, **every Windows leg died at the DISCOVERY step, before anything linked** —
  `'1' is not recognized as an internal or external command`, cmd having tried to run
  `1 skipped` as a program, plus a dangling `\` argument and a hunt for a source
  directory called `cases:`. **Escaping is not the remedy**: `\|` is a POSIX escape cmd
  does not honour, and no spelling survives three parsers — this file's own
  quoting-collapsed-through-three-parsers rule, arriving in a property value. The
  character must simply not be there; a wildcard matches it and the surrounding literal
  text carries the discrimination. `[|]` is no better (still a literal pipe on the
  command line) and `[^ ]` is worse (`^` is cmd's escape character).
  **No gate on a Linux host can reproduce this** — there is no cmd.exe in that path —
  so a green local gate is not weak evidence about it, it is none, which is this
  project's standing rule for a change whose subject is the build environment. Anything
  that ever carries a pattern on that command line must be checked against
  `& | < > ^ ( ) % " !` by a TEXT check, since CI is otherwise the first reader.
- **Not `WILL_FAIL`, measured.** A canary that must be seen to fail is the obvious
  reader for "does a four-failure case still fail", and it does not work: under 3.6.0's
  exit codes that case is scored **Skipped**, and ctest does not fail a skipped test
  carrying `WILL_FAIL` — the run reports `100% tests passed`. **The canary would be
  green under exactly the defect it exists to catch.** `catch-skip-exit-contract` runs
  the binary and reads what each shape EXITS instead, which is also the only thing in
  the tree that can see the linked Catch2 change: a text scan over CMakeLists cannot.

- **Measured, not inferred** — and this is the #499 measurement, kept as the record of
  how the false RED was established rather than as the current mechanism. One forced
  skip: `test cases: 1 | 1 skipped` with `BINARY EXIT: 4`, ctest `***Failed`; after
  `PROPERTIES SKIP_RETURN_CODE 4`, `***Skipped` and `100% tests passed`. **That last
  reading is exactly what #1128 turned out to mean for a case failing four
  assertions** on 3.6.0, which is why the property is only as sound as the exit
  contract under it, and why that contract has a reader and a pinned Catch2.
- **It is a false RED, which is the insidious direction.** Essentially every `SKIP`
  site in this tree is environment-conditional — a loopback bind, an IPv6 stack, a
  symlink, root, an MSVC-family driver, `AvailableCodecs().size() < 2` — so they fire
  on a constrained runner or a build configured without codecs and report a regression
  that is not there. **This bullet used to say "all seven … three on codecs, four on
  loopback"** — the pattern is `git grep -n 'SKIP("' -- 'src/**/*.cpp'`, excluding
  `CatchSkipCanary.cpp`, and it answered **39 sites across 17 files at #1128's merge
  base**, three of them still the codec ones and twenty-two loopback. **The figure moved
  WHILE #1128 was being written**: it was 38/16 when measured and 39/17 after a rebase
  picked up #870, which had added an honest root skip in the meantime. That is why a
  bare number cannot live here — not that this one was carelessly kept, but that any
  number describing this set is stale the next time somebody writes a `SKIP`, and the
  ARGUMENT has never rested on it. Quote the pattern, or quote the figure with the
  commit it was taken at. One site is not environment-conditional
  at all — `ServiceControl_test.cpp` skips because the property is exercised by the
  platform end-to-end paths, which is the legitimate *covered elsewhere* skip this file
  distinguishes from a `SUCCEED`. Nobody
  had hit it because those conditions had not arisen on CI, which is **luck rather
  than coverage**: the codec skips depend on how the build is configured and the
  loopback ones on what the runner allows, and neither is a property of the code.
- **It makes `SKIP` unusable as a tool.** Whoever adds one, watches the suite go red
  and concludes the skip was wrong will delete the skip rather than suspect the
  registration — the wrong lesson, learned permanently, by someone who did nothing
  wrong.
- **The value is part of the rule.** `77` is the GNU convention the eleven
  script-driven `add_test` registrations use, because a shell script picks its own
  exit code. A Catch2 binary does not: it exits **4**. `SKIP_RETURN_CODE 77` on a
  Catch2 registration is present, reads correctly in a diff, satisfies any
  "is the property there" scan, and still scores every skip as a failure.
- **A comment was never what was missing.** The mechanism was already written down in
  `src/tests/CMakeLists.txt` and applied eleven times, one directory away from five
  registrations that did not apply it. So the guard is a check —
  `ctest -R catch-skip-return-code`, reading the registrations from the tree rather
  than restating them — because **a sixth test binary would reopen this by omission
  exactly as the fifth did**.
- **`catch_discover_tests` writes its list at BUILD time.** A `POST_BUILD` step, so
  editing the CMakeLists and reconfiguring is not enough: measured, the old list
  survived a full successful `cmake --preset` and the case still reported `***Failed`;
  only a REBUILD turned it into `***Skipped`. **A stale result reads exactly like a
  current one**, so verify this property by hand only after rebuilding the target.
- **The guard is shown failing on every direction it claims**
  (`ctest -R catch-skip-selftest`): a bare registration, a wrong value, a
  registration split across lines that must NOT be reported, and a tree with no
  registrations at all, which must report a broken scan rather than a clean tree. Its
  own first version walked into `_deps/catch2-src` and reported vendored third-party
  code — `file(GLOB_RECURSE)` recurses from the base directory and treats only the
  last component as a pattern, so `src/*/CMakeLists.txt` does not mean one level down.

## A `SUCCEED` where the case could not RUN is a false GREEN

<!-- agent-tripwire: `SUCCEED` is right when a case RAN and had nothing to assert -->

The converse of the rule above, and the direction nobody investigates. `SUCCEED("...")`
records a **passing assertion**, so a case that bails out because its environment could
not be arranged reports a pass for a property nothing established (#685).

**`SUCCEED` is right when the case RAN and there was nothing to assert. It is wrong when
the case could not run.** That is the whole distinction, and `SKIP("reason")` is the
whole fix — it exits 4, and every `catch_discover_tests` registration carries
`SKIP_RETURN_CODE 4` so ctest scores it as skipped. Under the pinned Catch2 that
mechanism is exact; #1128, above, is the 3.6.0 exit code under which it was not.

- **It fires where coverage is already thinnest.** All twenty-one sites converted for
  #685 were environment-conditional: no loopback listener, no IPv6 stack, no symlink
  privilege on a Windows agent, running as root, a test port already bound. Those are
  precisely the runs on which a green is least justified and most believed — a
  constrained CI runner reports the same colour as a full one, and nothing distinguishes
  them.
- **The four states again.** Skipped, absent, unstarted and failed. A case that could not
  run is *skipped*, and rendering it as *passed* collapses two of them at exactly the
  layer that decides whether anybody looks.
- **A comment does not stop it, because it spread by IMITATION.**
  `DirectManifest_test.cpp` carried the idiom under a comment that was *correct* — it
  said the rule being demonstrated is unconditional, which is the reason the `SUCCEED`
  was wrong — and the next test written was copied from it, comment and all. The
  argument was there to be read and was not the thing being copied.
- **What a check can see, and what it cannot.** `ctest -R succeed-not-skip` fires on two
  signals: a `SUCCEED` whose next statement is a bare `return` — on the following line or
  on its own, since `if (!ready) { SUCCEED("x"); return; }` is the same defect written in
  one — and a message in skip vocabulary, "unavailable", "could not", "privilege",
  "exercised by", held as a table with one row per phrase. A silent bail-out with a
  message in neither vocabulary and no `return` is invisible to it, and so is a `SUCCEED`
  sitting between two block comments on one line, because CMake's regex engine is greedy
  and strips from the first `/*` to the last `*/`. Those limits are stated in the script
  rather than papered over: the check closes the door the defect came through, and this
  rule covers the rest.
- **A check that refuses its own documentation has no escape hatch.** This rule is
  written out in prose that quotes the idiom, and test files cite it in comments. The
  scan therefore strips `//` comments and tracks `/* ... */` blocks across lines — a
  leading-`//` test is not enough, because a block written without leading stars carries
  whole paragraphs and its body is exactly what a historic note looks like. A contributor
  tripped by that could make the build green only by rewording the comment.
- **A `SUCCEED` that NAMES a mechanism reads like an assertion about it, and is not one.**
  `BlockingSocket_test.cpp`'s `SO_NOSIGPIPE` arm said "SO_NOSIGPIPE arms the descriptor
  here, so a raw sender needs no extra flag" and observed nothing — while the checkable
  fact was one line away, `NoSignalSendFlags() == 0`, and is the fact the case exists for:
  `MSG_NOSIGNAL` may be *defined* by a macOS SDK while `CMAKE_OSX_DEPLOYMENT_TARGET` lets
  the binary run on an older kernel, and a flag the kernel does not know fails the send.
  Widening that arm is the exact regression, and it would have reported a pass. It was
  classified as legitimate twice — in the ticket and by the sweep — and only review caught
  it, by reading the code rather than the message. **The two signals a check can see do
  not reach this shape**: no bail-out `return`, no skip vocabulary. Which is why the rule
  is the thing that must be internalised and the check is only the door the defect came
  through.
- **"Covered by another test" is a reason to SKIP, never a reason to pass.**
  `ServiceControl_test.cpp` deliberately does not call `InstallService` on Windows and
  macOS — a unit test must not register a service on the host — and said so in a
  `SUCCEED`. The end-to-end scripts really do cover it; *this* case still observed
  nothing.
- **Inconclusive is refused, not passed.** A `SUCCEED` the check cannot read to a closing
  parenthesis on one line is reported as its own outcome. A site it could not read is not
  a site it cleared.
- **The guard is shown failing on every direction it claims**
  (`ctest -R succeed-not-skip-selftest`): thirteen synthetic trees, one verdict each, and
  each refusal asserted by the phrase naming *that* refusal — so a mutation that reddens
  everything fails the selftest instead of looking thorough. Measured against six mutants:
  removing each of the bail-out, one-line, block-comment and deleted-file guards reddens
  exactly its own case, emptying the vocabulary reddens the message-driven ones, and
  refusing everything reddens all seven cases that assert silence. Seven of the thirteen
  exist only to assert the check stays **quiet** — on `SUCCEED()` with no message, on a
  `SUCCEED` that ends a case, and on the idiom quoted in a comment of either kind.
- **A fixture that could not be STAGED says so.** The selftest's git cases build a real
  repository, and under a long scratch path `git add` failed with "Filename too long" —
  the tree then had no index, the check fell back to the directory walk, and two verdicts
  came back wrong for a reason that had nothing to do with the check. Every git command
  the fixture runs is checked, and a case that could not be arranged reports *that*,
  naming what git said. The scratch directory is also the root rather than a directory
  inside it, which is one long path component fewer.

## A CRASHED run is a fifth state, and a mutation harness reading a count scores it as caught

<!-- agent-tripwire: The repair for one collapse is the prime site for the next -->

A test binary that crashes reports **zero failures in every summary format there
is**. A mutation harness asks one question — *was this mutation caught?* — and
answers it from a failure count, so a run that died partway through arrives as
*0 of 482 cases failed* and is scored **caught**: indistinguishable from a real
result, and pointing the wrong way, toward believing the guard works.

This is the four states above with one more on the same axis, arriving where the
previous entry warns it will — *the repair for one collapse is the prime site for
the next*. Crashed, not-caught and caught are three states; the harness that
surfaced this had two (#1212).

**A mutation verdict is drawn from (exit status, completeness, failure count),
never from the count alone.** Each of the three is insufficient by itself, and
the reasons are different:

- **The count** cannot see a crash at all. Measured: a truncated JUnit document
  still carries `failures="0" errors="0"` on the elements it did emit, and the
  console reporter prints no summary line whatsoever.
- **The exit status** cannot say the run was whole. On Catch2 3.6.0 it was the
  failure count, clamped at 255 — the same fact that gave #1128 its
  `SKIP_RETURN_CODE 4` collision — so a run killed by SIGSEGV (128 + 11 = 139) and a
  run with 139 failing assertions were *the same number*; since 3.7.1 any failure
  exits 42, which separates those two and nothing else. A short run can exit **0**:
  measured in #1211 across six runs, exits `0 / 139 / 0 / 0 / 139 / 139` against
  element counts `551 / 507 / 551 / 551 / 518 / 518`.
- **Completeness** is what separates them, so it is asked FIRST and the status
  only refines it. It is read from the report's own terminator — `</testsuites>`
  for JUnit, one of `All tests passed`, a `test cases:` block or `No tests ran`
  for the console — never from a phrase the subject chooses.

**And a filter that matched nothing is a sixth reading, not a pass.** Catch2
exits **2** and prints `No tests ran`, which to a count-reader is another zero.
It is a mutation harness's likeliest failure of all, because an anchor that has
stopped matching is how a mutated arm silently measures nothing — and that has
happened here, in a mutation matrix that re-used a stale copy after its anchor
drifted.

`scripts/run-suite.sh` is the shared implementation and `run-suite-selftest`
drives its verdict table, including the 139-versus-139 pair that is the whole
argument for reading three inputs. **It is a helper, and helpers do not travel:**
harnesses are written fresh for each mutation campaign, which is the population
this entry reaches and a script does not.

**A crash is RETRIED and the retry is NAMED.** Scoring it is the defect; hiding
it behind a silent re-run is the other one — a retry makes an instrument's own
failures disappear without fixing them, and this repository keeps a list of the
times that has happened. Only a crash is retried, never a failure.

**Not a grep for the crash's signature.** `malloc(): invalid size` is what
#1211's crash happens to print; the next one aborts somewhere else. A guard built
on the signature passes the day the signature changes, silently, in the
direction that reads as *caught*.

What made this invisible for as long as it was: `subprocess.run(...)` read only
`.stdout`, the one `returncode` check covered the BUILD rather than the test run,
and a companion probe used `2>/dev/null`, discarding the line that would have
given it away on the first run. **It was caught by a denominator that MOVED —
482 / 496 / 530 — not by a verdict that looked wrong.** A crash that dies at a
stable point produces a stable, entirely wrong number and has no tell at all,
which is why this is a rule rather than a habit of reading carefully.

## A leader-pinned command goes to whoever leads NOW

<!-- agent-tripwire: A leader-pinned **mutating** command is put to whoever leads NOW, re-derived -->

`$leader_endpoint` is derived by whichever section of `cluster-e2e.sh` needed it
first, and leadership may legitimately move before a later section runs. A cluster
that has ELECTED is not one that has FORMED, a slow runner blows any election
timeout, and admission puts the cluster back into the state with no slack. So a
command put to the node that led a moment ago is a command put to a node that now
answers "ask somebody else" -- and the fixture reports that as the cluster refusing
something legitimate.

Two halves, and the second is the one that gets lost.

**A leader-pinned MUTATING command is put to whoever leads now, re-derived, never
to an endpoint recorded earlier.** Reads are exempt: any node answers
`--cluster-status`, and the one read that is leader-pinned re-derives inside its own
loop.

**The retry keys on the answer the caller ASSERTS, never on a recognised refusal
wording.** That refusal has two spellings -- one for "somebody else leads", one for
"an election is in progress" -- and a fixture matching them stops retrying the day
either sentence is reworded, silently, and back to failing the way it used to. The
contract is therefore "the answer carries this substring", never "the command
succeeded", which is also what lets the same helper assert a REFUSAL: the typo'd
setting case asserts that an unknown setting is refused BY NAME, and its substring
is the typo.

What makes this one worth writing down is where the rule already was.
`submit_setting` **was** this rule, correct in both halves, at line 778 of the same
file -- 117 lines above the `--cluster-admit` that lacked it and 212 above the
`--cluster-forget`. The argument was written down in a comment above it before
either of the sessions that read the file noticed the sites it did not cover.
Learned at [#117](https://github.com/LASTRADA-Software/fastcached/issues/117),
learned again at [#172](https://github.com/LASTRADA-Software/fastcached/issues/172).
A helper that implements a rule does not spread it; only a call site using the
helper does.

## A first failure masks its identical siblings

<!-- agent-tripwire: A first failure MASKS its identical siblings -->

`--cluster-forget` in section 5 of `cluster-e2e.sh` was one-shot against a pinned
leader endpoint, byte-identical in shape to the `--cluster-admit` in section 4, and
had **never once been observed failing**. Not because it was sound: because the
admit fails first. Under a moving leadership section 4 always failed, so section 5
was never reached, and the flake's second instance sat behind the first with a clean
record.

Two consequences, both worse than the original defect.

**Fixing only the observed site relocates the flake rather than removing it.** The
admit is repaired, the fixture gets further, and the forget starts failing at the
rate the admit used to.

**The relocated one then presents as a regression introduced by the fix.** It has no
failure history, it appears in the run immediately after the change, and everything
about it points at the person who just fixed the thing above it. That is expensive
to diagnose and it discredits a correct fix.

Which is the argument for auditing rather than trusting instinct: the sibling was
found by walking every call site of the pattern, and it was found *because* the walk
was mechanical. Nothing about section 5 looked suspicious, and it never had been.
When a failure is fixed, the question is not "is this site now correct" but "what
else has this shape, and would I have seen it fail?"
([#172](https://github.com/LASTRADA-Software/fastcached/issues/172))

## An identifier is READ, never reconstructed, and zero rows is not a verdict

<!-- agent-tripwire: An abbreviated identifier is a DISPLAY form: the full one is read -->

Two instrument failures in one session shared one shape, and neither returned an
error. A query was answered about a set that did not contain the subject, and the
caller promoted the empty result into a verdict
([#683](https://github.com/LASTRADA-Software/fastcached/issues/683)).

**A fabricated SHA.** A lane read a head as the abbreviated `b4331297`, needed forty
characters for an API call, and **padded it** instead of reading the full value. `gh`
answered `422 No commit found`; the script piped that into `awk`, the one-line error
JSON matched no red rows and produced no pending rows, and the watcher reported
**"ALL COMPLETE, NOTHING RED"** for a commit that does not exist.

What makes that one expensive is that the fabricated SHA shares its prefix with the
real one, so **every human-readable trace of the mistake reads correctly**. The
transcript, the log line, the summary a reviewer skims -- all of them show the eight
characters that are right. Only the raw response disagrees, and the raw response is
the one thing nobody reads.

**An absence nobody searched for.** In the same session a CI log was grepped for the
ctest summary block, fixture output was not found *there*, and "CI produces no test
output" was reported as a fact. `CMakePresets.json` sets
`"output": { "outputOnFailure": true }` on every test preset, and the evidence was
already in the log file on disk. A lane then spent a cycle diagnosing a fixture
defect that was not the failure.

So:

- **An abbreviated identifier is a display form.** The full one is read, never
  reconstructed. Padding, truncating or re-deriving one produces a well-formed value
  for a thing that does not exist -- which is strictly worse than a malformed value,
  because a malformed value is refused.
- **Validate a response's SHAPE before drawing a verdict from it.** N rows with the
  fields you expect, or it is not an answer. A query that does not parse is a hard
  failure, never a quiet retry.
- **Zero rows is not a verdict, it is the absence of one.** This is the same
  distinction the required-context scan draws between absent and passing, and the
  same one a `SUCCEED` gets wrong when it stands in for a skip: an instrument that
  cannot tell "no answer" from "a good answer" reports the good one.
- **Refuse a malformed identifier at the boundary.** A forty-hex-character check is
  one line, and the padding that caused this is invisible in a shell argument.
- **Before concluding "nothing there", state what was searched and whether that
  search could have found it.** "I grepped the log for the ctest block" and "CI
  produces no test output" are different claims, and only the first one was made.
- **A finished job's log is available while its RUN is still in progress — and the
  CLI says otherwise.** That is the fact; everything below is how to act on it.
  It matters because the moment somebody wants a failing job's log is precisely
  the moment the rest of the run is still going, so the tool's refusal arrives
  exactly when it is most convincing and least true.

  ```
  gh api repos/<owner>/<repo>/actions/jobs/<id>/logs --allow-escape-sequences
  ```

  **A tool that will not GIVE you the answer says so in a sentence that reads like
  "there is no answer".** Both of these are false negatives and neither is an
  error:

  ```
  gh run view --job <id> --log
      -> "run is still in progress; logs will be available when it is complete"
         ... while the log is retrievable RIGHT NOW by another route

  gh api repos/<owner>/<repo>/actions/jobs/<id>/logs
      -> a 99-byte refusal about terminal escape sequences, which looks like an
         empty result
  ```

  The log was available the whole time. Cost of not knowing this: an hour treating a retrievable log as gated, and an
  intermittent attributed to three successive wrong hypotheses while the answer
  sat one flag away. **Two different messages, both of which say "nothing here",
  neither of which means it** — which is this rule's own subject arriving in the
  tool you reach for to apply it.

This is the `producer | grep -q` false negative's family, recorded in
[`build-and-toolchain.md`](build-and-toolchain.md) -- same outcome, different
mechanism. There the pipeline corrupted the answer; here the caller corrupted the
question.

### A third instance, found while writing this rule

Worth recording because of when it happened. Auditing whether any Catch2 case name
contains a comma -- which would be a spec metacharacter -- the census was:

```sh
git grep -h '^TEST_CASE("' -- 'src/**/*_test.cpp' | sed 's/^TEST_CASE("//'   | sed 's/".*$//' | grep -c ','
0
```

Zero of 3135. The real answer is **428**, and one of them is at
`src/CowTree/BasicCowTree_test.cpp:285`.

This repository sets `grep.lineNumber = true`, so `git grep -h` emits
`<lineno>:<content>` rather than `<content>`. The `^TEST_CASE("` anchor therefore
matched nothing, the first `sed` stripped nothing, and the second truncated at the
first quote and left `57:TEST_CASE(` -- a string with no comma in it. Every line
produced an answer, the count was well formed, and it was false.

Three properties made it convincing, and they are the ones to distrust:

- **The pipeline did not fail.** No stage errored, no stage was empty, and the
  arithmetic was over 3135 real lines.
- **Zero was the expected answer.** A tree with no comma in any case name is exactly
  what a healthy tree looks like, so the result confirmed the prior.
- **The defect was in the environment, not the command.** The same pipeline is
  correct on a machine without that config, which is why reading it does not reveal
  anything.

What caught it was cross-checking with a second extraction that had no shared
assumption -- a Python `re.search` for the first quoted string -- and then confirming
the disagreement against a raw `git grep` of one name. **A census that returns zero
gets a positive control**: find one instance by other means, and check the census
sees it. Otherwise "there are none" and "I did not look where they are" are the same
output.

## A check that asserts WHICH refusal beats one that asks only whether it refused

<!-- agent-tripwire: A refusal test asserts WHICH refusal -->

**Measured, on Windows.** `reactor-teardown-gate-selftest` stages its stand-in canaries as
`#!/bin/sh` scripts, and CMake's `execute_process` is `CreateProcess` there, which **cannot
start a shebang script** -- ENOEXEC, *"inappropriate file type or format"*. So every case
refused, for a reason having nothing to do with the guard under test.

Four cases reported **"right verdict for the wrong reason"** and went red. A check asking
only *did it refuse* would have gone **green on Windows forever**, certifying a guard it had
never once exercised.

Two rules fall out of the same fixture:

- **A probe must use the EXECUTOR UNDER TEST.** Its "can this stub start" probe ran the stub
  through **Git Bash**, which handles a shebang fine -- not through the launcher that would
  actually run it. It answered a question nobody had asked. Same species as the
  mode-under-test rule: a guard that passes because it is testing something else.
- **A fixture that cannot BUILD on the only leg that runs it has never run.** That canary is
  registered `if(CMAKE_BUILD_TYPE STREQUAL "Debug")` -- correctly, since the assert compiles
  out of Release -- and three `fprintf` sites failed clang-tidy, so the branch did not build
  on Debug at all. It passed `gcc-release` **because there the fixture does not exist**. So
  build `gate-clang-debug` before gating anything that ADDS a file: it is the only leg that
  tidies, and otherwise you learn it twice from a 25-minute gate.

## Widening a gate makes the latent defects BEHIND it live, and they are in nobody's diff

<!-- agent-tripwire: widening a gate makes the defects BEHIND it live, and none of them is -->

`http_get` returned **0 for a response its own read bound cut short**, documenting only
*returns 1 if the connection was refused* — so every caller reported a truncation as the
endpoint having ANSWERED, and one of them concluded *the refusing worker exports no
`..._refused_not_a_member_total` series* from a scrape whose completeness nothing had
established (#1257, #1184). Measured against a real listener, both arms: a server that
answers and closes and one that holds the socket open mid-body were both status **0**, and
only the second's body was missing its terminator. Three named statuses now, because the
exit status is the ONLY channel that survives `$( )` — `_http_drain_ended` is set correctly
in that subshell and measured UNSET at the caller.

Underneath it, `_http_drain_fd3` took the sticky-EOF probe only when the body was EMPTY, so
a partial body on bash 3.2 — where a timeout and EOF both carry 1 — reached the classifier
as `(1, "-")` and was called `peer`. **The body is not a reading about who ended the read.**

Reachable rather than theoretical, and this is the figure that made it a ticket rather than
a note: a compile node's `/metrics` is **41,637 bytes and 133 series**, drained line by
line with a per-line bound. A stall anywhere in roughly a thousand reads truncates it, and
what goes missing is whatever `RenderPrometheus` emits last — the counter table.

What generalises is what happened next. Widening that gate to every ambiguous status made
an arm that had been reachable from ONE caller reachable from all of them, and the arm's
teardown was `kill -KILL "$sleeper"` and `wait "$sleeper"` with no `|| true`. **`wait` on a
job the previous line killed returns 137**, which under `set -e` ends the shell with a
status nothing explains and no output at all. It had been latent purely because of WHERE it
was reachable from: the one caller that met the old gate is invoked as `... && rc=0 || rc=$?`,
which suspends `set -e` through the whole function. On bash 3.2, where no status is decisive,
**every** probe would have taken it.

So: when a change makes a path reachable from more callers, the defects on that path become
live, and **none of them is in the diff** — the diff shows a condition being relaxed, not the
twenty lines below it that nobody had run. It is the reachability twin of *adding an OUTCOME
changes what an old condition does to every case that tolerated the wrong answer*, and it was
found the same way: by a neighbouring case going red for a reason that looked unrelated
(`http-headers exit=137`, printing nothing).

Its regression case asserts the script REACHES ITS OWN LAST LINE, and calls `http_get` in an
**untested position** deliberately — `&& rc=0 || rc=$?` or `$( )` suspends `set -e` and the
case would pass under the defect. Shown red: with the bare `kill`/`wait` restored it exits
137 while `http-complete`, whose caller IS in a tested position, stays green.

**What is NOT established**: the inverted bash 3.2 classification was not reproduced. No
bash 3.2 was available — Docker Desktop's daemon was not running and WSL carries no podman —
so `podman run docker.io/library/bash:3.2` was not run. What covers the decision everywhere
is `_e2e_probe_needed` as a pure predicate with both answers staged, plus a shape scan
refusing a second clause at the call site. Neither is the live 3.2 case and neither is
claimed to be.

## A background helper runs the fixture's cleanup until you have watched it not

<!-- agent-tripwire: A background helper in these scripts runs the fixture's CLEANUP until you have watched it not -->

Anything forked into the background in these scripts **inherits the shell's traps**, and
in a fixture the EXIT trap *is* the run's cleanup. So a helper signalled with a catchable
signal runs `rm -rf "$scratch"` on its way out — deleting the workdir of the run that is
still using it. Nothing in the resulting failure names a trap, a timer or a cleanup:
`node-ready-waits-for-marker` failed about a third of the time with

```
selftest FAILED: cannot arm a 15s deadline: '/tmp/tmp.XXXX' is not a directory
```

which is the *second* wait's arm refusing because the *first* wait's timer had already
deleted the directory. The trap's own `FUNCNAME` stack identified the site, with a
`BASHPID` that was not `$$`; no probe did.

**`trap - EXIT TERM INT HUP` as the subshell's first statement is the fix everyone
reaches for, and it is not sufficient.** It covers a subshell that has STARTED, and the
window that actually fires is the one BEFORE that: the disarm follows the arm by
microseconds on a wait that returns at once, so the helper is usually signalled before it
runs a single command, and an inherited `trap 'exit 1' TERM` takes it straight to the
inherited EXIT trap. Measured, interleaved and order-alternated so the arms share their
load — a sequential before/after on a host that goes idle produces exactly the false
"fixed" this investigation nearly shipped:

<!-- table-total: none -->

| arrangement | pass / fail |
|---|---|
| unfixed, load 47 | 9 / 3 |
| `trap -` inside the subshell, load 47 | **10 / 2** |
| unfixed, load 43 | 7 / 5 |
| uncatchable signal (`kill -KILL`), load 43 | **12 / 0** |
| uncatchable signal, load 36, N=25 | **25 / 0** |

`trap -` alone is indistinguishable from no fix. So **both** guards belong in the code,
each stating WHICH WINDOW it closes, or somebody deletes the one that looks redundant —
they are `_e2e_deadline_arm`'s `trap -` and `_e2e_deadline_disarm`'s `kill -KILL`. The
`trap -` is not useless; it is insufficient, and those are different claims.

**Two standalone probes reproduced none of it**, the first because the subshell's output
went to `/dev/null`, which is where its evidence went — a fake more permissive than the
thing it stands for, twice, on one question. A real fixture found it in one run. And the
inheritance is **version-dependent**: measured on bash 5.2.21, a background subshell does
not run the parent's EXIT trap at all and the shape does not reproduce, so the platform
that shows this is macOS's bash 3.2 — the one no development host here can measure. A
green Linux run is not evidence about it.

## A launcher fixture records only into its run's own state directory

<!-- agent-tripwire: A fixture handed a launcher records ONLY into its run's own state directory -->

The launcher records every invocation in `<state>/pace-cc/invocations.log`, and
`-z` / `--zero-stats` DELETES that file. `<state>` is the DEVELOPER's — `%LOCALAPPDATA%` on
Windows, `$XDG_STATE_HOME` or `$HOME/.local/state` elsewhere — unless the fixture says
otherwise. The Windows launcher e2e (`run-launcher-e2e.ps1`) did not: every run deleted
the developer's real statistics, and every compile it drove had first been appended to
them. Three more fixtures appended without deleting. Nothing looked wrong from inside any
of them — the result was right, and only somebody else's file had changed. The POSIX twin
had exported `XDG_STATE_HOME` all along, which is why nobody noticed the Windows one.

So a fixture handed a launcher — `$<TARGET_FILE:pace-cc>` (or any
`$<TARGET_FILE…:pace-cc>`) on its registration, directly or through a variable
carrying it, or a launcher parameter it declares — goes through ONE seam, **entered before
the launcher first runs**: `Enter-E2ELauncherState` in `scripts/lib/E2EEnvironment.psm1`,
or `e2e_launcher_state_enter` in `scripts/lib/e2e-common.sh`. Never a variable exported by
hand. An export names the variables its author remembered, while the seam READS them from
`StateDirectoryImpl` in `Stats.cpp` — only the branch of its `#if defined(_WIN32)` that
applies on this platform — and refuses a preprocessor shape or a base it cannot read.

**Scoped to the LAUNCHER, never the process.** `LOCALAPPDATA` is not the launcher's alone —
sccache, the CPM source cache and the VS tooling read it too — and `HOME` re-homes git. So
the PowerShell seam redirects around ONE launcher child (`Use-E2ELauncherState $h { ... }`)
and puts the caller's values back before the next line runs, an unset variable UNSET
again; the bash seam puts a shim in front of the launcher that sets the variables and
`exec`s it. Only the variables the launcher reads on THIS platform are redirected, because
its children — `cl`, `clang-cl` — inherit them. A process-wide redirect without a restore
was the defect `dist-compile-e2e.ps1` carried.

**A caller with no log at all is the common case, not an edge**: every CI runner, anybody
who has never run the launcher, anybody who just ran `-z`. It is a case of its own in every
check below, and nothing in the seam may end a `set -euo pipefail` fixture on a missing
file — a review found exactly that silent exit in every bash fixture, while every sentinel
it had been verified against held a record.

Four checks, each with the direction it fails in:

1. **A read-only guard when the seam is entered.** The seam asks the launcher where it will
   record, through the redirect, and refuses a path outside the run's root. It asks with
   `--show-stats`, which names the log while the log is empty. `-z` names it too, but only
   by deleting what is there — which on exactly the failure being checked is the caller's
   log. This guard, and not the readers, is what catches a state variable the readers
   cannot see: a base taken from a helper or from `std::getenv` is invisible to BOTH
   readers, and a review built exactly that launcher and watched `Enter` refuse it with
   every sentinel untouched. Blind spot: none at the moment it runs — but it runs ONCE, so
   the runs after it are checks 2 and 3's to judge.
2. **A positive control: this run's launcher runs were redirected, and its own log holds
   records**, asked BEFORE any `-z`. That the caller's log was spared is no evidence that
   the launcher recorded HERE, because a launcher recording nowhere spares it too. The bash
   shim also records, for every run, the value each state variable HAD when it ran, and
   the control refuses any that does not name the run's root. A fixture whose every run
   sets `PACE_NO_STATS=1` has no record to count — its runs write neither the log nor
   the toolchain fingerprint cache, which only a dispatch or `--print-toolchain-fingerprint`
   writes — so for it that shim record IS the control: at least one run beyond the guard,
   each with every variable at the run's root. `PACE_NO_STATS` does not gate
   everything, though: a PERSISTENT refusal from the daemon writes a throttle stamp
   (`refusal-*.stamp`, `RefusalNotice.cpp`, reached from `main.cpp`'s fetch path) into the
   same state directory. It is not used as the control, because `compile-cache-daemon-start`'s
   daemon never refuses on the path that fixture tests; it lands in the run's root, since the
   stamp and the log resolve one state directory.
3. **The caller's side, asked directly, on EVERY exit.** The caller's logs are snapshotted
   when the fixture STARTS — `e2e_begin`, or the `.ps1` fixture's startup
   `Assert-E2ELauncherFixture` — and check 4 holds every run that names the launcher
   variable BELOW that point: a bash fixture may not name it above `e2e_begin` at all, and
   a `.ps1` fixture can only run it inside the wrapper, which exists only after `Enter`. So
   damage done before the seam is entered is measured and does not become the "before"
   picture. At the end — from the bash EXIT trap the seam chains in front of the fixture's
   own, and from the `.ps1` fixture's `finally` through `Exit-E2ELauncherState` — a log
   present at the start must keep every byte (not deleted, not shorter, the same tail) and
   gain no record naming one of this run's trees; a log ABSENT at the start must still be
   absent or hold no record of this run. A fixture that fails midway therefore still
   reports the damage it did, which is where a leak shows. Blind spots, failing OPEN: a
   launcher reached WITHOUT naming the variable (a second copy of its path taken from the
   command line, or the other shapes check 4 lists) can run above the snapshot, and its
   damage then IS the "before" picture;
   a record whose source is relative, or spelled through `subst` or an 8.3 name, names no
   tree; and only the LOG is judged — `toolchains/` and the refusal throttle stamps in the
   same directory are not, since other builds on the machine write both and cannot be told
   apart from this run.
4. **No launcher runs outside the seam.** A `.ps1` fixture calls `Assert-E2ELauncherFixture`
   at startup, BEFORE its skips and self-test modes, so a machine that skips the fixture
   still judges it. It reads the fixture's syntax tree — `$script:`, `$global:` and
   `$using:` spellings included, and the parameter reached as `$PSBoundParameters["Launcher"]`,
   `$PSBoundParameters.Launcher` or `$MyInvocation.BoundParameters.Launcher` — and refuses a
   launcher run outside the wrapper. A path
   `Resolve-Path`, `Split-Path` or `Join-Path` derives from `$Launcher` is accepted only
   where it ends at a KNOWN sink — an assignment, `Test-Path`, `Write-Host`, another of
   those three — and every other consumer is refused: `&`, `.`, an executor or its
   `-ArgumentList`, a later pipeline stage, a method's argument, `Get-Item`, `cmd /c`, a
   hashtable. A `Start-Job` is accepted only binding the path to a block parameter named
   `Launcher`. Every shape two reviews found is a refused control row. A bash fixture is
   held to the ORDER instead, since the shim becomes the launcher variable only at
   `e2e_launcher_state_enter`: nothing may name the variable above `e2e_begin`; between
   `e2e_begin` and the seam only a test, a message or its absolute-path rewrite may, and
   none of them may hold a command substitution naming it, because
   `[ -n "$("$launcher" -z)" ]` is a test that RUNS it — nor pipe a message or hand it to
   `eval`, `source`, `.`, `sh -c` or `bash -c`, because `echo "$launcher -z" | sh` is a
   message that RUNS it; and no EXIT trap (`trap … EXIT`, or `trap … 0`, its other
   spelling) may be installed after the seam, which would replace the check it chained in
   front of the fixture's own (a background subshell resetting its own inherited traps
   excepted). Blind spots, failing OPEN, and caught at run time by checks 2 and 3 (except
   above the snapshot, as check 3 says): a launcher reached without naming the variable at
   all — in bash, a second copy of the path from the command line, a `${!name}`
   indirection, or a function from a sourced library that runs it; in PowerShell,
   `Get-Variable -Name ("Laun" + "cher") -ValueOnly` or
   `$ExecutionContext.InvokeCommand.ExpandString('$Launcher')` — and a PowerShell path
   derived from `$Launcher`, STORED in another variable and run through that, the
   assignment being the one sink accepted without following the variable further. And one
   rule that fails CLOSED where it could be wrong: a bash function defined above the seam that runs the
   launcher when called below it reads as a use above it.

**The enforcement is `ctest -R launcher-state-isolation`** (`scripts/check-launcher-state-isolation.sh`),
which selects TWO registrations of that script. `launcher-state-isolation` finds every
fixture handed a launcher and requires it to call its language's seam — a bash one in the
order check 4 gives — and it fails CLOSED on what it cannot classify: a launcher reference
or a carrier variable outside an `add_test`/`set` it can read, a block it cannot close, a
registration naming no script, a script declaring no launcher parameter, a bash fixture
calling no `e2e_begin`. Carriers are followed to a fixpoint, across files, and a census
that found no fixture is a failure. It fails OPEN where a registration reaches the launcher
without naming `$<TARGET_FILE…:pace-cc>` or a carrier — a path spelled from the build
tree's layout, a `find_program` of its own — and nothing catches that. It also holds the
two readers to one answer per platform. `launcher-state-isolation-selftest` (`--self-test`)
is the check's proof that it can fail: a planted tree that must earn every verdict, and
both seams DRIVEN against a stand-in launcher with the caller's log present, empty and
absent. Both run in the default set on EVERY platform rather than inside
`e2e-helpers-selftest`, which is not run on Windows — where the `.ps1` fixtures they are
mostly about run. Their cost is process spawns, which Git Bash makes expensive, so they run
one process per pass over the tree rather than one per file, and they are two registrations
so that each keeps its own bound on a saturated host rather than sharing a raised one.

A sentinel is the proof, not the developer's real log, and it is taken in all THREE
states: pointed at a directory holding one fake record, at one holding an EMPTY log, and
at one holding NO log. Require each to come out exactly as it went in. That is
deterministic whatever else runs on the machine, while other lanes' builds legitimately
append to the real log — and a sentinel that always holds a record cannot see the
fresh-machine case, which is how the silent exit above survived a verification that
passed.

## Open work

<!-- agent-tripwire: none: deferred work, tracked as GitHub issues; AGENT.md tripwires rules, not residuals -->

- **[#1567](https://github.com/LASTRADA-Software/fastcached/issues/1567)** — three sections here have no `AGENT.md`
  tripwire: `## A shared failure message describes one caller, and lies to the others`,
  `## A reproduction models the wiring as it is`, and `## A path-scoped revert is scoped
  to the FILE, not to the mistake`. Each fires in no session that does not open this
  file. A fourth, `## A CRASHED run is a fifth state`, is tripwired by a sentence it
  QUOTES rather than by its own rule, so the guard passes it — correctly, since it
  does not judge whether a phrase is the right tripwire. Marked `untriaged:` and not
  `none:`, and `ctest -R rulebook-tripwires` prints the count against this issue on
  every run.
