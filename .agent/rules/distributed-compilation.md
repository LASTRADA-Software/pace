# Distributed compilation

Rules for `src/Pace/Distributed/`, `src/apps/pace-node/` and the
dispatch half of `src/apps/pace-cc/`: preparing a translation unit for a
remote worker, running a worker as a service, the scheduler's gate, the node's
own cache tier, and what the end-to-end fixtures assert.

Read this before touching `SchedulerService`, `WorkerRegistry`, `LeaseTable`,
`Node::LocalCache`, `FrameEndpoint`, `DispatchPreprocessCommand`, or the worker's
`main`/`WorkerBody`.

One failure shape dominates this file and is worth naming up front: **distribution
appearing to work while never once helping** — every dispatched unit fails
remotely, falls back to a local compile, and the build goes green. Several rules
below exist only because that shape is invisible from both ends.

Distributed compilation adds two more, and both were found by running the feature
under **this repository's own build flags** rather than a toy command line — which
is the reproducible lesson, since no unit test can reach either:

- **The text sent to a worker is NOT the text the key hashed, and the difference
  is `#line`.** The key's probe suppresses markers so no checkout path reaches it
  (the rule directly above). Those same markers are the only thing telling the
  compiler which lines came from a *system header*. Feed a worker the key's text
  and every warning inside libc++ or the CRT is re-reported as if it came from
  the user's own file — under `-pedantic -Werror`, which this project builds with,
  that is a failed compile. Every dispatched TU would fail and be retried locally,
  so **distribution would appear to work while never once helping**: a silent
  100 % fallback with a green build. So `DispatchPreprocessCommand` preprocesses
  a *second* time, with markers, at ~45 ms on a path already committed to seconds
  of remote compilation. Reusing the key's text is the free-looking option and it
  is wrong.
- **A worker must be told its input is already preprocessed, AND what language it
  is in.** Having added the markers back, `-pedantic` then rejects the markers
  themselves as a GNU extension (`-Wgnu-line-marker`) — the fix for the first defect
  creates the second. The answer is the one ccache and distcc already use:
  `-x c++-cpp-output`. It is a `DriverSpec` column, not a branch, so a fifth driver
  is a row.
  - **MSVC's column was empty, and that was the whole of a second defect.** The
    reasoning was that `/E` emits standard `#line` which `cl` accepts in an ordinary
    source file, so there is nothing to tell it — true about the *markers*, and it
    left nothing stating the *language*. The worker writes its own scratch file and
    MSVC reads the language off that file's extension, so a dispatched `.c` came
    back compiled as **C++**: a failed remote compile wherever C is not valid C++
    (so C silently never distributed — the 100 %-fallback-with-a-green-build shape
    this list already records twice), and an object with C++ mangling stored under
    the C key wherever it is. `/TC` and `/TP` are the `-x` spelling MSVC does have,
    and `/TP` is a **byte-for-byte no-op** on a C++ translation unit, so nothing
    that worked before moves. Verified end to end on both Windows drivers.
  - **The extension does not decide the language; it is the last of three
    answers.** A `++` driver compiles *everything* as C++ — "g++ treats .c, .h and
    .i files as C++ source files", in as many words — so taking the language off the
    extension tells a worker to compile as C what the client compiles as C++. That
    is a wrong object, not a failed one, and `gcc` and `g++` are one `Flavor`, so
    the answer is a second column on the *name* table rather than a new question.
    Above both, a build may state the language itself (`/TP`, `-x c++`, which is
    what CMake emits for `set_source_files_properties(... LANGUAGE CXX)`); the
    launcher FOLDS that selector into the language it appends **last** and drops the
    build's copy, so the two cannot disagree (the entry on CMake emitting `/TP` below
    is why this is not a refusal). Refused are only a selector it cannot restate --
    an `-x` value with no `SourceLanguage` -- and `/Tc`/`/Tp`, for a second reason:
    they name a file, and with a bare file name they carry no separator, so
    `CouldNameAFile` lets them past.
  - **An extension whose language depends on the driver is never guessed at.** `.C`
    is C++ to a GNU driver and C to an MSVC one, and `.M` likewise — so the
    extension does not answer the question and a guess would hand a worker the wrong
    language. Both are excluded from the table by a case-*sensitive* row, ahead of
    the case-insensitive lookup that exists so a `.CPP` on Windows still dispatches.
  - **A module interface unit is refused by both gates, and that is now a rule
    rather than an accident.** `.ixx`, `.cppm` and their kin write a **BMI** beside
    the object, and what a hit reproduces is the object and the dependency record —
    so replaying one leaves the BMI missing (which fails loudly) or left over from a
    previous build (which does not). They were previously not in `IsSourceSuffix`,
    so nothing recognised them and every such line fell through as "no source file"
    and was passed through **in silence**, indistinguishable from the cache being
    broken; adding one there — the obvious "support modules" change — would have
    started replaying objects whose BMI nobody reproduced. They are now recognised,
    refused by name with the reason said out loud, and the same reason refuses an
    ordinary source promoted by a flag (`cl /interface`, `-fmodule-output`,
    `--precompile`, and `/Yc` for the precompiled-header case).

- **A MACRO SWITCH leaves the dispatched line and nothing else.** `-D`, `-U` and their
  MSVC spellings are dropped from what the worker is sent, and kept by the preprocess line
  and by the key. The worker compiles PREPROCESSED text, so every macro a definition
  introduced has already been expanded on the client -- including a
  `#include CONFIG_HEADER` resolved through one, whose file the worker never opens. It is
  the include directories' argument one step further along, and it is a NARROWING of what
  reaches the worker rather than a permission.
  - **Not a `PathValues` row**, although a path-valued `-D` is what exposed it: that table
    has three consumers and a macro must reach two of them untouched. The key hashes the
    text the definitions produced, so canonicalizing a macro's value would be a key change
    with no cause. One table per question.
  - **What this cost while it was missing is the point.** `CouldNameAFile` is the walk's
    last word and refuses the WHOLE command line for one unrecognised argument -- which is
    correct, since stripping an unknown one could change the generated code. An unrecognised
    `-DFOO="/abs/path"` therefore made the translation unit undispatchable, and this
    project's own build passes `-DPACE_SOURCE_DIR`. **Every** TU compiled locally, one
    stderr line each, `dispatched 0` and `never-picked n of n` on the fleet page, and **no
    counter anywhere** -- the fleet is not refusing jobs, it is never offered any. Any
    project passing a source root, a config directory or a version string with a slash in it
    gets the same silence, which is #226's shape reached through the launcher.
  - **It is PREFIX-matched, so the collision question is asked of the DRIVERS.** Measured
    rather than remembered: `g++ --help` over eight option groups (1401 options, with
    `-D<macro>`/`-U<macro>` as the positive control) and `cl /?` both have no other option
    beginning with an upper-case `D` or `U`. Case is load-bearing and the near-miss is one
    character away -- `cl` has `/u` and `/utf-8`, which this repository passes to every MSVC
    compile, so a matcher folding case would swallow them. The first census written for that
    comment folded case by accident and reported all three as collisions.
  - **A pass-through carrying one IS one** (`-clang:-DFOO=2`, `/clang:-UBAR`, #1680), and
    leaving it on the line is the defect in its WORST form, because a clang-cl worker compiles
    under `/TP` and that preprocesses the text AGAIN. Measured with clang-cl 22.1.8 at `/O2`:
    over `#undef x` and `int f() { int x = 1; { int y = 5; return x; } }`, `-clang:-Dx=y` on the
    dispatched line made the worker's `f()` return **5** where the client's returns **1** -- exit
    0, so the object was accepted and cached. It went live the day a worker learned to admit
    `-clang:<arg>` (#1672), while the drop still matched only the bare spellings.
    **A SEPARATED one is not dispatched at all**: clang-cl hands the clang driver its
    pass-throughs IN ORDER, so the value of `-clang:-D` is the next `-clang:` argument ANYWHERE
    on the line (measured, `-clang:-D /O2 t.cpp -clang:FOO=3` defines `FOO=3`), and no drop by
    position is right -- "the next argument" there was `/O2`. The key and a local compile read
    the whole line, so it is still cached.

- **The worker's argument filter is an ALLOWLIST, not a shape-based denylist**
  (`IsAcceptableJobArgument`, `CompileJob.cpp`). The client's arguments are spliced
  into the compiler's command line verbatim, and the compile port carries no
  credential while loopback is admitted unconditionally — so any local process can
  reach it. Naming the compiler is refused (the fingerprint rule above), but several
  driver options *run a program or load code* without ever naming one: `-wrapper
  prog,args`, `-fplugin=`, `-Xclang -load`, `-specs=`, `-B`. None carries a path
  separator, so the old "could this name a file?" filter admitted every one — a
  proven RCE as the node's service account
  ([#240](https://github.com/LASTRADA-Software/pace/issues/240)). The flag
  space belongs to GCC, Clang and Microsoft and grows every release, so a denylist
  we audit against upstream forever **fails open** the day we miss one; the allowlist
  **fails safe** — an unrecognised flag costs one local compile, visible as
  `pace_worker_jobs_refused_rejected_argument_total`, where a missed denylist
  entry was code execution. The accepted set (`AllowedArgs`) is per driver family —
  the worker knows its own compiler's family, never the client's — and refusal names
  the offending flag in `JobError::detail`, which rides the reply message to the
  client's fallback log.
  - **The `-f` space is ENUMERATED, never prefixed, and that is the load-bearing
    half.** A blanket `-f` prefix with a `Deny` row for `-fplugin` reads as an
    allowlist and behaves as a denylist over the largest and most volatile flag family
    GCC and Clang have: a new code-loading `-f*` is admitted *by default* until
    somebody adds a row. That is not hypothetical. `-fmodule-mapper=|program args`
    makes GCC **spawn a subprocess** — this tree already declares it path-valued and
    lists it in `SideArtefacts` — and `-fpass-plugin=x.so` is Clang's pass-manager
    plugin loader. Neither begins with `-fplugin`, and neither carries a path
    separator, so neither a carve-out on that spelling nor the shape rule beneath it
    stops them. Enumeration is what makes the class fail closed.
  - **A prefix row is legitimate only where its non-listed members are a CLOSED set,
    named as `Deny` rows beside it.** Two qualify: `-W` (whose only non-warning
    members are the three sub-tool passers `-Wa,`/`-Wl,`/`-Wp,` — there is no fourth
    sub-tool a GNU driver forwards to) and `-m` (whose only pass-through is `-mllvm`,
    which takes its value as a *separate* argument that must itself survive the
    table). Every other prefix row's spelling ends at the option's own `=` or `:`, so
    it names exactly one option and only its value is open. `-X` is not a prefix at
    all — nothing under it is code generation, so `-Xclang -load` is refused by
    absence.
  - **A prefix on one family's spelling reaches the other family's flags.** `/w`
    needs a prefix for `/wd4996`; written as `DriverFamily::Any` it admitted GNU
    `-wrapper` — the exact flag this ticket is about, let back in by a one-letter
    prefix. Caught by the regression case, not by review. A prefix row is scoped to
    the family that actually spells it that way.
  - **Every row carries a value shape (`Bare` / `NoPathSeparator`), so the old shape
    rule composes INSIDE a prefix rather than being deleted with it.** A row-level
    constraint kills a class of value; a `Deny` row kills one member per incident. It
    is defence in depth beneath the allowlist and never a substitute — `-fpass-plugin=`
    carries no separator either.
  - **The maintained tables are asked, not restated.** `ProducesSideArtefact` answers
    "does this write something besides the object" (`-fmodule-mapper=`,
    `-fmodule-output=`, `/Yc`); `DriverSpec::preprocessedInput` spells the language
    tokens the client sends; `TargetPinPrefixFor` spells `--target=`. Copying any of
    the three into rows here means a spelling added upstream turns every such job into
    a silent `RejectedArgument`.
  - **An unclassifiable compiler refuses the JOB, not its arguments.** With
    `DriverFamily::None` the allowlist refuses everything, which reports a *worker*
    misconfiguration as `RejectedArgument` and sends an operator to look at the
    fleet's flags — and a job with an **empty** argument list has nothing to refuse,
    so it sails past the loop and spawns a driver whose dialect this worker does not
    know. Checked once where the family is derived, answered `SpawnFailed` ("this
    worker is broken, compile elsewhere"), which already owns the right wire code and
    counter.
  - **`JobError::detail` carries client bytes onto the wire, so it is built by
    `RejectedArgumentsNaming` and never assigned directly.** It is encoded into the
    reply and lands in the client's fallback log, so each argument is capped and
    reduced to printable ASCII at the one producer — which also makes it valid UTF-8
    whatever arrived, as the fleet requires of text a peer sent.
  - **A refusal names EVERY argument the worker will not pass, never the first alone**
    (#1681): stopping at the first made an operator admitting it meet the next only
    after a reload, four rounds for one clang-cl line. `JobError::subjects` keeps them
    all, each with its own `judgedFor` (a reduced name cannot be re-asked, and must not
    take the question away from its verbatim siblings); the sentence lists them under
    the condition detail's ceiling and COUNTS the rest (`ListWithinCeiling`, which
    `ListDetail` also is). And it is still ONE compile: `RefusedArgumentsReport` files
    compiles by the SET of named arguments they carried, so admitting one of a
    compile's four arguments leaves it counted -- summing per-argument tallies would say
    four compiles for one, and dropping it would say fewer are refused than are.
  - **A refusal by ABSENCE and a refusal by ROW are the same answer only while nothing
    else is consulted.** `--allow-compile-arg` (#293) is the something else, and it
    turned that sentence from a distinction without a difference into a hole: the
    operator list is checked after the table fails to MATCH, and the whole `#240` class
    — `-wrapper`, `-fplugin=`, `-fpass-plugin=`, `-specs=`, `-Xclang`, `-B`, `/link`,
    `/analyze:` — was refused by not being listed, so naming one in a configuration file
    admitted it. Caught by the ticket's own acceptance test, on the first run, having
    been written to check exactly that; the implementation's comment claimed the order
    made it safe and was reasoning about the four `Deny` rows that existed. The table
    header had ALWAYS enumerated the class, in prose, under the words *"absent by
    construction, and therefore refused"* — a rule stated where nothing could read it,
    which is this rulebook's most-repeated shape and was true here for months before it
    could bite. They are `Deny` rows now, plus the side-artefact set (`/Zi`, `/ZI`,
    `-gsplit-dwarf`, `-fprofile-*`) that three test comments also called deliberate.
  - **A pass-through (clang-cl's `-clang:<arg>`) is judged by its INNER argument, under the
    grammar that parses it, by the WHOLE built-in set** — side artefacts, `Deny` rows and the
    allowlist alike — and a refused inner argument STAYS refused above `--allow-compile-arg`,
    which is why the verdict is three-valued (`BuiltInVerdict`) rather than a `bool` (#1672).
    **And the LAUNCHER unwraps it through the same seam** (`MatchPassThrough`, `CmdLine.hpp`),
    asked INSIDE its side-artefact, denial and macro-switch checks rather than beside them, so
    no call site can forget it (#1680). Deliberately not unwrapped: `PathValueFlags()` (its
    `-clang:-MF` rows are `joinedOnly`, a separated value being a second pass-through), and the
    language selectors, where a `-clang:` spelling is one the worker refuses -- a local compile,
    never a wrong object.
  - **A flag that decides what a compile of PREPROCESSED text reports is forwarded, never
    dropped — under `/WX` a dropped warning switch is a failed compile the client passed.**
    MSVC's `/external:` family is the case that forced it: CMake writes `-external:I<dir>
    -external:W0` on every `SYSTEM`-include unit, the worker had no row for the level, and
    a cl-debug build of this repository dispatched almost nothing while the node counted
    hundreds of refusals. The dispatch preprocess brackets each external header with
    `#pragma external_header(push)`/`(pop)`, and `cl` classifies the `.i` by those, so the
    DIRECTORIES stay behind (`/external:I` and `/external:env:` are `Deny` rows) while
    `/external:W<n>` and `/external:templates-` must travel; `/external:anglebrackets` is
    inert on a `.i` and travels so its builds dispatch. Measured, cl 19.51, `/W4 /WX`, a
    header with C4100, C4101 and a template C4244: local and worker agree in every
    combination, and the worker's `.i` with the level DROPPED exits 2 on all three. The
    rows are `Msvc` and so admit clang-cl too, which was measured rather than assumed:
    clang-cl 22.1.3, same shape, agrees in every combination — its `/E` marks a system
    header with line-marker flag `3`, so the level is inert on its `.i` (dropped, it still
    exits 0), and `/external:templates-` and `/external:anglebrackets`, which it does not
    implement, fail `/WX` as unused on BOTH ends because they travel. Both measurements
    sit on the `external:W` row in `CompileJob.cpp`; a new flag of this kind is decided
    the same way — local against the worker's `.i`, both exit codes, on EVERY driver the
    row's family admits.
  - **A `Deny` row is a PREFIX whose remainder is never examined, never a
    `NoPathSeparator` match**, and the difference is the wrong way round from the
    intuition: a refusal must not be escapable by the shape rule that exists to NARROW an
    allowance. `-fplugin=evil` carries no separator and `-fplugin=/tmp/evil.so` does, so
    a `NoPathSeparator` deny matches the harmless-looking spelling and lets the one naming
    a payload fall through. The rows are now `DeniedArguments` (`apps/pace-cc/ArgumentDenials.hpp`),
    where EVERY row is a prefix whose remainder is not examined, so the property is the
    table's shape rather than a `static_assert` over a column.
  - **ONE table, read by both ends, and the launcher reads it BEFORE the lease.** A row
    is a refusal no operator setting lifts, so a client that forwarded a denied argument
    spent a lease, a round trip and the whole translation unit on an answer it could read
    off the same table: `Dispatch` returns `DispatchStatus::DeniedHere`, recorded as this
    machine's refusal and naming the argument, and asks nobody. Header-only, for
    `CompileCacheWire.hpp`'s reason -- the launcher does not link `Pace`. The worker
    still enforces it, because two ends can be two builds and the launcher is not the only
    thing that reaches a worker's port.
  - **Operator entries EXTEND and can never shrink**, which is a property of the ORDER:
    they are consulted last, after `ProducesSideArtefact`, after the introducer rule and
    after every `Deny` row has returned. Matched WHOLE and exactly, with the same
    no-path-separator rule applied to the match — the config parser refuses a separator
    too, so it is two doors and the parser is the one that can say why. And the set
    rides into `MakeNodeServiceSpec`: a registration replays its command line forever,
    so a dropped entry is a worker that comes back refusing what it was installed to
    accept, as a silent local fallback — the failure the flag exists to remove.

Three more come from running the worker as a *service* rather than in a
terminal, and each has already been a bug:

- **A listener that cannot be woken cannot be shut down, and that is a property
  of the SOCKET rather than of the loop.** POSIX does not unblock a parked
  `accept()` when another thread closes the listening socket, so the only
  portable wake-up is `SO_RCVTIMEO` making `accept()` return periodically —
  which is exactly what `BlockingListener::SetTimeouts` exists for, and what the
  daemon's admin listener already does. `WorkerServer::Run` *documents* that poll
  timeout as the mechanism it relies on, and nothing supplied one: installing a
  SIGTERM handler then made the signal non-fatal without making the loop
  reachable, so `systemctl stop` hung until the supervisor escalated to SIGKILL.
  **macOS hides it** — there `close()` does wake the accept — which is why it
  passed locally and on `macOS-clang-release` and failed only on Linux, as
  `dist-compile-e2e ***Timeout 900.10 sec` in three jobs. It then arrived a
  *second* time through socket activation, where the caller was expected to apply
  the timeouts after adopting; `AdoptInheritedListeners` now takes them as
  parameters, so there is no way to obtain a listener that cannot be stopped.
- **`LISTEN_PID` is not a formality.** The activation variables survive fork and
  exec, so every grandchild of an activated service sees them. Adopting on their
  strength alone means treating whatever the parent left on descriptor 3 as a
  listening socket — a log file, a database connection, the read end of a pipe —
  and then accepting on it forever. The check is what makes "is fd 3 a listener?"
  answerable at all, which is why `ParseSocketActivation` is pure and every rule
  around it is a unit test. Two consequences: the variables are cleared **even
  when nothing was adopted**, since a process that decided they were not addressed
  to it must not pass them to a child that would decide differently on a reused
  pid; and the adopted descriptors are marked close-on-exec, because systemd
  deliberately omits that so a service can re-exec itself, while this worker
  spawns a compiler per job and a compiler holding the listening socket keeps the
  port alive after the worker exits.
- **Under socket activation the bind is READ off the socket, never guessed.** The
  socket unit owns the address and port, so `--listen-node`'s value describes
  nothing — and advertising it is the worst failure shape this system has:
  registration *succeeds*, the worker heartbeats happily, the scheduler leases that
  endpoint out, and every client fails to connect and compiles locally, with no
  error anywhere and a fleet that looks healthy from both ends. This was once
  closed by requiring `--advertise`, which made the stock package refuse to start.
  Instead `main` asks the inherited socket where it is bound (`getsockname`,
  `BoundEndpointOfDescriptor`) and adopts that as the Node surface's bind
  (`Node::AdoptActivatedBind`) **before anything derives an endpoint from it** —
  the startup table, the endpoint resolver, and every reload candidate
  (`ReloadBasis::activatedBind`, since `--listen-node` is unreloadable and a
  candidate holding the default would be refused). From there the advertised
  endpoint is derived as for any bind: a **wildcard** socket advertises the
  routed address on the socket's port (`auto`), a socket bound to **one address**
  advertises that address (pinned literal), and an `--advertise` that pins a value
  still wins. Only the value is adopted, never `nodeListenExplicit`: a unit's
  `ListenStream=` is not a promise the command line made. A socket that will not
  say where it listens is still refused, with the old text. All of it runs
  **before** the toolchain walk, the same cheap-and-fallible-first ordering the
  adoption check follows: a fingerprint takes seconds, a misconfiguration is
  decided in microseconds.

**The scheduler lives where leadership lives, and that is not the cache daemon.**
`WorkerRegistry` and `LeaseTable` used to be reached through a `Dispatch` role on one
of `pace-kv`'s listeners, which made the cache daemon a scheduler as well as a
store. The two have opposite deployment shapes: a cache is shared infrastructure
somebody operates, while handing out capacity is a decision only **one** node may
make at a time — and nothing in `pace-kv` can establish which node that is.
`Distributed::SchedulerService` is that logic with leadership as a first-class
input, and it is pure with respect to I/O for the reason the two tables under it
are: every rule below is a `ManualClock` unit test rather than a socket and a sleep.
Consequences that are each load-bearing:

- **Leadership and membership are one `Gate()`, not a check per handler.** These are
  the security- and policy-relevant decisions of the whole surface, so a verb added
  without them would be a verb that quietly skips both — and the test asserts the
  refusal *per verb* precisely because "I added a handler that forgot the gate" is
  the regression the arrangement exists to make impossible.
- **But the two rules answer different questions, and only one of them stops applying
  at demotion.** Leadership asks *may this node decide*; membership asks *may this
  caller spend the fleet's CPU*. Almost every verb here is a decision about the
  fleet's FUTURE — who joins, what is worth scheduling, what the cluster agrees — and
  a demoted node must make none of those, because a follower answering them is how a
  split fleet forms. **A release is not one.** It settles an obligation this node
  itself created, against a `LeaseTable` that is per-node and never replicated: the
  lease exists nowhere else, and no other node can free it. Gating it on leadership
  did not stop a demoted node doing harm, it stopped it cleaning up after itself, and
  the key stayed pinned on the one machine that could have released it until it
  expired ([#371](https://github.com/LASTRADA-Software/pace/issues/371)) — while
  the client was doing exactly the right thing, because the rule below requires a
  release to go to whoever ISSUED the lease.

  So the exemption is a **scope on the gate** (`GateScope::Settlement`), never a verb
  that skips it: membership is still checked, and `Scheduling` is the default so a new
  verb has to type out the relaxation. The test for whether a future verb qualifies is
  checkable rather than a feeling: **does it act only on non-replicated state this
  node created itself, AND can it create nothing?** Both clauses are load-bearing —
  `Lease` touches the same non-replicated `LeaseTable` and is excluded by the second.
  Measured against every gated verb, `Release` is the only one that passes:
  `ClusterStatus` reads replicated state, the three cluster verbs propose,
  `Register` and `Lease` create, and `Heartbeat` refreshes the registry the LEADER
  schedules from — a demoted node's copy going stale is the mechanism that pushes a
  worker to re-register with the new leader, not a cost.
- **Letting a settlement through must not mean letting any settlement through.** The
  half that turns this fix into a hole is the one that stays: a token this node never
  issued still answers `UnknownLease`, because a resolve answers on liveness rather
  than presence and that refusal is the only place "this job outlived its lease" can
  be observed. `LeaseTable::Release` matches on token **and** key and erases only on
  both, so a release cannot free a key it does not name.
- **Leadership is asked first, and the reason is the diagnostic rather than the
  cost.** A follower cannot know the cluster's membership any better than it knows
  the fleet, so answering `NotAMember` there sends an operator to inspect a policy
  that was never consulted. `NotLeader` carries the leader's endpoint **in the
  message**, so a client redirects instead of giving up; `SchedulerRole::Undecided`
  is the same code with an empty message, because an election in progress is a
  different fact and there is nobody to name. That "so a client redirects" was true of
  the design and false of every client for the whole life of the code — the launcher
  read it as an ordinary refusal until #237. Serving the endpoint is half a rule; the
  half that makes it work is below, under *a refusal that names somewhere else*.
  Three roles rather than a `bool`, for exactly that third state.
- **A node's cache tier serves THIS MACHINE, always — locality is a property of the
  VERB, never of the bind and never of a member list** (#287). `CacheResponder` used
  to admit `Membership::Member`, and a Member is any machine the operator listed, so
  a fleet peer could `FETCH` every object this machine had ever compiled. The docs
  promised exactly that ("its own machine and its cluster"), which is why the fix is
  a breaking change rather than a bug fix.
  - **Admission and locality are two questions.** Admission -- a proven key, a verified
    ticket, `--fleet-open` -- says which machine may spend this node's **CPU** and be
    leased its slots. The cache tier is this machine's entire **build output**.
    Contributing capacity does not make another machine entitled to read it, and there
    is no configuration in which it should — so the responder does not take an
    `IMembershipOracle` at all. Its absence is the fix; a flag it consulted would be a
    flag somebody could set wrong. A ticket widens it no more than a proof does.
  - **"It is only bound to loopback" is not a policy, and since #290 it is not even
    available.** The default bind closed this by accident, and the accident evaporated
    the moment `--listen-node` was widened — or, now that the cache and scheduler
    verbs share one listener, the moment a node passes `--serve-scheduler` and that
    listener takes the wildcard by default. A rule on the verb survived that merge; a
    rule on the bind did not, which is why this ticket was its hard prerequisite. On a
    scheduling node the locality check is the whole defence, and
    `NodeCacheRequestsRefusedNotLocal` rises in normal operation there rather than
    staying at zero.
  - **The question is ambient, so it arrives through a seam with a clock**:
    `Platform/ILocalityOracle`, over `IHostAddressSource` (`getifaddrs` /
    `GetAdaptersAddresses`). Not a syscall in the responder — a security decision
    nothing can substitute for is one no test can present a non-local caller to.
  - **Fast by construction before it is fast by cache.** `IsLoopbackHost` is asked
    first and takes no lock, so essentially every real caller — the surface binds
    loopback — never touches the address set, and the cache bounds only the rare
    path. Loopback is NOT the whole answer, though: a local client dialling this node
    at its own routable address on a widened bind is still this machine.
  - **Refreshed on an INTERVAL or on a HOST EVENT, never on a miss.** A host event -- a network
    change or a wake, `LocalityExpiryFor`'s rows; a suspend is not one -- MARKS the set due and the
    next question re-probes on the asking thread (W-7): no peer can raise one, so it is no
    amplifier, and without it a VPN re-address kept accepting tickets minted for an address another
    machine now holds for up to one interval. A miss-triggered refresh hands a
    remote peer a free amplifier: one probe per request, just by asking, and
    `GetAdaptersAddresses` measured **2.04 ms** against `getifaddrs`' **0.0086 ms** —
    238×, so a design that is free on Linux dominates a request on Windows. Nothing
    about the *answers* distinguishes the two designs, so the test counts probes.
  - **Both staleness directions are named in the header, because one of them alone is
    how a longer interval gets talked into being fine.** An address just GAINED is
    refused for at most one interval — fails closed, self-heals, costs one local
    compile. An address just LOST stays admitted for at most one interval, which
    needs a DHCP reassignment racing the refresh to exploit. Neither is a wrong
    answer served confidently, which is the line the project's caching rule draws.
  - **Folded with `SameHost`, never compared raw.** A surface bound to `::` reports
    an IPv4 caller as `::ffff:10.0.0.7` while the interface list says `10.0.0.7`, so
    a raw compare refuses this machine's own clients on exactly the dual-stack bind
    the rule was written for — the failure #180 already paid for once on the member
    list. It also refuses an unnameable peer against an empty entry, which a raw
    compare admitted.
  - **`NotAMember`, not a code of its own.** `pace-cc` reads a FETCH outcome as
    "is this daemon worth a second command" and steps over this one, so a peer whose
    access was withdrawn compiles locally. A new code would be an unknown one to
    every launcher already deployed, and an unknown refusal is what cost this tree a
    permanent 0% hit rate before. `NodeCacheRequestsRefusedNotLocal` carries the
    operator's half: the tightening removed access somebody had, and a peer whose hit
    rate fell needs one number that says why.
- **The fleet's shared cache is a different VERB PAIR on the same listener, never `FETCH`
  widened.** `SharedFetch`/`SharedStore` are `VerbFamily::SharedCache`, a `FamilyRoutes`
  row on the merged `0xFC` listener every built node already opens, so naming a machine at
  runtime opens no port.
  - **Admission is the node's one fold** (`Distributed::ExplainConnection`), then a
    narrower bar, `RestsOnMachineKey`. The caller needs a key its connection PROVED or a
    ticket it presented, never loopback alone and never `--fleet-open` alone: an open
    fleet must not make the fleet's objects anyone's. A revoked key is refused through the
    fold from any address.
  - **Every node answers the family.** A node the setting does not name answers an
    admitted caller `NotSharedCache` through its own counted row, never
    `UnimplementedVerb` and never `NotAMember`, which would be a confident wrong signal.
  - **Which leg a node's private tier reads through to is one `UpstreamKindTable` row.**
    `--upstream` is the override and speaks the daemon's verbs. The setting is the fleet
    leg. On the named machine itself the tier is read IN PROCESS, never over its own
    socket.
  - **The locality rule above is untouched.** `Fetch` and `Store` never reach the shared
    responder, and these verbs never reach `CacheResponder`.
- **A kept shared-cache session is a cached answer, bounded below the server's sweep.**
  `SharedSessionIdleLimit` is DERIVED from `FrameServer::HeaderTimeout` and
  `static_assert`ed below it, so this end hangs up an idle session before the server
  closes it under the next request.
  - A REUSED session that fails at the transport is re-proved ONCE, in the same operation.
  - A FRESH session's failure is the answer, and so is an exchange-deadline expiry: that
    is a slow live machine, never a dead session.
  - A session is dropped whenever its target's (id, key, endpoint) changes, and whenever
    the server stops admitting its key (`NotAMember`, the one row of `SessionEndingRefusals`).
    Every other refusal, `NotSharedCache` included, answers the request and keeps the session.
- **Anti-leeching refuses the fleet, never the cache.** A non-member reads and
  writes objects exactly as before — the cache is a separate service this class
  cannot reach — and is refused only the fleet's CPU time, which is the thing
  membership pays for. Hence `NotAMember` rather than `Unauthenticated`: one is
  about a credential an endpoint requires, the other about contribution.
  - **An empty key roster refuses everybody but this machine, and "admit everybody" is
    a named type somebody constructs.** A roster with nothing in it is the state of a
    node whose consensus has not formed, or that is misconfigured — and a scheduler that answered "member" there would silently become
    an open one, which is invisible from both ends because the fleet keeps working and
    merely serves strangers too. `OpenMembership` is the right answer for one machine or
    a fleet whose reachability is its boundary, but it is never a *default*: "no policy"
    and "a policy that admits everybody" have to be the same explicit decision, which is
    also why `Membership::Outsider` is the zero value.
  - **A membership flag is the NODE's, not the scheduler's, and a startup rule that
    assumed otherwise closed every worker.** One `NodeMembership` serves all three
    surfaces — the scheduler, the cache tier and the compile port — and `WorkerServer`
    is constructed unconditionally, so the admission policy — `--fleet-open` and, since
    #178, the key routes — is consulted on every node there is. `StartupPolicyRejection` nonetheless refused them without
    `--serve-scheduler`, reasoning that "a policy nothing consults is a policy an
    operator believes is in force" — and the premise was simply false. What the row
    achieved was pinning every non-scheduler node's oracle to an *empty list*, which
    admits loopback and nothing else, so the worker the getting-started page called
    "the whole of it" refused every dispatched compile with `NotAMember` (#235). A
    rule stating what a flag is *for* is a rule that has to be re-derived when a
    second surface starts reading it — so check which tiers reach the value, not
    which flag it reads like.
  - **Admitting peers and advertising an address are two halves of one decision.**
    Peers are admitted so that they can *dial* this worker, and `--advertise` falls
    back to `--listen-node`, which is the wildcard on a scheduler — which the scheduler
    hands to clients verbatim, so a client on another machine dials `0.0.0.0` and
    reaches itself. `NodeServiceRejection` had always refused that for an *install*;
    letting a worker admit other machines at all is what made it reachable from a
    hand-started one, so the startup table gained the row in the same change.
    Deliberately scoped: a node that registers **nowhere** and admits peers to its
    cache tier is reached at `--listen-node` and needs no advertise, and a node that
    admits no other machine is the one-machine deployment and is correct as it stands.
    Only the wildcard is refused, never an address that might not resolve — a host
    that is down today can be right at the next boot (#208), while the wildcard is
    wrong on every machine and forever.
  - **A refusal one hop past the lease is invisible from the side anybody watches.**
    The lease **was** granted, so every scheduler counter is correct and unmoved; the
    only signal is the *worker's* `WorkerJobsRefusedNotAMember`, on a machine whose
    operator has no reason to scrape it and which exports nothing at all without
    `--admin-listen`. "No counter moves" is the tempting summary and it is wrong in a
    way that matters — it sends a reader looking for a missing counter instead of at
    the one that exists. What was actually missing is a line at **startup**:
    `AdmissionSummary` is one phrase for the worker's ready line and the scheduler
    tier's, so a node that admits nobody says so while an operator is watching, and a
    node running both surfaces states one policy rather than two.
  - **A registration's endpoint is where work gets SENT, and nothing ties it to the
    connection that carried it. What landed for #242 is a counter, and calling it a
    fix would be the error.** `SchedulerService::Register` runs `Gate()` and then
    checks only that the fields are UTF-8; `WorkerRegistry` stores the endpoint
    verbatim and `Lease` hands it to clients, which dial it and send a whole
    preprocessed translation unit. The obvious remedy — refuse an endpoint whose host
    is not the caller's — was priced and **rejected**, and both halves of that are
    the rule:
    - **It refuses the ordinary case.** A worker that advertises a DNS name
      mismatches and the scheduler cannot resolve it: the service is I/O-free by
      construction, and a resolver is not something a security decision may depend on
      — which `IsLoopbackHost` already records about `localhost`. So do multi-homed
      workers, NAT, a VPN, and the **first fleet the getting-started page builds**,
      where a node registers with its own scheduler over loopback while advertising a
      routable name. A control whose false-positive set is the documented setup is
      not deployable.
    - **And it buys less than it looks like.** The caller is already an admitted
      member, so it may receive the fleet's work by naming its **own** address; the
      comparison only stops it naming a *third* host. Membership already granted "may
      this machine receive work", so the check narrows the primitive without removing
      it — which is the same shape as the security theater it was meant to replace.
    - **The real mechanism is a credential, and this tree already has it one layer
      over.** Discovery proves a `(node, endpoint)` pair with a signature over a nonce the
      challenger chose, *precisely* so a claimed endpoint cannot be substituted. A
      registration wants that, and it is the same mechanism as the planned signed
      lease tokens.
    - **So what shipped is instrumentation, and it says so.**
      `DispatchWorkerEndpointMismatch` counts an **accepted** registration whose
      endpoint host is not the caller's, beside a bounded `Info` line naming both
      addresses — `Info` and not a warning, because on a DNS-named fleet this is every
      registration and a permanent warning is one an operator learns to filter. No
      wire code was added: a code nothing returns would put a lie in the refusal
      table. The number exists because *nobody knows* how often endpoints legitimately
      differ on a real estate, and that is what decides whether a stricter rule is
      viable — both ends of the argument were guessing.
    - **`CallerContext::peerId` used to disclaim itself, and that comment is how the
      hole stayed open.** It said "who the peer says it is, for logs; never trusted
      for a decision" — every clause false. The transport fills it from
      `ISocket::PeerAddress()` and hands the same string to the membership oracle, so
      it is already the basis of the decision on that surface and is the one fact a
      caller cannot forge. A comment asserting a check is impossible is worth more
      than a missing check: it stops the next person looking.
    - **Hosts only, never ports, and unmapped on both sides.** A peer dials from an
      ephemeral source port, so `peerId` carries none — the reason no admission rule
      here ever keyed on a caller's port. And `::ffff:10.0.0.1` versus `10.0.0.1` is a property of how
      the *listener was bound*, so `Core/HostPort::UnmappedHost` folds them or two
      identically configured nodes disagree about one machine.
    - **A lease's dial hint is `peerId`, and only that.** The default `--advertise` is
      `auto` -- the address this machine routes from, an IP literal, re-derived and
      RE-REGISTERED when the network changes (`EndpointResolver`), so the registration
      itself moves and no hint rides it. A NAME is the opt-in pin (and `auto`'s stand-in
      while no route is known), and after a VPN reconnect a name resolves to an address the
      machine no longer holds for as long as the TTL says -- which is what hints are still
      for. A pinned LITERAL is the opposite: it does not roam, and it vetoes every hint
      (`AdvertiseIsLiteral`), so a literal kept as a work-around turns both mechanisms off.
      The scheduler has seen the current one on every heartbeat, so a grant carries it BESIDE the name
      (`Distributed::DecideDialHint`): never for loopback or a link-local observed host,
      an unparsable or IP-literal advertise, or an address the worker does not itself
      report -- the NAT filter, because a relay's address dialled is somebody else's port.
      The token signs the advertised NAME and never the hint, which is the whole safety
      argument: a hint that has gone stale onto another fleet worker is refused
      `LeaseEndpointMismatch` there, and the client dials the name. The observed host and
      the reported list are REPLACED together on every REGISTER and HEARTBEAT, an empty
      list included, so the NAT filter never pairs one exchange's host with another's list.
      The client dials the hint first under `AtDialHint` (connect capped at
      `HintConnectBudget`, an unbounded configured connect included) and retries the name
      ONLY on `Unreached` or `LeaseEndpointMismatch` (`HintRetryTransportFailures`,
      `HintRetryRefusals`): nothing ran in either. `PeerLost`, `Expired` and `Silent`
      reached a machine that may be compiling, and a second dial could run the job twice;
      every other refusal is the worker's own answer. The name gets what is LEFT of the
      grant when it is dialled, never a fresh budget, and the two dials are one lease,
      released once. A hint that reached nothing while the name answered is a stale
      address, never an unreachable worker, so only a dead NAME enters the exclusion memo.
    - **The worker reads that list from its LOCALITY ORACLE in EVERY round, never once
      at construction** -- `HeartbeatRound::locality` is the seam, not a vector, for
      `--requirepass`'s reason: a captured list is the address the VPN had before it
      reconnected, and the hint would then be vetoed as a NAT for the rest of the process.
    - **And the report is the SET the ticket audience answers from -- one value, never a
      second probe** (`ILocalityOracle::Addresses`, the integration of lane 3's hints with
      lane 2b's tickets). The client mints a ticket for the address it DIALS, so a hinted
      compile is spent at the worker only if `NodeAudience`'s oracle calls the hint's host
      this machine; a heartbeat reporting from its own probe hints a VPN's new address
      before the audience knows it, and the `wrong-audience` refusal is final -- a local
      compile rather than the name. With one set, a GAINED address is not reported until
      the refresh (no hint: the name, as before hints existed) and a LOST one is reported
      for one interval (a hint that reaches nothing or `LeaseEndpointMismatch`: the name).
      The oracle refreshes on its interval, never because a heartbeat asked.
      `FleetDialHint_test`'s refresh case goes RED with a second acquisition.
      `Node::ReportableInterfaceAddresses` leaves out, one `UnreportedAddresses` row
      each, what the wire refuses (`IsCarriedInterfaceAddress`, asked and never restated),
      loopback and link-local -- nothing the scheduler could ever hint, so none of it may
      spend the `MaxInterfaceAddresses` budget -- filtering BEFORE the cap, then sorting so
      a cap drops by the set rather than by adapter order. A cap that bites is said once
      per process at `Info`; an address source that answers nothing is an empty list, no
      hint, and never a failed round.
  - **The oracle is a seam and not a call into `Cluster::PeerDirectory`.** The
    dependency would run the wrong way — `Distributed` is the policy, `Cluster` is
    one way of establishing the fact it needs — and the answer is *deployment*-shaped
    rather than universal, which is what an interface is for. `PublishCluster` is a
    setter and one of the documented carve-outs to configuration-at-construction: membership
    is precisely what changes while the object lives, and rebuilding the oracle per
    join would mean handing a new one to a running server.
  - **Admission is decided by a machine's KEY, never by a list of addresses — so the
    derivations that kept two address lists apart are gone with the lists.** The #251
    two-lists argument, the `ForgottenMembership` precedence argument and the reload
    asymmetry of a host list were all about keeping an address list right; since #178's
    tickets there is none to keep. What replaced them is *Admission without addresses*,
    under the node proof below. What carries over is these rules:
    - **The forget reaches an open node too, by the key.** `--fleet-open` says *I have
      not enumerated who may use this fleet* -- a blanket over callers nobody named -- and
      a forget names one machine by its key, so a connection presenting that key, as a
      proof or as a ticket, is refused under the flag like anywhere else. What the flag
      still serves is a caller presenting NOTHING: it is anonymous by design, and a
      forgotten machine that presents nothing is served as a stranger is. Letting the
      blanket outrank the forget would make a local flag resurrect a machine the cluster
      positively removed, on exactly the node nobody has reconfigured yet.
    - **On an open node the forget reaches a machine by its CREDENTIAL, and that is also
      its limit** (#1555). One that presents a revoked credential -- a proof, or a ticket
      refused (and counted) as revoked -- is refused as itself on every later verb of that
      connection, the verbs it pipelined behind the AUTH included. **Only the PROVEN path
      names it**: a proof shows possession, so it gets `KeyForgottenWhy`; a revoked key a
      TICKET showed is refused on the same row and counter in the surface's STRANGER
      words, and the self form of `explain-admission` answers it as a stranger (host,
      refused, by nobody) -- a ticket may be a captured one. How the key was shown travels
      WITH the verdict (`MembershipDecision::revokedBy`, read by `RevocationIsProven`),
      never inferred from which facts a connection lacks. **Except on an open node, which
      discloses it**: an unknown ticket is served there and a revoked one refused, and the
      self form answers the revoked ticket `Outsider` where a stranger gets `Member` by
      `fleet-open` -- so a captured ticket's holder DOES learn its machine was forgotten,
      the price of the forget biting under the flag at all; forged and unknown stay alike,
      both served. The ticket's half is `ConnectionFacts::revokedMachine`: a
      `RevokedKeyEvidence` whose ONLY operation answers `Forgotten`
      (`Distributed::DecisionOf`), recorded by the endpoint and never cleared. It is never
      asked of a key roster, because the lease roster that refused the ticket and the
      fold's key roster publish at different moments, and asking the second could read
      the key LIVE and admit the machine the first just refused. **A refused ticket grants
      no admission, and a revoked one refuses.**
    - **The revocation is published from `PublishCluster` and never from `Adopt`.** A
      forget is the cluster's fact, and a reload that rebuilt the participants from a
      config file would erase every revocation agreed since startup -- #251's shape in the
      one direction where the erasure fails open. `Adopt` writes `--fleet-open` and only
      that. **No ADDRESS is ever forgotten, loopback included**: a revoked key is refused
      from this machine too, and what loopback keeps is the admission of a connection that
      presents nothing -- the local builds a node exists for.
    - **The refusal is counted APART from a stranger's**, one counter for every surface
      (`NodeRequestsRefusedKeyRevoked`). A machine an operator removed and a machine nobody
      ever admitted are opposite diagnoses -- one is to investigate, the other is already
      decided and means the far end has not been told. One counter and not six because the
      remedy is the machine's, never the door's: split per surface it would have to be
      summed by hand to answer the only question anybody asks of it.
    - **`NodeMembership` IS the oracle rather than handing one out, and that is what
      makes `--fleet-open` live at all.** Surfaces take an `IMembershipOracle const&`
      once, at construction, and hold it for their lifetime; an `Oracle()` returning
      one of two owned objects chosen by a flag read once would leave every surface
      bound to whichever was right at startup. A test that re-asks `Oracle()` after
      the reload passes under precisely that defect -- so bind the reference BEFORE the
      reload and classify through it after, which is what the fixture does and what
      the production call sites do.
    - **A reload may not WIDEN admission while the running worker verifies no lease**
      (review I-2b). A worker may have built `Cc::UncheckedLeaseValidator()` at startup,
      which is safe only while no machine but this one is admitted -- and neither guard for
      that can see a reload. `StartupPolicyRejection` decides reachability from
      the configuration's bind (under socket activation, the socket's own bind, adopted at
      the start), and `MakeWorkerLeaseValidator`'s activated-case backstop has already run. Widening
      would hand it an open unauthenticated compile port with every refusal counter
      reading zero, which is
      [#282](https://github.com/LASTRADA-Software/pace/issues/282) arriving
      through the door #405 opens. Asked as a TRANSITION -- the candidate admits remote
      peers and the previous configuration did not -- because a keyless worker that
      already admits them passed its own startup rules, is running today, and must
      stay free to NARROW: a guard refusing its reloads would punish the one edit that
      makes it safer. Keyed on what the running worker BUILT (`LeaseCheckInForce`, recorded
      inside `MakeWorkerLeaseValidator` so no worker can build one unrecorded), never on flag
      shapes: the shapes missed a path, and a configuration carries no such fact. So it is not
      a row of `ValidateNodeReloadable`, whose rules are about configurations; `ReloadCheckWith`
      composes it beside that, LAST, so a save that also moves an unreloadable setting is told
      about the setting first.
    - **It does not contradict *absence from `ClusterState` is not removal*.** That
      rule is about ABSENCE -- a member the state never named, which must not be read
      as a removal -- while a forget is a positive act, and it revokes the key the
      removed record held. The two look contradictory to a reader meeting them cold,
      which is why both are written down here rather than left to be re-derived.
  - **A fold that is right and unaskable is half a feature**
    ([#1471](https://github.com/LASTRADA-Software/pace/issues/1471)). Every rule
    above decides admission correctly and NONE of them could be asked about: an operator
    who finds a machine still served had no way to learn which route admits it -- the
    key it proved, a ticket it presented, or `--fleet-open`. So the decision is a `MembershipDecision` — a verdict and
    the SET of routes that produced it — `IMembershipOracle`'s one virtual returns it,
    and `Op::ExplainAdmission` reports it through the SAME oracle the surfaces enforce.
    Never a second walk over the same participants: two folds kept in step by discipline
    is the defect this verb exists to make visible rather than one more instance of it.
    - **A set, never a winner.** Two routes may admit one host and reporting either
      alone answers a question nobody asked, sending the operator to edit a file that
      changes nothing. `Outsider` is attributed to NOBODY (`DecidedBy`): an oracle
      answering it has no opinion rather than an answer it produced, and naming the
      author of a silence is the confident wrong signal.
    - **The question about the caller's OWN connection is answered to a caller the node
      refuses** -- an empty subject. Gated, it would leave the refused machine the one
      caller that could never ask why. It answers only what that connection established
      (its host, the key it proved, the ticket it presented), which a gated verb's
      refusal already tells a stranger, so `Op::ExplainAdmission` is `OpenBeforeAuth`,
      bounded by `MaxExplainAdmissionPayload`, and `NodeStatusResponder::RefusePeer`
      passes it. The MACHINE form reads the roster and so describes a third party: it
      is gated inside `Answer`, counted on the non-member row. A machine's route set is
      `ExplainConnection` over its roster key presented as a proof AND a ticket -- the
      enforced fold, never a second walk.
    - **A verb answered before admission must not answer the machine form's question
      either**, and AUTH did: a ticket is checked under the ROSTER's key for the id it
      claims, so `forged` against `unknown-machine` told a stranger signing with its own key
      whether an id is admitted, and `revoked` told a captured ticket's holder the machine
      was forgotten. The three travel as ONE message (`TicketRefusalSays::NotAdmitted`)
      with their counters kept apart; what a caller can check itself, or the node's own
      state, still names itself. The node proof gets the same property the other way
      round -- the signature under the key the CALLER presented, the roster only after.
    - **The verdict must be known and the route set may be partial**, which is one
      decision per field rather than one rule twice. `DecodeAdmissionExplanation`
      REFUSES a verdict byte this build cannot name — defaulting it to `Outsider`
      would report *refused by nobody* on a build that learned a fourth answer, and
      that reads exactly like the healthy case — and KEEPS a route bit it cannot
      name, because dropping it under-reports authorship on a fleet mid-upgrade. The
      renderer counts the leftovers rather than dropping them, for the same reason.
    - **The library↔wire mirror has ONE mapping**, `Distributed/MembershipWire.hpp`.
      `CompileCacheWire.hpp` must stay dependency-free so it MIRRORS `Membership` and
      `MembershipParticipant`, and a mirror needs a reader at each end — the node
      ENCODES an answer and `pacectl` RENDERS one. Two copies are two things
      that can disagree about which bit means which route, inside the verb whose whole
      subject is attributing a decision. The client's SPELLINGS are keyed on the
      participant rather than on the wire bit, and that is the guard rather than a
      preference: a bitmask enum has no `Last`, so a table keyed on one cannot be
      checked for completeness, and a route added without a spelling would render as
      *a route this client is too old to name* — blaming the node's version for the
      client's omission.
- **An unbounded wait does not avoid an ending, it only chooses who picks it — and
  the supervisor picks `SIGKILL` with no diagnostic.** `~WorkerServer` drained on an
  unbounded condition variable, and the comment defending that was right about its
  premise and wrong about its conclusion. The premise: a job on the executor holds a
  pointer into the server — the counter, the protocol, the metrics sink, the logger,
  the byte budget — so *returning* from the drain while one is still running frees
  all of them underneath it. Bounding the wait does not make that safe. The
  conclusion it drew, that the wait therefore had to be unbounded, bought nothing: a
  single wedged compiler turned `systemctl stop` into a supervisor timeout and a
  kill, and on Windows into an SCM stop timeout an operator reads as "the service is
  hung" (#239). Observed, not theorised — `dist-compile-e2e` case 8 failed on a
  loaded macOS runner with the worker not exiting in 15s while cases 1–7 passed, so
  the fleet worked and only the *stop* did not.
  - **So on expiry it states what it is abandoning and ends the process.** That is
    the one exit which abandons those jobs without touching what they are still
    inside, and each one's client resolves its own lease on every path out of a
    compile (#212). `_Exit`, never `exit`: static destructors would run the very
    teardown being avoided.
  - **The decision is a pure function, and the arm that carries it out is injected.**
    `NextDrainAction` is arithmetic over (outstanding, waited, timeout), exhaustively
    unit-tested, and `Drain` is left with nothing but carrying it out. `Finished`
    outranks an expired bound, or a stop that had already finished would log a false
    abandonment at exactly the moment the thing worked.
    - **This bullet used to end "because the interesting arm cannot be tested", and
      that was a claim about a LINE recorded as a property of the ARM** (#297). A
      branch that calls `_Exit` inline is indeed a side effect no in-process case
      survives; a branch that calls `IDrainAbandonment::Abandon` is a virtual call a
      case can substitute, and `ExpiryReaper` had been taking that seam while
      `BoundedDrain.hpp` named THIS drain as the shape it modelled. The class the
      comment pointed at was the one class that could not take it.
    - **A rule saying something cannot be done instructs the next session not to
      try**, which is the expensive shape — the same one `## Open work` entries are
      checked for. Here it held from #239 until #297 was picked up, with the arm
      carried by a pure-function proxy and by nothing else: `CompileCapacity_test.cpp`
      had no case for `Drain` at all, and a case that reached the arm did not fail, it
      took the test binary down with every case that would have run after it. So when an arm
      is called untestable, say what makes it so — here, that the effect was written
      inline rather than reached through a seam — because that sentence is the one a
      later reader can check and refute.
  - **The bound is a flag, and zero still means forever.** How long a compile
    legitimately runs is a property of the site, not of this program, and a
    compile-time answer on a binary whose `--install-service` replays its command
    line forever is one nobody can move afterwards. Zero is what the node did before
    the bound existed and stays sayable, so a behaviour change is not one an operator
    is unable to turn off.
  - **A silent bounded wait is barely better than an unbounded one.** It reports the
    outstanding count on a cadence, because a stop that says nothing for thirty
    seconds is indistinguishable from one that has hung — which is the reading the
    whole change exists to prevent.
  - **It does not close the ticket, and the other half is where the real subtlety
    is.** Killing a wedged compile's *direct child* would not even unblock the drain:
    `posix_spawn` dup2s the pipe write ends onto the child's stdout/stderr, so every
    grandchild inherits them and EOF arrives only when the last holder exits. The
    drain blocks on the pipes, not on the wait. So the process-**group** kill (a job
    object on Windows) is load-bearing rather than a refinement, and the naive fix —
    kill the child, wait for EOF — looks correct and hangs forever.
- **A dispatched compile is bounded by how long a COMPILER runs; a cache exchange
  by a round trip. One number cannot be both.** The launcher armed a single deadline
  on every exchange it made and handed the dispatch dialler the cache's -- ten
  seconds, which is right for a `FETCH` answered out of memory and is the wrong
  question entirely for a `COMPILE`. A worker writes nothing until the compiler has
  finished, so the client sits in **one read** for the whole remote compile, and every
  translation unit slower than ten seconds was abandoned mid-compile and rebuilt
  locally — precisely the set distribution exists for. The worker meanwhile ran the
  job to completion and wrote back an object nobody read, so the CPU was spent twice,
  the network carried a wasted object, and `leases_granted` kept rising: this file's
  own headline failure, distribution appearing to work while never once helping.
  Measured at 23.5 s of worker CPU and 84 MB returned to a client that had already
  given up (#223). `DispatchBudgets` is the split — `control` for the scheduler's
  `LEASE`/`RELEASE`, `compile` for the worker — and the two knobs are
  `PACE_TIMEOUT` and `PACE_DISPATCH_TIMEOUT`. Four things about the
  shape are load-bearing:
  - **A per-call socket ceiling is not a bound, and the seam is where that becomes
    sayable.** `SO_RCVTIMEO` bounds one `recv`, so a peer dribbling a byte before each
    expiry holds a build forever without ever exceeding it — and a *dialler* seam can
    arm nothing else, because all it hands back is a socket. Bounding the exchange
    needs a `DeadlineTimer` that CLOSES the socket, which needs the reactor the
    exchange runs on. So dispatch asks for an **exchange** (`IEndpointExchange`) and
    hands over the budget it must finish inside, which is `ReactorExchange` — the one
    the cache path already used. A second mechanism here would have been a second
    thing to get wrong.
  - **A bigger constant only moves the cliff, so the default is anchored on something
    real.** Ten minutes, because that is `LeaseTable::DefaultLeaseTimeout`: above it a
    client is waiting on a lease the scheduler has already reclaimed and may have
    re-granted for the same key, and below it a compile the fleet is still holding
    capacity for is thrown away. The two cannot be `static_assert`ed together — the
    launcher deliberately does not link the library the scheduler lives in — so moving
    either means moving both.
  - **A flat deadline cannot tell "still working" from "gone", so the second question
    is answered somewhere else and NOT by the number.** The same value used to be how
    long a legitimate compile may take and how long a genuinely dead worker goes
    unnoticed, and it went from ten seconds to ten minutes -- sixty times slower to
    notice a machine powered off, unplugged or suspended mid-compile, which on a
    `-j16` build is a handful of slots and a build that looks hung. Sizing for the
    slow compile is nonetheless the only choice the *number* has: sizing for the dead
    worker is the defect above, reintroduced. TCP keepalive with real intervals on
    the dispatch socket answers the dead HOST in ~16 s (Linux, macOS) or ~30 s
    (Windows) with the total untouched (#247), and the one row keepalive cannot reach
    -- a kernel that answers the probes while the process makes no progress -- is now
    the worker's own `Status::Progress` pulse (#245).
  - **Silence is only measurable against something that would otherwise be said, so
    the fix is a WIRE change and not a client-side heuristic.** A worker writes a
    five-byte pulse every `DefaultProgressInterval` while a compile runs, and the
    client stops measuring *how long this compile has taken* -- which must stay
    minutes -- and starts measuring *how long since the worker last said anything*,
    which is `DefaultCompileIdleTimeout` and is thirty seconds. Four things about it
    are load-bearing:
    - **Both numbers live in `CompileCacheWire`, and the RELATION between them is
      `static_assert`ed.** They bound one silence from opposite sides, exactly as
      `DefaultCompileLeaseTimeout` does, so neither end can pick its own without
      describing a fleet the other end is not running -- and the launcher links none
      of the library, so that header is the only place both can look. An idle bound at
      or below the cadence refuses a healthy worker on the ordinary jitter of its own
      reactor, which reads as a fleet that has stopped working; the assertion is what
      stops the next retune from spelling that.
    - **The pulse says NOTHING about the compile, and the encoder takes no argument
      so there is nothing to put in it.** A liveness signal carrying partial
      diagnostics would be a second, racy channel for output the result frame already
      carries whole -- two sources for one fact, differing by however much of the
      compile had happened when each was written. A receiver still DRAINS the declared
      length rather than asserting it is zero, so a later version that says something
      there cannot desynchronise a reader that ignores it.
    - **`MinSupportedVersion` moved WITH `CurrentVersion`, and that is the negotiation.**
      The issue's premise -- that the framing already lets a receiver step over what it
      does not know -- is **request-side only**: a reply carries a status byte and a
      length and no kind, so `DecodeReplyHeader` refuses an unknown status outright and
      the launcher turns that into a transport failure. Leaving the range open would buy
      a mixed fleet that fails several minutes into a translation unit, naming nothing;
      refusing the older request is `UnsupportedVersion`, which names the range that
      would have worked and arrives before a byte of source is sent. It also makes the
      capability implied by the version, so nothing has to remember a per-connection
      flag. Compatibility on this wire is not owed (#332).
    - **A pulse is a SECOND writer on the socket for the length of the answer, and the
      endpoint hands the socket back before it writes anything.** `ServeConnection` is
      the only writer by construction; while the responder answers it writes nothing, so
      the pulse takes over, and `SettlePulse` is where that stops being true. A reply
      written over a pulse still suspended inside `Write` is two writes sharing one
      write-op slot -- the same family as the READ slot's #663, reached from the other
      direction -- and it does not fail loudly, it splices five bytes into an object
      file. A pulse still parked past the bound therefore ENDS the connection, which is
      `SettleWatch`'s rule applied to the write side, and the `break` falling through to
      `Close()` is the only cancellation a parked write has. It is bounded and ordinarily
      costs one step, because the pulse wakes on a clock this side owns rather than on
      the peer.
      - **There IS symmetry now, and this bullet used to deny it.** It said *"there is
        no `ClaimWriteSlot`, so the write slot is exactly as shared and entirely
        silent"*, and #893 added one -- so the text told the next reader not to look for
        a guard that was already in the tree, which is the expensive direction for a
        stale rule to fail in (#1218). core-cpp's `contract::claimWriteSlot`
        (`core/net/SocketContract.hpp`, once `Net/WriteSlot.hpp`) does for the write slot what
        #663's `ClaimReadSlot` does for the read slot: a double-arm ends the process naming the
        slot -- in every build since core-cpp 0.3.0, in Debug only before. It reaches THIS
        case because
        `WriteAll` sends a whole frame in one `Write`, so a parked write is a half-sent
        frame. Watched by core-cpp's `socket-contract-canary`, and the rule
        lives in [`wire-and-protocol.md`](wire-and-protocol.md).
      - **`ReclaimFromPulse` is still load-bearing and the guard does not replace it.**
        The claim names a misuse by ending the process; it does not SETTLE the pulse, so
        the ordering test remains the only thing that would notice the settle going
        away before a double-arm aborts a live node.
    - **A test that only watches the answer cannot see any of it.** Reading one framed
      reply stops at the first terminal status, so a pulse emitted AFTER the reply -- what
      a missing settle produces -- is invisible, and a case asserting "every frame but the
      last is a pulse" passes VACUOUSLY on a build that pulses not at all, because with
      one frame the run before the last is empty. So the ordering case reads to EOF,
      requires at least two frames, and there is a control on a surface that pulses
      nothing. Both were observed: a counterfactual that stopped the pulse left the
      ordering case green until the size guard was added.
    - **A budget derived by copying another budget drops the field that made them
      different, and nothing here could see it.** `DispatchBudgetsOf` built the
      compile budget as `auto compile = control; compile.total = ...`, reasoning in a
      comment directly above that "only the total differs" -- true when written, false
      the moment #247 put `KeepAlive::Yes` on the compile leg without touching
      `main.cpp`. Every shipped launcher dialled unarmed, so keepalive was present,
      correct and unreachable, and the ten-minute dead-worker figure stayed true by
      accident. Three things had to be absent at once for that: `main.cpp` is in **no
      test target**, so the only production producer of these budgets could not be
      read by a test; the type's default member initializer was the sole statement of
      the intent and had no reader; and `Dispatch_test.cpp` asserted against
      `DispatchBudgets const defaults` -- the TYPE's defaults, which were right and
      which production bypassed. So: the derivation lives beside the type as
      `DispatchBudgetsFor`, it NAMES every field on which the two legs differ instead
      of inheriting the rest, and the test reads the production derivation rather than
      the default. A `<field> = <value>` written in a struct definition is a claim; it
      is only a rule once something reads it.

      Naming the fields leaves the intent written **twice** -- in `DispatchBudgetsFor`,
      which production uses, and in `DispatchBudgets`'s own default member
      initializers, which every caller taking the default argument uses -- which is
      the defect's own shape one level up. So they are `static_assert`ed equal through
      a **defaulted** `operator==`, never a hand-written one: a field added to
      `ExchangeBudget` joins that comparison by itself, where a spelled-out comparison
      would go on agreeing about the fields it still mentions. And the knobs travel as
      a named struct, because three adjacent `std::chrono::milliseconds` parameters
      transposed at a call site in `main.cpp` -- which is in no test target -- hands
      the compile leg the cache's ten seconds and restores #223 in full, silently.
  - **Zero means UNBOUNDED, and the arithmetic alone says the opposite.** A zero total
    puts the deadline at `Now()`, so every exchange dies on the reactor's next turn —
    a knob documented as "turn the ceiling off" that turns the *cache* off instead,
    silently, because every caller answers a transport failure by compiling. The
    timer is not armed at all below one millisecond.
- **A node's toolchain identity is derived once and the machine keeps moving, so it
  is re-derived.** The launcher recomputes its fingerprint per invocation; a worker
  computed one at startup and then ran for weeks. A compiler patched in place — a
  distribution upgrading `gcc`, a Windows SDK update — left the node advertising the
  pre-upgrade digest while spawning the post-upgrade compiler, so clients received
  objects built by a compiler they had not keyed against and stored them in the
  shared cache under the old key, where the whole fleet then read them (#238). A
  wrong-object path, and the one a staggered upgrade across an estate walks into
  deliberately.
  - **Re-register under the new fingerprint AND stop serving the old one; they are
    not alternatives.** Stopping is the load-bearing half — it *is* the wrong-object
    path — but stopping alone takes a machine out of the fleet on every routine
    upgrade, and a staggered rollout would empty the fleet one machine at a time with
    nothing saying so. The dropped fingerprint is refused `UnknownFingerprint`, which
    already exists with its own wire code and counter; nothing new is invented, and
    the client falls back to a local compile. The compile port is updated **before**
    the registration, or the window between them is the defect itself.
  - **The staleness check spawns nothing, and that is what makes it affordable.**
    `ComputeToolchainStamp` is pure filesystem stats — it is its *inputs* that cost
    driver spawns. So the banner, the resolved compiler path and the include roots
    are recorded at survey time and the stamp is recomputed from them: a stat of the
    binary plus one per root, on every heartbeat, with the expensive re-survey paid
    only when it says something moved. Re-stamping per job would be the cost #188 is
    separately removing from the launcher's hot path.
  - **A witness-driven recheck can only notice what it is already watching, so it
    needs an unconditional sweep beside it.** A toolchain that leaves the served set
    takes its evidence with it, and `IdentityDefect::UnrunProbe` is transient by
    construction -- so one unlucky spawn drops a healthy compiler permanently, and a
    node left serving nothing has no witnesses at all and could never recover without
    a restart. That directly contradicts the promise the rest of this makes, that a
    compiler may come back with the next package. A slow unconditional survey is the
    way back; it must answer unchanged when it finds the machine unchanged, or it
    re-registers the whole fleet on a timer.
  - **The re-survey is `ResolveToolchains` itself, never a cheaper second
    derivation.** A node whose identity was computed one way at startup and another
    way afterwards drifts from its own clients exactly when nobody is looking.
  - **A witness recorded from a probe that did not RUN is worse than no witness.**
    The identity was computed from what the FIRST include probe found, so a witness
    built on a failed SECOND probe watches a narrower root set than the fingerprint
    covers — and the node then stops noticing SDK-side changes for that toolchain,
    permanently and in silence. This is #225's rule reaching a second caller, by a
    door nobody had opened yet: **a probe that did not RUN is not a probe that
    answered nothing**, so `IncludeSearchRoots::answered` decides, never an empty
    `roots`. Not watching a toolchain is visible at the next sweep; watching the
    wrong evidence is not.
  - **An operator's pinned identity has no witness and is never reconsidered**, and
    an unstampable compiler yields an empty stamp that must read as "cannot be
    watched" rather than as "changed" — the latter is a re-survey loop with no exit.
  - **A set that stops being fixed at startup makes every remaining reader of it a
    race.** `toolchains` was `const` and read by the ready line on the main thread;
    making the heartbeat thread able to replace it turned that read into UB on a
    `std::map`. The count is captured before the thread starts -- which is also the
    honest number, since a ready line is a statement about starting.
  - **A map a job reads must not be held as an ITERATOR across the compile.**
    `CompileJobRunner::Run` looked its compiler up and then dereferenced that
    iterator twice far downstream — after the scratch directory was made and the
    whole preprocessed source written — on the two lines that decide which program
    executes and which driver family names the output flag. Making the map
    replaceable turned that into a dangling read. The compiler path is copied out
    under the lock at lookup, so a job already admitted finishes against the compiler
    its client was told it would get. A test that replaces the map before or after
    `Run` proves nothing; the replacement has to land while a job is provably inside.
- **Duplicate suppression is asked BEFORE capacity, and the order is the whole
  point.** `LeaseTable::Acquire` needs a worker id, so the code this was lifted from
  had to `Pick` first — which meant a second client missing the same key at a busy
  fleet was told `NoCapacity`. Both conditions genuinely hold; the operator reads
  "buy more machines" where the truth is "this build asked for the same object
  twice", and it lands hardest exactly where duplicate suppression does the most
  good: a wide parallel build where many translation units miss one key at once.
  That is the same defect the no-worker/no-capacity split already exists to prevent,
  reached by a third route. `LeaseTable::IsInFlight` is what makes the question
  answerable without a worker; it is **advisory**, and `Acquire`'s own refusal stays
  as the backstop for the race, because that one decides atomically. It reports
  *liveness*, not presence — an expired entry is left behind until the next
  `Acquire` for that key sweeps it, so a check on the map alone would refuse one key
  forever after a single client abandoned it, with nothing saying so.
  A client's EXCLUSIONS are asked inside `Pick`, before capacity and not as a match:
  a fleet whose every matching worker was excluded answers `NoWorker` on the wire and
  moves `DispatchLeasesAllExcluded`, never `DispatchLeasesNoWorker`, because one is
  the network and the other a toolchain nobody serves. `PickErrorTable` rows carry
  the counter, and `PickRefusalsCountOnce` keeps the code-keyed table from counting a
  second time.
- **A launcher remembers a scheduler NOTHING reached, per user, for fifteen seconds**
  (`Cc::ReachabilityMemo`). One process per translation unit made every miss of a
  wide build pay the full connect budget, a second preprocess and a fingerprint
  against a machine that was down. Only `TransportFailure::Unreached` at the
  CONFIGURED endpoint writes it -- a leader a redirect named is not the configured
  machine, and a peer that was reached and then went wrong is not a down one -- and
  a completed lease clears it. Stamps are WALL clock because a steady clock is not
  comparable across processes after a sleep, so a stamp in the future is its own
  outcome and reads as stale. It lives in the per-user state directory rather than
  `TEMP`: `/tmp` is shared between users on POSIX, and every e2e fixture already
  isolates the state directory.
  It remembers a WORKER nothing reached as well, by the endpoint it ADVERTISES, for a
  minute, and the next launchers name the fresh entries on their LEASE, newest first
  and at most `MaxLeaseExclusions`, on every redirect hop. **One verdict decides both
  ends**: `TransportFailureTable`'s `marksUnreachable` column, true for `Unreached`
  alone -- a worker lost mid-compile, outwaited or `Silent` was reached and is up,
  and naming it would steer every launcher off a working machine for the whole TTL.
  The list is read BEFORE the dispatch, so it can never name the worker that dispatch
  is granted; what the dispatch learns comes back as `unreachedWorker`, for the next.
  Only a dial at the worker's NAME can set it: a dial HINT that reached nothing is
  followed by the name, and the name's outcome decides.
- **A lease has THREE transitions and expiry is only the third.** `Acquire` takes
  one, `Release` resolves it, and the lifetime running out is the safety net for a
  client that *died* — `Ctrl-C` on a build. For a long time only two of the three
  were built: there was no wire verb for resolving, so `LeaseTable::Release`,
  `ReleaseWorker` and `WorkerRegistry::JobFinished` had no production caller at all,
  and every key stayed suppressed for the full 600-second timeout. Recompiling one
  translation unit inside ten minutes of dispatching it was refused
  `AlreadyInFlight` and fell back to a local compile, while `inFlight` only ever
  climbed between heartbeat overwrites. **The client sends `Release`, not the
  worker**, and on *every* path out of the compile — an object built, a job refused,
  a worker that was not there — because the client is who the lease was issued to
  and the only party that sees all three. That is why the compile half of `Dispatch`
  is a function: four early returns are four places to forget it. The release rides
  a **fresh** connection; the scheduler sweeps one idle for five seconds and a
  compile is longer, so reusing the lease socket would fail exactly when there was
  something to release.
- **A lease token is a CREDENTIAL, and its MAC covers the granted endpoint or it is
  a credential for the whole fleet.** For a long time it was a small decimal serial
  the scheduler minted for its own bookkeeping, and the worker's validator was
  literally `[](...){ return true; }` — so a worker compiled for anyone who could
  reach its port and present any string, and membership (which matches on a source
  address) was the entire boundary. A grant now carries an **Ed25519 signature**, made
  with the ISSUING scheduler's own identity key and naming that scheduler, over the
  worker's **endpoint**, the fingerprint, the object key and an absolute expiry (#178;
  an HMAC under the pre-shared key until then, which could not say WHICH member minted
  a grant and so could not refuse one the cluster had removed). The endpoint is the
  load-bearing field: a signature over "somebody may compile" is a token captured on
  the way to one machine and replayed against every machine that trusts the signer,
  which is the identical failure `Cluster::DiscoveryWire` closes by covering the
  `(node, endpoint)` pair. The claim fields are **length-prefixed, never joined**,
  and here the separator argument is not hypothetical — an endpoint is `host:port`,
  so `{endpoint="a", key="b:1"}` and `{endpoint="a:b", key="1"}` would authenticate
  identically. The message is prefixed with its own **domain label**
  (`fastcache-lease-v3`), because the same key signs Raft handshakes and node proofs,
  and one key serving two constructions is how a signature made for one
  comes to pass for the other. The token wraps the `LeaseTable` serial rather than
  replacing it, which is what keeps that component pure — no key, no wall clock, no
  crypto in the thing whose whole job is a deterministic unit test. See
  `src/Pace/Distributed/LeaseToken.hpp` (#281, #282, #178).
- **A credential lives in `SecureByteBuffer`, and the wipe is an ALLOCATOR rather than a
  destructor.** The cluster key was a plain `std::vector<std::byte>` in every one of its
  holders, freed without being touched — the key that MACed discovery proofs and lease grants
  then, left in freed memory for whatever allocated next (#324). The key is gone since #178
  PR 6; the rule is about every credential, and an identity key's secret half is one. The wipe rides on
  `deallocate` so that every release goes through one door and no holder has a line it can
  forget — the `Refuse`/`ClaimReadSlot` argument again, a guard folded INTO the operation
  being self-enforcing where one called alongside it needs a scan. It is what makes the
  COPIES safe without anyone thinking about them, and there are several: the validator
  takes the key **by value** and `SchedulerService` builds its own from a span, so one
  secret lives in several buffers with independent lifetimes. It also covers a vector that
  GROWS, whose old block is freed long before the object dies and which a destructor-based
  design cannot see — **no holder here grows one today**, so that half is cover for a
  future change nobody would connect to the secret, and saying so matters because the
  tempting version of this rule cites a growing holder and this tree has none. The first
  draft of this bullet did exactly that.
  - `std::memset` is not a wipe. Measured, one function, both spellings inlined into one
    `main` under LTO with hidden visibility and `-fno-semantic-interposition`: gcc 14.2 and
    clang 22.1 **delete the `memset` entirely** and both keep the `explicit_bzero`. The
    platform table is in `SecureBytes.cpp`; macOS and the BSDs take the volatile-pointer
    fallback deliberately, because their `explicit_bzero`'s availability varies with the
    deployment target and a wrong guess is a build break on a host this lane cannot test.
  - **Container-agnostic is not the same as SUFFICIENT, and where it falls short is ONE
    platform.** The allocator instantiates for `std::basic_string` too and is not enough
    there: short-string optimisation keeps a short secret INSIDE the object, where no
    allocator is ever called. Measured, sweeping length 0–40 against an arena that counts
    allocations:

    <!-- table-total: none -->
    | standard library | `sizeof` | inline capacity | first allocating length |
    |---|--:|--:|--:|
    | libstdc++ 14 | 32 | 15 | 16 |
    | MSVC STL 19.51 | 32 | 15 | 16 |
    | libc++ 22 | 24 | **22** | **23** |

    **libc++ is the sole outlier**, so the claim is not *this varies per platform* — it is
    that a **16-to-22-character** secret is on the heap on Linux and Windows and lives
    **inline on macOS**. The consequence is operational rather than theoretical: **the
    platform to write the failing test against is macOS**, and a string fix validated on
    Linux and Windows looks complete while being absent exactly where it is not. (CI pins
    MSVC toolset 14.44 and 14.51 was measured; the inline capacity is an ABI property of
    that `std::string`, so they are expected identical — inferred, not read.) Every
    `--requirepass` and scheduler token is far inside all three — `hunter2` is 7 characters
    and allocates **0** times — so a string fix built on this seam alone is correct for
    long secrets, silently absent for short ones, and green under any test written with a
    realistic value.

    **So a secret does not live in a `std::basic_string` at all: `SecureString` puts the
    characters in a `std::vector`, and that is #1125's answer rather than the inline wipe
    this paragraph used to call for.** The wipe was the obvious repair and it cannot be
    made correct: a destructor-based one misses the INLINE-TO-HEAP transition, where the
    characters are copied out and the inline buffer is left holding the secret in the
    object's own storage, at a moment no destructor and no allocator is told about. There
    is no hook there, so that residue can only be avoided rather than cleaned. A
    `std::vector` has no small-object optimisation, so every byte of a secret is in a
    block the allocator releases, identically on all three libraries -- which also
    retires the sentence above about macOS being the platform to write the failing test
    against. The measurements stay because they are why the shape had to change; the
    REMEDY they argued for did not survive being implemented.
    `SecureBytes_test.cpp`'s *"a text credential short enough to fit inline is still in
    allocator storage"* is what holds it, on every leg, with an eight-character secret
    that both libraries would have kept inline.
  - The holders are found by NAME (`scripts/check-credential-containers.sh`), and the
    limits of that are on the script rather than implied: a credential under a name its
    table does not carry is invisible to it, `clusterKeyFile` is a PATH and not a row, and
    a bare `key` cannot be one because this is a cache and `key` is what it stores. Each
    row must still MATCH something — a term that has quietly stopped matching is a guard
    that has quietly stopped guarding and reads exactly like a clean tree. It earned its
    place on its first real run, finding two holders in `src/tests/FleetHarness.hpp` that a
    careful hand census had just missed.
- **Every signature carries its domain label as its first FIELD, and one identity key signs
  under all of them.** The pre-shared key's seam for this -- `Cluster/ClusterSigning.hpp`, its
  `SigningDomainTable` and `ctest -R psk-signing-seam` -- was DELETED with the key at #178 PR 6
  (#402 is why it existed). The question it answered did not go: a scheduler's node key signs
  its leases, its challenge replies, its Raft proofs and verdicts and its discovery proof, so a
  construction whose label another shares is a credential valid on
  the other surface. `NodeProof_test` asserts the labels distinct ACROSS constructions; the
  argument is in `consensus-and-cluster.md`.
- **Asymmetric cryptography has ONE seam too: `Core/Ed25519`, `Core/X25519` and `Core/Hkdf`,
  over the vendored Monocypher (#178).** Only `Ed25519.cpp` and `X25519.cpp` include a Monocypher
  header, and `ctest -R crypto-seam` refuses any other first-party file that does -- the include
  directories are PUBLIC on the vendored library, so the build alone cannot say it. A primitive
  the seam lacks is added THERE, beside the RFC vectors that check it, never by reaching past it.
  - **Why asymmetric at all.** The per-node identity #178 builds has to let ONE machine be revoked
    without rotating anything on the others, and with symmetric keys a verifier holds the key
    that mints: Raft is all-to-all, so every key reaches every member, and every member can then
    sign as every other. Verifying without being able to mint is what a signature is.
  - **Why Monocypher.** OpenSSL is optional here (`PACE_ENABLE_TLS`, off by default) and
    the launcher, which will verify signed leases, must stay free of it; hand-written curve
    arithmetic is refused when an audited, constant-time, public-domain implementation exists.
    Monocypher is two C files with no dependency and no random generator of its own -- every
    seed and ephemeral secret is the CALLER's, which is what #1527's `ISecureRandom` supplies. It
    is built as C++ (`cmake/Monocypher.cmake`), and 4.0.3 is the floor: its changelog opens with
    a fixed timing leak in EdDSA signatures.
  - **What the seam decides once, so no caller can get it wrong.** Ed25519 is RFC 8032's, over
    SHA-512 (`crypto_ed25519_*`), NEVER Monocypher's default `crypto_eddsa_*`, which is EdDSA
    over BLAKE2b: a different scheme no other Ed25519 verifies and the RFC vectors cannot test.
    `crypto_ed25519_key_pair` WIPES the seed it is handed, so it is handed a copy. A signature
    whose S is not below L is refused -- that range check is all that stops a valid signature
    being turned into a second one. An all-zero X25519 result is refused, since a low-order peer
    key fixes it for everybody -- the ephemeral exchange of the node proof and of the Raft peer
    handshake both reach it (`DeriveNodeSessionKeys`, `RaftPeerSession`). And a raw X25519
    secret is not a key: it goes through HKDF.
  - **A small-order key proves nothing, and Monocypher does not say so.** It checks the COFACTORED
    equation, [8](SB - hA - R) = 0, and multiplying by 8 sends every point of small order to the
    identity -- so with a small-order A, a small-order R and S = 0 the equation holds for EVERY
    message. Its decoding refuses neither point. The all-zero key with the all-zero signature
    verified anything -- 400 of 400 through `DiscoveryService` with real secure-random nonces when
    it was reported: a proof whose key vouches for itself was no proof, and one reaching the roster
    question as an UNKNOWN key was reported with the `--cluster-admit` that would admit a key
    anybody can prove. So `Ed25519Verify` asks `Ed25519PublicKeyFaultOf` of A AND of R before
    Monocypher is asked, and the vendored library stays unmodified -- the seam is where a missing
    check goes, as it is where a missing primitive goes.
    - **SMALL-ORDER is libsodium's blocklist** (`ge25519_has_small_order`), seven rows compared
      with the SIGN BIT MASKED: the five y coordinates of the eight torsion points (0, 1, p - 1
      and the two of order 8) and the non-canonical twins p and p + 1. Masking covers both x of
      each y, and the x = 0 "negative zero" RFC 8032 refuses. It is a TABLE in `Ed25519.cpp`, and
      it was re-derived independently before it was trusted -- the subgroup generated in exact
      arithmetic from the order-8 point, and every y + p below 2^255 decoded -- because a
      blocklist copied wrong refuses nothing and passes every test that uses the same copy. The
      test file spells its OWN copy for the same reason.
    - **NON-CANONICAL is y at or above p**, which Monocypher accepts ("*Allow* non-cannonical
      encoding" in `crypto_eddsa_check_equation`, `fe_frombytes` masking bit 255 and reducing)
      and RFC 8032 section 5.1.3 refuses. Ten of the nineteen such spellings decode to points
      that are NOT of small order (y + p for y in 3-6, 9, 10, 14-16, 18): nobody holds their
      discrete logarithms, so none can sign, but each is a second spelling of a point, and a
      revocation or a roster keyed on bytes would miss the twin. Refused for A and for R.
    - **A MIXED-order key is not refused**: telling one apart takes a multiplication by L, and it
      grants nothing a freshly minted key does not -- only the holder of the honest half signs.
      So a REVOCATION is per key bytes: a forgotten holder's A0 + T reads as unknown, not
      revoked (`consensus-and-cluster.md`, "per key BYTES, not per HOLDER").
  - **And every door a key ENTERS by asks the same predicate and refuses BY NAME, before anything
    is stored or approved.** The verify is the guarantee; the door is where somebody is TOLD, and
    where a key that proves nothing is kept out of a list an operator reads and compares. The
    doors on master: `ParseEd25519PublicKey` (every flag and verb reading a key as TEXT --
    `--cluster-admit[-learner]`, the cli's `cluster-admit`, and the leader's `ClusterAdmit`);
    the enrollment door (`EnrollmentResponder::AnswerEnroll`, the
    malformed row: no build mints such a key); `ValidateAgainst` and `Apply`
    (`KeyStanding::Unusable`, asked first, since it is a fact about the POINT); `DecodeState`'s
    roster rules; and `DecodeRoster`, by the holder's name. A REVOKED entry is not asked --
    revoking a key that proves nothing grants nothing. A key reaching a VERIFY only (a discovery
    proof, a node proof, a Raft handshake, an endorsement, a lease) needs no door of its own.
    A node's OWN key is derived by `Ed25519KeyPair::FromSeed` from a clamped scalar, which is
    never of small order, and its file is refused when the stored half disagrees.
  - Secrets at the seam live in `SecureByteBuffer`, temporaries are wiped with `SecureZero` --
    the tree's one zeroing primitive, rather than Monocypher's `crypto_wipe` beside it -- and the
    names they are held under are rows of `scripts/check-credential-containers.sh`, which since
    #178 also refuses a secret held in a `std::array`, the spelling of this tree's PUBLIC keys.
- **That consolidation changed the discovery proof wire, and
  `DiscoveryWire::CurrentVersion` deliberately did NOT move.** (#178 later moved discovery off
  the shared key altogether and DID move it, 1 to 2: a key and a signature where a MAC was is
  a change of GRAMMAR. The paragraph below stands as the other half of the same question.) The proof message gains
  `fastcache-discovery-v1` as a leading length-prefixed field, so every proof tag differs
  from a pre-#402 build's and a node on an older build cannot prove the key. Lease token
  messages are byte-for-byte unchanged: `fastcache-lease-v1` was already the leading
  field, and a test pins that against the pre-seam construction written out as a literal
  rather than against the code that produces it — "the tests still pass" cannot show it,
  because the tests moved with the code.

  Leaving the version alone is deliberate and is the load-bearing half. What changed is
  the MAC *input*, not the datagram grammar, so bumping it would misdescribe the format.
  It is also the better of the two failures: an older node reaches the proof step and is
  logged `discovery: <node> at <endpoint> failed to prove the cluster key`, where an
  unsupported version is silently dropped by `ClassifyDatagram` and presents as peers
  seen and never admitted — the same silence `--discovery-reply-port` exists to prevent.
  Loud beats silent; a cluster that quietly will not form while every node looks healthy
  is the shape that costs a day. The obvious counter-proposal — "we changed the MAC, so
  bump the version" — is what this paragraph is here to answer.
- **The MAC is verified BEFORE any other claim is reported on, and the expiry is not
  a capacity bound.** Checking the plaintext endpoint first would be cheaper and
  would turn a diagnostic into an oracle: `EndpointMismatch` and `Expired` are only
  ever reported for a token that provably came from the scheduler, so a forger
  learns exactly that their forgery failed, while an operator whose worker
  advertises a name clients do not resolve is told precisely that — which is the
  overwhelmingly common cause and is a NAT or a hostname, not an attack. The expiry
  carries **five minutes of slack** because a fleet's machines are not all
  NTP-managed and an unsynchronised clock is minutes out, not seconds; it bounds how
  long a *captured* token is worth replaying and nothing else. A worker will
  therefore accept an authentic lease for minutes after the scheduler stopped
  suppressing its key, and that is correct: what bounds what a worker runs is its
  own slot accounting and its in-flight byte budget, never the lease. Anything built
  on "an unexpired lease implies the scheduler still holds capacity" is built on a
  guarantee that does not exist.
- **A lease is single-use, and until [#614](https://github.com/LASTRADA-Software/pace/issues/614) nothing enforced it.** The scheduler mints
  one grant per lease, the client presents it in exactly one COMPILE frame with no retry
  (`Dispatch::CompileOnWorker`), and a RELEASE goes to the SCHEDULER rather than to a
  worker. So a token arriving twice at one worker is a replay and never an honest
  client — and for the whole of #281, #322 and #421 it was served every time it arrived.
  A captured grant was replayable at its granted worker, at will, until it expired.
  `SpentLeases` closes that: an authentic, unexpired grant is spendable once, a second
  presentation is refused as `Replayed` with a counter of its own.
  **The spend runs LAST, after every reading of the token**, because it is the one step
  with a side effect: a grant declined for a wrong toolchain, a wrong endpoint or an
  expiry has not been consumed, and the client still holds something legitimate.
  **The bound is the grants' own `expiresAt`**, pruned amortized onto the next spend —
  no timer, because a worker with no traffic has nothing to prune. Keyed by a digest of
  the token, not by the serial: `LeaseTable::_nextToken` restarts at 1 with the
  scheduler process, so serials repeat across a restart while tokens do not.
  **What it does not close, stated rather than discovered**: a worker restart empties the
  set, so a token captured and withheld before the restart is spendable once afterwards.
  That is the residual the expiry is documented to bound, and it is not a regression —
  the term expectation had the identical hole for the identical duration, since a
  restarted worker had learned nothing and accepted every term.
  - **Retention window and acceptance window are ONE window, and the way to keep them one
    is ONE PREDICATE rather than one constant.** `VerifyLeaseToken` accepts a grant for
    `LeaseTokenClockSkewSlack` past its own `expiresAt`, so a spent entry dropped at
    `expiresAt` alone would leave that token acceptable AND unspent for the rest of the
    slack — replayable again, five minutes at a time. **A spend that expires before the
    thing it is spending is not a spend.** So `SpentLeases::Spend` prunes through
    `Detail::WithinAcceptanceWindow`, the verifier's own function, and takes the same
    `slack` the verifier was given: sharing the CONSTANT would leave both sites spelling
    the comparison, and the comparison is the part that is easy to get wrong. The prune
    runs BEFORE the lookup, and a token reaching there is inside the window by
    construction, so nothing can be pruned by its own arrival.
  - **And the comparison comes BEFORE the subtraction, because `expiresAt` is
    attacker-chosen.** Not `now > expiresAt + slack`: that sum pushes an already-large
    instant past the tick count's ceiling, and `expiresAt` decodes from the wire up to
    `MaxExpiryMillis`. The difference is not unconditionally safe either — `now` is
    whatever this host's wall clock says, including a pre-epoch instant on a machine with
    a dead RTC — so the ordering is established with a comparison, which cannot overflow,
    and the subtraction only ever runs on `now > expiresAt >= epoch`, where the result is
    bounded by `now` and therefore representable.
  - **A wall clock stepping BACKWARDS is a second residual, and not the restart case in
    disguise.** Retention is re-evaluated only inside `Spend`, against the caller's `now`,
    so "everything still acceptable is still remembered" holds exactly while the clock is
    monotone. A worker whose clock is minutes AHEAD — a resumed VM, a container with no
    time source, the population `LeaseTokenClockSkewSlack` exists for — prunes entries
    whose window merely looks passed, and when NTP steps it back those tokens verify again
    and are no longer remembered. One extra spend each, bounded by the same window and by
    how far the clock moved. Two worker PROCESSES advertising one endpoint is a third, for
    the same reason: each keeps its own set, and that one is a deployment mistake rather
    than a property of this type.
- **The learned term is a DIAGNOSTIC, not a gate — and the gate it replaced was exactly
  inverted.** #421 made a worker refuse any grant naming a term below the one it had
  learned, taking the maximum so a late message could not walk it backwards. Measured on
  the tree before [#614](https://github.com/LASTRADA-Software/pace/issues/614), with a worker holding term 7 and a scheduler whose Raft
  directory had been wiped truthfully stating term 0: the **honest fresh grant was
  REFUSED** (0 < 7) and a **token captured under term 7 was ACCEPTED** (7 >= 7). The rule
  written to stop replay refused every legitimate grant and admitted the replayed one, in
  precisely the scenario it existed for — and it stayed that way until every worker in the
  fleet was restarted, with only `..._lease_stale_epoch_total` climbing to say so, which
  reads as an election storm.
  So the comparison is gone, `LeaseEpochCheck` with it, and `KnownSchedulerTerm` adopts
  whatever an authentic, unspent grant names, in either direction. **The monotonic term
  was standing in for replay protection all along**; once the spend provides that
  directly, a lower term no longer has to be refused and the downward path falls out
  rather than needing to be designed. Note what that sentence may NOT say: *not* "a lower
  term is a scheduler that was legitimately reset". It is a term that REGRESSED, which is
  a reset **or** a grant that arrived late across a leadership change, and the bullet
  below is there because an earlier draft of this one made exactly that claim.
  **The trade is real and is stated rather than hidden**: an unspent grant captured
  before an election used to stop being good at the next one, and now stops being good at
  its expiry. That is the weaker of the two bounds and it is the one the expiry already
  documented; the stronger bound could not be kept, because a lower term and a replayed
  older grant are indistinguishable inside a token, and refusing them together is what
  stopped the fleet.
- **`WorkerJobsRefusedLeaseStaleEpoch` was RETIRED, not left reading zero.** The refusal it
  named can no longer happen. A series reading zero because its event is impossible and
  one reading zero because the event did not happen are two facts nobody can tell apart
  from a graph — which is this file's *skipped, absent, unstarted and failed are four
  states* rule, one level up. Its replacements are
  `pace_worker_jobs_refused_lease_replayed_total` (the new refusal) and
  `pace_worker_scheduler_term_regressions_total` (the adoption, which is not a refusal
  and so is deliberately not in `LeaseRefusalTable`).
- **A worker cannot tell a scheduler RESET from a grant that arrived late, so neither the
  counter nor the line may claim it can.** Both shipped asserting the reset — the counter's
  help said *"zero except on the day somebody resets a cluster"* and the log line named a
  wiped Raft directory outright. Both are false on any fleet that elects: a client holds
  its grant across a preprocess and a multi-megabyte upload, and an election inside that
  window delivers a term-N grant behind a term-N+1 one at the same worker. That is the
  ordinary case, and it is indistinguishable from the alarming one in the token.
  **The RATE separates them** — occasional counts tracking elections against a sustained
  rise — so the signal reports what it OBSERVED (`TermTransition::Regressed`, a term
  regression) and names both causes. This is #614's own defect class pointing the other
  way: the ticket exists because `WorkerLeaseStaleEpoch` climbing *read like* an election
  storm, and the first replacement read like an operator error that had not happened. A
  confident wrong signal is worse than a vague right one.
- **Adoption happens after the MAC verified AND after the spend, never before either.**
  The grant is a learning channel precisely because `VerifyLeaseToken` authenticates
  before it reports on any claim; reading a term off a *refused* token would let anybody
  who can reach the port move a worker's expectation at will. The spend ordering is the
  second half and it is what makes the downward path safe: a captured grant naming an old
  term, replayed, would otherwise teach a worker a term the fleet has moved on from, on
  demand, as often as somebody sent it. Spending first means only a grant nobody has used
  can move the number.
- **Never-learned is a state, not a term value.** `StandaloneSchedulerTerm` is
  literally `0` — the term of a node leading alone — and its own declaration warns
  that "a literal at a call site is exactly how somebody later reads it as unknown and
  starts treating it as one". So `KnownSchedulerTerm` carries a flag beside the
  number. It still matters with nothing refusing on the term: it is what keeps the FIRST
  grant from reading as a reset. Term 0 arriving into a worker that has learned nothing is
  an advance; the same 0 arriving into a worker that knows 7 is a reset. Collapsed to a
  zero sentinel, every cold worker's first job would announce a scheduler reset that did
  not happen.
- **The grant is the ONLY channel that teaches a term, and the heartbeat reply was
  deleted rather than defended.** #421's first shape had the scheduler state its term
  in the HEARTBEAT reply — fast, scheduler-driven, on a reply that was empty and whose
  client read nothing from it, so the bytes were additive in both directions. Every
  one of those facts was true and the design was still wrong, because that reply is
  **unauthenticated**: `Credential` is client-to-server, the `0xFC` surface is
  plaintext, and a reply carries no integrity protection at all. So anything able to
  answer a worker's `--scheduler` dial — on-path, a spoofed name, or an operator who
  typos the flag at another fleet's scheduler — hands it `UINT64_MAX` once, and that
  worker refuses **every authentic grant** until its process restarts.
  **Deleting the surface beats defending it**, which is the choice `CacheResponder`
  already records by taking no membership oracle — its absence IS the fix. Signing the
  term with the cluster key would have worked too, and would have been more code
  guarding more attack surface.
  The reusable half was written as **a value that can only be raised, never lowered, must
  not be writable by an unauthenticated peer** — a ratchet an attacker can turn is a
  permanent denial of service rather than a transient one. #614 is the sharper version of
  the same lesson and is worth reading beside it: **that ratchet was a permanent denial of
  service with no attacker at all.** An operator wiping a Raft directory turned it, and
  the mechanism could not distinguish them because nothing in the design could. A value
  that can only be raised needs a way DOWN, or the legitimate reset and the attack are one
  case — and the way down is not a permission, it is a different mechanism answering the
  question the ratchet was standing in for.

- **A scheduler IS a consensus member, alone or not, so no grant is unsigned.** It signs
  with its own identity key, which a consensus node always holds, and every worker checks the
  grant against the replicated state its own consensus applied (#178, owner decision 3). One
  without `--listen-raft` is refused by name (`SchedulerNeedsConsensusRefusal`), and
  that is a refusal of the SCHEDULER, not of a single-machine install: a pure worker
  runs no consensus. It closed #303, whose objection -- a refusal would break every
  single-node install -- was about refusing on a MISSING KEY; this refuses on a missing
  port, which `--print-surfaces` shows and every install can state. And it asks a flag,
  never a bind, so the socket-activation hole the worker's rule below has to backstop
  does not exist here. The row it replaced -- a non-clustered scheduler with no member
  set -- describes a node that can no longer be configured.
- **A worker checks a grant against the ROSTER ITS OWN CONSENSUS APPLIED** (`StateLeaseRoster`,
  #178). Principal mode is retired: every machine in a fleet is a member, a voter or a learner,
  that applies the replicated state, so the certified roster, its endorsements, the
  `--voter-key` anchors, the roster store and `RosterExpired` existed for a machine that no
  longer exists, and they are removed rather than kept dormant. A learner whose machine was off
  for days verifies against the state it last applied and catches up through Raft (a snapshot if
  it fell behind compaction); a grant from a voter forgotten meanwhile is refused as soon as the
  learner applies the forget.
  - **The threat that survives Raft, and its bound.** A worker cut off from its fleet with a voter
    the fleet has since FORGOTTEN still lists that voter, so the voter's fresh grants verify; the
    certified roster bounded that at its hour, and nothing replaced the bound until it was taken
    from the node's OWN consensus: past `LeaderSilenceBound` (65 minutes, chosen on purpose --
    too short refuses work during a consensus-only partition, too long widens the window) without
    a leader its APPLIED configuration counts, every grant is refused `Isolated`, a `NoRoster`-class
    fact about THIS worker with a counter of its own, and `consensus-leader-silent` is raised. The
    contact is the driver's (`RaftNode::LastLeaderContact`, read raw per reconcile pass through
    `LeaderReadingOf`), on the steady clock, so an NTP step neither lapses nor revives it -- and
    whether its leader COUNTS is asked of the voters the ROSTER applied
    (`StateLeaseRoster::NoteLeaderReading`), never of the driver's configuration: that is the
    ACTIVE one, which an uncommitted entry can move, so a learner promoting itself there would
    otherwise refresh the bound.
  - **The residual, and the direction it fails in**: WITHIN the bound, a worker isolated with a
    revoked voter honours that voter's grants until it next applies; and a forgotten voter that
    keeps the worker's session alive and goes on speaking AS a leader its stale configuration
    counts -- altered code, since an honest one alone loses its quorum and stops leading -- is not
    bounded at all. It fails OPEN in that direction; only reaching the fleet ends it. And the
    START counts as contact, so a node starting cut off has the bound to find its fleet -- which
    means every restart, and every reform, re-opens the window for a worker that stays isolated.
  - `SignedLeaseValidator` takes an `ILeaseRoster` and never a key, and
  `KeysOf` answers VOTERS only: a grant is a voter's, and a learner never leads. `NoRoster` is
  the state that records no voter's key yet -- a fact about THIS worker, so answering it before
  the signature is no oracle -- and `SignerRevoked` shares `LeaseUnauthorized`'s code and keeps a
  counter, for `ClusterMismatch`'s reason. A worker that runs no consensus holds no roster, so
  one other machines can reach is refused at startup (`RosterlessWorkerRefusal`) and a reload
  may not widen admission onto it.
- **Whether a worker CHECKS a lease is a startup decision, never a per-request
  fallback.** The two are not the same rule written twice. "No key, so skip the
  check" taken per request is silent degradation of exactly the kind this file
  exists to name: the compile port is open, all three `worker_jobs_refused_lease_*`
  counters read zero, and the fleet looks healthy from both ends — indistinguishable
  from a fleet where nobody ever presented a bad lease. Taken once, before anything
  is served, it is a node that states what it cannot do. So a node another machine
  could dial and holding no key is refused **by name** at startup, and a node
  nothing else can dial runs unchecked and warns once, loudly.
- **The question is "can a machine that is not this one reach the surface", never
  "is a key configured".** Keying the refusal on the key alone breaks every
  single-machine install to prevent nothing — a process on this host already has
  this host's compiler, so a lease check there escalates nobody. "Could reach it"
  has **two halves and either one closes it**: the socket (a loopback
  `--listen-node` answers no other machine whatever the policy says — which is what
  keeps this repository's own `--fleet-open` e2e fleets working) and the policy
  (`--fleet-open`, a roster, or consensus). **A roster counts**, because a node that
  verifies keys admits machines by proof and by ticket whatever address they dial from,
  and a clustered node's admitted set GROWS at runtime: the agreed keys are published
  into the same oracle the compile port consults, so such a node admits machines nobody
  typed. `CompilePortFacesTheNetwork` and
  `AdmitsRemotePeers` in `NodeConfig.cpp` (#282).
  - **"Loopback" is an IP LITERAL -- `127.0.0.0/8` parsed as four octets, or `::1` -- and a
    NAME never is.** `IsLoopbackHost` matched `127.` as a PREFIX, so a bind spelled
    `127.cache.example.com` read as unreachable from the network whatever it resolved to and
    switched the lease check OFF: the socket half failing OPEN. A name is judged by what it is,
    and every rule asking the question now fails closed (`localhost` included, which the
    usability rows that want it spell out themselves).
- **A validator returns a REASON, not a `bool`, and it does not take the endpoint.**
  Three refusals are distinguishable on the wire and counted apart, so a boolean
  collapses the one distinction an operator needs — somebody probing the port, a
  worker whose advertised endpoint is not the one clients dial, and a machine whose
  clock has drifted are three different things to go and do. The endpoint checked
  against is the WORKER's own advertised address, read through
  `Cc::IAdvertisedEndpointSource` at every request: a parameter would invite a caller
  to pass something the *request* supplied, which is the whole failure the endpoint is
  inside the MAC to prevent. **That rule is about the DIRECTION the value comes from,
  not about when it is read** — it said *captured at construction* until #1279, which
  was a true statement of the code and never what made the rule sound. A node behind a
  NAT learns its address after it starts, so a captured one is a worker verifying
  against an address nobody dials.
- **And the address it verifies against is the address it is REGISTERED under, at every
  moment.** One seam, read by the lease check and by the registration, published at one
  point — the heartbeat that re-announces. Two independent readers of the live
  configuration is the shape that looks more correct and is the one that breaks: a
  reload would move the check immediately while the scheduler still held the old entry,
  so the worker would refuse grants it had authentically signed, for a whole heartbeat
  interval, with nothing anywhere misconfigured. The registration's own key is
  `(fingerprint, endpoint)`, so the old entry is WITHDRAWN rather than left to expire
  (`AdoptRegistrars`) — without which the scheduler goes on minting grants for an
  address this worker has left, and those grants are valid credentials for nothing. And the refusal is
  never `UnknownLease` — that is the SCHEDULER's code, meaning "a lease I issued and
  have since forgotten", and a worker answering with it sent an operator to the
  scheduler to look for a fault that is local.
- **The two endpoints a node advertises -- the `0xFC` one and the Raft one -- have ONE
  publisher, `EndpointResolver`, and it re-derives both from the configuration IN FORCE
  over the LIVE route host**, never from a flag and never from a snapshot. `--advertise` and
  `--raft-self` default to `auto` (a row of `AdvertiseModeRow`, read through
  `AdvertiseModeOf`, so `auto` is "unset" at every site that used to ask "empty"): on a
  wildcard bind the host is the address the kernel would send from (`IRouteProbe`, a
  connect-only UDP socket that sends nothing), probed toward the IP-literal schedulers this
  node registers with first and the default route last, re-probed on a network change or a
  resume and every 30 s regardless. Consequences:
  - **A failed probe keeps the LAST route host**, and a loopback, link-local, unspecified
    or multicast answer is refused by one table (`UnusableRouteHost`): publishing one would
    tell the fleet to dial a client's own machine, or no machine.
  - **A reload re-derives rather than re-reads.** A save that changes nothing keeps the
    roamed address; one that re-pins `--advertise` publishes the pin. Judged by comparing
    FLAGS, a reload would re-register a fleet for a save that moved nothing the scheduler
    keys on, and miss a move no flag made (`AddressReloadableFlags` says why).
  - **The route host outlives a body** (`RouteHostCell`, one per process, also read by
    every reload candidate through `ReloadBasis::routeHost`), and a resolver ADOPTS it at
    construction, silently and uncounted: a body reformed after a roam otherwise logged and
    counted a move nobody made.
  - **A moved `0xFC` endpoint wakes the heartbeat at once** (`IEndpointMoveSink`), and the
    lease check follows the REGISTERED endpoint, not the published one, so a grant is
    honoured until the re-registration that moves it.
  - Two counters, one per endpoint (`pace_node_endpoint_changes_total`,
    `pace_node_raft_endpoint_changes_total`), and an Info line per move; a pinned
    literal is reported ONCE as not roaming. `EndpointResolver_test`, and `WorkerTier_test`'s
    "A worker re-registers under a moved endpoint and withdraws the old one exactly once".
- **A fixture that carries the key and never dispatches proves only that a keyed node
  STARTS.** `cluster-e2e` and `fleet-dashboard-e2e` were given `--cluster-key-file`
  because they left `--bind` at the wildcard, and neither compiles anything — so for
  a while the only end-to-end evidence for the lease check was construction. (Both
  bind loopback since #290 stage 3, which merged the compile port into
  `--listen-node`; they carried the key until #178 PR 6 deleted it, and their own
  comments say the bind is the half that closes them rather than the half that opens
  them.) Meanwhile the fixtures that *do* dispatch bind loopback, slipped under the
  startup rule, and ran `UncheckedLeaseValidator` for every one of their hundreds of
  compiles. Both halves have to meet in one fixture, which is why `dist-compile-e2e`
  runs every worker as a member of its scheduler's fleet, checking the grants it applies: an
  in-process test mints and verifies inside one process and cannot show that the
  endpoint a worker ADVERTISED is the endpoint the scheduler signed.
- **A flag that describes nothing under socket activation cannot answer whether a
  port faces the network.**

  > **The flags this entry names no longer exist.** #290 stage 3 retired the dedicated
  > compile port and deleted `--bind` and `--port` with it; the node opens one 0xFC
  > surface and `--listen-node` configures it, so `CompilePortFacesTheNetwork` reads
  > that row and nothing else. The entry is left as it was written, deliberately: what
  > it records is not a fact about a flag but a shape — a premise that is true on the
  > path it was written for and false on another path that reads it — and the sibling
  > it warns about at the end is now the *only* flag, which makes the hole wider rather
  > than smaller. Rewritten in today's spelling it would read as a rule about
  > `--listen-node` and lose the two things that make it worth keeping: that this was
  > #282 recurring inside the fix for #282, and that review found it and CI did not.
  > Read `--bind` below as "the flag that then configured the compile port".
  >
  > **And the premise moved again with roaming node addresses.** A START now reads where the
  > handed-over socket is bound and adopts it as the Node row's bind
  > (`Node::AdoptActivatedBind`, before the startup table, the endpoint resolver and every
  > reload candidate), so at a start the row describes the real socket and the table judges
  > it. What still describes nothing is the TYPED value an `--install-service` registration
  > and `--print-surfaces` judge: neither runs under the supervisor, so neither sees a
  > socket. Both guards therefore stay, and for the reason below rather than a new one.

  `--bind` is the obvious answer to "is this port local",
  and it is wrong for a reason nothing in this tree stated until now. Under
  activation the unit owns the address -- the shipped
  `pace-node.socket` says `ListenStream=6674`, every interface -- and
  `--bind`/`--port` are read by nothing. The value is still *in* the configuration;
  it has simply stopped describing anything. So a keyless node carrying a stale
  `--bind=127.0.0.1` in its configuration, plus `--fleet-open`, passed the startup
  table, built `UncheckedLeaseValidator` and
  served an unauthenticated compile port to the network with all three
  `worker_jobs_refused_lease_*` counters reading zero. #282 recurring inside the fix
  for #282, and found by review rather than by CI.
  - **The table's rule is INSUFFICIENT, not wrong, and that distinction is the whole
    entry.** `--install-service` bakes `--bind` into a command line it replays at
    every boot, so a startup-time check on it is right for the configuration it was
    written about -- and it is the only check that can run before any tier exists.
    What it cannot cover is a listener this process did not open. Hence two rules:
    the table keeps `--bind`, and `MakeWorkerLeaseValidator` takes whether the
    listener was inherited and refuses the activated case by name. Delete either as
    redundant and one of the two shapes goes unguarded.
  - **So the test asserts the PAIRING, not either half.** One case drives the same
    `NodeConfig` through `StartupPolicyRejection`, checks it PASSES, and then checks
    `MakeWorkerLeaseValidator` refuses it. That regresses the gap. A case asserting
    only the guard regresses the rule, and leaves the next reader free to collapse
    the two.
  - **The family: a premise that is true and a conclusion that does not follow.** The
    premise -- `--bind` records what this process asked for -- is true. The
    conclusion -- therefore it says what the port faces -- does not follow, and only
    under activation. This file already carries the same shape in the
    `~WorkerServer` unbounded drain, whose defending comment was "right about its
    premise and wrong about its conclusion". That one was in a comment; this one is
    in a guard. Two instances make it a family rather than a coincidence: when a
    premise is doing load-bearing work, check it still holds on every path that reads
    it, not only on the path it was written for.
  - **And the sibling was known, and did not arrive.** `--listen-node`'s typed value
    describes nothing under activation for exactly the same reason (a start now replaces
    it with the socket's adopted bind, a registration never can), so a scheduler-side
    refusal asking the typed bind would have had this hole. The one #178 landed asks `RunsConsensus` -- a port
    this process binds itself -- so it has none.
- **The trust decision does not live in `main()`.** It lived there, as
  `[](...){ return true; }`, through a fully passing suite — the shape this file
  already names as *a reclaimer nothing constructs is the bug it was written to
  fix*. `main` is the one translation unit no test can reach, so the choice is
  `Node::MakeWorkerLeaseValidator`, exercised directly from a `NodeConfig` and a real
  key file, and `main` is left with a call. A key file that cannot be READ stops the
  node; falling back to checking nothing is the failure this whole rule is about.
- **A `--cluster-key-file` rule keyed on "does anything read it" has been wrong
  twice and is gone.** It began as *unless `--discovery`*; #281 made the scheduler a
  reader and the rule refused the correct scheduler. It was widened to name the
  scheduler; #282 made the worker a reader, and a plain worker runs neither of the
  other two surfaces — so the rule refused the configuration the lease rule above
  *requires*. There is no third narrowing: whether a worker tier exists depends on
  what `--toolchain` and discovery resolve to on the machine, which the config table
  cannot see. A refusal whose premise has become false is worse than no refusal, and
  one that cannot state its premise without guessing has no business firing.
- **A resolve answers on liveness, never on presence, and an unknown token is
  refused.** Nothing visits an expired token but an `Acquire` for the same key, so
  an expired entry is still sitting in the table when its holder finally reports —
  and calling that a successful release would leave the one condition worth naming,
  a job that outlived its lease, with nowhere to be observed. The entry is dropped
  either way, through the one helper `Release` and `ReleaseWorker` share: the key
  index is erased only when it still points at *this* token, and two copies of that
  guard is how one of them comes to evict the client that replaced the lease.
- **And a resolve that answers nothing says WHICH nothing.** `Release` had three ways
  of resolving nothing and returned one `nullopt` for all of them, so the scheduler
  answered one `UnknownLease` and counted none — leaving the condition the bullet
  above calls *the one worth naming* observable to a single client's stderr and to no
  fleet anywhere (#1074). The stated reason was that it is a statement about one
  client's timing rather than about the fleet's capacity, which is **right about
  capacity and beside the point about fit**: fit is what nothing else can measure, and
  #522 cannot choose a lease lever without it. One code — telling a client apart here
  is a wire change every deployed launcher must understand — and three rows.
  - The counter is keyed on the **outcome**, never the code. Second instance of
    *the row is the REFUSAL, not the code*, now at the scheduler rather than the
    worker: `RefusalTable` maps code→counter and provably cannot hold three refusals
    sharing `UnknownLease`. `ReleaseRefusalsCountOnce` is what stops the row's counter
    and the code-keyed lookup both firing, because that safety was otherwise a
    coincidence of `UnknownLease` not appearing in the other table.
  - **Only ONE of the three is counted, and counting all three is the tempting fix
    that makes the series useless.** A second release is ordinary client behaviour and
    a reissued token is what an ordinary restart looks like; either would bury the one
    signal a site can act on. The two that stay uncounted carry their reason at the
    row, or *forgot* is spelled in the vocabulary of *decided*.
  - **A lease RECLAIMED from a live client lands in `UnknownToken`, and must.**
    `ReapExpiredWorkers` drops a machine that stopped heartbeating and calls
    `ReleaseWorker`, so a client still compiling resolves a token naming a lease
    nobody holds — through no fault of its own timing. #573's `Withdraw` adds a
    second and DELIBERATE route to the same state. Counted beside `Expired` it moves
    a number an operator reads as *your lease bound is too short* in exactly the
    direction that claim points, for an event that says nothing about the bound.
    It cannot happen by construction rather than by anyone remembering — `ReleaseWorker`
    ERASES the entry and `Expired` needs one still present and naming this key — and
    `A lease reclaimed with its worker is not counted as a job that outlived it` pins
    that, with the clock stopped WELL INSIDE the lease's own lifetime so a build
    answering `Expired` there is answering about a lease that had not expired. It is
    the fourth cause behind one code, and the ticket that split the first three
    believed there were only three: **the causes are not enumerable from the outcomes,
    which is the whole argument for naming outcomes after observations.**
  - **The enumerators name what was OBSERVED, and the map from observation to cause
    is many-to-many** — which is why they cannot name causes. A token from a scheduler
    instance that no longer exists arrives as `UnknownToken` when this instance has not
    yet reissued its number and as `KeyMismatch` when it has, so an enumerator called
    `SchedulerRestarted` would be a claim the table cannot make. The ticket itself
    assumed a clean 1:1 split of three causes onto three outcomes; it is not one, and
    only `Expired` has a single cause — which is exactly why it is the only one worth
    counting. Same lesson as `KnownSchedulerTerm` adopting a lower term rather than
    calling it a reset: report the observation, name the causes beside it.
  - Acceptance is a **discrimination** case, not one section per arm: all three answer
    the same wire code, so per-arm sections pass on a build that counts all three,
    none, or the wrong one. Assert the three counter readings against each other, and
    show the counter **not** moving for the two — a test that only checks it rises is
    green on a build that counts everything.
- **A refusal is only ever as good as what the table it consults can SAY.**
  `RemoteCompileArgs` refused any command line naming the input language, on sound
  reasoning: the launcher appends "this text is preprocessed <language>" LAST so it
  wins, and silently overriding a language the build chose is a wrong object rather
  than a failed one. But `LanguageSelectors` recorded only *that* a language was
  named, never *which* -- so refusing was the best answer available to it, and the
  comment describing the language as coming from an explicit flag, then the driver
  default, then the extension described an order only its last two thirds
  implemented.
  The cost was total and silent: **CMake emits `/TP` on every C++ source it compiles
  with MSVC**, so no CMake + MSVC translation unit was ever dispatchable. The fleet
  cached normally and distributed nothing. Nothing anywhere said so, because no lease
  was ever *requested* -- `granted`, `no-worker` and `no-capacity` all read zero, and
  the dashboard showed registered workers with every slot free. A fleet that has
  never distributed anything is indistinguishable from an idle healthy one.
  The row carries the language now, so a selector that names one is folded into the
  language and **dropped** -- what the launcher appends says the same thing and more.
  Three shapes, and only the first changed: a spelling that names a language is
  dropped; `/Tc<file>` and `/Tp<file>` are still refused because they name a FILE,
  which is the build's own source path; and an `-x` value with no exact
  `SourceLanguage` is still refused, because guessing is how a worker comes to
  compile something other than what was asked for.
  The test is a **CMake-shaped** command line, not a minimal one. The hand-written
  argv the old test used is what let this through: the refusal reads as correct on
  `cl /c /TP a.c`, and the line CMake actually emits is the one nobody wrote down.
  - **And the CMake-shaped line hid the next defect in the same drop.** The skip that
    lets `-x c++` take its value also fired for `/TP`, whose language is in its own
    spelling, so the argument AFTER `/TP` never reached a worker. CMake writes a `-D`
    there, which the dispatched line drops anyway, so every CMake case stayed green;
    `/TP /W4 /WX` reached the worker as `/WX` alone, and a template warning that
    fails the local compile under `/W4 /WX` passed on the worker and was SERVED. Only
    a row whose language arrives as a VALUE owns the next argument; the case puts a
    code-generation and a warning flag right after the selector, where CMake never does.
- **A worker being dropped has to be an EVENT, or nothing can release what was held
  against it.** Registry expiry used to be a filter — `IsLive` hid a dead worker
  from `Pick` while its entry stayed in the map forever — so `ReleaseWorker` had no
  moment to be called at, and a fleet losing a machine went on refusing every client
  that missed on one of its keys until each lease timed out. `ExpireStale()` erases
  and *names* what it erased; the registry does not touch the lease table itself,
  because that is its sibling rather than its dependency, so `SchedulerService` pairs
  them — from `Lease` and nowhere else, that being the one decision the leftovers
  corrupt.
  - **`Register` does NOT release leases, and this rule used to say it did.** The
    sentence read "a node that restarts inside the heartbeat window keeps its entry, so
    `Register` releases its leases too, on the same reasoning that already resets
    `inFlight` there" — and the code declines that reasoning explicitly, in a comment
    beside the call. The two are not the same bet: a node re-registers after **any**
    refused heartbeat — `EndpointBusy`, or `NotLeader` during an election — and not only
    after a restart, so releasing there would wipe leases for compiles that are **still
    running** and hand a second client the same work. `inFlight` recovers from that
    guess at the next heartbeat; a lease does not. A worker that genuinely restarted
    needs nothing: its client's compile exchange fails and the client resolves its own
    lease on that path, like every other (#212). So `Register` closes the **`inFlight`
    capacity** pin, and `ReleaseWorker` is reached from `ReapExpiredWorkers` alone.
  - Found by reasoning **from this file** while designing #403's reload-driven
    re-registration, which is the third route into the same machinery — the rule said
    the leases were already released, the code said the opposite, and only one of them
    runs. A rule that misdescribes the code is worse than a missing one, because it is
    trusted at exactly the moment somebody is deciding whether a new caller is safe.
- **A SUSPEND withdraws the worker's registrations, bounded to 1.5 s in all**
  (`SuspendWithdrawBudget`), and recovery never waits on a host event. Windows allows about two
  seconds for a suspend notification; the power-event handler posts to the heartbeat thread
  through `HostEventInbox` -- the registrars are the heartbeat's alone -- and waits, measured
  through the injected `IDrainWait`, for the withdrawal, returning at the budget whatever the
  heartbeat is doing. A withdrawal the heartbeat had not TAKEN by then is dropped: it could only
  run once the machine is awake again, withdrawing a machine that is back.
  - The withdrawal is `WithdrawOnce`: ONE dial to the endpoint the link names, never a fallback
    walk, a redirect or a registration. Only its CONNECT is bounded by `SuspendDialTimeout`; the
    exchange after it rides the dialler's own I/O ceiling, which is safe because the handler stops
    waiting at the budget regardless. Deliberately NOT through `SchedulerReachability`: a machine
    going to sleep is not a scheduler outage.
  - A resume or a network change runs the next round at once -- the heartbeat through
    `CompileCapacity::WakeHeartbeat`, the presence round through `PresenceWake` -- on each loop's
    own thread, never on the one that delivered. Which events do what is ONE table,
    `HostEventActionFor`, read by both loops; its `supersedesOlderWakes` column makes a suspend
    cancel every wake still pending from before it, in both.
  - A Modern Standby PC may report neither the suspend nor the resume. After a suspend with no
    resume, `RetireAllRegistrations` has left registrars carrying no worker id, so the first
    ORDINARY round registers again (asserted with no event fired). With neither reported, a
    sleep longer than the scheduler's heartbeat timeout is un-filed by its expiry and the next
    heartbeat is told to register again; after a shorter one nothing was un-filed, the heartbeat
    simply continues, and the worker may have been leased while it slept. A roster that lapsed
    during sleep is renewed by the next ordinary presence round, also asserted with no event
    fired. Where the registrations were withdrawn or expired, the cost is a gap of up to one
    `NodeAnnounceInterval` (20 s) after a wake nobody reported, and it fails CLOSED: an
    unregistered machine is leased nothing.
  - Host events reach the node through `Platform/IHostEvents`: power events from the SCM
    (`SERVICE_ACCEPT_POWEREVENT`, a table of `PBT_*`), so only a node running AS A SERVICE hears
    them, and interface and address changes through the pure `NetworkChangeDebouncer` on every
    platform: `NotifyIpInterfaceChange` and `NotifyUnicastIpAddressChange` on Windows, a
    `NETLINK_ROUTE` socket (link, address and route groups) on Linux, a `PF_ROUTE` socket on
    macOS -- whose messages two pure, byte-fixture-tested classifiers judge
    (`NetlinkReportsChange`, `RouteSocketReportsChange`), with `ENOBUFS` counted as a change
    because the kernel dropped notifications. A watcher that will not start is warned about
    once and is not fatal: no consumer may DEPEND on a host event, so the recovery above, and
    the endpoint resolver's 30-second re-probe, make a missing one a slower answer rather than a
    wrong one. `src/tests/ScriptedHostEvents.hpp` is the shared fake.
    - **A POSIX watcher starts INSIDE the body the daemon host runs, never before it**
      (`NetworkWatcherStart::InsideTheBody`): its thread does not survive `PosixDaemonHost`'s
      `fork()`, so one started first is a watcher in the parent that exits, and the daemon hears
      nothing -- silently, since a missing event is only ever a slower answer. Windows starts it before
      `host->Run`, where nothing forks. Where it starts is one constant per platform, read
      through `StartNetworkWatcherAt`, so the two call sites cannot both start one.
- **A reloadable flag that feeds REGISTER is a claim, not a setting, and adopting one
  without telling the fleet is the silent failure the whole column exists to prevent**
  ([#403](https://github.com/LASTRADA-Software/pace/issues/403)). `--toolchain`
  and `--no-toolchain-discovery` decide which fingerprints this node registers, so a
  reload of either has to re-derive the served set **and** re-register. Three things
  make that safe, and none of them was built for it:
  - The heartbeat thread already replaces the served set mid-life when a compiler is
    patched underneath it (#238), in the order that matters — the compile port first,
    the registration second — so a job naming a dropped fingerprint is refused
    `UnknownFingerprint` rather than served by a compiler nobody keyed against.
  - `RefreshToolchains` already reads the set from the configuration, and
    `ConfigReloaderOf` already publishes an immutable snapshot any thread may read. The
    reload therefore *feeds* the existing path; it does not open a second one.
  - Re-registration leaves outstanding leases alone (the bullet above), which is what
    makes a reload safe while compiles are running.

  **But a configuration change moves no WITNESS, and that is the trap.** The re-survey
  is triggered by a compiler's stamp moving on disk; editing a file moves nothing, so a
  reload that only published a snapshot would be accepted, logged, and then do nothing
  until the periodic sweep came round — an operator saving a file, seeing it accepted,
  and watching the fleet keep dispatching the old set. The reload therefore forces
  `RecheckDepth::Unconditional` on the next beat, and that decision is a pure function
  (`RecheckDepthFor`) rather than an expression in the heartbeat loop, because
  `main.cpp` is in no test target and this is precisely the rule that fails silently in
  one direction.

  **What stays `Reloadable::No` is a decision with a reason, not an omission.** This
  paragraph opened with `--advertise` until it was wrong twice over: #1279 made it
  `Reloadable::Yes`, and roaming node addresses made `--raft-self` reloadable beside it
  (`AddressReloadableFlags`, the kind that moves WHERE a registration is filed rather than
  what it serves). The reason it once stayed is now the stated COST of moving it:
  `--advertise` is inside every outstanding lease's MAC as `expected.endpoint`, so a grant
  for the old endpoint is honoured only until the worker re-registers under the new one
  (*the address it verifies against is the address it is REGISTERED under*), and after that
  fails `EndpointMismatch` -- one local compile each, for a grant naming an address that
  had stopped working anyway. The same cost is paid with no reload at all when `auto`
  follows the network. `--slots`,
  `--node-class` and `--reserve-cores` feed `NodeCapacityOf`, which is derived **below**
  the cache tier (#167) and would have to re-establish that ordering without restarting
  it. And because "we decided not to" and "we forgot" are the same diff, the reloadable
  set is pinned by a `static_assert` beside the option table: a further `Reloadable::Yes`
  row fails the build until its author classifies it in `AdvertisedClaimsDiffer`. That
  sentence said "a fourth" and now names no number — #404 and #405 each added rows, and
  a count stated beside a table is a second claim about it.

  **The removal direction fails CLOSED, and #403's own text says otherwise.** Admission
  is a single funnel — `WorkerProtocol` is the only caller of `CompileJobRunner::Run`,
  which looks the fingerprint up under its lock and refuses `UnknownFingerprint`
  (or `ToolchainSurveyInFlight` before the survey lands) — and the lease's own
  fingerprint check composes with it rather than replacing it. So a stale
  `(fingerprint, endpoint)` entry costs a failed dispatch and a local compile for at
  most one `DefaultHeartbeatTimeout`, never a wrong object. There is no wire verb that
  retires a registry entry, and adding one
  ([#573](https://github.com/LASTRADA-Software/pace/issues/573)) is therefore a
  latency optimisation over a bounded, self-healing window — not a correctness fix.
- **An OUTBOUND credential is read at the moment it is presented, through one seam,
  and a site that captures one is invisible until somebody rotates**
  ([#404](https://github.com/LASTRADA-Software/pace/issues/404)). On this worker
  `--requirepass` is presented and never required, and each of the three sites that
  presented it — the shared `pace-kv`, the scheduler round, a cluster admin verb —
  built its own `Cc::Credential` from `cfg.token` at construction. Marking the row `Reloadable::Yes`
  publishes a snapshot none of them reads, which is the "green while doing nothing"
  failure in the one area where the symptom is an authentication failure nobody can
  reproduce, on a machine nobody is watching. **A rotation that reaches two of three is
  worse than one that reaches none**, because none is a restart an operator plans and
  two is a fleet in a state no file describes.
  - **The seam is `Node::ICredentialSource`, held by REFERENCE, and the type is the
    guard**: a site holding one has no field for a stale secret to sit in, so the
    defect cannot be reintroduced by omission at a site that already reaches for it.
  - **What the type cannot guard is a site that never reaches for it**, and that is a
    scan — the rulebook's own split between an obligation to *do something* and an
    obligation to *say why*. `Cc::Credential` may be constructed from a `NodeConfig`
    in exactly one file, and `NodeCredential_test`'s seam case walks the node's
    sources to say so. It carries a positive control on the PATTERN as well as on the
    file count, because a scan whose spelling has stopped matching reads identically
    to a clean tree.
  - **The daemon's `SharedAuthSource` does not transfer, and reaching for it is the
    available mistake.** That one answers "does this client's credential satisfy what
    I require"; this one answers "what do I present". They are opposite directions
    with the same noun, and only the outbound one can be rotated a machine at a time —
    which is the entire reason this row could become reloadable while the daemon's
    inbound settings could not.
  - **Making it reloadable is what forced `HeartbeatRound` and `AnnounceOnce` out of
    `main.cpp`.** The third site lived in the one translation unit no test reaches, so
    a case could assert the other two and the missed one was structurally
    undemonstrable. Both halves of that are the fix: the type makes the defect
    unwritable, the move makes the absence of it provable.
  - **And it goes to `--upstream` ALONE, since the scheduler never checked it.** A
    scheduler answers a password `AUTH` `Ok` and establishes nothing, so the rounds #404
    kept current were handing the upstream's secret, in the clear and pipelined ahead of
    any seal, to every `--scheduler` and to every endpoint a `NotLeader` named. A node's
    credential with a scheduler is its PROOF: every verb it sends one goes through
    `Cc::ExchangeWithScheduler`, which takes no credential, so presenting one again is a
    new parameter rather than a forgotten argument. `NodeCredential_test` reads the bytes
    of a proof, a registration and a presence round with a secret configured, and finds no
    `AUTH` frame in any. An operator verb chooses per endpoint (`OperatorCredentials`) and
    a cordon asks this machine's own node, which checks none.
- **A file's MODE is in no configuration, so the worker's secret-file check follows
  the RELOAD and not only the start** ([#868](https://github.com/LASTRADA-Software/pace/issues/868)).
  One of this binary's five secret settings is `Reloadable::Yes` since
  [#404](https://github.com/LASTRADA-Software/pace/issues/404), so a node file
  **can** now gain a `requirepass` across a reload exactly as the daemon's can, and
  that half of #753 is live here rather than absent — which is not a hole, because
  `SecretSubjectFiles` is a function of the LIVE snapshot: the re-ask below asks about
  the configuration in force rather than the one the process started with, so the file
  that just acquired a token is a subject from that reload onward. The four settings
  reached BY PATH remain `Reloadable::No`. The half that was always here is the one a snapshot cannot
  answer: an operator edits `log_level:`, sends SIGHUP, the reload is accepted, and
  nothing re-asks the filesystem, so a `--cluster-key-file` that went to 0644 an hour
  after the node started is silent for the rest of the process's life. That key MACed
  node proofs AND lease grants until #178 PR 6 retired it; `--dashboard-token-file` is the
  same case today. `SecretExposureWatcher` re-asks and remembers
  `(path, exposure)`, so a standing exposure is said once; an implementation reasoning
  from the reloader's previous-and-current pair concludes nothing changed and never
  looks, which is what makes the snapshot-diffing version look correct while covering
  half the ticket.
  - **`ApplyReloadRequest`'s decline is about `WorkerBody`'s frame, and reading it as
    "the worker cannot `Subscribe`" is one frame too wide.** The reloader is declared
    in `main` and outlives `WorkerBody`, and `Subscribe` has no unsubscribe — so a
    subscriber capturing that frame's locals would outlive them, which is why the
    heartbeat is still signalled by comparing snapshots. A subscription attached from
    **`main`**, beside the reloader's own declaration, capturing only what `main` owns
    and what is declared before the reloader, is the arrangement that decline
    describes as safe: it is what `DaemonBody` already does. #753 read the decline the
    wide way and declined to generalise the seam on the strength of it, which is the
    reason this took a second ticket. **Answer such a reason by satisfying it, not by
    routing around it** — and check which frame it is about before concluding it
    forbids the shape.
  - **Two arms, because the difference is whether there is a SECOND moment at all.**
    A worker started with no configuration file still names its key files and still
    has to be told; what it has no use for is the memory, since nothing will re-ask.
    `ReportSecretExposure` is that arm and carries no watcher, so there is no second
    copy of the remembering rule — and both arms are asserted by the wiring scan
    separately, or a `main` that lost one reads exactly like a `main` that has both.
  - **The resolved path travels UNGUARDED by "was the file applied", and the reason is
    that the guard could never decide anything.** A resolved path that will not load
    already ends the run above (`RefuseUnderService`), except under
    `--uninstall-service`, which returns at the service block — so a run reaching the
    check either applied its file or never
    had one. In the unreachable case the gate answers false either way: `cfg` IS the
    command-line parse there, so argv named the token or no secret is in force. **It is
    NOT a reload fix**, and the REASON for that changed under #404 while the conclusion
    did not. It used to be that `--requirepass` was `Reloadable::No`, so a SIGHUP
    introducing a token was refused and published nothing; it is `Reloadable::Yes` now,
    so a node file CAN gain a secret across a reload exactly as the daemon's can. What
    covers that is the filesystem re-ask, and it covers it already because
    `SecretSubjectFiles` is a function of the LIVE snapshot rather than of the
    configuration the process started with. What the dropped guard could never decide is
    unchanged: `argvNamedSecret` is a fact about ARGV, which no reload rewrites.
    **A rule whose stated reason has gone false is worse than no rule**, which is why
    this paragraph moved with the row rather than being left standing beside it.
- **A refusal that moves a counter says so in a table.** `RefusalTable` pairs each
  code with the counter it moves, and `std::nullopt` is a legitimate row: a
  malformed frame is a *client* defect, and counting it beside the capacity
  refusals would put one broken build's noise into the numbers a fleet is sized
  from. Four hand-written `Count(...)` calls beside four `Refuse(...)` calls are
  four chances to forget one, and a refusal with no counter is invisible in exactly
  the situation an operator is trying to diagnose.

**The scheduler's port is reachable before membership is established, so its payload
cap is the small one.** `SchedulerServer` refuses a frame declaring more than 64 KiB,
against the cache port's 256 MiB, and the asymmetry is the whole point: the gate runs
*inside* `SchedulerService`, i.e. after the frame has been read, so an unauthenticated
peer can make this endpoint buffer whatever it declares. That is the same hole
`OpDescriptor::maxPayload` closes for `AUTH`, reached by a different route, and it is
closed the same way — a scheduler verb carries a fingerprint, an endpoint and a key,
none of which is large. Three consequences:

- **The check is on the DECLARED length, before the read**, so an over-cap frame costs
  no allocation at all. Checking after would be a memory-exhaustion hole opened by the
  check meant to close one.
- **The refusal names both numbers and is a reply, not a close** — `payload-too-large`
  with the ceiling in it, because "too large" alone tells an operator nothing about a
  64 KiB limit, and a close is indistinguishable from a dead host.
- **A wrong magic is still the one condition that closes.** With no declared length
  there is nowhere to resynchronize to, so there is nothing an answer could mean.

**An endpoint reports the port it bound, not the one it was asked for.** `Start` formats
`BoundEndpoint()` from `listener->BoundPort()`, which matters because `0` means "pick a
free one" — an endpoint echoing `:0` back cannot tell an operator, a log line or a test
where it ended up. `ParseTcpPort` still refuses `0` as a *CLI* value, correctly: as
something an operator types it names no port anyone could dial. The two rules are not in
tension, and the node's tests find a free port by binding a probe and releasing it, the
idiom `AdminEndpoint_test` already uses.

**The cache and the fleet are two failure domains, and the client must not join
them.** `RunCached` returned on a `FETCH` that failed at the transport, and that
`return` sat above the call site that would dispatch — so a cache the launcher could
not reach turned distribution off with it. Every property this repository cares
about held while it did: the build succeeded, the object was correct, the exit code
was zero, and one `PACE_VERBOSE` line said the cache was unavailable, which is
true and is not the interesting half. On a forty-machine estate a mistyped
`PACE_ADDR` made every build local while the fleet sat idle and healthy
(issue #236). The rule is that **a fetch outcome decides one thing only: whether the
daemon is worth sending a second command to** (`Cc::CacheIsServing`). It does not
decide whether the invocation continues, because the docs put the shared cache on a
different machine from the scheduler and an answer about one is not an answer about
the other. Three parts of that are each load-bearing:

- **A refusal and a transport failure stay distinguishable, and both carry on.** The
  daemon's own code and words go in the fall-back reason for a refusal, `fetch
  exchange failed` for a transport failure, because an operator fixes those in
  different places. What they have in common is only that neither is an answer about
  the fleet.
- **The reason is still recorded, under `Outcome::Unavailable`.** Reaching the
  dispatch path must not make a broken cache invisible — so the MISS trace is
  *skipped* when the daemon did not answer, since tracing one clears the reason
  `--show-stats` ranks and reports a broken cache as a cold one.
- **The `STORE` is skipped when the fetch was not answered, and that is not an
  optimisation but a restoration.** Before the fix a failed fetch returned, so
  nothing was ever pushed at a daemon that had just failed to answer; carrying on
  had to leave that true, or every translation unit in a build against a wrong
  address pays another connect — a *timeout* rather than a refusal whenever the
  address is remote enough to be worth pointing at, and on a refusing daemon an
  object-sized transfer paid to be told the same thing again. It is **not** a claim
  that one connect is all a dead cache costs: direct mode is on by default and asks
  for a manifest before the object fetch runs at all, so the ceiling is two either
  way, and `TryDirectMode` is what would have to change for it to be one.
- **The carrying-on is guarded END TO END, in every shape a dead cache can be silent,
  because no unit case can see it.** `main.cpp` is in no test target (#909), so the
  seam cases in `ReactorExchange_test.cpp` pin every value `RunCached` reads and cannot
  see a `return` added after the fetch. Measured: making a transport-failed fetch end the
  invocation passed every `pace-cc-tests` case and the whole Windows launcher e2e,
  and was caught on POSIX by one leg pointed at a refusing port. So both fixtures
  (`run-launcher-e2e.ps1`, `compile-cache-e2e.sh`) compile against a peer that REFUSES,
  one that LISTENS and never accepts, and one that ACCEPTS then RESETS. Each must exit 0
  with the baseline's object inside an elapsed bound DERIVED PER SHAPE from the
  launcher's own deadlines: the live-daemon baseline, plus the two exchanges above at
  what ONE exchange against that shape can cost, plus HALF an exchange -- `total` for
  the peer that never accepts (its handshake completes into the backlog, so it never
  spends a connect), `connect` for the refusing and the resetting peer. The half is the
  point: one exchange too many then overshoots by half an exchange of that shape. The
  shared bound this replaced, connect plus total per exchange, left the silent shape a
  whole exchange of slack, and a launcher that retried a failed fetch passed it on
  Windows. A regression specific to one shape, a wait on the silent peer, is then a
  named failure rather than the test's timeout.
  - **A bound cannot count what costs nothing, so the RESET leg COUNTS**: every exchange
    against it is a connection the fixture accepts, and there must be exactly two.
  - **What neither reaches, and the direction it fails in:** a refusal on Linux costs
    about nothing, so one extra exchange against the REFUSING peer is invisible there --
    SILENT, which is open. It stays covered because an extra exchange runs through the
    same launcher code whatever the peer's shape, and the reset count and the silent
    bound both see it. On Windows a refused connect costs about the connect deadline, so
    that leg's bound bites there too.

**A premise can be correct when it is written and false when it is read, and
nothing connects the two.** `CacheProxy`'s STORE handler ignored the roots the
client sent, with a comment saying why: *"Canonicalization is the SHARED cache's
job ... What this tier stores is what this machine will replay."* Both halves were
true. A node was a private tier in front of `pace-kv`, which canonicalized every
store, and doing it twice would have been the redundancy the comment refused. Then
[#229](https://github.com/LASTRADA-Software/pace/issues/229) made a node the
shared cache in its own right, and neither half survived: there was no longer a
daemon behind it doing the job, and "this machine" is not one layout, because every
checkout on it is a different one. Nothing failed at the moment the premise did.

The result was that a value stored through a node kept the producing checkout's
absolute paths in its text regions
([#319](https://github.com/LASTRADA-Software/pace/issues/319)). Three things
follow, and each is a rule of its own:

- **A policy every server must apply belongs with the thing it applies to, not with
  one of the servers.** `CanonicalStoredValue` now lives beside `CompileValue`
  and both servers call it. It had been a file-local helper in
  `Protocol/CompileCacheHandler`, so when a second server appeared there was one
  copy and no way to notice the other end lacked it — `grep` for the function
  answered "one caller" and that read as normal.
- **A replayed region is not diagnostics; it is a dependency record.** `/showIncludes`
  notes are handed to the build system as the object's dependencies, so a region
  naming another checkout gives this build dependencies on files it will never
  edit — and no edit here can then invalidate that object. Wrongness that arrives
  once persists indefinitely.
- **A path with no `<SRCROOT>` sentinel is NOT evidence of corruption, so do not
  build a reader that treats it that way.** 92 of the 93 paths a trivial translation
  unit reports are toolchain headers, which correctly have no token; a consumer
  refusing sentinel-less paths would refuse essentially every hit. What distinguishes
  a poisoned region from a sound one is not visible in any single path, which is why
  the retirement is a schema-tag bump (`objkey-v6` / `manifest-v6`) rather than a
  heuristic.

**A manifest that revalidates nothing revalidates forever, and `all_of` is how it
gets written.** `BuildManifest` drops a reported dependency classified as toolchain,
because `toolchainStamp` covers those collectively. `ClassifyAgainstRoots` calls every
path outside both roots toolchain — so a header belonging to ANOTHER checkout is
classified exactly as an SDK header is, and dropped. Feed it the paths from an
uncanonicalized region and every one of them drops, leaving a manifest naming the
translation unit and not one header. `ValidateManifest` then re-hashes the TU, finds
it unchanged, and serves the object however the headers move — on a first build, in a
fresh directory, with no stale ninja graph anywhere in the story. Both sides now
refuse: `BuildManifest` answers `NoProjectDeps` when dependencies were reported and
none survived, and `ValidateManifest` refuses an empty entry set rather than passing
`all_of` vacuously. The refusal costs direct mode for that compile and the ordinary
preprocessed key still serves it, which is the same trade `Unanchored` already makes.

**A refusal that names somewhere else is an instruction, and reading it as an answer
takes the whole fleet out of distribution.** `SchedulerService` has always answered a
non-leader with the leader's endpoint. Only the interactive `--cluster-*` CLI ever read
it: the launcher dropped it into the same branch as `NoWorker` and `NoCapacity` and
compiled locally, so a single election removed every client from the fleet until forty
machines were re-pointed by hand
([#237](https://github.com/LASTRADA-Software/pace/issues/237)). Everything looked
healthy while it happened — the builds succeeded, the objects were correct, and the only
symptom was that they were slow.

- **The redirect is judged by PARSING the message, never by asking whether it is
  empty.** An empty message is replaced with the error table's default sentence by
  `EncodeErrorReply` before it reaches the wire, so "no leader is known" and "the leader
  is at `h:p`" arrive as the same shape. Only "does this parse as an address" separates
  them, and a client that skipped the test dials a sentence — which is a scheduler
  endpoint no operator ever typed. `Cc::RedirectTarget` is the one owner of that
  question, and `ClusterAdminCli` — which had the only previous copy — asks it rather
  than keeping a second.
- **Parsing is not splitting, and the difference is the whole rule above.**
  `SplitHostPort` takes the LAST colon and returns whatever follows it, so
  "no leader: try again" splits contentedly into a host and a port of `" try again"`. A
  redirect needs a host, a colon and a port that is a number. Not `ParseEndpoint`
  either, close as it looks: a bare port there takes the caller's default host, which
  for every caller in this tree is loopback -- so a scheduler answering `6675` would
  send the client back to itself.

  Those three refusals are `Core/HostPort.hpp`'s `ParseDialEndpoint`, and they are one
  function because `Cc::DialEndpoint` asks the identical question of the identical
  string a moment later. Two spellings of "is this an address" cost a hop whichever way
  they came to disagree: one the redirect accepts and the dial refuses is a connect
  that could never succeed, and one the dial would have taken is a leader the client
  can reach and declines to.

  This is the consumption test from the claim-record rule below, arriving at the
  opposite answer. `NotLeader`'s message was diagnostics for as long as
  `ClusterAdminCli` merely PRINTED it, and a loose test cost a confusing sentence. It
  follows the redirect now, through the one loop every operator verb shares (`AskTheLeader`).
  A launcher DIALS it, so it became a dependency record in that same moment — the
  bullet below says *"the moment something did, it would stop being diagnostics and
  this bullet would be wrong"*, and this is that moment, for a different field.
- **`NotLeader` is the one code whose message is DATA, and that is not an exception
  to the table rule.** `wire-and-protocol.md` says a refusal's wire code and its
  message are one fact and therefore one table row, because a ternary picking the code
  beside a separate call picking the text made them disagree. `NotLeader` obeys it from
  the other side: the table supplies its default sentence, and `Gate()` overrides that
  in the one place it refuses (`Refuse(NotLeader, LeaderEndpoint())`), so the code and
  the endpoint are still chosen together. The override is *why* the empty case has to be
  parsed rather than tested for empty -- the table's sentence is what fills the gap when
  there is no endpoint to name.

- **The chain is bounded.** Two nodes with a stale `_knownLeader`, or a partition
  healing, name each other indefinitely; without a ceiling a build spends one connect per
  translation unit per hop discovering it. Two hops is one more than a correct fleet
  needs, and running out is an ordinary local compile — which is what every other lease
  refusal already means.
- **This is the CLIENT half, and one half alone is not a fix.** A node used to
  register only with its own `--scheduler` (`main.cpp`'s heartbeat round, through
  `WorkerRegistrar`, which special-cased `UnknownLease` and nothing else), so a
  `NotLeader` there was logged and retried against the same address forever. A launcher
  that follows its redirect perfectly then reached a leader whose registry every worker
  had expired out of, and got `NoWorker` — the same outage one layer down, which is why
  fixing one half moves where it is observed rather than whether it happens. Closed by
  the worker-half section below; "a fleet survives an election" became sayable only
  when both halves redirected, and not before.
- **The RELEASE follows the lease, not the configuration.** A lease issued by the leader
  the client was redirected to must be resolved there: sent to the configured endpoint it
  resolves nothing, and the key stays marked in flight on the machine that actually holds
  it for the whole lease timeout. That is the `already-in-flight` outage #212 records,
  reached from the client's side.
- **A LEARNER answers the scheduling verbs with that redirect, so this machine's own node is a
  scheduler to name** ([#1639](https://github.com/LASTRADA-Software/pace/issues/1639)).
  A node that runs consensus and serves no scheduler (`Node::RedirectsScheduling`,
  `RunsConsensus && !ServesScheduler`) knows where the leader is and used to answer every
  scheduling verb `UnimplementedVerb` instead, which a launcher reads as *this build is too old*
  — so `PACE_SCHEDULER=127.0.0.1:6674`, the one value right on every PC whoever leads,
  dispatched nothing. `SchedulingRedirectResponder` now answers them as a follower scheduler
  does, and each half of its answer is a rule:
  - **Admission FIRST**, through the scheduler's own fold (`Distributed::CallerContextOf`): a
    caller the node does not admit is answered `NotAMember` naming nobody and never learns where
    the leader is. No identity check (`ProvenNodeOnly`) is applied here; the leader applies it to
    the redirected request, so the learner is not a second, stricter door.
  - **The endpoint is the leader's `0xFC` one, from the applied member record**
    (`ClusterState::SchedulerEndpointOf`), never its Raft endpoint, read through
    `ISchedulingLeaderSource` rather than a reach into the consensus tier. NODE-STATUS reads its
    `leader` from that SAME object (`NodeRuntimeSources::schedulingLeader`,
    [#1641](https://github.com/LASTRADA-Software/pace/issues/1641)), so `pacectl node`
    and the redirect cannot disagree; the role stays ABSENT, since the node runs no scheduler.
  - **A silent leader is named by NOBODY once its silence passes the tier's own Raft
    `electionTimeoutMax`** — 300 ms today, judged once per 1 s reconcile pass, so the effective
    bound is up to one pass longer. That is the moment a follower VOTER would stop naming it,
    which a learner, having no election timer, never does by itself; without it a launcher off
    the VPN pays a connect to an unreachable leader on every miss. Empty is the ordinary
    election answer: the launcher declines with `NoLeader` and compiles locally. It is NOT
    `Distributed::LeaderSilenceBound`: the `consensus-leader-silent` condition keeps its own
    65-minute bound, which answers a different question. One decision,
    `SchedulingEndpointToPublish`, folds the role observer and the reconcile pass through
    `SchedulingLeaderPublisher`: the role half is the role observer `StartConsensusOrExplain`
    hands the tier, the pass half `LeaderContactObserverFor`.
  - **RELEASE is refused `DispatchNotPermitted`**: it settles a lease with whoever granted it,
    and a learner granted none, so only a broken client sends one there.
  - **A node running NO consensus follows no leader**, and answers as the `pace-kv` daemon
    does: the capacity verbs (`Register`, `Heartbeat`, `Withdraw`, `Lease`, `Release`,
    `NodeAnnounce`, and the admission verbs `Admit`, `Settle`, `MachineBudget`)
    `DispatchNotPermitted`, the cluster verbs `NoCluster` — the daemon reaching
    `NodeAnnounce`'s code through `RefusalFor`'s fallback. The codes agree on every scheduling
    verb, and `NodeFrameSurface_test` pins that agreement on the wire; the words are each
    binary's own.
  - **Never `UnimplementedVerb`** for a scheduling verb on either kind of node: that code says
    *upgrade*, and both builds are current. A case asserts its absence beside the positive code,
    because a positive code alone passes for a row that answers something else.
- **A fixture with one scheduler cannot fail.** If the first endpoint contacted is
  already the leader, a build that follows no redirect at all passes every assertion. The
  case has to have two, and the assertion is that the SECOND is reached.
- **A scripted fleet proves the client, never the server.** `ScriptedFleet` hands the
  launcher a `NotLeader` the test wrote, so on its own it shows that a stub can redirect
  and nothing about whether a scheduler emits that shape. The two ends are pinned
  separately and deliberately: `SchedulerService_test` fixes what `Gate()` puts in the
  message (a follower names the leader, an undecided node names nobody), and
  `CacheProtocol_test` drives the empty case through the REAL `EncodeErrorReply` to fix
  what an empty one becomes on the wire. The premise the parse rests on is asserted
  there rather than asserted about here.

**A WORKER follows that redirect too, or the client's half of it arrives at an empty
fleet.** `SchedulerService::Gate()` refuses **every** verb off the leader, `Register`
included — leadership and membership are one gate and it runs for reads as well. So
while the heartbeat thread dialled the configured `--scheduler` unconditionally and
merely *logged* the refusal, an election did this: every worker went on announcing
itself to the demoted node, expired out of the new leader's `WorkerRegistry` inside
the 90 s heartbeat timeout, and the leader answered every lease `NoWorker`. A
launcher that now correctly follows the redirect then arrived at a leader that knew
of no workers and compiled locally — the same #237 outage, one layer down, behind a
green build and a fleet whose counters all read zero. Fixing one half without the
other moves where the outage is observed and not whether it happens.

- **One rule, one implementation.** The worker reads its redirect through the same
  `RedirectTarget` the launcher does, so what counts as one — a host, a colon, a
  numeric port, and never prose or a bare port — is decided in a single place for
  both. A second copy on the node would be a second thing to be wrong, and the two
  would drift in the direction the tests did not cover.
- **A refusal has to reach the caller as an ENDPOINT, not as a phrase.**
  `Register` returned `expected<void, std::string>` and `Heartbeat` a bare `bool`,
  so the redirect was already being thrown away one frame after it arrived, and no
  amount of loop in the caller could have followed it. `AnnounceRefusal` carries the
  words and the endpoint separately because they answer different questions: the
  words are for the operator and are always set, the endpoint is for the node and is
  set only when there is one.
- **A leader is committed only once a round has been ACCEPTED there.** An endpoint
  some scheduler *named* is a lead; an endpoint that took this node's registration is
  a leader. Remembering on the name alone lets one bad redirect become the endpoint
  every future round starts at, outlasting the election that caused it — and an
  endpoint that answered but refused every registrar for its own reasons (not a
  member, a fingerprint it will not take) is exactly that case.
- **A remembered leader that stops answering falls back inside the SAME round.** Not
  a heartbeat interval later: this machine is missing from the fleet for as long as
  it takes, and the configured `--scheduler` is both the endpoint an operator can
  actually fix and the one still standing after an election the remembered leader
  lost. Arriving back at the configured endpoint *forgets* the remembered one rather
  than storing it as a value equal to the default, or every diagnostic that says
  which endpoint this node is following becomes a lie.
- **`--scheduler` is a LIST, and the fallback walks it — for REACHING the fleet,
  never for deciding who leads** ([#1310](https://github.com/LASTRADA-Software/pace/issues/1310)).
  A registration replays its command line forever, so one value was one machine's
  address in every unit file, and retiring it meant re-registering the fleet. Three
  rules came with the list, and each is a way the obvious version is wrong:
  - **Each configured endpoint is dialled at most ONCE per round**, starting at the one
    that last accepted and wrapping. A redirect target that fails falls back to the
    next configured endpoint NOT yet tried — never to the one that issued the
    redirect, which answered a moment ago and names the same dead leader again. The
    single-value version re-dialled it, a spin bounded only by the hop budget.
  - **`NotLeader` never consults the list.** It is an instruction followed to the
    endpoint it names; a list that answered it would register a worker with a
    follower that refuses every verb.
  - **A one-shot verb falls back only where nothing was SENT** (`DialFirstReachable`).
    A dial that did not connect delivered no request; a connection that failed
    mid-exchange may already have applied `--cluster-admit` or `--enroll-approve`
    where it landed, so it is reported and never retried at the next scheduler.
  - The acceptance is a FALLBACK, and one value always worked, so a case listing two
    endpoints whose first answers passes under every defect here. `AnnounceRound`
    left `main.cpp` for exactly that: the dial is `IEndpointDialer`, the replies are
    scripted, and the case asserts WHICH endpoint was sent the registration.
  - **A node that SERVES a scheduler walks its OWN first, then the other voters its applied
    state records** (`AppliedSchedulers::Current`). Its own answers whenever it hears the
    leader -- it accepts, or redirects -- so the voters cost nothing in the ordinary round.
    They are there for the voter whose address VANISHED: no leader's message reaches it, its
    election timer fires within an election timeout, and its own scheduler then answers
    `NotLeader` naming NOBODY, which no round can follow. With its own scheduler as the whole
    list, its NODE-ANNOUNCE and its REGISTER never reached the leader, the move was never
    committed, and the voter stayed unreachable until its old address came back -- while every
    membership case went green, because each injected the announcement AT the leader.
    `FleetVoterMove_test` drives the voter's own rounds through `FleetHarness` (a follower,
    a deposed leader, and the control whose own scheduler still redirects) and was RED on the
    tree that answered the own endpoint alone. The same list is the voter's route-probe targets
    (`SchedulerProbeTargets`), so a split-tunnel voter advertises the address its peers reach.
- **`NotLeader` must not clear the worker id; `UnknownLease` must.** They are
  different sentences: one says *this scheduler is the wrong one to ask*, the other
  *the fleet has forgotten you*. The registry is replicated, so the leader a redirect
  names may well be holding the very registration that id belongs to — clearing it on
  a redirect turns every election into a fleet-wide re-registration storm.
- **The budget is per round, not per process.** A fleet that re-elects once an hour
  should spend one redirect an hour. A lifetime ceiling would follow redirects for a
  while and then silently stop, which is the same outage as never following one,
  arriving later and harder to see.
- **The policy is a testable object, and so is the dialling around it.**
  `SchedulerLink` is pure — no socket, no clock, no logger — because the alternative
  home for it is `main.cpp`, which is in no test target. Same reasoning that moved
  `MakeWorkerLeaseValidator` out of `main`: a decision that lives there is a decision
  nothing can assert, and this list already records what that costs. The round that
  dials what the link names, `AnnounceRound`, followed it out for #1310: `main.cpp`
  holds only the call and the production `BlockingEndpointDialer`.

**A node caches for itself, and what that saves is the round trip rather than the
compile.** The shared `pace-kv` holds every object, so a second copy on the node
looks redundant — it is not, because a developer who rebuilds one tree twenty times a
day pays the network twenty times for objects that never left their machine, and on a
slow or lossy link that is the difference between a cache that helps and one that
hurts. `Node::LocalCache` is pure over an injected `IStorage`, an `ICacheUpstream` and
a clock, so every rule below is a unit test rather than a socket and a sleep. Four
rules, none of them the obvious one:

- **A local hit does not consult the upstream at all**, and the test asserts *zero*
  calls rather than few, because "few" is not the property. Revalidating would have
  moved the round trip rather than removed it, and it is unnecessary by construction:
  an object key is a digest over the preprocessed text, the arguments, the compiler
  identity and the dependency set, so a key that matches names the same object.
- **A local miss populates the tier**, or this is a proxy and the second build is
  exactly as slow as the first. A failure to populate is *not* a failure to serve —
  the value is in hand and the caller is owed it.
- **A store writes local FIRST, then offers upstream.** The local write must not fail
  for a reason the network chose; the upstream offer is best-effort by contract, so
  its answer is **counted rather than returned** — a client retrying on it would be
  retrying something already durable where it matters.
- **An unreachable upstream is a MISS, not an error.** Every caller compiles either
  way, so distinguishing them would give a build a failure mode it does not need. The
  distinction lives in a counter, where it is actionable. `NoUpstream` is a named type
  rather than a null pointer, so "this node has no shared cache" is a decision
  somebody made rather than a pointer nobody set.

Six more about what the tier IS and who gets to see it:

- **What a node holds back from compiles is what its tier BUILT, never what a flag
  asked for.** `--cache-memory` is a request, and three things grant it and one
  denies it: `--cache-memory 0` with no `--cache-dir` leaves nowhere to keep objects
  and builds no tier at all, and `--cache-memory 0` beside a `--cache-dir` builds no
  memory half. Neither touches `cacheMemoryBytes` (a held `--listen-node` no longer
  is a third: it refuses the start), whose default is a quarter of RAM, so
  `NodeCapacityOf` reading the flag reserved 8 GiB on a 32 GiB box that cached
  nothing and offered the fleet 24 slots instead of 32. Under-utilisation rather than
  breakage, and therefore silent forever: nothing anywhere reports a reservation for
  a tier that does not exist. `NodeCapacityOf` takes the `NodeCacheCapacity` that
  `CacheCapacityOf` read off the tier, which is why `WorkerBody` derives capacity and
  `slots` BELOW the tier startup rather than above it — and why the record the leader
  renders and the number the worker enforces are now one call rather than a patched
  copy.
- **Which tiers cost the machine RAM is a column of `StorageTierTable`, not a check
  for `StorageTier::Memory`.** The taxonomy is open — the enum's own comment
  foreshadows a tier on a peer and a tier on a second filesystem — and enumerators
  are appended, so a resident tier added later would land past any hand-written
  check and be reserved as nothing. That direction over-commits the machine, which
  is the swapping-and-OOM failure `MemoryBudgetPerJobBytes` exists to prevent. And
  the reservation is total over the vocabulary: **absent** is a tier this node does
  not run, while **present and zero** is a tier with no ceiling, so a resident one
  is reserved as the whole machine rather than as nothing — the same two meanings of
  zero the bullet below already records.
- **`--cache-memory 0` means no in-memory tier, and zero is how
  `InMemoryLruStorage` spells UNBOUNDED.** `EvictToFit` returns immediately on a
  zero budget, so for as long as the flag existed the one number an operator could
  switch the cache off with was the number that removed its limit — a node told to
  hold nothing held everything, growing until the machine ran out of memory, with
  the cache appearing to work better and better on the way. Both halves off (no
  `--cache-dir` either) means no tier at all, said out loud rather than left to
  produce a cache port answering out of nothing.
- **`--slots=0` means NO WORKER, and zero used to be how `OfferableSlots` spelled
  DERIVE** (#206). The obvious way to keep a machine out of the work was therefore the
  one value that built a full worker, so it was refused, and operators gave schedulers
  a toolchain identity nothing could match -- which still registered, and under a
  fingerprint a client did compute took the work anyway. Absent now derives and zero
  runs none, and the flag reaches `OfferableSlots` only through `WorkerSlotsOf`, which
  answers NOTHING for a node running no worker: the fail-open direction is a derived
  count on the machine an operator excluded. `RunsWorker` is the one predicate. Such a
  node surveys nothing, registers nothing and starts no heartbeat thread; its compile
  family is refused `DispatchNotPermitted`, the code the daemon already answers a
  cordon with for the same fact, never `UnimplementedVerb`. **A setting only the
  worker reads names the worker in `NodeOptions()`'s `component` column, and ONE
  generated rule refuses it on a node running none** -- never a `!RunsWorker(c) &&`
  row per flag, and a rule ABOUT a worker carries the `scope` column rather than a
  pasted `RunsWorker(c) &&`. Six such conjuncts were written by hand in the branch that
  introduced them, and it dropped one (the reload widening rule). `--scheduler` is NOT
  worker-only: `RunClusterAdmin` and `RunEnrollAdmin` read it, so a no-worker node keeps
  it and registers nothing -- but it is still a **fleet-page machine**, because the
  Machines rows and the history handover ride `NodeAnnounce`, which every node sends
  (#1440). Its slot count on a fleet report is **absent**, never zero: a registered
  worker always offers at least one slot, so a zero there could only ever mean *a
  machine with no worker* said in the vocabulary of *a worker offering nothing*, and
  the fleet totals would put a machine that can take no work into the denominator of
  *how busy is this fleet*. Its own `pace_node_slots_configured` **does** read 0,
  and that is correct rather than the same defect: a node offering no slots has a
  capacity of zero, which is a reading rather than an unmade measurement. The two
  fields answer different questions and the same word would be wrong in one of them.
  **"No worker" is not "no machine" for the fleet's compile queue (#1728, R6)**: every
  node, a `--slots=0` one included, states its machine's compile budget
  (`MachineBudgetOf`: `--machine-slots`, `--machine-memory-budget`) on the presence loop's
  round, which runs everywhere. It is a budget record and not a worker registration -- such
  a node still registers nothing and is never sent a dispatched compile -- and its flags are
  deliberately NOT worker-column rows, or the generated rule above would refuse them on
  exactly the node that needs them.
  **The worker is `WorkerTier`, null on such a node** (#1387): no idle pool thread, no
  capacity sized to zero, no validator. It owns the `SchedulerLink`, so a worker cannot
  exist without one and a start that reaches it with no `--scheduler` is refused by
  name rather than heartbeating nowhere. **And a node running no worker may run only
  consensus**, which reached two answers written for "every node has a compile
  component": the merged listener's bind predicate (`AnswersAnyFamily`) and its
  session-ceiling fold (`MergedResponder::Largest`) both count the never-null operator
  families -- node, live and fleet -- or such a node names a port it does not bind -- or
  binds one whose ceilings fold to zero and closes every connection, NODE-STATUS (`pacectl node`)
  included. The second was found only by a test that EXCHANGED a frame over the bound
  port; the bind alone passed. The bind, the fold and the connection sum all read
  `FamilyRoutes`, one row per `VerbFamily` with a presence column and a ceilings column
  that a new family must STATE (`EveryFamilyIsClassified`), because a hand-written list
  of members beside the router was silent about `Fleet` when that family landed. The
  `OnEveryBuiltNode` owners' connection allowances ADD, since they coexist on every port
  while the live subscriptions are all held.
- **A store that will not open is always fatal; a port that will not bind is fatal
  only when the operator typed the address.** The two leave `CacheTier` through one
  `std::string`, so `StartCacheTierOrExplain` opens the store itself rather than
  letting `Start` do it — otherwise a bad `--cache-dir` on a node using the DEFAULT
  cache port is logged as a warning and stepped over, and the error names
  `--listen-node` while pointing at a directory.

- **A port this node LISTENS on is a row of `NodeSurfaceTable()`, and an opener takes
  the `NodeSurface` rather than an address.** The port map lived in five places --
  `EndpointFlags`' install-time grammar (four surfaces), a `StartupPolicyRejection`
  row (raft), four `*ListenDefaultHost` constants, the six opener call sites, and the
  operator documentation -- and an operator's firewall list was the sixth
  ([#288](https://github.com/LASTRADA-Software/pace/issues/288)). They are one
  table now, and the guard is the **type system**: `FrameEndpoint::Start` and
  `AdminEndpoint::Start` take an enumerator, so there is no argument to pass a bare
  string to and a port cannot be opened without a row. A guard that fails the build
  beats one that fails a suite.

  **The operator documentation was the one copy the type system could not reach**, and
  #288 left it that way: the tables and the firewall advice are hand-written prose, and
  a hand-pasted `--print-surfaces` transcript looks like machine output while being a
  string in a markdown file. `ctest -R node-surface-docs` holds five documents to the
  table, in **both** directions — every declared surface present, and nothing
  surface-shaped that the table does not declare, because on a firewall worksheet an
  extra row reads as authorisation to open a port.
- **The row rule cannot see prose, and prose is what survived the hand-edit.** #290
  stage 3 rewrote every one of those lines by hand and got every port NUMBER right;
  what it left behind were two sentences — *"carries the full six-surface table"*
  against four rows, and *"Five TCP rules and one wrong one"* against three TCP
  surfaces, sitting directly under a correct four-row table an operator counts rules
  from. So the check carries a COUNT rule as well, and that is the half that found
  both. A hand-edit correcting a table is not evidence that the paragraph under it
  was re-read.
- **`surface` names two different things here, and #290 is why.** There are FOUR ports
  and THREE policy roles sharing the node port, and prose legitimately counts either —
  so a count rule anchored on the word alone checks two concepts with one regex and
  fires on correct writing, and a rule with a known false-positive class gets disabled
  by the third person it inconveniences. The anchor is therefore narrow (a phrasing
  that names the port set: a *table*, a *process*, a protocol's *rules*) and the
  residue is **refused rather than ignored**: any other number-plus-`surface`
  collocation must be classified in the check's exemption table with a reason. Covering
  less and being right beats covering everything and crying wolf — and the exemption
  rows are now the only written record that the word is overloaded.

  What that removes is subtler than the duplication. **The default host used to be a
  caller's argument**, so the cache's loopback and the scheduler's wildcard -- which
  exist for a security reason, not a preference -- were mechanically whatever the call
  site passed. A test binding a bare port with an explicit `"127.0.0.1"` default
  against a wildcard-defaulting surface would have bound every interface and gone
  green.

  Three columns carry what the openers cannot: **protocol** (discovery is UDP and the
  other five are TCP, so a worksheet without it yields five correct firewall rules and
  one wrong one), **`defaultHost`** (the host a bare port falls *back* to -- loopback
  for the node surface on a worker and the wildcard once `--serve-scheduler` is given,
  since peers are elsewhere by definition), and a free-form **note** for what a column
  cannot say.

  There is deliberately **no `presence` column**: `resolve` already answers it, and a
  column restating it was wrong for raft, whose address an operator can name while
  `--node-id` is what actually binds it. No `explicitBit`: that is `OptionSpec`'s, and
  copying it here would create the fifth place while removing it. And **no
  `HostOrigin`** naming which mechanism supplied the host -- it documented rather than
  drove, and what it tried to record is enforced by code instead: discovery's sockets
  bind the wildcard whatever `--discovery` says because its *resolver* says so, never
  because a label described it.

  `--print-surfaces` renders the **resolved** configuration, never the defaults --
  a worksheet claiming `127.0.0.1` for a node started with `--listen-node 0.0.0.0:6674`
  is a security misstatement rather than an untidy one -- so it parses the whole
  command line (`ParseFlow::Continue`, unlike `--help`) or it describes a machine
  nobody configured.

  **`--advertise` is not a surface.** It is what this node tells others to dial, not a
  socket it opens.

  **A bare `--listen-node` follows `--serve-scheduler` and nothing else, and that is a
  decision rather than an omission**
  ([#463](https://github.com/LASTRADA-Software/pace/issues/463)). Widening it for
  a *fleet participant* -- `--scheduler`, `--fleet-open` -- restores
  no ergonomics: the wider bind is what makes `CompilePortFacesTheNetwork` true, so
  a way to check a lease becomes required, and the wider bind *becomes* the advertised
  endpoint, so `AdvertisesWildcard` requires `--advertise` too. It costs two things.
  It silences `AdvertisesPastALoopbackBind`, whose message is the remedy. And "is
  this a fleet participant" already has three deliberately different spellings -- the
  reachability rows' gate, `AdmitsRemotePeers`, `CompilePortFacesTheNetwork` -- so a
  fourth would decide a bind by one predicate and judge it by another.

  What the question exposed is a hole in the refusals instead, and the refusals are the
  mechanism: **all three reachability rows judged a flag somebody had TYPED.** A worker
  naming neither `--advertise` nor `--listen-node` fell through every one -- the
  advertise falls back to the `Node` surface, so both halves are loopback and the rule
  about their *disagreement* has nothing to say -- and registered `127.0.0.1` with a
  scheduler on another machine. `NodeServiceRejection` refused exactly that at install
  time while nothing refused it at a hand start, which is the reverse of the asymmetry
  #166 composed the two tables to delete. `AdvertisesLoopbackToARemoteScheduler` is the
  fourth cell, and **the scheduler's host is the only thing that can decide it**: a
  loopback bind advertising loopback is the single-machine fleet this repository's own
  fixtures run, so neither the bind nor the advertise separates the two.

  **"The operator typed it" is `cfg.cacheListenExplicit`, never a comparison against
  the default** ([#286](https://github.com/LASTRADA-Software/pace/issues/286)).
  Why a comparison cannot answer it, and why the registration side of the same flag
  had it wrong too, is
  [`platform-service-and-config.md`](platform-service-and-config.md) under
  "provenance is not value" — read it before adding a flag whose default means
  something.
- **The tier lives behind a single-shard `ShardedStorage`, and that wrapper is the
  lock rather than any kind of sharding.** The tier is mutated on the reactor thread
  while the heartbeat thread and the `/metrics` scrape read its statistics, and
  `Snapshot()` on these backends writes a `mutable` member. It is the same reason
  the daemon's `useShardingWrapper` includes `metricsEnabled`. A node's `--cache-dir`
  still does its I/O on the shared reactor thread (#136), which is stated where an
  operator meets it.
- **A store file belongs to exactly one open store, and the store enforces that
  rather than documenting it.** `FilePageStore::Open` claims the file — POSIX
  `flock(LOCK_EX | LOCK_NB)`, and on Windows the `FILE_SHARE_READ` share mode it
  already passed — and a second opener gets `StorageErrorCode::InUse`, which is a
  distinct code because the remedy is another process or another path, not a
  repair. Before this, two nodes on one `--cache-dir` (or two daemons on one
  `--storage`) silently lost half their writes on POSIX: 400 committed puts,
  200 readable, no error anywhere. It must stay `flock` and never `fcntl` — an
  fcntl lock is per PROCESS, so a second store inside one process would take it
  again and report success. Nothing is written to the file, so a store stays
  byte-compatible with builds that predate the claim; and a filesystem that
  cannot lock opens anyway and *says so*, because refusing there would break a
  working deployment over something that is not contention.
- **A cache is per NODE, and the registry is keyed per (fingerprint, endpoint).** A
  node with two `--toolchain` flags is two entries against one machine —
  deliberately — and both heartbeat the SAME cache figures, so summing a cache field
  across `LiveWorkers()` counts one node's objects once per toolchain it serves.
  `WorkerRegistry::NodeCaches()` is the deduped view, and it does not pick
  arbitrarily between siblings: `Register` clears a worker's load, so an entry that
  just re-registered holds nothing while its sibling holds last round's figures. One
  that has reported a cache wins over one that has not, most recently seen breaking
  the tie — otherwise a node reads as having no cache for one heartbeat interval,
  intermittently, depending on an `unordered_map`'s iteration order.

The cache facts themselves ride **nested**, inside the capacity and load records
rather than beside them, for the reason those records are nested inside REGISTER
and HEARTBEAT: `SplitFields` is exact by design, so a fact added at any fixed-arity
level makes two builds of a fleet unable to speak at all. Tiers travel
**positionally**, because `CompileCacheWire.hpp` is compiled into `pace-cc`
and cannot see `StorageTier` — which makes that enum's ORDER a wire contract, and
makes `CacheCapacityToWire`/`FromWire` the only pair that knows index 1 is the disk
tier. A transposition between them decodes perfectly and reports a node's RAM
budget as its disk budget, so both round trips give every tier a distinct value.
None of it is scheduling input: `AvailableSlots` does not read it and must not
start to, because how full a node's cache is says nothing about whether it can take
another compile.

`NoExpiry` is `TimePoint::max()` and **not** a default-constructed `TimePoint`: the
storage tests `entry.expiry <= now`, so zero means "expired before any clock reading"
rather than "no deadline" — every write landed and was unreadable, a cache that
silently stores nothing while reporting success on every write. `CacheEngine` already
spelled it the same way, which is what makes this a drift rather than a discovery.

- **`PACE_ADDR` defaults to LOOPBACK, and set-but-empty is the opt-out.** Unset
  resolves to `Cc::DefaultAddr` (`127.0.0.1:6674`), which is where `--listen-node`
  answers, so the launcher caches against a node on this machine with no
  configuration at all. Three-valued on purpose, and `EnvOr` — which collapses
  set-but-empty into unset — must not be used to read it, or the documented opt-out
  `cmake/portable/CompileCache.cmake` exports becomes the default. A *remote*
  default would be indefensible: every TU on a machine with nothing listening would
  pay a connect timeout in silence, the exact cost `USE_COMPILER_CACHE` probes at
  configure time to avoid. Loopback is not that — a closed port refuses immediately,
  with no timeout and no round trip — which is the whole argument for this address
  and why it could not be another one.
- **A cache answer that dials must not be serialized behind the accept loop.**
  `FrameEndpoint` owned a thread and served its connections ONE AT A TIME, and
  `RemoteUpstream` dials the shared cache from inside a cache answer -- so a single
  upstream that took five seconds held every local `pace-cc` behind it, one
  after another. A node whose shared cache was unreachable had an unusable port of
  its own, and nothing anywhere said so: every client eventually got a correct
  answer, just far too late. `NodeIoLoop` is the reactor both framed surfaces now
  accept on, with a `DetachedTask` per connection. Six consequences, each
  load-bearing:
  - **The payload cap became a PER-CONNECTION cap the moment serialization went.**
    Serving one at a time bounded peak memory to a single `MaxRequestBytes()` frame
    by accident; serving them concurrently makes it N of them. So
    `MaxConcurrentRequests()` and `MaxInFlightBytes()` are columns on the responder,
    and they had to land in the same commit as the detach -- a fix that opens a
    memory-exhaustion hole is not a fix. The spread is the point: 256 concurrent at
    64 KiB for the scheduler, 8 for the cache with a 256 MiB total budget that is
    deliberately ONE request's worth, so eight ordinary objects run in parallel while
    a single 256 MiB monster still cannot be joined by seven more.
  - **The request deadline was otherwise silently lost.** It used to be
    `SO_RCVTIMEO`, applied to every accepted socket by `BlockingListener::SetTimeouts`.
    A reactor socket has no such option -- its reads suspend rather than block -- so
    without a replacement a client that connects and sends half a header holds a
    descriptor and a coroutine frame until the process dies. A free slow-loris on the
    node's cache port, created by the change that removed the stall. One sweeper per
    server on a bounded tick, NOT a timer per connection: `IReactor::Schedule` cannot
    be cancelled, so a per-connection timer would stay on the wheel for the full
    interval after its connection had finished.
  - **Every close is posted onto the reactor.** On epoll and kqueue `ISocket::Close`
    completes a parked awaitable by resuming its coroutine INLINE, so closing from
    the stopping thread would run the server's connection tasks there while the
    reactor thread is still driving them. IOCP routes cancellation back through the
    port and does not -- which is exactly what makes it a race that passes CI on
    Windows and corrupts state on the other two.
  - **`Shutdown()` waits for the LOOPS, not only the connections**, and the first cut
    did not. `~FrameServer` then freed state the accept loop and the sweeper still
    pointed into: SIGSEGV, plus a port still bound after the endpoint claimed to have
    stopped. The state is shared with the loops now. Found by the endpoint's own
    destruction test, which is the one that exists to catch exactly this.
  - **The reactor is stopped by its loops, when the last one ends** -- the sweeper
    counted among them, because a frame parked on the timer wheel is precisely what
    `IReactor::Run` must not return over. And `NodeIoLoop` is declared BEFORE the
    tiers in `WorkerBody`, so it is destroyed after them: a tier's destructor posts
    its closes onto this reactor, which therefore has to still be running.
  - **It is NOT consensus's reactor.** A cache answer now awaits a dial with a
    multi-second ceiling, and putting that in front of the Raft heartbeat timer would
    be this same defect moved one layer over -- the failure this list already names as
    nine role changes in twelve seconds. It is also the only node header that includes
    `PlatformReactor.hpp`, which is what keeps `<windows.h>` out of everything that
    includes `FrameEndpoint.hpp`; the endpoint holds an `IListener` rather than the
    platform type, which is what `IListener::BoundPort()` was added for.

- **A worker's compile port had the SAME defect, and the slot cap hid it.**
  `WorkerServer::Run` awaited each compile inline, so a node advertising 32 slots ran
  exactly one at a time: `_inFlight` could never exceed 1, the cap it enforces was
  unreachable, and the scheduler dispatched 32 jobs to a machine that would serve them
  in a queue. Nothing reported it -- every client got a correct object, and the fleet
  page showed a worker that was never busy because it never was. A cap that cannot be
  reached is indistinguishable from a cap that is never hit.
  - **A compile cannot go on a reactor.** It spawns a process and holds its thread for
    seconds, so `ResumeOn { someReactor }` would stall every other coroutine that
    reactor owns -- the same defect one layer over. It goes on a `ThreadPoolExecutor`,
    which is what `IExecutor` was split out of `IReactor` for: `ResumeOn` only ever
    needed `Submit`, and a pool is not a reactor.
  - **The hop is one-way only because the worker's listener BLOCKS.**
    `BlockingSocket::Read` does its `recv` eagerly and returns an already-ready
    awaitable, so nothing after `ResumeOn { _jobs }` suspends and the whole of
    `Serve` stays on the pool thread. Move that port onto a reactor and every read
    would resume the coroutine on the reactor thread -- putting the compile back
    there, invisibly, with no call site changed.
  - **On the merged `0xFC` surface it is TWO hops, and the second one is the invisible
    one.** #290 gave the compile verbs a second door, and that door is a reactor: a
    frame arrives on the reactor thread, so the compile has to leave it (the bullet
    above, one layer over again) *and* the reply has to come back to it, because
    `FrameEndpoint` writes what a responder returns to a **reactor socket**. Returning
    from the pool thread leaves the connection task's writes, its deadline rearm and
    its close running off the loop that owns them -- and nothing reports it. The object
    is correct, the write usually succeeds, and no call site changes. So
    `CompileResponder`'s test asserts the **thread identities**: that the compiler ran
    somewhere other than the reactor, and that the reply was produced on it. Both
    mutations were staged, and each was caught by exactly one assertion while every
    other assertion in the case -- the object included -- still passed. A test that
    checked only the reply passes under both bugs.
  - **The second door spends the FIRST door's accounting.** `CompileResponder` holds
    `WorkerServer::Capacity()`, never a `CompileCapacity` of its own: two counters
    would make one machine answer to two caps depending on which door a client used,
    and the slot figure it advertises to the fleet would describe neither. It is also
    what makes one bounded drain cover both -- `~WorkerServer` waits on a count both
    doors raise -- and it is why `main.cpp` declares the worker BEFORE the surface, so
    the listener stops admitting compiles before the drain starts counting them. The
    responder has no accept loop whose condition would stop admission, so the stop is
    decided by `CompileCapacity::TryTakeSlot` itself -- together with the cordon and the
    cap, in one locked step (#1303; see *The cordon* below).
  - **A merged door is an ADDITIONAL door onto one policy, never a relaxed one.**
    Membership is the accept loop's own `RefuseUnlessMember`, moved beside the refusal
    rows rather than restated, and the lease is checked where it always was, inside
    `WorkerProtocol`. `AuthRequired` answers **false** for `Op::Compile` -- which is a
    `RequiresAuth` row, so that answer is what decides it -- because a compile already
    carries a per-job credential the scheduler signed for this worker's endpoint, and a
    connection-scoped secret would be strictly weaker while refusing every client the
    dedicated port serves.
  - **The pool is sized to the cap, and the cap is what refuses.** The pool does not
    bound admission -- it runs what it is given -- so an unsized pool would queue
    silently and hide the overload from the scheduler trying to route around it.
    `WorkerServer` refuses over the cap and the pool has one thread per slot, which is
    what makes an admitted job always find a thread.
  - **The payload cap became a per-connection cap the moment serialization went**,
    exactly as it did for `FrameEndpoint`, and the byte budget had to land in the
    same commit rather than after it. Serving one at a time bounded peak memory to a
    single `MaxRequestBytes` by accident; `slots` jobs each declaring the maximum is
    `slots` times it -- 8 GiB on a 32-slot node, asked for by any cluster member. The
    budget still grows with `slots`, but by a chosen per-slot figure rather than by the
    ceiling (#1667): `slots` times 64 MiB (a quarter of the default per-request ceiling),
    never below 256 MiB nor below the ceiling, inside the 1 GiB per slot the slot clamp
    already assumes -- because a flat 256 MiB refused half the leases a 30-slot worker
    was granted on translation units of median 12.5 MiB, max 21.6 MiB. Both are options
    (`--compile-request-max`, `--compile-inflight-max`, restart-only). And the
    listener's one pool folds to the LARGEST owner, so wherever the compile budget
    exceeds the cache's 256 MiB -- five or more slots, a raised `--compile-request-max`, a
    typed `--compile-inflight-max` -- the cache and shared-cache reads share it (#1338 is
    why there is one pool). And the SCHEDULER prices it: a heartbeat carries the budget and
    what the running compiles hold of it, and `SlotCeilingsFor` turns the remainder into a
    `compile-budget` ceiling at this worker's own mean per job, so a worker out of bytes is
    passed over rather than leased and refused; NODE-STATUS carries both ceilings.
    Checked on the DECLARED length before a payload byte is read, and refused with
    `EndpointBusy` and its own counter: slots were free and memory was not, so
    reporting it as `NoCapacity` would send an operator to buy machines that would
    not help.
  - **And the declared length it checks is the COMPRESSED one, which is not what the
    request costs.** A COMPILE carries its preprocessed source in a codec envelope
    whose `rawLen` is what the decoder sizes its output buffer from, so a hundred-byte
    frame may declare a 256 MiB expansion and pass admission having reserved a hundred
    bytes -- `slots` of them are `slots` times the per-request ceiling all over again,
    now where the budget cannot see it. #241's ceiling is per REQUEST and closes only
    half of this; the budget charges `DeclaredRequestFootprint`, the larger of the
    frame length and the declared expansion, raised onto the same reservation once the
    payload has been read. It cannot be asked earlier -- the envelope is a field of the
    payload. The reasoning, including why the larger and not the sum, and why a
    footprint above the whole budget is left to the decoder rather than answered
    `EndpointBusy` on an idle worker, is in
    [`wire-and-protocol.md`](wire-and-protocol.md).
  - **Concurrency turned a per-call scratch path into a per-thread one.**
    `CompileJobRunner` derived `job-N` from a plain `++`, and the source file and the
    hard-coded `tu.o` both live inside it. Two jobs reading the same counter compiled
    into the same file and one returned the OTHER's object -- which its client then
    cached under its own key. Silent wrong-object delivery is the worst thing a
    compile cache can do, and it was reachable in about one run in six once two jobs
    started together. Anything a worker derives per job is derived per THREAD now, and
    `Run` says in its docs that it may be called concurrently.
  - **A spawned child inherits what the PROCESS has, not what the call set up.**
    `CreateProcess` with `bInheritHandles = TRUE` hands over every inheritable handle
    in the process, and a POSIX fd without `FD_CLOEXEC` survives `exec`. So a
    sibling's compiler held another job's pipe write-end open, that job's drain never
    saw EOF, and it blocked until an unrelated compile finished. Windows names what
    may be inherited (`PROC_THREAD_ATTRIBUTE_HANDLE_LIST`) rather than chasing what
    may not -- which also closed a live leak of *accepted client sockets*, since
    `::socket()` returns an inheritable handle. POSIX marks both pipe ends
    close-on-exec, under a lock that also covers the spawn, because the window between
    creating a descriptor and marking it is a window a sibling can spawn in.
  - **A bounded wait MEASURES its ceiling; it does not count polls towards it.**
    `waited += poll` is the obvious spelling and it is wrong, because a sleep costs
    what the platform's timer granularity says rather than what it asked for: on
    Windows a 5 ms request costs ~15 ms, so `FrameServer::Shutdown` stated a 5 s
    ceiling and enforced 15, and `RaftPeerTransport::Stop` enforced 7.5 (#452).
    Nothing observes this. Every drain still ends, every reply is still correct, and
    the only symptom is a stop that takes three times as long as the code says --
    which reads as a slow machine, and on a supervisor with a stop timeout is the
    difference between stopping and being killed. Both copies carried a comment
    citing `RaftPeerServer::Shutdown`, which is correct, and which they had
    reimplemented rather than called; one of them cited its cadence while using a
    different one. **A comment naming the implementation it duplicates vouches for
    whatever the duplicate got wrong**, so the fix is the call, not a better
    comment: `Core/BoundedDrain.hpp`'s `DrainWithin` is the one bounded drain here
    and the four shutdown paths take it. Its ceiling and cadence are `DrainBound`'s
    defaults, so a site states neither. And the blocking and the clock arrive on one
    injected seam (`IDrainWait`) rather than two, because a test whose sleeps cost
    what they requested cannot tell the counting implementation from the measuring
    one on ANY platform -- the fake that makes a request and its cost disagree is
    the entire regression test.
  - **A drain must not wake on an atomic it is about to destroy.** `~WorkerServer`
    waited on `_inFlight.wait()`; an atomic wait can return on observing the store
    alone, so the destructor could finish and free the object while the job that
    released the last slot was still inside `notify_all` on a member of it. It waits
    on a condition variable whose notifier holds the mutex, which is what proves the
    notifier is past its critical section before the waiter can run.
  - **A destructor that drains closes the door first.** Waiting without `Shutdown()`
    races the accept loop admitting one more job just as the count reaches zero, and
    the wait then returns while that job is starting. The loop re-checks the flag after
    `Accept()` returns too, since the check at the top of the loop was made before it
    parked.

- **`EndpointBusy` is not `NoCapacity`, and the split is for whoever reads it.**
  `NoCapacity` is a statement about the FLEET -- every matching worker full of this
  build's own work, which an operator answers by buying machines. `EndpointBusy` is
  one node's own front door: it has hit its concurrent-request cap or its in-flight
  byte budget, and the same client asking again shortly will very likely be served.
  Reporting either under the other's code sends an operator to fix something that was
  never wrong, which is the same argument `Withdrawn` already makes for splitting off
  its own case.

- **The launcher runs its cache exchange on a reactor of its own, and gets a bounded
  name lookup for it.** `main.cpp`'s private `TcpClient` is gone -- fifty lines in a
  file that is in no test target, existing only to give four sites an
  optional-shaped `Connect` and to `SyncRun` two loops. What it bought is not
  latency: the launcher is one-shot per translation unit and has nothing to
  interleave. It is that `getaddrinfo` takes no timeout, so `PACE_ADDR` pointing
  at a name whose resolver is wedged used to stall every translation unit in the
  build with no knob anywhere. Three things about `ReactorExchange`:
  - **One reactor per exchange, asserted rather than documented.** `IReactor::Run`
    returns only on `Stop()` and no reactor here clears that flag, so a reused
    instance performs the first exchange and silently skips every later one -- which
    the launcher answers by compiling locally, making every build slower with nothing
    anywhere saying why.
  - **The deadline CLOSES the socket rather than stopping the reactor.** Stopping
    would leave the coroutine parked on a read nobody completes: a leaked frame and a
    leaked descriptor, once per translation unit. Its test asserts the close, and
    fails without the timer.
  - **`Threads::Threads` is linked and named.** The resolver pool is the one thing
    this launcher genuinely needs a thread for. Not a departure from the rule this
    binary exists to protect -- that rule is about not linking `Pace` and
    therefore not dragging in yaml-cpp, OpenSSL and the reactor's transitive world --
    and it is named rather than left to glibc folding pthread into libc since 2.34,
    which happens to work on the distributions CI uses.

- **One accept loop serves all three of the node's framed surfaces.** `FrameEndpoint`
  over an `IFrameResponder`; a second and third accept loop would be near-copies of a
  listener, a shutdown order and a poll timeout. An interface rather than a
  `std::function`, because a responder outlives the endpoint and a closure would keep
  its whole enclosing scope alive with it. Three things the seam keeps per-surface that
  one constant would have flattened: the **payload cap** (64 KiB for scheduler verbs,
  256 MiB for a cache STORE carrying an object file — sizing both large hands an
  unauthenticated peer a way to make the *scheduler* allocate megabytes, sizing both
  small silently stops caching this machine's largest translation units); the **default
  bind**, which is inverted between them (wildcard for the scheduler, because one no
  peer can dial does nothing; loopback for the cache, because a node's private cache
  reachable from the network is a decision); and **whether the peer's identity is
  consulted at all**, which only the scheduler does.
- **Each surface is one owned object, and the reason is not tidiness.**
  `SchedulerTier` and `CacheTier` each hold a *reference chain* — endpoint → responder
  → protocol → service, and endpoint → responder → proxy → cache → storage + upstream
  — so as locals in a function body their declaration order is load-bearing and
  silently so: getting it wrong is a dangling reference rather than a compile error. As
  members it is checked by the language. `WorkerBody` also reached a cognitive
  complexity of 67 against clang-tidy's 60 with both inline, and extracting only one of
  them left 62 — the number was pointing at two coherent decisions, not one.

`scripts/dist-compile-e2e.sh` asserts the consequence rather than the mechanism:
that a worker's object is **byte-identical** to a locally compiled one. That single
assertion is what fails if either rule is broken, and it is the whole soundness
claim of the feature — an object that differs is stored under a key other machines
then fetch.

> **The launcher's `PACE_VERIFY` answers a different question with the same
> fact**, and for a long time answered it wrongly — it compared objects with
> `memcmp`, so every Windows hit reported a wrong object
> ([#493](https://github.com/LASTRADA-Software/pace/issues/493)). This
> paragraph existed then, in this file and two others, and none of them is one
> somebody editing `HitVerification.cpp` opens. The launcher's copy —
> including why `.debug$S` and `.chks64` are **not** excused there, which is the
> opposite of the conclusion this fixture reaches from the same measurements — is
> [`compile-cache.md`](compile-cache.md#an-object-file-is-not-a-byte-string-and-pace_verify-is-where-that-bites).
> Change either and read the other: they share the facts and not the conclusions.

**On Windows that assertion has to be spelled differently, and it is measured
rather than relaxed.** Both MSVC drivers write the **clock** into the COFF header
(two compiles of one file to one path two seconds apart differ in exactly byte 4;
only `/Brepro` suppresses it, and a fixture that passed `/Brepro` would be asserting
something about a command line no build uses). `cl` additionally records the
**absolute path of the object file** in `.debug$S` and hashes the file it opened
into `.chks64`, with no debug flag asked for — and a worker compiles its own scratch
file to its own scratch path, so neither can ever match. Everything carrying code or
data does: `.text$mn`, `.rdata`, `.xdata`, `.pdata`, `.drectve`, `.data$r` and
`.bss` are byte-identical between a reference compile of the original source and a
worker-shaped compile of `/E` text elsewhere. `dist-compile-e2e.ps1` therefore
compares **section by section** against a per-driver table of what may differ, and
`clang-cl`'s row is *empty* — it records only the source's base name, which the
worker is now told, so its objects differ by the clock alone. Three lessons are
worth keeping, and each was a hole first:

- The COFF **header** is compared field by field rather than skipped, because an
  object built for another architecture differs *there and nowhere a section walk
  would look*. Its two excused fields are excused by name — the clock, and the
  symbol-table pointer, which moves whenever an excused section changes size.
- **A section walk alone accepted a truncated object.** MSVC writes the symbol
  table last, so cutting a tenth off a file leaves every section intact and
  comparing equal — and a truncated transfer is one of the few faults distribution
  can actually introduce. COFF states its own end (the string table opens with a
  size that includes itself and is the last thing in the file), and that check runs
  on both sides under every rule: "the file is as large as it claims" is not a
  property a driver gets to opt out of. Whether the tail's *content* may differ is
  a second per-driver column, measured the same way — clang-cl's is identical, and
  `cl`'s is not.
- The comparison has a **`-SelfTest`** of its own, because the fixture's own logic
  is the one thing nothing else tests. Two defects in it were found that way and
  one by asking it to reject deliberately wrong objects: the earlier control
  compared two objects with different **names**, which `cl` records inside the
  object, and so reported a perfectly reproducible driver as non-reproducible in a
  CI log — as the answer to the question the fixture had been asking for three
  commits.

**Every wait in that fixture is bounded, and that is a rule rather than a
detail.** Its first version killed a worker and then `wait`ed, which HANGS when a
signal is handled but the stop never completes — and a 900-second ctest timeout
naming nothing is the least useful way CI can report a defect. `stop_and_require_exit`
fails in 15s saying what it waited for, and the cleanup trap escalates to SIGKILL
rather than blocking, because cleanup runs on every exit path including the
failing ones: an unbounded wait there turns any single failed assertion into a
silent suite timeout. The same lesson applies to unit tests — a helper thread
spinning on a counter a regression never advances hangs instead of failing, which
is what the `IdleListener` hook exists to avoid. Relatedly, CI's live-systemd step
waits for the worker's **own** readiness line rather than `systemctl is-active`:
`Type=simple` is reported active the moment systemd forks, while the worker still
has seconds of include-tree walking to do.

**A dashboard route is a verb, and gets the same leadership answer as the rest of
the surface.** `/fleet` and `/fleet.json` are not registered at all on a node with
no `--serve-scheduler`, so they are a plain 404 rather than a route answering with
an empty fleet -- a process with no fleet view offers no fleet route. Where one
exists, a node that does not lead answers `503` naming the leader, which is
`Gate()`'s `NotLeader` rendered in HTTP. The reasoning, and why it is never a
redirect, is in
[`metrics-and-observability.md`](metrics-and-observability.md).

**The ceilings behind `AvailableSlots` are reported, not just the minimum.** That
function folds five numbers into one and the fold loses the only part an operator
can act on: a node offering 2 of its 16 slots is a different problem depending on
whether somebody is *using* the machine, its memory is gone, its scratch disk
has filled, or its own compiles hold its byte budget, and the four have opposite fixes. `SlotCeilingsFor` is the same
arithmetic with each ceiling named and `AvailableSlots` is one line over it, so
there is one author for the subtraction. Two properties travel with it: the
ceilings are `optional`, so a machine that could not read its CPU has *no* CPU
ceiling rather than one of zero; and a tie names the earlier limit in enumerator
order, which is application order -- left unstated it would depend on how the
comparison happened to be written and change under somebody tidying it.

**The CPU ceiling charges only the external cores beyond the HEADROOM the slots leave
(`cores - slots`, floored at zero), never all of them and never a cap at the idle
cores.** Slots are the share of a machine the fleet may have; charging every external
core against that share charges all of somebody's work against it. It did: `--slots=4`
on a 32-core machine was fully withdrawn by four busy cores with 28 idle, and a
workstation's reserve was spent twice, once deriving the slots and again the moment
its owner used the cores it holds back. The first repair, `min(slots, idle)`, broke
the other end: `OfferableSlots` takes an operator's count untouched, so `--slots=64`
on 16 cores offered 16 on an idle machine, named `external-cpu`. With the slots at the
core count -- the default on a dedicated node, and every fixture that asked for "the
whole machine" -- all three formulas agree, which is why no test noticed either. What
a fixture can never run under is a host with no idle core: that is a machine the fleet correctly
refuses, so both `dist-compile-e2e` fixtures SKIP on it -- and only when the
scheduler's `limited-by` and their own CPU reading of the host BOTH say so, since
the scheduler's answer alone is the product vouching for itself -- and the host
reading is taken NET of the fixture's own processes, because a spinning daemon or
scheduler saturates the host by itself and is exactly the regression a raw reading
would skip.

**A heartbeat age is a duration on a report, never a `TimePoint` on `WorkerInfo`.**
`WorkerInfo` is what `Pick` returns and what a lease is built from, and an age
frozen inside a lease stops meaning anything the moment it is stored. Worse,
handed a raw `TimePoint` the obvious thing for a consumer to do is subtract
`steady_clock::now()` -- right in production, wrong under every `ManualClock` test,
and silent, because the two clocks agree about nothing. Subtracting inside the
registry means the answer comes from the clock it was injected with; it clamps at
zero, because a manual clock can legitimately be set backwards and an unsigned
duration would otherwise read as several hundred million years.

**Nothing a receiver can RECOMPUTE travels on the wire.** A node hands its closed
buckets over on the heartbeat it already sends, and the record carries two instants
and the readings -- no fold and no coverage. The leader replays those readings at
those instants to fold them into its own rings, so it rebuilds both anyway; carrying
either would be a second answer to a question already answered, and the one a decoder
trusted would be the one nothing kept correct. A counter's peak is a RATE and cannot
be recovered from a single reading, which is the tempting reason to send it -- but it
*can* be recovered from the SEQUENCE, and the sequence is what travels.

**Handed-over history is filed under the MACHINE, never the worker id.** A host with
two `--toolchain` flags registers twice and heartbeats the same figures twice, so
keying per registry entry holds one machine's series once per toolchain and sums it
that many times -- the rule `WorkerRegistry::NodeCaches()` already exists to enforce
on the neighbouring number. `Heartbeat` therefore returns the endpoint rather than a
bool, which also removes the second lookup and the expiry gap in the middle of it.
A heartbeat from a worker the scheduler does not know is refused and routes nothing:
the refusal is what tells the node to register again, and the endpoint it would be
filed under comes from the very entry that is missing.

**The wire carries no acknowledgement, and needs none.** The leader keeps a
high-water mark per endpoint, so a batch redelivered after a reply the node never saw
is ignored there rather than counted twice. The node's own cursor is the other half:
it advances **only when the verb that carried the batch succeeded**. The cursor lives
on the sampler beside the series it indexes, not as a bare integer in `main()` that
only running the program could exercise.

**And exactly one verb carries it: NODE-ANNOUNCE, which every node sends** (#1440).
That is forced rather than chosen. A machine running no worker never sends `Register`
at all, so a carrier riding registration cannot serve the machine the handover matters
most for -- a scheduler-only leader, whose own series is the one an election is about
to orphan. And it cannot ride both verbs, because `NextHistoryBatch` advances a
cursor: two callers in one process would each take a batch and each step past it,
splitting the buckets between two verbs and losing any batch one took and the other
acknowledged.

The defect this rule was first written for was `accepted` counting a *registration*,
which carries no history, so a round where every heartbeat failed and one re-register
succeeded stepped the cursor over a batch that was never sent. **That shape is now
unreachable rather than merely fixed**: `HeartbeatRound` has no sampler, so the
worker's round cannot obtain a batch to step over. Reach for the type system when the
obligation is *do something*; the comment was doing a job a missing field does better.

**A leader persists what it was handed, and that is not an optimisation.** A node
advances its watermark once and never resends, so a leader that forgot what it had
been handed leaves those windows a gap for as long as the rings hold them -- the
exact failure the handover exists to remove, reintroduced by a restart. The store
nests one `FleetHistory` body per machine, written by the code that reads it back: a
second copy of the ring encoding drifts the first time a bucket grows a field, and
drifts *silently*, because both halves still round-trip against themselves.

**A worker discovers the machine's compilers; `--toolchain` narrows that, and does
not supply it.** `--toolchain` was required and had no default, which meant
`packaging/` shipped a worker that could not start: the Linux unit reads an env file
whose every line is commented out, so the service starts, refuses and exits, and the
Windows MSI registered no node at all. The reversal rests on a distinction that is
easy to lose — **"no default compiler" and "no discovery" are different claims**. A
default is how a job ends up running against something nobody chose; which compilers
a machine holds is a *fact*, and it is the half of the configuration that has to be
redone after every toolchain upgrade. Seven rules under it, each already a defect
caught in review:

- **Discovery adds CANDIDATES and must not add a second way to identify one.** The
  flavour comes from `Cc::ClassifyCompiler` and the fingerprint from
  `CachedToolchainFingerprint`, unchanged — a worker that derived either differently
  from its clients registers, heartbeats, and is never matched, with nothing anywhere
  reporting why.
- **A discovered path never goes back through the operator's grammar.**
  `SplitToolchain` reserves the first `=`, which is right for something a person
  typed and wrong for a path this process found itself: `/opt/gcc=13/bin/gcc` would
  register the fingerprint `/opt/gcc`, and a leading or trailing `=` would abort
  startup as "malformed --toolchain", naming a flag nobody passed.
- **The operator's list wins whole; the two are never merged.** A merged set would
  quietly re-add a compiler an operator had deliberately narrowed away, which is the
  entire reason a build farm names its toolchains.
- **A found compiler that cannot be spawned is not a toolchain.** That is the
  `SpawnFailed` refusal a client otherwise meets at job time, moved to startup where
  an operator can see it. An operator-NAMED one is not probed — the
  `<fingerprint>=<compiler>` override exists precisely for a compiler this process
  cannot execute.
- **An empty resolved set refuses startup, and the message names where it looked.**
  Left to run, such a worker registers nothing, heartbeats "0 of 0 toolchain(s)
  registered" as a complete success, and prints a ready line: a healthy unit, a green
  fleet, and every build compiling locally with no error at either end. The search
  list comes off `ToolchainLayouts()` rather than a list written by hand, which is
  maintained by the same person who forgot to add the row.
- **One location has one spelling, or one machine registers twice.** A root arrives
  spelled however its source spells it — the registry writes `C:\Program Files\LLVM`,
  an environment variable writes `C:\Program Files`, a table row writes `C:/msys64` —
  so the same `clang.exe` reached through two rows came back as two strings.
  `WorkerRegistry` keys on `(fingerprint, endpoint)`, so that is the double-counting a
  fleet view then has to render. Separators are collapsed on every host, case only on
  Windows; a scripted host cannot catch it, because it normalizes on the way in.
- **A fingerprint that names no compiler is refused, not registered**
  ([#140](https://github.com/LASTRADA-Software/pace/issues/140)). A driver this
  build cannot ask for a version falls back to a digest of its own basename, and
  discovery of its include tree is best-effort by construction; a toolchain that hits
  both at once digests to a value this repository could print with nothing installed. `ToolchainProbe.hpp` permits a
  banner-only fingerprint on the argument that it "can only cause two
  genuinely-identical toolchains to be treated as identical" — true, with an unstated
  precondition that the banner is a real version string. Check the precondition where
  both halves are known. An operator-pinned identity is never judged this way; it is
  the escape hatch for exactly the compiler this process cannot interrogate.
- **A probe that did not RUN is not a probe that answered nothing**
  ([#225](https://github.com/LASTRADA-Software/pace/issues/225)). Include-root
  discovery spawns the driver, and `DiscoverIncludePaths` returned a bare vector
  documented "empty when undiscoverable" — so a spawn that failed produced the same
  value as a driver that ran and listed nothing, which is a state this fingerprint
  legitimately serves. The digest was then taken over nothing and returned as the
  toolchain's identity. The refusal above does not fire, because it also requires the
  banner to be the fallback name, and a driver whose *include* probe failed usually
  answered `--version` perfectly well. `CompileRun::exitCode == NotSpawned` already
  told the two apart and nobody asked.
  - **The cache is not the self-correcting half it looks like.** The roots feed the
    stamp as well as the digest, so one failure stamps differently and the next good
    run recomputes — which is why the value moved and moved back. But a machine whose
    probe keeps failing stamps that failure *consistently*, hits its own entry, and
    settles on the wrong fingerprint permanently. A probe that did not run therefore
    neither reads nor writes the cache.
  - **A short WALK is worse, and is the case with no self-correcting run at all.**
    `ComputeToolchainStamp` folds each root's path and mtime, never its contents, so a
    walk that stopped inside a root that is there leaves every stamped input
    identical: the short digest validates against its own stamp forever and nothing
    walks again to notice. `ToolchainFileScan::complete` reports it.
  - **What is NOT a gap is half the rule**, and the test is DETERMINISM rather than
    "did something go wrong". A gap is worth refusing over when two ends running this
    same code would disagree about it. Three omissions are not: a root that is merely
    absent (drivers list paths they would search if they existed), an entry that is not
    a regular file, and a root whose bytes this process cannot decode into a path —
    that last one being a property of the bytes and of the UTF-8 narrow encoding every
    executable here pins, so both ends digest the same narrower tree and still match.
    Two of the three are easy to get wrong in the same direction: keying the
    absent-root test on `error_code` rather than on the resolved `file_type` calls
    every machine without `/usr/local/include` incomplete, because MSVC reports
    `no_such_file_or_directory` for a path that is simply not there; and treating a
    failed `is_regular_file` as a gap refuses every toolchain tree containing a
    dangling symlink. Refusing a healthy toolchain is a worse error than the one being
    caught.
  - **Why refuse rather than serve it anyway.** Both ends are silent otherwise: the
    worker registers, heartbeats and is matched by nobody, and the client sees
    `NoWorker` and compiles locally. Neither names a cause, and the failure is
    intermittent by nature. `IdentityDefect` carries which way an identity is
    unusable, and its reason and remedy are columns of a table because two surfaces
    report them — the node's refusal and `--print-toolchain-fingerprint`'s warning.
  - Related: [#148](https://github.com/LASTRADA-Software/pace/issues/148) is the
    same fact discarded one function away — `CompilerBanner` knows whether it spawned
    and reports only the banner, so `CanSpawn` runs the identical command again.
- **`cc` and `gcc` stay two candidates.** Usually one binary under two names, and they
  fingerprint *differently*, because a GNU driver prints its own `argv[0]` in the
  banner its clients hash. Collapsing them looks like tidiness and costs the fleet
  every `cc` build.
- **A layout describes a DIRECTORY LAYOUT, not a vendor.** Visual Studio ships
  clang-cl of its own, under `VC\Tools\Llvm` rather than beside `cl` — so the
  `visual-studio` row walked past it while all three LLVM rows wanted a *standalone*
  install, and a machine whose only clang-cl came with Visual Studio advertised none.
  The failure is the quiet half of the pair the whole feature exists to avoid: those
  builds were still **cached**, because a launcher needs no worker for that, and could
  never be **dispatched**, because nothing advertised the fingerprint. A green fleet,
  a working cache, and distribution simply off. One installation reached by two rows
  is normal; what must not double is the *process* — `vswhere`'s answer is memoized
  across rows, empty answers included, or a second row spawns it again at every start
  forever to be told the same thing.

**Only the native MSVC target variant is offered, and only what the filesystem
confirms.** This was once forced: every target variant of one toolset — x64, x86,
arm64 — shares an include tree, and they shared a banner too, so all of them
fingerprinted identically and offering them all registered one machine several times
under ONE identity. That is retired
([#195](https://github.com/LASTRADA-Software/pace/issues/195)) — the banner names
the target now, so they are distinct toolchains, and until then a fleet would happily
dispatch an x86 compile to an x64 worker. Offering them is therefore a capability
nobody has asked for rather than a duplicate; the restriction stands as scope, and
`ToolchainDiscovery_test` pins it so the day it changes it is a decision. Two neighbouring rules for the same reason: `vswhere` is
asked without `-requires`, because filtering on `...VC.Tools.x86.x64` is a false
negative on exactly the ARM64-only host the arm64 bin path exists for — an install
with no C++ toolset simply has nothing beneath its `versionRoot`; and nothing is
spawned to learn what the filesystem already said, so `vswhere` runs only when its
installer directory is present and the Xcode row (which asks once *per compiler
name*) only when `xcrun` is on the search path.

**A driver's include roots come from what it OWNS, never from the environment**
([#140](https://github.com/LASTRADA-Software/pace/issues/140),
[#145](https://github.com/LASTRADA-Software/pace/issues/145)). `INCLUDE` is set
per shell by `vcvarsall` and a Windows service inherits none, so any mechanism that
reads it gives a launcher in a developer prompt and a worker under the SCM two
different answers for one compiler — and a fingerprint disagreement is invisible from
both ends, presenting only as a scheduler that answers `NoWorker`. Both MSVC-family
drivers were on it and both had to come off, by different routes, because *owns*
means different things to them:

- **`cl` owns the VC toolset it lives inside**, so `MsvcToolsetIncludeRoots` walks up
  from the driver to `VC\Tools\MSVC\<version>`. Those roots no longer reach its
  FINGERPRINT (the corollary below, #1656). Discovery is kept for the fingerprint
  cache's stamp and so a node notices a toolset or SDK update and re-surveys; both are
  per-process local checks that never cross a machine, so a service and a prompt
  disagreeing about these roots costs a recompute and no longer affects matching. The
  `INCLUDE` fallback stays for that stamp, for a wrapper outside the layout.
- **`clang-cl` owns only its resource directory** —
  `<prefix>/lib/clang/<version>/include` — and it is **asked** for it
  (`-print-resource-dir`) rather than having it derived. That is correctness, not
  taste: `/usr/bin/clang-cl-20` has `/usr` for a prefix, whose `lib/clang` holds `20`,
  `20.1.2`, `22` and `22.1.8` on an ordinary Debian, and no rule over those four names
  picks the right one — "the newest" hands a clang 20 driver the headers of clang 22.
  The layout is modelled for `cl` only because `cl` cannot be asked anything; this
  driver can, so it is. It reads `INCLUDE` **not at all**, not even as a fallback,
  which is what makes it symmetric *unconditionally* rather than merely wherever a
  layout is derivable. It can afford that because its banner is a real version string:
  a driver that does not answer degrades to a banner-only identity that still tells
  one clang from another.

The corollary is the part that looks like an omission and is not: **the VC toolset and
the Windows SDK stay out of every fingerprint** — `clang-cl`'s since #145, and `cl`'s
and an MSVC-targeting `clang`/`clang++`'s since
[#1656](https://github.com/LASTRADA-Software/pace/issues/1656). A worker compiles
text the client already preprocessed and so opens no header from either, so folding them
buys no discrimination while spending real matches: the newest-kit rule splits two boxes
with different SDKs installed, and an installed VS language pack drops IntelliSense XML
into the toolset's `include` and split two office machines on one toolset and one SDK.
Which tree a fingerprint walks is `DriverSpec::fingerprintTree`, a column, never an `if`
on the driver: `cl` folds **none** (its banner names toolset and target, #195), a clang
whose `-v` probe names a `*-windows-msvc*` target folds only its resource directory (the
`gcc` row too, since a `cc` that IS such a clang reaches it by its stem), and every
other GNU driver keeps its whole `-v` list — libstdc++ IS read, and two machines
can differ in it under one `--version`.
- **That makes the banner the whole of `cl`'s identity, so a FALLBACK banner is
  `NoEvidence` under `cl` whatever its layout** — a row that folds no tree BY
  CONSTRUCTION is judged as having none, or #195's "every MSVC is `cl`" comes back behind
  a located layout. Every other row is judged on discovery's roots before the cache read,
  and asked AGAIN of the tree it folded on the walk: an MSVC-targeting clang whose banner
  fell back and whose `-print-resource-dir` named no directory folds nothing, so it is
  `NoEvidence` too, and NOT cached, since a later hit asks only discovery's roots and
  would serve it.
- **The fingerprint cache's stamp folds `FingerprintSchema`** (stamp v2), so a schema bump
  misses every older entry rather than serving a value the new rules would not compute.
  Before it, nothing tied a cached value to the rules that produced it.

**A cold start fingerprints several toolchains at once, and reports them in table
order.** A cold walk is seconds per toolchain and a surveyed machine routinely holds
four or five; sequentially that is a node sitting silent for half a minute before it
reaches its scheduler, on the one start where an operator is watching. Bounded rather
than one thread each, because every one of them is a recursive directory walk hashing
what it finds. Results are collected positionally — the "serving" lines are where two
machines' digests get compared, so a log ordered by which thread finished first would
be a poor place to do it. The pool is joined **explicitly** before the return: locals
are destroyed after the return value is constructed, so leaving it to scope exit
copies the results while the workers are still writing into them.

**A node SERVES while it identifies its toolchains, and registers only once it
knows what it is.** The survey has two halves that cost three orders of magnitude
apart: deciding WHICH compilers to serve is a spawn per candidate, while IDENTIFYING
them walks every byte under every include root — 5136 files and over 300 s on a cold
Windows CI runner, measured at 2.7% CPU duty, which is a filesystem wall and not
something more threads reach past (#354). Run before the bind, that walk was time
during which the node served *nothing*: not its cache tier, not `/healthz`, not
`/metrics`. So `DiscoverToolchainEntries` stays on the startup path and
`FingerprintToolchains` moves to the heartbeat thread's first round (#365).

- **Anything that decides "has this changed since the survey" is seeded BEFORE the
  survey, never after it.** The heartbeat notices a configuration reload by comparing
  the snapshot it last acted on against the current one, and a baseline left null
  until the first beat reads that beat as a reload — so every node with a
  configuration file ran a second full survey immediately after its first: minutes of
  include-tree walking on a cold machine, and a window in which one transient probe
  failure drops toolchains the node had just successfully identified. Seeded before,
  the first beat is comparable to every other one AND a reload that lands *during* the
  survey is still seen, which a baseline taken afterwards would have swallowed. The
  bullet above is about when the survey runs; this is about what the survey is measured
  against, and getting the second wrong costs the whole benefit of the first (#403).

- **Registration is not moved with it, and cannot be.** A `ServedToolchain` cannot
  exist without a real fingerprint, so `toolchains` is simply empty until the walk
  answers and `registrarsFor` builds nothing from it. That is the acceptance
  criterion rather than a happy accident: a node registering a provisional identity
  advertises a value **no other machine will ever compute**, and both directions of
  that are silent from both ends (#225).
- **The survey runs on the heartbeat thread, not a new one.** That thread already
  owns `toolchains`, already calls `ReplaceToolchains` then `registrarsFor` in that
  order on every re-survey (#238), and already runs before the first announcement.
  A dedicated thread would be a second writer to all three and would need a lock the
  re-survey path has never needed.
- **An empty map is two opposite answers, so the state travels beside it.**
  Surveyed-and-serving-nothing and not-yet-asked are the same `std::map`, and
  reporting `UnknownFingerprint` for the second tells an operator the fleet is
  matching the wrong machines when this one is merely starting. `ToolchainSurvey` has
  a **deleted default constructor** for the reason `PreAuth` and `PayloadCap` do: a
  defaulted value answers by omission, and the answer it would give is the conflation
  being fixed. `ReplaceToolchains` completes it, because the answer ARRIVING is what
  completes it.
- **"Nothing to serve" stays fatal, and only its timing changes.** Left running, a
  worker with nothing to serve is the worst shape this system has — it registers
  nothing, the heartbeat calls "0 of 0 toolchain(s)" a success, and the ready line
  says the node is up. Splitting discovery out is what keeps the *common*
  misconfiguration (no compiler, a malformed `--toolchain`) a prompt refusal; what
  arrives late is only the case where compilers were found, spawned, and every one
  failed to yield a usable identity.
- **`/healthz` stays green during the survey**, deliberately. The node is serving its
  cache tier, which is the whole point; a readiness probe that went red for minutes on
  every restart would read as an outage to a supervisor and could produce a restart
  loop that never lets the walk finish. The state is visible as
  `pace_worker_jobs_refused_survey_in_flight_total`, as the named wire refusal,
  and in the ready line — which says *identifying* N toolchain(s), because printing
  the served count there would tell an operator "0 toolchain(s)" about a node that is
  starting normally.
- **A wait's budget belongs where the work is.** `node-scratch-isolation-e2e` had
  300 s on "compile node ready" because a node used to fingerprint before binding.
  After this change the bind is prompt and the walk happens before REGISTRATION, so
  leaving the budget behind would have moved the same timeout to a new line and made
  it look like a different bug. The number followed the work; so did the sentences
  describing it, one of which ("all three nodes were already up, so this is
  heartbeats, not startup") was true before and false after.

**The workers share the ONE injected runner, and `IProcessRunner` requires that.**
Making a runner per thread reads like a courtesy to the seam and is the opposite of
one: a function whose caller passed an `IProcessRunner&` and that calls
`MakeProcessRunner()` anyway spawns real compilers no test can script, and every case
that believed it was driving a fake was quietly interrogating whatever the machine it
ran on happened to have installed — five of them passed for that reason and failed
the moment the hole was closed. If concurrency needs something of a seam, say so in
the seam.

**The codec a reply travels in is chosen from what the OTHER end said it accepts,
and a hard-coded list is a fleet that never compresses.** Both directions negotiate
the same way — every exchange is client-initiated, so the request states what its
sender can decode and the answer picks from it, which is what buys the whole thing
without a handshake round trip. The worker's half of that was wrong three times over
and each defect hid the next (#265): `ChooseCodec` was called with the worker's own
list on **both** sides, so the client's was never read; the answer was then discarded
and the envelope hard-coded to `Identity`; and the node constructed both its
`WorkerProtocol` and its `WorkerRegistrar` with a literal `{ Identity }`, so even a
correct negotiation had nothing to pick from. The last of those governs the *request*
direction too — the scheduler files that list against the worker and the grant relays
it to the client — so a preprocessed translation unit, several megabytes on the hot
path of a parallel build, crossed the network uncompressed as well. Nothing anywhere
reported any of it: an uncompressed envelope is a *correct* envelope, so every object
arrived intact and every counter read normally.

So: a codec list is `AvailableCodecs()`, never a literal, and it is **one** function
in `CodecEnvelope.hpp` that both halves call rather than each deriving what it can
speak. `Envelope` sits beside it for the reason `Unenvelope` already does — the
encoding and decoding halves of one negotiation, in the module named for it. It takes
the peer's list and this end's, falls back to `Identity` for anything compression did
not actually shrink — the same shrink-check `Core/Compression` applies to stored
values — and always declares the **uncompressed** size as `rawLength`, because that
is the field `Unenvelope` bounds its allocation by before it decompresses a byte. A
list wider than the build can honour is not an error: `Compression::IsAvailable` is
asked at the point of use, so two peers compiled with different codec sets still
complete the exchange, and a build never loses distribution over configuration.

One consequence worth stating, because a comment in `CodecEnvelope.hpp` used to rest
on it: "the source arrives `Identity` — the only codec a node negotiates" was true
only *because* of this defect. `UnenvelopeText` exists to spare that path a copy, and
after the fix it is the compression-less build's path rather than every build's.

The property to assert is what the two ends **disagree** about, which is why a single
"the object round-trips" case is worth nothing here: it passes under every one of the
defects above. What separates them is a client that accepts a codec being answered in
one, and a client that accepts only `Identity` being answered in `Identity` — with an
object that actually compresses, or the shrink-check makes both cases `Identity` and
the pair is indistinguishable again.

- **A scratch root is CLAIMED, not merely named — and claiming is the liveness
  check.** A worker's root came from `temp_directory_path() /
  "pace-node"` with jobs numbered from a counter starting at 1 in every
  process, so a second node on one host derived the identical `job-1` and everything
  beneath it. `create_directories` succeeds on a directory that already exists, so
  nothing was told anything (#279). Two outcomes, and the quiet one is worse: one
  node's `ScratchGuard` removes the shared directory under the other, whose compile
  fails and whose client falls back to compiling locally — the build stays correct
  and **distribution silently stops**, which is #232's shape again. Or the two share
  `tu.o` and one answers with the other's object, which its client caches under its
  own key.

  The fix is an **OS-level exclusive claim held for the process's lifetime**, and
  three properties follow that a pid-inspecting design would not have. There is no
  race, because acquiring the lock IS the answer rather than something checked before
  taking it. `_Exit` stops being special: `WorkerServer`'s abandoned drain (#239)
  bypasses every destructor, but the OS releases the lock however the process died,
  so a leaked root is one whose lock is FREE — which is exactly what "reclaimable"
  should mean, with no staleness to infer. And a recycled pid cannot confuse it,
  because nothing reads a pid.

  Consequences that are each load-bearing:

  - **`flock`, never `fcntl`.** The rulebook already says this for the CoW store
    because an fcntl lock is per process. Here it bites twice: two claimants inside
    ONE process would both take an fcntl lock and both succeed, which is the
    in-process form `a22e056` fixed — and it would **pass the two-runner model this
    defect was reproduced with**. A guard that its own test cannot fail is worse than
    no guard.
  - **The lock file lives BESIDE the root, never inside it.** Reclaiming empties the
    root, and so does ordinary success. On POSIX it is worse than untidy: deleting an
    `flock`'d file is legal, and a second process may then create a fresh file at that
    path and lock *that*, giving two live owners of one root.
  - **The lock decides ownership; the record never does.** The claim file carries a
    versioned record, and on a root whose lock we hold an unknown version is stale
    data to overwrite rather than a refusal — `FleetHistory`'s rule that no state of
    a file may keep a node from starting. Making the version load-bearing would mean
    a bump left every root unclaimable and no node able to start.

    Calling that record *diagnostics* is earned here rather than asserted, because
    the rule above says a replayed region is **not** diagnostics but a dependency
    record. The test is whether anything consumes it: a `/showIncludes` region is
    handed to a build system as the object's dependencies, while nothing reads this
    one but a person looking at the directory. Nothing branches on it, so it decides
    nothing — and the moment something did, it would stop being diagnostics and this
    bullet would be wrong.

    The `objkey-v6` / `manifest-v6` bump above is not a counter-example either. That
    version identifies stored VALUES that must not be reused, so it has to be
    load-bearing; this one labels the format of a note attached to a resource whose
    ownership the operating system decides. A version is load-bearing exactly when
    something downstream would otherwise trust bad data.
  - **No unclaimed fallback.** `FilePageStore` opens unguarded when a filesystem
    cannot lock, because refusing would stop a working deployment and a second opener
    is only a possibility. The reverse holds here: an unclaimed root IS the defect and
    two nodes collide by construction. `TEMP`/`TMPDIR` relocates the root, so the
    escape hatch exists without a flag — which is also what the end-to-end fixture
    uses as its control.
  - **The claim belongs to the WORKER tier.** A machine that schedules and compiles
    nothing -- `--slots=0` -- has no use for a root and must not fail to start for want
    of one (#206), so the claim is conditional on serving compiles and says so.
  - **Counted where a counter can be read.** Reclamation gets
    `WorkerScratchRootsReclaimed`; the refusal to claim does not, because that path
    exits the process and nothing would ever scrape it — an operator learns of it by
    the node not starting, and the log names which refusal it was.

**A COMPILE reply is tied to the request that asked for it, or it is refused.**
Nothing did that before #280. The cache key covers the inputs, the fingerprint covers
the toolchain and the lease covers the authorization -- every one of them **upstream
of the reply** -- so a client sent a job and accepted whatever object came back on
that connection. Any defect crossing two jobs therefore produced a build that
succeeded with a **wrong object under a correct key**, and nothing downstream could
notice: it is silent, the client stores it, and every other machine that fetches that
key gets it.

**Where the digest is computed is the entire mechanism.** It is taken in
`CompileJobRunner::Run`, from the argument vector about to be spawned and the text
just written to scratch -- never folded in `WorkerProtocol` from the decoded request.
At the wire layer both of two crossed requests are still *pristine*: a digest taken
there would be computed from job A's fields, travel with job B's object, and agree
with whatever the client compared it against. That implementation satisfies the
ticket's own acceptance criterion -- swap two in-flight replies, watch the client
refuse -- and catches nothing. `WorkerProtocol` therefore takes `ICompileJobRunner`,
because a fake at the inner `IProcessRunner` seam sits *below* the point where the
runner records what it compiled and so can make the object wrong but never the
report.

**What it covers is generated by a constraint, not chosen.** A field belongs in the
correlation exactly when the CLIENT knows it before sending **and** the runner
observes it at execution: a value only the worker knows cannot be verified, and a
value only the client knows cannot be reported on. That admits the preprocessed text,
the client's argument slice, the fingerprint and the source name -- and excludes the
resolved compiler path, the scratch paths, `-c`, the accepted codecs, the object
itself (that would make it a checksum of the reply rather than a correlation of reply
to request) and the lease token (a credential authorizes a job, it does not describe
one, and folding it into a value that travels is how one reaches a log).

Two of the four get missed. The **fingerprint**, because two jobs identical in text,
flags and name but built for different toolchains have different correct objects and
crossing them is invisible in every other field. The **source name**, because a
compiler records the name of the file it was handed -- the COFF/ELF `.file` symbol,
seven bytes on clang-cl -- so two otherwise identical jobs really do differ. It is
covered **raw**, before `SafeSourceName`, so the client is not made a second author
of the sanitization rule; that makes the digest finer than strictly required, which
is safe, where coarser would be a hole.

**The source name is read once on the client.** The worker digests the name it was
SENT, so a client that sent one spelling and verified another would refuse every
honest compile -- a fleet that silently stops distributing rather than one that
mis-serves, which is harder to notice and reads as "distribution just is not
helping". Two derivations beside each other is exactly how that arises, which is why
the field is read once into a local and used twice. Since #660 there is no derivation
at all: the client's whole spelling travels.

**The refusal is a refusal.** `DispatchStatus::Mismatched` is its own enumerator and
is checked before the object envelope is opened -- a correlation is a string
comparison, an envelope is an allocation the peer's declared length decides. There is
no best-effort match and no fallback to using the object anyway. The build still
succeeds, because the client holds the source and compiles locally as it does for
every other non-answer; what it must never do is *use* that object.

**And it is not counted, deliberately.** The issue asked for a `MetricsCatalog` row
and there is nowhere for one to live. Only the client can detect a crossed reply -- a
worker that knew its reply was crossed would not have sent it, so the server has
nothing to count -- and the client is `pace-cc`, one short-lived process per
translation unit with no metrics sink anywhere in its production path. A row
incremented only by tests would export a `/metrics` series reading a permanent zero
**while the defect fires**, which is worse than no series: it is the
reclaimer-nothing-constructs shape and the series-an-operator-was-told-to-scrape
shape at once, and it misinforms rather than merely failing to inform. So **no
fleet-wide aggregate of this exists and none can** until a client has a way to report
one. The two places the fact lives are an *unconditional* stderr line -- not behind
`PACE_VERBOSE`, because a correctness alarm and a "distribution did not help
today" note must not share a verbosity level -- and a fixed detail string that
`--show-stats` ranks by cause. The recorded outcome stays a MISS: the cache answered
honestly and still stores this object, so recording `Unavailable` would blame the
cache and file the source under "never cached", both untrue.

**Read the scope, because read as unconditional it makes something else look
redundant.** This catches a reply routed to the wrong waiter, and a runner that fed
the driver something other than what it was handed. It does **not** catch a runner
that fed the right bytes and read back the wrong object file -- there the metadata is
honest and only the object is foreign, and no input-side digest can see that. That is
#279's failure and #279's exclusive scratch claim is what closes it. #279 secures the
output side and this the input side; **neither alone is sufficient**, and removing
either because the other exists is how this codebase's worst regressions have
happened. It is also `MurmurHash3` with no key, so it is integrity against
**accident**: a worker that can return a wrong object can return a wrong digest just
as easily. Not a security control, and the header says so before somebody cites it as
one in a design review.

**What a test must separate here is the two ends disagreeing.** A case that asserts
the field is present proves nothing, and so does one that computes both sides with
the same helper -- they agree by construction. The cases that earn their place are a
crossed pair (both directions, with an uncrossed control, or a client that refused
*everything* would pass), a table over the four covered fields, and one that drives
`Dispatch` against a real `WorkerProtocol` over a real `CompileJobRunner` through the
real framing, with an empty argument and one containing a space. That last one is the
only thing that would catch an encoding that drops a field on the way.

**Against a machine that is NOT the worker, a COMPILE reply is SIGNED, and checked
before anything is stored.** The correlation above is unkeyed, and an endpoint is a
name: a VPN address reassigned between a heartbeat and a compile hands the job to
whatever machine now answers there, which can return a well-formed, correctly
correlated object -- stored here and written through to the shared tier, under a key
every other machine fetches. So the grant names the identity key the worker's
`REGISTER` connection PROVED (`LeaseGrant::workerKey`, from `CallerContext::provenKey`,
never from anything the worker CLAIMS), the worker signs `(correlation, SHA-256 of the
object as sent)` under `IdentityKeyPurpose::CompileReply` (`Protocol/CompileReplySeal.hpp`,
one header both ends include), and `InterpretCompile` checks it FIRST -- before the
correlation and before the envelope. Missing or wrong is `DispatchStatus::Unauthenticated`:
compiled locally, released, its own `--show-stats` row and an unconditional stderr line,
the same alarm shape as `Mismatched` for the same reason (no client metrics sink). A grant
naming no key is refused BEFORE dialling: it names nobody whose reply could be accepted,
so dialling it can only spend a worker's slot on an object that will be thrown away.

**The key travels TWICE, and neither copy is redundant.** The clear copy is the
CLIENT's, which verifies no lease claims. The copy inside the token's signed claims
(layout 4, `fastcache-lease-v4`) is the WORKER's: a fleet worker that has come to hold
ANOTHER worker's endpoint refuses `EndpointMismatch` naming *another identity key*,
before a compiler runs. An honest-but-misrouted worker is caught at the worker; a
machine outside the fleet is caught at the client -- remove either because the other
exists and one of those two goes uncaught. The impostor case and its honest control are
`FleetDialHint_test`'s `[reply-seal]` pair; neutering `CompileReplyIsSealedBy`'s call
turns the impostor case red and leaves the control green.

## The cordon (#1303)

<!-- agent-tripwire: A cordon is the worker PROCESS's state, never replicated and never persisted -->

A bounded stop abandons whatever outlives `--drain-timeout`, which is exactly the compile
that was about to succeed. A cordon refuses new compiles, lets the running ones finish,
and reports once when nothing is left. Four rules, each of which has a plausible wrong
version that passes an obvious test:

- **The cordon is the worker PROCESS's state** (`CompileCapacity`), never a replicated
  entry and never a configuration value: a cordon that survived a restart would be a
  machine that silently never came back. The scheduler learns it from the heartbeat
  (`LoadFields::cordoned`), the heartbeat loop wakes on a change, and a cordoned worker
  heartbeats straight after a (re)registration -- a registration carries no load, and a
  new leader after an election is exactly who would otherwise believe it serving.
  `--cordon`/`--uncordon` are on `notFromFile` and out of every service registration.
- **"Drained" means DELIVERED.** `FrameEndpoint` writes a reply after the responder has
  returned it, so a slot released at `Answer`'s `co_return` made the drained report --
  and the stop's own drain -- claim nothing was owed while an 84 MB object was still
  going out. The slot is an `IReplyHold` carried by `FrameReply`, released by the
  endpoint right after `WriteAll` and by scope on every `break`. A test driving the
  responder directly must KEEP the hold to see the property (`ReplyHold::Keep`); one that
  lets `SyncRun`'s temporary die reads zero in flight under both builds.
- **Admission is one locked decision** (`SlotAdmission`): stop, cordon and full are
  decided under the drain mutex together with the take. A cordon checked BESIDE the take
  lets a compile start after the cordon's own drained report, which then reports "stopping
  abandons nothing" while it would abandon something. A stop outranks a cordon.
- **A cordon is asked of LOCALITY, not membership.** A fleet member elsewhere is admitted
  to compile here and must not be able to take this machine out of the fleet. The gate is
  per verb inside `CompileResponder::RefusePeer`, so a compile from the same peer is still
  admitted -- the case asserting both is what separates a per-verb gate from a surface-wide
  one.

`SlotLimit::Cordoned` is applied last in `SlotCeilingsFor` and named on every tie: the
other limits lift themselves, a cordon only when a person acts, so naming `scratch` on a
cordoned machine whose disk also filled sends an operator to the wrong fix. The refusal a
cordoned worker answers is `NoCapacity` on the wire -- the client compiles locally either
way -- and its own counter, because a stop ends by itself and a cordon does not.

## Enrollment (#1298, #1299; on keys since #178; without a window since zero-config formation)

<!-- agent-tripwire: Enrollment is served by a node that runs consensus (`ServesEnrollment`) -->

A leader records every machine that asks, up to `MaxPendingEnrollments`, refusing past
it rather than evicting, and forgets a row nobody polled for `PendingRowLifetime`. There
is no window to open: since #178 nothing secret crosses, so the APPROVAL is the gate,
and a window in front of it only made the zero-config join need a person twice.
`enrollment-requests-waiting` is raised while rows wait.

**An ungated list is bounded per SOURCE HOST as well as in total, or one peer holds it
forever.** Refusing rather than evicting keeps a flooder from pushing a real joiner OFF the
list; it does nothing about one that FILLS it, and one peer polling under fresh ids held all
sixty-four rows until the leader restarted -- a denial of service against zero-config
formation that no restart-free remedy reached. So a host holds at most
`MaxPendingEnrollmentsPerHost` UNDECIDED rows (a decided row is a record, and stops
counting), past which it is refused `EnrollmentHostFull` and counted apart from `Full` --
the two send an operator to different places, one address asking a lot against many
machines waiting. The host is the kernel's: enrollment is TCP, so it is not a claim the
peer chose. The HOST's bound is asked first, so `Full` keeps meaning many hosts.

**The bound counts a row by the address it was CREATED from, never the one a later poll
shows.** A re-poll from another address may refresh the displayed `peerId`, but the row keeps the
address it was created from (`EnrollmentPendingEntry::firstPeerId`). `--enroll-list` shows that
address on every row as `first from`, and MARKS a row asked since from elsewhere, as #242
settled: shown, never gated. `EnrollmentHostFull` names the host in that same spelling, so the
rows a refusal counts can be found on the list. Moving the row between bounds let one dual-stack machine add four rows from
its IPv4 address, re-poll them from its IPv6 one, and repeat: sixteen undecided rows were
measured against a cap of four, with nothing short of the global bound to stop it. An
IPv4-mapped address folds to its IPv4 form (`UnmappedHost`). IPv6 is **not** grouped by /64,
because an office LAN is one /64 and twenty machines asking from it on go-live day are twenty
legitimate joiners. **The accepted residual, and its direction:** a host that rotates through
the addresses of an allocated /64 buys four rows per address, up to the global 64, so the
bound fails OPEN for an attacker inside a network that can reach the leader; the remedy is
`--enroll-clear` and the firewall in front of the enrollment port. And an
operator has `--enroll-clear`, a row of `EnrollControlVerbTable`, leader-only like its
siblings, which drops every undecided row, keeps approved and rejected ones, and is counted
and logged: it makes room and bans nobody, since a machine still asking is recorded again.

**No secret crosses, and a test proves it against the whole frame.** The joiner sends
its role and its public key; `Approved` carries `Cluster::EncodeRoster(ProjectRoster(state))`
-- members with seat, key and recorded `0xFC` endpoint, and revoked keys, in a
versioned encoding. The endpoint is what the joiner remembers its fleet's voters at, so a
fleet serving another port is reached where it RECORDED, never at a guess from the consensus
host; and it moves the fingerprint when a member announces a move, which only mattered while
voters certified a roster per digest. The acceptance case scans the WHOLE approve frame for
the leader's seed, its 64-byte signing layout and a cluster key -- raw, and as base64,
base64url and hex in both cases, because a hand-over that forwarded a key FILE carries no
raw run of the key's bytes -- beside POSITIVE controls: a seed planted where a roster
travels IS found by the same scan through the same responder, and a secret in a setting
IS found in the whole state's encoding. Without them the scan passes over a reply it
cannot see into.

**Nothing is spendable, so nothing is re-armed.** `Collected`, `EnrollmentAlreadyCollected`,
`ReturnClaim`, `StoreClusterKey`'s exclusive create and the re-approve that re-armed one
collection existed only because a key handed over could not be handed over twice -- and
they cost a lost reply a stranded joiner. All of it went with the key; the error code
`0x24` and the decision byte `0x03` are retired and never reused. A lost reply is
recovered by the joiner asking again.

**The key an operator compared is the key an approval admits.** A row keeps the FIRST key
and role its id asked with. A later poll under that id with another key is ANOTHER
MACHINE: counted in `claimsChanged`, answered `Pending`, never recorded. Refreshing it --
which the ADDRESS fields still do while a row is pending, because those are display --
would let whoever polled last swap a key in the minutes between `--enroll-list` and
`--enroll-approve`, which are the minutes an operator's comparison is supposed to cover.
A joiner that genuinely re-minted (a wiped state directory) enrolls again once its old row
is forgotten.

**And the address a row refreshes is the KEY HOLDER's word, because the request is SIGNED**
(`Cluster::SignEnrollRequest`, label `fastcache-enroll-request-v1`, over every field the request
states). The id and the key are public -- a beacon carries the key, the roster both -- and the
pending row's `0xFC` endpoint is what an approval RECORDS, so an unsigned request let any host
poll under a joiner's pair with its own endpoint and the last poll before the approval was the
member record (T26 review I-1). The responder verifies before the window records or refreshes
anything, and before any other claim is reported on -- a forged request under a REVOKED key is
told `NodeProofRejected`, never that the key is revoked -- counted
(`EnrollmentRequestsRefusedForged`).

**And a REFRESH is fresh for the leader, not only for the joiner** (T26 re-check I-1). The
joiner's nonce binds the ANSWER to one ask; nothing bound the REQUEST to one, so a genuine
request recorded on the way and replayed later rolled a pending row back to an endpoint the
joiner had left. Each row holds a challenge the leader drew from `ISecureRandom` (a failed draw
is refused `NoCluster`, uncounted), every `Pending` answer hands it out inside the admission
signature, and only a request signed over the challenge the row holds NOW refreshes the row --
replacing it. A stale answer is still answered and keeps the row alive; it moves nothing, and an
endpoint it states that the row does not hold counts in `claimsChanged`. The list goes with the
leadership, so every challenge does too. What remains: a replay may CREATE a row on a leader whose
list is empty (it states an endpoint the joiner itself once stated), and the joiner's next two
polls take the row over.

**And the approval NAMES the key it admits** (`--enroll-approve=<id>@<key>`, verb `0x09`;
`0x04`, the id alone, is retired). Keeping the first key covers a row that lives; it does
not cover a row that LAPSED, after which the next machine to ask under the id is recorded
under ITS key and an approval by id would admit it unseen. The leader refuses a key that is
not the row's by name, before anything else about the row, and counts it
(`EnrollmentApprovalsRefusedKeyMismatch`); `--enroll-list` prints the paste-ready line.

**An approval admits a newcomer and never changes a member's seat**: an id the cluster
already seats is refused by name, by a person's approval and by an armed deadline alike. A
machine the cluster already records under the key it asks with, and the list holds no row
for, is answered the roster with no approval -- the list is one leader's memory, and a
demoted leader DROPS it (lowering `enrollment-requests-waiting`), so without that answer a
joiner admitted just before a change of leader would poll forever against an approval
refused as *already a member*. A row the list does hold still decides, so a rejection keeps
the roster back.

**Auto-approve is a DEADLINE, not a mode.** `--enroll-auto-approve=<duration>` sets
`now + duration` on the LEADER's `EnrollmentWindow`, against the injected clock, and every
`Enroll` compares `now < deadline` when it arrives; nothing wakes on a timer. It is
never replicated and never persisted, so a restart ends it, and a DEMOTION ends it (a
leader that loses and regains leadership inside the deadline must not resume admitting:
the operator armed a window on a leader, not on a cluster). Zero and anything above
`AutoApproveCeiling` (24 h) are refused BY NAME from one table, at the CLI and again at
the leader. An auto-approved row is marked in `--enroll-list` with when the window was
armed, the condition `enrollment-window-open` names the mode and the minutes left, and
`EnrollmentApprovalsAuto` counts apart from `EnrollmentApprovalsManual`, because the
audit question after a window is *who got in while nobody was looking*. It is the one
exception to *the key an operator compared*: a bounded, delegated comparison, audited.
The key admitted is still the key the joiner FIRST asked with, and a `claimsChanged` row
is never auto-approved.

**`Approved` means the leader's roster RECORDS the joiner, not that a person typed
approve.** `ClusterAdmit` returns at the APPEND, and a joiner polling in between would be
handed a roster lacking its own entry -- exactly what it is told to refuse -- so an
approved row answers `Pending` until `RosterRecordsJoiner(ProjectRoster(state), id, key, role)`
holds -- the same predicate the joiner asks of what it receives.
The responder test holds the fake's applies and commits them, asserting both sides.

**The joiner checks the roster against ITSELF, and prints a fingerprint an operator
compares.** `DescribeAdmission` refuses a roster that does not record this id under this
machine's key and role -- an operator approved a different key, or something rewrote the
reply -- and prints nothing from it. The leader records the fingerprint of what it SENT on
the row (`NoteServed`), per row, because the roster moves with every admission and one
cluster-wide fingerprint would make a batch of approvals disagree for no attack at all.

**A formation joiner believes an admission on its SIGNATURE, never on its roster.** A roster
is PUBLIC -- every member's id and key rides every beacon and summary -- so a check of its
CONTENT, however strict, is satisfied by a copy: a roster naming the proven member under its
public key, seated as a learner or a voter, and the joiner was believed from whoever answered
at the polled endpoint, measured. Requiring the proven key to be a VOTER bought nothing -- the
forger seats it as one as easily -- and would refuse a join decided on a learner's beacon.
So every `Enroll` carries a nonce the joiner drew from `ISecureRandom` (a failed draw sends
nothing), and EVERY answer -- `Approved`, `Rejected` and `Pending` alike -- carries the
ANSWERING node's signature (`IdentityKeyPurpose::EnrollAdmission`) over that nonce, the joiner's
id and key, the cluster id its own FLEET-SUMMARY states, the OUTCOME and the roster's digest
(`Cluster/EnrollAdmissionSignature.hpp`). A refusal sends a joiner away for an hour and a
not-yet keeps it from giving a dead join up, so an unsigned one of either was a lever for
whoever answered at the polled endpoint; each is now held to the same key, and one that does
not verify is NO answer -- asked again on the beat, counted towards the give-up -- never the
refusal it claims to be (`SignedOutcomeTable`). **And only a VERIFIED answer resets that
give-up**: a full list, a `NotLeader` naming nobody and a redirect are wire refusals nobody
signs, so whoever answers the poll's connection could say one every beat -- each counts
towards the give-up exactly as silence does, and a legitimate full list lasting past it gives
the join up and asks again, which is benign. The signature is judged before the key
(`Forged` before `Unproven`), and an unsigned, forged or unproven answer is refused by name and
counted (`FormationAdmissionsUnverified`), apart from a signed admission whose roster is wrong
(`FormationAdmissionsRefused`). There is no one-shot join any more: a machine asks through
`--fleet-seed`, at run time, and every answer it acts on is judged as above.

**And the key an answer is held to is reached from the key the join was DECIDED on, never
from whichever key answers at an endpoint.** A fresh FLEET-SUMMARY probe proves only that
somebody there holds SOME key, and a `NotLeader` redirect is unsigned, so a probe of where it
points bound the admission to nothing at all. The chain's root is `JoinTarget::provenKey`: when
the decided summary's speaker leads, the root is the key polled; when it names another leader,
the key it states for that leader (`FleetSummary::leaderKey`, inside what the root signed) is
the one that endpoint must prove; after a redirect, an endpoint whose key the chain already
proved -- the root's own where the summary states it, else the first endpoint the chain proved,
so the chain is rooted at `provenKey` TRANSITIVELY -- is asked which key leads now, and the
redirect's endpoint must prove EXACTLY that key (`FormationController::ProvePollEndpoint`).
Root-only would leave a member leaving on a dissolve, whose order names no speaker endpoint,
unable to follow any redirect. A
dissolve carries the survivor's leader key the same way (`DissolveOrder::leaderKey`), reached
by the leader that decided, so a leaving member is held to it too. The case that pins it is a
redirect to an endpoint proving the right cluster id under another key: refused, where the fresh
probe believed it.

**A role is a table (`EnrollRoleTable`), and each column is a decision.** A joiner enrolls
as a LEARNER, the one role the wire carries (`EnrollRole::Learner`, 0x03; 0x01 and 0x02 are
RETIRED and refused by the decoder), states the endpoint its `0xFC` port answers on (recorded as
`schedulerEndpoint`) and no consensus endpoint, and is admitted by `ClusterAdmit` in the learner
seat with the key it first asked with; a voter is an operator's PROMOTION, never a role. The table
has one row, pinned to the wire by `EnrollRoleTableMatchesTheWire`, and states no seat opinion
beyond that, so an approval cannot promote a demoted learner. There is no removal column, because one
verb removes any member ([#1555](https://github.com/LASTRADA-Software/pace/issues/1555)):
`--cluster-forget` takes the id out of the record and revokes its key, so the
reject-after-approve warning names it. Until #1555 it could not be named for a worker -- it
touched members only, and a warning naming it would have sent an operator to a command that
reported success and removed nothing.

**A revoked key is refused at the door**, before the window records anything
(`EnrollmentRequestsRefusedRevokedKey`, `InvalidClusterChange` -- the code the approval would
be refused with). No approval could admit it, so a row for it is one the operator reading the
list cannot act on, and `Pending` would keep a forgotten machine polling for an answer that
cannot come. The door is the courtesy; `ValidateAgainst` refusing `KeyRevoked` at the
approval, and `Apply` dropping it on commit, are the guarantee.

**A window is openable wherever consensus runs.** `ServesEnrollment` in `main.cpp` asks
`RunsConsensus` and whether a scheduler tier was built -- the second a runtime fact only
that translation unit holds. It took a key clause until #1308, and the APPROVAL read the
key before `ClusterAdmit` until #178, because a key file that broke after boot let an
approval commit a member that could never collect -- a phantom counted towards every
election. Nothing is collected any more, so that read had nothing left to protect and
went. The `--cluster-key-file` consensus still required then, for the lease and the node
proof, went at #178 PR 6 once both proved identity keys.

**A node that runs no consensus refuses the family `NoCluster`, never
`UnimplementedVerb`.** This is *unimplemented is not served elsewhere* on a new
surface: such a node implements the verbs perfectly well and has no cluster to let
anybody into, so `UnimplementedVerb` — which the client reads as `UnknownOpcode` — told
a joiner *the seed is running a build older than this one*. The documented flow then pointed
a joiner at ANY member and most members ran no consensus, so that wrong sentence
was the likeliest thing a healthy fleet would ever print, sending somebody to upgrade a
node that was already current. `CompileCacheHandler`'s `RefusedVerbs` table had drawn
exactly this distinction for the daemon, with the argument written beside it, and the
node's merged surface did not carry it across — so `MergedResponder::UnservedReply`
takes the VERB, and all four routes to an unowned verb get the right code rather than
four call sites remembering. A test asserts it is NOT `UnimplementedVerb`: both codes
refuse, so a case asserting only that the peer was refused passes under either.

**Rejecting an already-approved joiner does not un-admit it.** `Reject` reaches no
`ClusterAdmit`, which is right for a PENDING row — nothing was committed — but
`EnrollmentWindow::Decide` permits `Approved -> Rejected`, which is the path an
operator correcting a mis-approval takes, and there the approval has already committed
the member. It is not refused outright, because the reject still stops the roster
hand-over and that is worth having; what changed is that the flag's own description and
a Warn both name what removes it -- the ROLE's remedy, above. The control that a PENDING
reject stays SILENT is what keeps that warning worth reading.

**A one-shot verb's shape is refused on the path that uses it.** The retired joiner's
seed flag had a `StartupPolicyRejection` row, and `main` dispatched the flag and RETURNED
before that table was consulted, so the row was reachable only through `--print-surfaces`.
Left to the dial, a bare host was reported as *cannot reach the seed* — the wrong problem —
and reported it after this node had minted its identity into `--cluster-dir`, so a typo
wrote durable state. `ParseDialEndpoint` at both sites, never a second spelling, for every
one-shot verb's `--scheduler`.

**The redirect budget is a CHAIN bound, not a total.** `MaxRedirects` exists for the
loop two nodes with a stale `_knownLeader` make by naming each other; counted across a
ten-minute wait for a person — some three hundred polls — three ordinary leadership
changes anywhere in it aborted a legitimate enrolment with a message naming a loop that
never happened. A reading that a node answered on its own behalf breaks a chain, so it
resets the count, and a genuine loop never reaches that arm.

**And the enrollment state is REPORTED, or the counters cannot be read.** Both enrollment
series are rendered by every node and read zero on a machine that serves no enrollment at
all, so *nothing served here* and *nothing has come through* are one number.
NODE-STATUS's `enrollment` field (`pacectl node`) is ABSENT on a node that serves no enrollment
(`main` hands the status responder a window only where `ServesEnrollment` holds), `manual`
otherwise, and `auto-approve` with the minutes left while a deadline is armed
(`WireEnrollmentState`; `0x01` closed and `0x02` open are RETIRED, since every request is
recorded now). None of the three is inferred from a counter: a zero counter cannot say
whether a window was ever armed. That field was once encoded, decoded, round-tripped in a
test and rendered by NOTHING, while the operator documentation pointed at it three times --
so the claim was circular. A case asserting only one reading leaves the field's purpose
untested; absent-against-`manual` is what earns its place.

## The node proof (#1428; identity keys and sealed frames since #178)

<!-- agent-tripwire: a caller that PROVES a live identity key is a member wherever it dialled from -->

Node-to-node admission on the `0xFC` surface was decided by the caller's SOURCE ADDRESS and
nothing else — the committed endpoints of the cluster's members, and a host list an operator
typed. An address is a stand-in for *this is one of our nodes*, and it stops being one the
moment an address is not stable: a worker that joins over a VPN gets a different one each
session and no literal host match can follow it (#178 item 1). #1428 let a caller PROVE the
cluster's pre-shared key instead; #178 PR 6 made it prove WHICH machine it is, by signing with
its own identity key, and sealed every frame after the proof. Each rule below is what some
plausible simpler design gets wrong.

**No address admits another machine, and the verbs a machine JOINS with need a proof.** They --
`Register`, `NodeAnnounce`, `Heartbeat`, `Withdraw` -- decide where the fleet's work is sent, and
`MachineBudget` decides how much work a machine is ADMITTED (the memory budget the leader charges
it against, #1728); all five are `IdentityRequirement::ProvenNodeOnly`, a COLUMN of `OpTable`
pinned by `JoiningVerbsNeedAnIdentity`, refused `NodeIdentityRequired` and counted
(`SchedulerRequestsRefusedNodeIdentityRequired`). Loopback is NOT exempt: a process on the
scheduler's own host could otherwise register an endpoint of its choosing and be leased the
fleet's jobs. Every node naming `--scheduler` therefore needs a key to prove -- and every node
has one since the zero-config defaults gave every node a state directory: `--cluster-dir`, or
the platform's default, machine-wide for a privileged process or a service and per-user
otherwise (`DefaultNodeClusterDirectory`). The refusal that guarded a node with nowhere to keep
a key (`SchedulerNeedsIdentityRefusal`) went with the case. What a PACKAGED registration must
still get right is WHICH directory: a POSIX service runs as an unprivileged account, so the
Linux unit's `StateDirectory=pace-node` hands it `STATE_DIRECTORY` and a launchd
registration states the same variable (`ServiceSpec::serviceAccountEnvironment`), or the
service would take the per-user default in its account's home -- a second identity, or on the
packaged unit (`ProtectSystem=strict`, home `/`) an unwritable one. The Windows service is
privileged by its service SID and takes `%ProgramData%\pace-node` by itself. A client
asking for a lease presents a machine ticket instead (*Machine tickets*, below), and a ticket
never satisfies `ProvenNodeOnly`: a ticketed connection is not sealed.

**An operator's CONTROL verbs need a caller a route IDENTIFIES, and `--fleet-open` identifies
nobody.** `--fleet-open` admits a caller to what the fleet SERVES -- a lease, a status, a cache
request -- and never to what DECIDES the fleet. With the scheduler's password gone, membership was
the only gate on `CLUSTER-ADMIT` and on `ENROLL-CONTROL`, so on an open node an anonymous remote
caller could approve its own enrollment or arm an auto-approve window. Two columns decide it,
never an `if` at a handler:
- `OpDescriptor::identity` names the verbs: `IdentityRequirement::OperatorStanding` on
  `ClusterSet`, `ClusterForget`, `ClusterAdmit`, `ClusterAdmitLearner` and `EnrollControl`
  (`ClusterAdmitWorker`, 0x1D, is retired), pinned by `ControlVerbsNeedOperatorStanding`; `IdentifiedCaller` is only its
  PREREQUISITE (`IdentityRequirementRow::prerequisite`, walked by `UnmetRequirement`) and no verb
  names it.
- `Distributed::MembershipRoutes`' `standing` column names the routes: loopback is an `Operator`
  at the node being asked, a proven key and a verified ticket identify a `MachineSeat`, and
  `OpenPolicy` is `Anonymous`.

**A machine ticket proves a fleet MACHINE, never an operator** (W-1). Any process on an admitted
laptop can have its node mint one over loopback, so a ticket that opened the control verbs made
every process on every machine an operator of the whole fleet -- `cluster-set fleet-open=1`, the
shared cache pointed at itself, a forget, a 24 h auto-approve window. A `MachineSeat` route
therefore confers an operator's standing only while the machine it names holds a VOTER's seat in
the applied state: `PublishClusterKeys` publishes the voters beside the keys, in one swap, and the
key roster marks the evidence in `MembershipDecision::votedBy`, which the fold carries like
`revokedBy`.

`CallerContextOf` reads both facts off the same fold that admitted the connection
(`RestsOnIdentifiedCaller`, `RestsOnOperatorStanding`). One table, `Distributed::IdentityRequirements`,
answers the first for the scheduler (`RefuseUnlessIdentified`) and for the enrollment surface
(`RefuseUnidentified`, at the door and again in `AnswerControl`).

The refusals are `IdentifiedCallerRequired` (0x2e) for a caller `--fleet-open` alone admitted, and
`OperatorStandingRequired` (0x33) for an identified machine that is no voter -- not `NotAMember`,
because the caller IS admitted -- each counted on each surface's own row. `Cordon` and `MintTicket`
are not rows: each already answers this machine alone. A reviewer's neuter -- `OpenPolicy` made to
identify, or a `MachineSeat` row made an `Operator` -- turns the matching refusal cases red.

**A proof is worth nothing unless every frame after it is SEALED.** Without the seal, a machine on
the path relays a genuine worker's handshake to the scheduler, watches it succeed, and writes a
`Register` of its own into the connection the worker's proof admitted -- an identity check that
authenticates the first frame and trusts the rest. So both ends derive two session keys from an
ephemeral X25519 exchange (HKDF over both nonces, both ephemeral keys and both ids), and every
frame both ways carries a `Core/SessionSeal` tag over an implicit position, its header and its
payload (`Protocol/SealedFrameSocket`). A bad tag, a replayed frame, the other direction's key
or an oversized frame closes the connection UNANSWERED and is counted
(`NodeSealedFramesRefused`). A frame the in-flight budget has no room for is the one sealed
refusal that is ANSWERED -- `EndpointBusy`, sealed, counted on the busy row of the verb's owner,
or of the budget's owner when nothing owns the verb -- and then closed, never resynchronized;
why is `wire-and-protocol.md` § Framing. The acceptance case is that relay, injecting a
`Register` with a forged tag after an honest proof, and its neuter is a seal that accepts any
tag -- under which the relay's worker is registered and the honest control stays green.

**The socket is wrapped from the start and ENGAGED later**, rather than swapped at the proof: the
loop's reader, the sweeper's registration, the peer watch and the progress pulse all hold the
connection's socket, and a swap would have to reach every one at the same instant. Until a proof
engages it the layer passes bytes straight through, so a launcher on the same port pays one
virtual call per operation.

**The answer to `ProveNode` is the first sealed frame, WHATEVER it says** -- `Ok`, or a refusal
decided after the keys were agreed (a bad signature, an unknown key, a revoked key) -- so the
grammar of the answer never depends on the verdict, and a caller learns the two ends agree on the
keys before it sends a verb. Only a refusal decided before any key exists (a payload that does
not decode) leaves the connection unsealed. **A connection proves ONCE**: either verb on one that
has proved or is sealed closes it, because a second handshake would re-key mid-stream and a
revoked machine re-proving under another key on the connection its tombstone marks would be
asking to be judged afresh by the one fact that condemns it -- the revocation its key carries. Bytes pipelined past `ProveNode`
close the connection too: they arrived in the clear, before the seal existed.

**The SERVER signs first, and a caller that holds a roster checks it** (`NodeProofClient`). A
revoked ex-scheduler still named in a worker's `--scheduler` gets nothing -- not even a proof it
could relay -- and the four answers about the server (`Voter`, `Unchecked`, `NotVoter`,
`Revoked`) are kept apart because the two refusals are opposite diagnoses. A machine with no
roster yet takes the server's word for its key, and the seal is what still stops a relay.

**Three verdicts on a VERIFIED proof, and the revoked one is not a refusal.** A key the roster
holds live for that id admits (`ProvenIdentity`); one it holds for no one is `NodeKeyUnknown`
(`NodeProofsRefusedUnknownKey`), whose remedy is the operator's -- an admission -- rather than the
caller's; one it REVOKED is `NodeKeyRevoked` (`NodeProofsRefusedRevokedKey`), and the connection
KEEPS that identity, marked: every later verb on it is `Forgotten` through `KeyTombstone`, which
outranks every other route on `PrecedenceOf` -- loopback and `--fleet-open` included --
and is counted at the gate (`NodeRequestsRefusedKeyRevoked`). Dropping the identity instead would
hand the forgotten machine back to its address, which is the one outcome a forget exists to
prevent. The signature is checked BEFORE the roster is consulted, so a caller who cannot sign
learns nothing about which ids and keys the cluster holds. Admission is re-asked of the roster
on every verb (`IMembershipOracle::ExplainKey`), never frozen at the handshake, so a key revoked
while the connection is open refuses its very next verb.

**"Holds for no one" is a claim about the APPLIED state, so it is not made before that state has
caught up** (batch 3's M3, measured on every start). A lone voter before its election commits, and
a follower before its leader first speaks, hold a roster that lacks keys their cluster holds; they
answered a genuine member `NodeKeyUnknown`, whose remedy tells an operator to ADMIT it, and the
prover waited a whole announce interval. While the node has not applied the log it recovered
(`AppliedStateOf`, through the SHORTER of the recovered log and the log it holds now, or a truncated
tail would read "not yet" forever), a key the roster lacks is `RosterNotYetApplied` (0x32, retriable,
`NodeProofsRefusedRosterNotYetApplied`) and the prover backs off from `RecordAwaitedInterval`,
doubling to `NodeAnnounceInterval` (`DeferredProofWait`). It replaces ONLY the refusal that may be
wrong: a key the roster holds, or revoked, is answered as ever. Publishing uncommitted state early
to close the window instead was REJECTED as unsafe.

**The fold lives in ONE function and every gate reaches it**, `Node::RefuseUnlessMember` over
`Distributed::ExplainConnection(oracle, host, proven)`. The alternative — folding at each surface
— is the shape this file already records for the membership verdict itself: five copies of a
one-armed decision were exactly as correct as one until a second arm arrived, and then five files
each had to grow it. A tie unions rather than choosing, for `AnyOfMembership`'s reason: a
connection on this machine under `--fleet-open`, or one that proved a live key AND presented a
ticket, is admitted by both routes, and an operator asking why has to be told every one of them.

**Every gate INCLUDES the live-stats one since #1512, and how that came about is the transferable
part.** It was the one exception, and the reason was never about subscriptions: a subscription is
re-gated on every tick through `Protocol::ILiveGate`, a seam `pace-kv` shares, and that seam
passed the peer as a bare host — so the re-gate *could not* see a proof, and a door honouring one
alone would admit a proven watcher and end its stream one tick later, which is worse than
refusing it. The exception was therefore a property of the SEAM, and it was recorded as a
deliberate narrowing (`RefuseUnlessMemberAtAddress`, a differently-named spelling that took a
written reason) rather than as an omission — which is what made it findable and fixable instead
of looking like policy. #1512 widened the seam to a `LiveWatcher` carrying the host and the
proof, both ends now fold, and the narrow spelling was DELETED rather than left unused: a policy
that reads as available and describes nothing is how a table stops describing the file it is
about. Since #178 PR 6 the watcher carries the `ProvenIdentity` itself, so a key revoked while a
stream runs ends it at the next tick.

**Neither verb is pre-auth, and the reasoning from `Enroll` does not transfer.** `Enroll` exists
for a machine that holds NO secret of this cluster, so a credential gate there refuses the whole
population. A node proving its identity is the opposite case: it came to send `Register`, which
requires the credential when one is configured, so a caller that cannot pass that gate gains
nothing from being proved and one that can passes it first. *The verb admits a non-member,
therefore it is pre-auth* is the inference a reader makes from the table alone, so
`VerbFamily::NodeProof` states the answer beside the rows.

**The challenge is the SERVER's, per connection, and spent whatever the outcome.** Discovery's
rule and the Raft handshake's, in the same words, and the endpoint holds it because it is
connection state — the prover is shared by every connection on the surface. Asking twice
re-draws it and the old one is gone: a server holding two live nonces would accept a proof over
either, which is a replay window opened by nothing but politeness.

**`NodeProofsAccepted` is the positive half and is not decoration**: every other row counts a
refusal, so a fleet where the proof is configured but never taken reads identically on all of
them to one where it works perfectly. `NodeProofsMalformed` is a client-library mismatch,
`NodeProofsRejected` a signature that did not verify, `NodeProofsUnchallenged` a client with the
exchange wrong -- five refusal diagnoses beside it, and not one of them is folded into another.

**The presenting half runs once per CONNECTION, before the first joining verb, and an unproved
connection is UNREACHABLE.** Anything but `Proved` means every verb that round came to send would
be refused, so `DialAndAnnounce` moves on to the next `--scheduler` rather than sending them --
which is also what keeps a revoked ex-scheduler from being told anything.

**A consensus node presents no proof before its OWN cluster records its key.** A member the
cluster was started with is recorded once the cluster has elected, and the worker and presence
loops start before that -- so a node scheduling for itself proved its identity to itself and was
refused `node-key-unknown` with a remedy to ADMIT it, at every such start. `DialAndAnnounce`
holds the round while the node's own admission oracle -- the one its node-proof surface asks --
has no opinion of its key (`NodeProofClient::HoldUntilRecorded`): said once at Info, and at Warn
past `OwnRecordPatience`, where it also raises `own-record-awaited` so an operator arriving later
can ask for it. A REVOKED key is never held, since that refusal is the scheduler's to say. An id
the cluster records under ANOTHER key is not a wait at all but a `node-key` replaced while the id
survived (`OwnRecord::OtherKey`, told apart through `IMembershipOracle::LiveKeyOf`): said and
raised at once, with one remedy for both ends, `ReplacedNodeKeyDiagnosis`. The client-side
`Unchecked` carve-out in `NodeRoster::StandingOf` survives only for voter records that carry no key,
and is to be deleted once the member key is required by type. And the responder never
answers its own id with "admit it" (`UnknownKeyReason`): its own key is this node awaiting its
record, or its replaced key; another key under its id is a copy of its `--cluster-dir`. It never
tells a STRANGER'S id to forget itself either: from the scheduler's side a replaced key and
another machine claiming a member's id look the same, and "forget it" would remove the member.

**What it does not cover, stated rather than left to be found.** The cache tier is unaffected and
that is the fix rather than an omission: locality is a property of the VERB, and a machine that
proved its identity is still not this one (#287). `FleetText` and a live-stats subscription
are BOTH behind the dashboard credential as well as membership, and that credential is untouched
-- it answers a different question and is its own file by rule, so a proof is not a substitute
for the token. And a REGISTER's endpoint is still not bound to the machine that proved: the proof
says WHICH machine, never that the address it registers is its own.

**Every membership gate on this surface folds the proof, and that is a census rather than a
description**: `CompileResponder`, `EnrollmentResponder`, `FleetTextResponder`,
`NodeStatusResponder`, `SchedulerResponder` and -- since #1512 -- `LiveStatsResponder` at BOTH
its door and its per-tick re-gate. There is no spelling that refuses to widen, so a seventh
surface folds by reaching the one function rather than by remembering to.

### Machine tickets

A proof admits a NODE, over a sealed connection it holds; a launcher on a laptop holds no such
connection and should not -- it dials a scheduler, a worker and a cache once per exchange. So a
machine proves itself per exchange with a **ticket**: a claim set (label, machine id, audience,
expiry, nonce, each length-prefixed) signed by the machine's OWN identity key, minted by this
machine's node over loopback (`MINT-TICKET`) and presented in an `AUTH` pipelined ahead of the
command. Each rule is what a simpler ticket gets wrong.

- **Admission keys on a VERIFIED ticket, never on an `AUTH` answered `Ok`.** A node with no
  password answers a password `AUTH` `Ok` so a token-configured launcher is not broken by it --
  `NoPolicy`, which establishes nothing. The declared KIND decides what is verified: a genuine
  ticket's bytes under the password kind establish nothing either.
- **A refused `AUTH` CLEARS what an earlier one established** (Review Focus 3). A connection must
  not keep a machine it can no longer vouch for by presenting something worse afterwards, so the
  endpoint resets the fact when an `AUTH`'s header is read -- a header refusal never reaches the
  verifier -- and `AnswerAuth` ASSIGNS what a served one established. Only a revocation is merged:
  it is permanent, and a later `AUTH` must not lift it.
- **Audience-bound and spent once, because an `AUTH` is sent on an unsealed connection.** A
  captured ticket is replayable by whoever saw it, so it names the ONE endpoint it may be presented
  to -- never loopback or a wildcard, which every node is -- lives `MachineTicketLifetime`, and is
  spent at the node that accepts it (`SpentTickets`, bounded by count and refusing
  `spent-set-full` by name rather than evicting an entry that could still be replayed).
- **Refused by REASON, signature first** (`TicketRefusalTable`). The signature is checked before
  any claim is reported on, so a caller who cannot sign learns nothing; `forged`,
  `unknown-machine` and `revoked` travel as ONE message with their counters apart, since telling
  them apart would tell a stranger which ids the roster admits.
- **`no-roster` is its own reason, never `unknown-machine`** (Review Focus 5). A worker whose
  certified roster lapsed while its machine slept admits the machine as soon as a voter
  re-endorses; answered `unknown-machine`, it would send an operator to re-admit a machine that is
  admitted.
- **A pure worker verifies against the roster its voters CERTIFIED**, the same `NodeRoster` its
  lease check reads, so a forget reaches it on its next round with no restart.

### Admission without addresses (spec 2026-09-26 §5)

**Why an address stopped being evidence.** An address list was a stand-in for *this is one of
our machines*, and it stopped being one twice. A roaming machine -- a laptop on a VPN, DHCP, a
container -- has no address to list, so the list either chased it or was opened to everybody.
And #235 showed the other half: loopback is admitted before every other route is asked, so a
suite whose clients are all local never reached the list at all, and a worker that admitted
nobody else passed it. Removing an address from a list also failed OPEN: the list lived on N
machines, and the one an operator forgot kept serving the machine.

**Five participants, one fold** (`Distributed::ExplainConnection`, reached only through
`Node::RefuseUnlessMember`): a REVOKED key, which refuses and outranks everything; loopback;
a proven key; a verified machine ticket; `--fleet-open`. The four admitting routes tie and are
unioned, so `explain-admission` can name every one; `MembershipParticipant` 0 is reserved.

**Removal by key cannot fail open where removal by address did.** The key lives in ONE
replicated state and the fold asks it on EVERY verb, so `--cluster-forget` -- which drops the
record and revokes its key in one entry -- reaches every node as it applies, every surface, and
every connection already open, with nothing to edit on any machine. What it still cannot reach
is a caller that presents nothing on an open node, which is `--fleet-open`'s stated meaning.
The fail-open predicates (`AdmitsRemotePeers`, `CompileVerbsReachOtherMachines`,
`NamesAnAdmissionRoute`) COUNT the key routes, each call site stating what it knows about the
roster (`RosterPresence`) -- a worker that read a key route as absent would build a lease check
that verifies nothing.

**Adding a machine fails CLOSED and self-heals; removing one fails OPEN and reports nothing**,
because admission succeeding is the ordinary case -- so the removal is the direction every case
here asserts first, with the addition beside it only to stop a change that satisfies the easy
half from passing. The in-process fleet asserts it from addresses nobody listed
(`FleetTickets_test`, `FrameEndpoint_test`'s relabelled-peer cases).

## The compile queue (#1728)

<!-- agent-tripwire: A miss is ADMITTED (queued) at the fleet's leader -->

A build with more compiler processes than the machine has memory for was killed by the kernel
rather than slowed. The leader now holds a queue in front of every machine's compile budget.
Each rule below is a shape a plausible simpler design gets wrong, and none of them fails a build.

- **A miss is ADMITTED (queued) at the leader, never refused for capacity.** A refusal sends the
  client to a local compile, which is exactly the load the queue exists to bound. Waiting is the
  product; the leader pulses (`Status::Progress`, `Admit` being the second verb allowed it) so a
  long queue reads as alive against the client's sliding idle bound. A request larger than a whole
  machine's budget waits for an idle machine and runs ALONE; it is never starved and never refused.
  A `NoRoom` Local grant is an ordinary queue decision, not a refusal, and is not counted as one.
- **The connection is the lease.** A grant is charged to the connection that asked, carries no
  token to expire, and is released by `SETTLE` on that connection or by its close. A close is an
  abandonment, counted apart (`AdmissionAbandoned`); a `kill -9` of ninja must give the memory back
  at once with no timer. The only frame a held connection may send next is its `SETTLE`, or, after
  `Settle{WorkerRefused}`, a fresh `ADMIT` that binds to the SAME ticket (Ruling 9).
- **A worker refusal keeps the ticket's place and count.** The leader re-parks the same ticket at
  the FRONT; after `MaxWorkerRefusals` the grant is Local. Abandoning it instead would lose the
  front position and let a flapping worker starve the head of the queue.
- **A worker FAILURE settles `NotStored`, never abandon**: an
  abandon raises the ESTIMATE of a translation unit that merely met a bad worker, and feeding that to the
  estimator poisons every later admission of it.
- **Deduplication is woken by STORE, never by a release.** Only a `storable` compile that shares a
  cache with its peers waits on another's key, and it is answered `Stored` when the object is
  STORED. A release wakes nobody: a compile that failed stored nothing, and the waiters must then
  compile.
- **Every node states its machine budget, `--slots=0` included, and that is not a worker
  registration.** `MachineBudget` rides the presence loop's round, which runs everywhere; its flags
  (`--machine-slots`, `--machine-memory-budget`) are deliberately not worker-column rows.
- **A failover admits nothing on a machine before that machine's budget report arrives**, and the
  ledger charges `max(charged, held)`: the new leader knows only what the machine says it holds,
  and an admission before that report double-books memory a surviving compile still has.
- **Every non-leader forwards `Admit`/`Settle` inline to the leader, never to itself**: a voting
  follower as well as a learner. A voter that answered `NotLeader` would leave a launcher with no
  queue on every node but one. The relay holds one upstream connection per client connection.
- **The grant says what it granted**: `workerKey`, `lifetime` and `dialHint` as `LeaseGrant` does
  -- the hint from the same `DialHintFor`, so a worker reachable only where it was last seen is
  dialled there whichever path granted it -- and a `reason` on a Local grant of a dispatchable
  request, so a fleet that never distributes still says why (`DeclineDispatch`) instead of reading
  green.
- **An admission's worker lease is filed under its TICKET, never under the cache key** (Ruling 17).
  Deduplication is the QUEUE's, and only where a waiter can fetch the result; a lease table keyed by
  the cache key refused the second of two machines that missed one key `AlreadyInFlight`, which its
  launcher read as "compile here" -- an uncharged compile, the load the queue exists to bound. The
  token still signs the OBJECT key, as a `Lease` grant's does: the table's key is bookkeeping the
  worker never sees.
- **A launcher asks the queue at its OWN node, `PACE_ADDR`, whatever `PACE_SCHEDULER` names** (Ruling
  16, `Cc::AdmissionEndpointOf`). The leader charges a compile to the machine that ASKED, and names
  it only by a key the connection PROVED or by loopback: the launcher's node proves its machine's key
  when it relays, while a launcher dialling a remote scheduler directly proves nothing and would be
  charged to no machine. `PACE_SCHEDULER` keeps one meaning, where a `LEASE` goes when no queue
  answers, and a plan is refused for a remembered-unreachable endpoint only when EVERY place it could
  be spent was unreached (`Cc::PlanUnreachableAt`).
- **A launcher fails OPEN only where no queue ANSWERED.** An unreachable, refusing or unreadable
  node costs the build nothing, and a launcher whose FETCH already found the node unreachable does
  not dial it again: on Windows a refused loopback connect can take the whole connect budget. The
  one compile with no such evidence is a passthrough whose command line did not parse -- it makes
  no FETCH -- so with the node stopped and the reachability memo empty it pays one connect, up to a
  second on Windows, and records it; a stopped node costs a build at most one such connect per
  fifteen-second memo window, never one per compile. Where the queue DID answer and the launcher
  gives up on it anyway -- `MaxWorkerRefusals` worker refusals in a row -- the compile is asked for
  again `LocalOnly`, excluding that worker, and runs HERE charged, never in the open.
- **A held admission connection carries TCP keepalive at BOTH ends** (Ruling 18, #1736): the
  launcher's dial of its node (`Cc::DefaultAdmitBudget`) and the node's relay to the leader
  (`Node::ForwardDialBudget`) arm it per dial, as `wire-and-protocol.md` requires, and the leader arms
  it on the ACCEPTED connection once that connection holds a grant, through core-cpp's
  `ISocket::armKeepAlive` (v0.11.0). The intervals are core-cpp's `KeepAliveSettings {}`, which every
  `KeepAlive::Yes` dial applies -- a dial takes none of its own -- and ONE constant names them for all
  three, `Pace::AdmitKeepAliveProbe` (`Pace/Protocol/AdmitKeepAlive.hpp`), pinned by a `static_assert`:
  a peer whose host vanished is noticed in `idle + count * interval` = **16 s** on Linux and macOS and
  **30 s** on Windows, where the OS fixes the count at 10. That bounds the relay noticing a vanished
  LEADER (failing its launcher open, giving back its own held charge), a launcher noticing a vanished
  node, and the leader noticing a vanished caller -- whose Worker grant would otherwise hold another
  machine's budget until `MaxCompileLeaseLifetime` (one hour) sweeps it, which stays as the backstop.
  - **What arms is a COLUMN of what is held**, `IConnectionHold::KeepAlive()`, pure so a new hold
    answers rather than inherits a silence; `FrameServer::ArmHeldKeepAlive` asks it on the loop thread
    (which `armKeepAlive` requires) once a reply that left a hold is WRITTEN, and a queued request
    that holds nothing is not armed. Once per CONNECTION (`ConnectionScope::NoteKeepAliveArmed`), so a
    requeue on the same socket is not a second request. A failure to arm is a `Warn`, never a
    refusal: the sweep is still there.
  - **Every pace socket that wraps an `ISocket` forwards `armKeepAlive`** (`SealedFrameSocket`,
    `TotalDeadlineSocket`, and the test fake `RelabelledPeerSocket`), or the call lands on the
    interface default, `Unsupported` -- `SetReceiveDeadline`'s defect class, one rule higher. Each
    has a case asserting the request reaches the socket under it.

## Open work

<!-- agent-tripwire: none: deferred work, tracked as GitHub issues; AGENT.md tripwires rules, not residuals -->
- **[#661](https://github.com/LASTRADA-Software/pace/issues/661)** — `IProcessRunner`
  has no cancellable seam, so a compile whose client has GONE runs to completion and this
  machine pays for an object nobody will read. The departure is already detected and
  already counted (`WorkerJobsAbandonedClientGone`, #223, which measured 84 MB handed to a
  socket nobody was reading for a single translation unit); what is missing is the ability
  to act on it. The constraint is cited at the one place it bites,
  `CompileResponder::PeerWatchCounter`, and was recorded ONLY there until #670 — which is
  the convention this file exists to keep: deferred work is an issue linked from a
  rulebook's `## Open work`, never a residual in prose. It is filed HERE rather than in
  `wire-and-protocol.md`, where #670 expected it, because the seam is a compile-node
  process runner and not a property of `ISocket`; the other three residuals that ticket
  listed have since been implemented rather than deferred (`ISocket::CancelRead`,
  `ISocket::ShutdownWrite`, and #663's read-slot rule), which is why it is one entry and
  not four.
- **[#201](https://github.com/LASTRADA-Software/pace/issues/201)** — a node
  offers only the NATIVE MSVC target variant, on a reason that no longer holds: the
  variants shared a banner and so a fingerprint, and
  [#195](https://github.com/LASTRADA-Software/pace/issues/195) gave the banner the
  target it names. They are distinct toolchains now, so offering the cross-target
  drivers is a capability rather than a duplicate -- but it multiplies one machine into
  six registrations, and capacity is per NODE, so it is not a one-line change to the
  layout table.
  **#1126 was the same fact read the other way round and is closed as refuted**: it
  claimed the variants still digest identically and asked for a wire-level refusal to
  compensate. Measured on Visual Studio 18, toolsets 14.44 and 14.51, all eight
  `Host<a>/<b>` pairs exit 0 from a bare `cl` and name their TARGET in the banner
  (`... for x64` against `... for x86`, following the target rather than the host), so
  nothing needed compensating. The two entries stood here saying opposite things,
  which is the cost of a claim inherited rather than re-derived — and the stale reading
  survived because it also sat in `ToolchainDiscovery.cpp`'s own comment, where it read
  as the tree's answer about itself. `ToolchainFingerprint_test.cpp`'s *One MSVC
  toolset's target variants are two toolchains* pins it now, over a deliberately
  byte-identical include tree, so it cannot go stale a second time in silence.
- **[#1646](https://github.com/LASTRADA-Software/pace/issues/1646)** — `NodeRuntimeSources`
  is composed in `main`, which no test reaches, so which sources a node is handed is asserted
  by nothing: the learner's `.schedulingLeader` wiring
  ([#1641](https://github.com/LASTRADA-Software/pace/issues/1641)) is a pointer `main`
  sets on `RedirectsScheduling`, as every other field of that record is set there, and a
  wiring that dropped it would leave every case green while `pacectl node` on a
  learner named no leader again.
- **[#148](https://github.com/LASTRADA-Software/pace/issues/148)** — every
  discovered compiler is spawned twice at startup with the same argv, once to learn
  it can be spawned and once for its banner, and the first is in a serial loop in
  front of the pool built to hide exactly that. `CompilerBanner` knows both facts
  and reports neither, so two callers reconstruct what it discarded.
- **[#1730](https://github.com/LASTRADA-Software/pace/issues/1730)** — one cache key is not
  deduplicated across machines that share a cache, so the same compile can be admitted twice.
- **[#1731](https://github.com/LASTRADA-Software/pace/issues/1731)** — admission test gaps
  deferred by the #1728 reviews.
