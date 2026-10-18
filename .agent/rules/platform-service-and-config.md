# Platform integration, service registration and configuration

Rules for `src/Pace/Platform/` and `src/Pace/Config/`, plus the CLI
option tables both binaries drive their parsing and help from.

Read this before touching `ServiceControl`, `IDaemonHost`, `DefaultConfigPath`,
`FileTrust`, `HostInfo`, `CliOptions()`/`CliParser`, `NodeConfig`, or any
packaged unit/plist/WiX fragment that launches a binary.

Two failure shapes recur: a registration that **succeeds** and then produces a
service which cannot do its job, and a configuration file that is present,
readable and silently ignored. Every rule below has already been one of them.

## Registering a service

<!-- agent-tripwire: A service to register is a `ServiceSpec`; what it runs as is part of it -->

- **A service to register is a `ServiceSpec`, and what it runs as is part of it.**
  Every function in `Platform/ServiceControl` took `Config const&` -- the *daemon's*
  configuration type -- so a second binary could reach none of it without either
  depending on the daemon's configuration or growing a parallel copy of a 1273-line
  file. That is the whole reason `pace-node` had no service integration
  on macOS or Windows. Four things about the seam's shape are load-bearing:
  - **`daemonFlag` is a field rather than an argument**, because the two supervisors
    disagree and one spec has to answer both: the Windows SCM needs it (it is the
    hook that hands control to the Windows `ServiceHost`) and launchd needs its absence,
    since like systemd it supervises the process it started and reaps a job that
    forks as "exited".
  - **`serviceAccount` and `ownedPaths` replaced a constant and a reach into
    `cfg.storagePath`.** Which account a service runs as, and which paths it must
    own before its first write, are properties of the *service*. The rule they
    carry is unchanged and still the point: only paths the operator actually named,
    never a parent -- `--storage=/var/db/fc` must not hand `/var/db`, shared with
    other system services, to an unprivileged cache account.
  - **An empty `serviceAccount` means root, so a worker names one.** A system-scope
    launchd job with no `UserName` runs as root, and `pace-node`
    compiles input that arrived over the network. Naming `pace-node` -- the
    account the Linux unit already uses -- puts the existing "that account does not
    exist" guard in the way, so a macOS system-scope install refuses rather than
    silently succeeding with root privileges. It is deliberately not the daemon's
    `_pace-kv`: one account would let a compromised compile rewrite every cached
    object. **The package creates it** (issue #87), from the *Runtime* component and
    not the LaunchDaemon one -- which launchd choice an operator made for
    `pace-kv` says nothing about whether they will run a worker, and the
    installer's default is the per-user agent. One spelling reaches the binary, the
    packaging and the Linux unit; `ctest -R service-accounts` fails on every
    platform when they drift, because the failure itself is macOS-only and silent.
  - **An empty `applicationName` means "configured entirely from argv", and
    `WithScopeDefaults` must then bake in nothing.** It used to look the machine-wide
    config up under `DaemonApplicationName` unconditionally, so *every* spec got the
    *daemon's* defaults: a worker registration was handed `--config=` (system) or
    `--storage=` (user), and `NodeOptions()` has neither flag. That is the
    supervisor-must-survive-its-own-parser rule below, produced by the installer
    itself -- the job registered, reported success, and answered `unrecognised
    argument` at every boot. On a packaged macOS system it was worse than that: the
    daemon's config is `0640 root:_pace-kv`, so `ServiceAccountReadDenial`
    refused the worker install for a reason that had nothing to do with the worker.
    `WithScopeDefaults` was private to the `__APPLE__` block for all of this, which
    is exactly why no test saw it; it is declared in the header now, like
    `BuildLaunchdPlist`, and asserted on every platform.
  - **`ownedPaths` is not just the daemon's `--storage`.** A worker given
    `--cache-dir` or `--cluster-dir` gets directories root created for an account
    that is not root, so they must change hands too -- and only those, never a
    parent.
  - **On Linux the PACKAGED UNIT is that handover, so it declares the directory the docs
    cite.** Under `ProtectSystem=strict` a service writes only what its unit declares,
    and the one directory the node unit declared persistently, its state directory, is
    not a `cache_dir`: the node starts beside no entry there it has no row for ("this
    build keeps no entry by that name"). The unit shipped with no `CacheDirectory=`
    while the docs cited `cache_dir: /var/cache/pace-node`, so following them gave
    a store the service could not open and the obvious workaround, a directory inside
    the state directory, gave a node that refused to start -- found installing 0.5.0 on
    a laptop, nowhere else. `ctest -R node-working-directory` judges every `cache_dir`
    the docs and the reference configuration cite under `/var/` against the unit's
    `CacheDirectory=`, and fails OPEN on a path outside `/var/`, which reads the same
    for a node started by hand.
  - **And it listens where this machine's CLIENTS dial, which is 6674 on every
    platform** (#1676). The socket said 6676 on the reasoning that a scheduler hands
    out a worker's endpoint, so the port is "never a client-side default" -- true of
    the compile port, false once #290 put the node's cache verbs behind the same
    socket: `pace-cc`, `CompileCache.cmake` and `pacectl` all default to
    `127.0.0.1:6674`, so no local build reached the node's cache while the docs said
    one needed nothing set. The MSI already registers the node on its default and
    `pace-kv` DISABLED beside it; on Linux the socket takes the port from the
    daemon `%post` starts by `Conflicts=pace-kv.service` **and** `Before=` -- with
    no ordering the two ran in parallel and the bind failed `Address already in use`,
    and `After=` is a cycle through `sockets.target`. The packaging e2e steps assert
    the takeover, the .rpm one across a boot with both enabled.
  - **An owned path is created only when it is absent AND is not a file, and is
    otherwise handed over as whatever it already is.** The field is `ownedPaths`
    and not `ownedDirectories` because `storage_path` is allowed to name ONE CoW
    file -- `ResolvePhysicalShards` keeps a path with a file extension single-file
    for backward compatibility. Both handovers used to `create_directories` over
    their entries unconditionally, and that failed in both directions on the same
    value: `--storage=D:\fc\cache.cow` on a fresh install produced a *directory* of
    that name, which the very next start read as a shard directory and silently
    fanned out into; and once the file existed, the create *failed*, so the
    chown/grant was skipped on exactly the upgrade the handover is there for.
    `Core/PathKind`'s `PathNamesAFile` is the one answer to "is this a file", and
    `ResolvePhysicalShards` asks it too, so the shard count and what the installer
    may create cannot drift apart. A `chown` and an `SE_FILE_OBJECT` DACL apply to
    a file just as well as to a directory, so only the *create* has to care --
    which is why the refusal lives in the **handover** and not in each producer of
    an owned path. `MakeDaemonServiceSpec` and `main.cpp`'s install branch are two
    such producers of the very same value, and gating one of them was the first,
    wrong, shape of this fix.
  - **`serviceAccount` does not answer the SCM, so `windowsLogon` does.** The two
    supervisors take different *kinds* of answer: launchd wants an account name that
    must already exist, while the SCM derives a per-service identity from the
    service's own name. `CreateService` passed `nullptr` for `lpServiceStartName`,
    which is **LocalSystem** -- so on Windows `pace-node` registered
    itself with the whole machine while the macOS spec was carefully naming an
    unprivileged account for the same binary. It names
    `WindowsLogonAccount::VirtualAccount` now: `NT SERVICE\<serviceName>`, created by
    the SCM itself, no account to make and no password to keep. **Both** services name
    one; neither has any use for the local Administrators group. What the daemon can no
    longer do is WRITE its configuration, which is the point: a service that cannot
    rewrite its own configuration cannot be made to load a different one. How it READS
    it has moved -- this used to say the `%ProgramData%\pace` access list grants
    `BUILTIN\Users` read and a virtual account is an Authenticated User, which was true
    and was also why `requirepass:` in that file was readable by every local account
    (#741). The seeded config carries a protected list of its own naming
    `NT AUTHORITY\SERVICE`; see the secrecy rule under *Finding and trusting a configuration file*.
  - **The daemon's storage is granted from the MERGED config, and that is not the
    `--install-service` rule below being broken.** `storage_path` is read from YAML at
    every start, so a registration built from the command line cannot see it -- and the
    daemon no longer runs as an account that can write wherever it likes. `main.cpp`'s
    install branch therefore adds `effective.storagePath` to `ownedPaths`.
    Nothing from the merged config is *registered*: this contributes a path to hand
    over, never a flag to bake in, so the hazard that rule exists for -- a path in
    `ProgramArguments` outranking the very file it came from, forever -- cannot arise.
    Only what is configured, never a speculative default: a daemon with no
    `storage_path` is memory-only and needs no directory at all. Whether that path may
    be *created* is not decided here but in the handover (see `ownedPaths` above),
    because `MakeDaemonServiceSpec` contributes the same value from the command-line
    config and gating one producer leaves the other open. An
    operator who adds one *after* installing gets a permission failure naming the
    account and the `icacls` line, because at that point nothing has handed the
    directory over -- and the message must not tell them to re-run
    `--install-service`, which returns on `ERROR_SERVICE_EXISTS` *before* the grant
    loop and would repair nothing. The startup hint is gated on an actual write probe
    rather than on the error text, because three of the four storage failures report a
    string from the storage layer rather than an `error_code`, and because a localized
    "permission denied" is not something to build advice on. It is also gated on
    `--daemon`: the probe proves only that *this* process cannot write, so a foreground
    run by an administrator would otherwise be handed a diagnosis naming an identity
    that is not running it, and an `icacls` line for an account that may not be
    registered at all.
  - **A virtual account cannot write what an administrator created, so the install
    grants it.** LocalSystem never noticed, which is why nothing on the Windows path
    had ever needed the equivalent of the launchd `chown`. Two things about the
    grant: `NT SERVICE\<name>` does not resolve until the service exists, so it runs
    **after** `CreateService` (before it, `SetEntriesInAcl` fails with
    `ERROR_NONE_MAPPED`); and the entry is *added* to the existing list rather than
    replacing it, or the directory becomes one only the service can repair. A grant
    that fails is reported and the registration kept -- an operator can fix an ACL,
    but not a registration that was rolled back.
  - **`BuildServiceArgv` stays hand-written per binary.** An `OptionSpec` says how
    to *parse* a flag and carries no way to read a value back out, so "emit every
    field that differs from its default" cannot be written once generically. Each
    binary's version is guarded by a test that walks its own option table and
    requires every non-excluded row to be emitted -- the daemon's table once
    stopped after nine fields, so `--install-service --tls --metrics` reported
    success and registered a plaintext, unmonitored daemon.
  - **The refactor was checked to change nothing rather than argued to.** The
    registered command line is byte-identical to the one the previous version
    produced, which is why `--daemon` is inserted at the *front*: nothing downstream
    cares about flag order, and a refactor that can be shown to be identity is worth
    more than one that merely ought to be.
- **An install-time refusal is the only place an operator is watching.** Every rule
  in `NodeServiceRejection` describes a registration that would **succeed** and then
  produce a service which cannot do its job -- silent from both ends, since the
  operator is told it was installed and nothing later says otherwise. `--advertise`
  is the one worth naming: left empty it bakes in whatever `--listen-node` resolves
  to, which on a scheduler is `0.0.0.0` -- not an address a client can dial. Such a worker
  registers, heartbeats happily, is leased out by the scheduler, and is never
  reached. `--scheduler` gets the same treatment because it would start and exit at
  every boot.

- **An install is judged by the STARTUP rules as well, through
  `NodeInstallRejection` -- never by `NodeServiceRejection` alone.** The install
  branch returns before `StartupPolicyRejection` is ever reached, so for a while it
  applied four rules where seventeen were fatal: `--install-service` with
  `--tls-cert` and no `--tls-key` registered cleanly and exited `ExitUsage` at every
  boot, and so did `--dashboard` with no `--admin-listen` and a dozen more
  ([#166](https://github.com/LASTRADA-Software/fastcached/issues/166)). Every
  startup rule is a **pure invariant of the parsed configuration** -- no clock, no
  filesystem, no port -- so each is decided the moment the command line is typed,
  and `--install-service` bakes that command line in. That makes a startup rule
  strictly *more* worth refusing at install than at a start: a start refuses once,
  in front of the person who typed it.

  The two tables stay separate and `NodeInstallRejection` only composes them, so a
  new row in either reaches the install path without anyone remembering to add it
  twice. `StartupPolicyRejection` must keep running at startup as well, or a
  hand-started worker makes the identical mistake in silence. And the composition
  lives in `NodeConfig.cpp` rather than `main()`, because `main()` is in no test
  target -- which is exactly how a gap between two well-tested tables survived.

  `--toolchain` used to, and **no longer does** -- the reversal is the whole of
  [#139](https://github.com/LASTRADA-Software/fastcached/issues/139). Registering a
  worker before anybody knows what a machine holds is precisely what makes
  installing the package the entire setup; the node surveys the machine at boot and
  answers the question itself. What still cannot work is `--no-toolchain-discovery`
  with nothing named, and that shape alone is refused. The flag therefore has to
  survive the round trip into the registration: it changes what the service DOES at
  every boot, so losing it would leave the worker quietly serving compilers the
  operator excluded, with nothing saying the registration had changed meaning.

  Two related choices: an **uninstall** is not gated the same way -- refusing to
  remove a registration because it was misconfigured is how a bad one becomes
  permanent -- and a bare compiler path is **not** resolved to a fingerprint at
  install time, because the worker derives that at startup through the identical
  code its clients use and a digest computed once would pin the registration to a
  toolchain an update then changes underneath it.
- **A rule that is fatal at every boot belongs in a table, not in the tier that
  needs it.** `ConsensusTier::Start` made three refusals that were pure functions of
  the parsed configuration -- a malformed `--raft-peer`, a `--node-id` naming no
  peer, and an unusable `--listen-raft` -- and the install path returns long before
  any tier is built. So `--install-service --node-id=n1` with no peer passed both
  rejection tables, was reported installed, and exited `ExitUsage` at every boot
  ([#168](https://github.com/LASTRADA-Software/fastcached/issues/168)). The rule
  above closed that shape for the rules in the tables; this is what keeps a rule
  from living outside them in the first place. Being *reachable only through a
  tier* is not a reason for a check to live there: the question is whether the
  answer depends on anything but the parsed configuration, and if it does not, the
  table is where it goes.

  **A property of the BUILD is not I/O either.** TLS material on a build without TLS was
  refused only by the admin tier's `#else`, so `--print-surfaces` accepted the line and
  an install baked it in; it is a row (`BuildServesTls`, `TlsUnavailableRefusal`) now. The
  daemon has the same shape and its own table, `DaemonStartupRejection` -- duplicate
  listeners and both TLS rules, which its body asked only once the host had been entered
  -- asked in `main` before the install branch.

  Where it goes depends on what the answer needs to say. A **grammar** goes in the
  option table -- `--raft-peer` holds `Cluster::ClusterMember`, parsed by the row
  that accepts it, which refuses a bad token on every path and *names the token*.
  A **cross-flag invariant** goes in `StartupPolicyRejection`, whose messages are
  static prose and so can name flags but no values. When both a row and a tier must
  assert one rule, they share a predicate and a message constant -- `ClusterSelfMember`
  and `ConsensusNamesNoSelfPeerRefusal` -- because a rule asked two ways is one that drifts,
  which is the whole reason for a table. And a new row goes **after** any narrower
  rule about the same flags: first match wins, so `--raft-join needs --raft-peer`
  would otherwise be answered in its place and become a rule nothing reaches.

  Two things that look like members of the group and are not. `--cluster-dir` is
  read by `FleetHistoryPath` for the dashboard's history file, so it is *not*
  refused alongside `--raft-peer` when there is no `--listen-raft` -- a node running
  no consensus still has a use for it. And a row asks `ParseEndpoint` rather than
  `raftListen.empty()`, so an unusable port is refused with the missing one, the
  way the `--dashboard` row judges the address `AdminEndpoint` will actually take
  rather than the text an operator typed.

  **The line is "pure function of the command line", and it is narrower than "would
  be fatal".** `--serve-scheduler`, `--admin-listen`, `--listen-node` and
  `--discovery` were the same defect one tier along
  ([#186](https://github.com/LASTRADA-Software/fastcached/issues/186)): each names an
  address, each grammar was checked where the surface is opened, and a typo therefore
  registered cleanly and killed the node at every boot. They were one `EndpointFlag`
  table, because four rules differing only in a flag name and a grammar are the
  repetition a table exists to remove -- and `--listen-node` is in it, which is easy
  to miss: its failure is fatal only once the address is *named*, and a value that
  does not parse is named by construction.

  **Since [#288](https://github.com/LASTRADA-Software/fastcached/issues/288) that
  table is `NodeSurfaceTable()`, and `--listen-raft` is in it. The old exclusion was
  CORRECT and stopped being so.** `EndpointFlags` deliberately left raft out, on the
  reasoning that its own rules already refuse it both absent and unusable and a second
  row would answer in their place. That was true of a table holding four hand-picked
  flags. It is false of one holding every surface: leaving raft out would need a
  column meaning *"somebody else checks this one"*, which is a column encoding an
  exception, in the table written to delete exceptions. Do not re-derive the old rule
  from the old reasoning -- the premise moved, not the logic.

  **The general form, which is the part worth keeping: a narrower rule and a table
  rule coexist as long as the narrower one still fires for the inputs it was written
  about.** That is the check to run before repointing any rule loop, and it is what
  made this move safe rather than a behaviour change with unknown blast radius: with
  raft in the loop, `--node-id` plus an *empty* `--listen-raft` still reaches the
  cross-flag rule, and a *well-formed* `--listen-raft` with no `--node-id` still
  reaches the other. Only a malformed address moves -- and it moves to the better
  answer, because the table's message echoes what the operator typed while the
  cross-flag prose can name a flag but not a value.

  **And when a check moves to where the table is walked, its message moves with it,
  and the test follows the message.** Three checks relocated in one change --
  raft's grammar into the surface loop, `FrameEndpoint::Start`'s parse out to
  `StartupPolicyRejection`, and `AdminEndpoint`'s with it -- so a test asserting only
  "it was refused" now passes under both behaviours and pins neither. The raft case
  did exactly that and had to be rewritten to pair each input with text only the
  answering rule produces. **Assert the message, not merely the refusal.**

  **And "was it refused" is satisfied by ANY row, so it is not evidence that the row
  you mean still exists.** That is what makes the rule above sharper than it looks:
  the presence check and the message check fail in different circumstances, and the
  presence check is the one that cannot fail. Measured while adding a second
  `StartupPolicyRejection` row for an advertised endpoint no remote client can reach
  ([#290](https://github.com/LASTRADA-Software/fastcached/issues/290)): with the new
  row disabled, `REQUIRE(refusal.has_value())` **still passed**, because an unrelated
  row fires for the same configuration, and only the per-row phrase went red. A test
  written the obvious way would have gone on passing while the rule it was named after
  had ceased to exist -- and it would have done so from the day it was written, not
  after some later edit. So a table's test pairs every input with text **only the
  answering row produces**, and asserting the refusal alone is worth nothing here.

  **Which is also why two conditions never share one message.** A widened predicate
  covering both passes every row of such a table individually -- each input is still
  refused, each still matches the shared phrase -- so nothing catches the merge. The
  operator pays for it twice over: two different mistakes with two different remedies
  arrive as one sentence describing neither, and the person who typed nothing at all
  reads about a value they never wrote. Two rows, and a case asserting the two
  messages **differ**, or the split is only a comment. `--advertise` naming the
  wildcard and `--advertise` defaulting to loopback are that pair.

  What stayed out needs stating carefully, because the easy reason is the wrong one.
  `--advertise`, `--scheduler` and `--upstream` are addresses on
  the same command line, and it is tempting to say they are excluded
  because they fail at `bind()` or `connect()` -- but that is about **reachability**,
  and their *grammar* is every bit as much a pure function of the command line as a
  listen flag's. The honest split is narrower: this table covers the surfaces this
  node OPENS, whose grammar was already being checked in a tier and only in the wrong
  place. What genuinely cannot move here is only the resolving: an address that does
  not exist when a service is installed may exist by the time it boots.

  **The DIALLED addresses are a second table beside it, one predicate per row, and the
  per-row part is the rule** ([#208](https://github.com/LASTRADA-Software/fastcached/issues/208),
  [#968](https://github.com/LASTRADA-Software/fastcached/issues/968)). One widened
  predicate cannot serve them, because they do not share a grammar:

  - `--advertise`, `--scheduler` and `--upstream` are DIALLED, so a bare port names no
    machine and `ParseDialEndpoint` refuses it — the same call `--discovery` makes.
    `--advertise` was the costly one: nothing parsed it, so `--advertise=nope`
    installed, registered, heartbeated, was leased out and was never reached. The other
    two fail VISIBLY at `connect()`, which is why they were the residual rather than
    the defect. `--scheduler` is a list since #1310 and EVERY element is judged, an
    empty one included: for a scalar, empty means never given, while an empty ELEMENT
    is a value somebody typed — and a fallback that can never answer is found on the
    day the entries before it are gone.
  - **Shape and presence are different rules.** `--scheduler` is REQUIRED, by a rule of
    its own; the shape row is "parses when GIVEN", exactly as the surface loop is. A
    shape row that also demanded presence would answer "is not an address to dial" for
    a flag nobody typed, which describes the wrong problem.
  - `--bind` is deliberately in neither table. Its value is a HOST with `--port` beside
    it, and whether a host is usable is answerable only by binding it.
  - The rows carry a PREDICATE rather than a member pointer, because they are not one
    shape: two are `std::string` and two are repeatable lists, and a table that could
    hold only scalars would have left the list to a hand-written check beside it —
    which is the fifth-place-the-map-lives failure #288 records, one flag earlier.
  - A test asserting only "refused" passes whichever rule fired. Assert WHICH: the
    membership row's own case had a `--scheduler=6675` fixture expecting NO refusal,
    and its comment already said the right answer was a refusal about the value's
    shape. That expectation MOVED rather than loosened when the row landed.

  **A host somebody did not write is not a host they meant.** All four rows refuse an
  empty one, and it is worth knowing why that is not fussiness: an empty BIND host
  reaches `getaddrinfo` as nullptr under `AI_PASSIVE` (`SocketAddress.cpp:163`), which
  is the WILDCARD -- so `--listen-node=:6674` would quietly serve this node's private
  cache to the whole network, which is exactly what `CacheListenDefaultHost`'s loopback
  exists to make a decision rather than a typo. `UdpSocket::Send` refuses an empty
  destination outright, so `--discovery=:6681` announces to nobody. A **bare** port is
  a different thing and stays legal for the three bound surfaces: it names no host at
  all, so it takes that surface's default instead of silently replacing it.

  And a table column must be one an answer can depend on. The endpoint table carries
  no default host: `ParseEndpoint` uses one only to fill in the host of a bare port,
  never to decide whether the text parses, so a column for it would have been a value
  that could be wrong for years with nothing to show it. The default hosts are named
  (`SchedulerListenDefaultHost` and its siblings) for the rules that *do* turn on
  them -- `--dashboard`'s loopback test is the one that does.
- **A refusal in `main` still owes the SCM its answer.** The SCM waits for
  the service it started to CONNECT; a process that refuses and returns from `main`
  first is reported as error 1053, *did not respond in a timely fashion*, however
  clearly it named the refusal in the event log -- and `pace-kv`'s refusals there
  went to stderr, which a service does not have. So every refusal between choosing the
  host and entering it goes through `RefuseStart(host, logger, reason, code)`, which the
  foreground and POSIX hosts answer with the code and the service host answers by
  connecting and reporting a stop with the code as `dwServiceSpecificExitCode`
  (`Platform/ServiceStatusPlan.hpp` is the order, as a table), never RUNNING first. The
  Windows host is therefore CHOSEN before the configuration is judged, and a refusal
  from before any configuration exists -- a command line that does not parse, a file
  that does not load -- is reported under the service the command line names.
  `ServiceStatusPlan_test`'s source walk refuses a bare refusal `return` in that
  stretch of either `main`, which opens at the PARSE: an unknown flag is a refusal too.
  The host is `ServiceHost`, platform-neutral over `IServiceControlManager`'s three
  calls, so what it reports is asserted against `Testing::ScriptedServiceControlManager`
  -- which records every SCM rule a caller breaks, nothing after `STOPPED` among them,
  because a fake more permissive than the SCM passes a host that is not. **Reporting
  `STOPPED` is the LAST thing the host does**: the dispatcher returns once the SCM records
  it and `main` frees the host, so nothing of the host's is held or released after the
  call -- the `Close()` rule's shape. The fake runs the service main INLINE, which is its
  blind spot, so `AfterStopped` stands a case in that window. **And the control handler
  reaches the host only through a gate**: the SCM keeps its registration for the life of the
  PROCESS and calls it on its own thread, so the registration holds `ServiceControlGate`,
  never `this`; the host closes it before any member goes, a delivery runs wholly under its
  lock, and the Win32 slot holding it is never destroyed.

  Only a start and an install are judged by the serving rules (`ServingRulesRejection`, over
  `JudgedByServingRules`): an uninstall refused over the typo it was reached to undo is
  recovery blocked.

- **A refused start exits with a code of its OWN, and a supervisor that can read it never
  restarts it** -- `ProcessExit::Refused`, 78 (`EX_CONFIG`), in `Platform/ProcessExit.hpp`.
  A defect in the build's own wiring (`NodeRefusalCause::BuildDefect`) borrows it: no
  configuration reaches one, and every start meets it.
  A retry cannot change a refusal and can change a failure, so the code is decided **by the
  ARM that gave up, never by the step**: only a VERDICT -- on the command line, or on bytes
  that were actually READ (garbage, a foreign layout, an empty file, a contradiction) -- is
  `Refused`. **Every I/O arm is `Failed`** (`EXIT_FAILURE`, restarted), whatever its errno
  and without interpreting it: an open, a read, a directory created, a file written, a random
  draw; the supervisor's own start limit bounds the retries. So a step that both reads and
  judges has a row per arm (`IdentityKey` / `IdentityKeyIo`, `NodeIdentity` /
  `NodeIdentityIo`, `ConfigurationFile` / `ConfigurationFileIo`), chosen from the fault that
  refused (`StageOf`, `ConfigurationFileStage`) -- never one row for a site whose arms differ.
  **ABSENCE is an I/O arm too, with no carve-out**: a named configuration file, credential or
  roster that is not there is `Failed`, because a start at boot can race the share or the mount
  it lives on, and a path that is simply wrong still stops once the start limit is spent. An
  earlier ruling refused an absent configuration file; it was revised. Measured before this
  rule: a mode-000 kept roster exited 78 and systemd never tried it again. `ProcessExit_test`
  holds each row to a written verdict and both `main`s to the table.
  - **WHO READS an exit decides it, and a one-shot command is not a start.** A START is read by
    a supervisor: 1 or 78 by the arm, as above. A ONE-SHOT command -- `--print-surfaces`,
    `--print-identity`, `--install-service`, `--uninstall-service`, `--migrate-storage`,
    `--migrate-cache`, `--seed-config`, `--cluster-*`, `--enroll-*`, `--cordon`
    -- is read by an operator or a script, and ends as a `CommandEnding` by what that reader
    should do next: **2 (`Declined`) is a DECISION -- the same command gets the same
    answer, so do not retry; 1 (`Failed`) is TRANSIENT -- a retry may get past it.** A decision:
    a verdict on the arguments or on bytes read, a refusal a peer REPLIED with (`NotLeader` naming
    a leader the verb does not follow, `UnknownLease`, `NotAMember`, a body this build cannot read,
    `NoCluster`, `UnsupportedVersion`),
    a store another process holds, a precondition only the operator changes (elevation, an
    account that does not exist, a name the registration refuses). Transient: an I/O arm (an
    open, a read, a write, a directory, a draw, a file that is not there), a transport that
    delivered no reply (a dial, a broken or timed-out exchange, a seal), a system call that
    failed on its own, a change stopped part-way that a re-run finishes. It is the start's own
    rule asked of a command: a step that has a stage or a cause ends by it (`EndingOf(StartStage)`,
    `EndingOf(NodeRefusalCause)`, the key and identity faults' stages, `ConfigurationFileStage`),
    the refusals decided BEFORE a one-shot runs included (`ExitReaderRows`' `Operator` row). A
    `--healthcheck` is read
    by a container runtime, which knows 0 and 1 only (Docker reserves 2), so its every refusal
    and failure is 1.
    - **The ending is DATA, never a literal at the site**: a verb's result carries it --
      `ServiceControlResult::ending`, `CowTreeStorage::MigrationFailure::Transient()` (part-way, or
      an I/O error before it began), `UnfinishedCommand` -- and `CommandExitCode` is the one mapping
      to a code. It is named apart from a start's `ExitCodeFor` because they answer different
      readers, and `ServiceStatusPlan_test`'s scan reads that name as a start's refusal. **No
      site in either `main` spells a code** -- no literal, no `EXIT_*`, no local constant standing
      for one: a local decision states its ending (`CommandEnding::Declined`) and the mapping turns
      it into a code, and `ProcessExit_test` pins both mains to that. The node's pre-verb refusal
      asks `RefusalExitCode(ExitReader::Operator, stage)`, the row the daemon reads, so one row
      governs both binaries. A command
      over several parts ends as the WORST of them -- the enumerators are in order of severity and
      `std::max` reads it.
    - **A registration decides its ending over a SEAM, compiled on every host**: every SCM and
      launchd call goes through `IScmCalls` / `ILaunchdCalls` (one per supervisor -- they share no
      primitive), the registration itself is `ScmInstall`/`ScmUninstall`/`LaunchdInstall`/
      `LaunchdUninstall` over it, and the real calls live behind `#if` in one implementation per
      platform. An SCM error travels as its raw code, compared against `ScmError*` constants the
      Windows build `static_assert`s against the SDK, so WHICH code declines is tested on Linux as
      well; `src/tests/ScriptedServiceCalls.hpp` scripts both. The interface names no Win32 API
      (`Create`, not `CreateService`): `<windows.h>` defines those as macros, and a member one TU
      renames and another does not is two vtables.
    - **A network verb ends by WHERE ITS ANSWER CAME FROM, never by its words**
      (`Node/OneShotAnswer.hpp`): `AnswerSource` -- `Local` (refused here before any dial),
      `Transport`, `Reply`, `Pending` -- is a table, and the exchange's own outcome is classified
      ONCE (`SourceOf`: `Transport` is transport, every outcome that arrived is a reply unless it
      decided nothing). A runner
      returns `std::expected<std::string, UnfinishedCommand>` and `ReportOneShotVerb` maps it. The
      enrollment `Fatal` reading is BOTH sources, so the joiner keeps the outcome and classifies it
      rather than the reading. **A reply that decided NOTHING is not a decision**, and is `Pending`,
      transient (1): a refusal whose code the WIRE calls retriable (`ErrorDescriptor::retry`, a
      type with a deleted default so no row omits it, a `retryWhy` per code, and the set pinned by
      `RetriableCodesArePinned`) -- a code is a structured fact the peer states, not its words; a
      `NotLeader` naming nobody, which is an election; a redirect chain that did not settle; and a
      joiner that gives up at the approval bound after `Waiting` or `Closed`. Only a joiner the
      seed REFUSED is 2. **A peer on another wire version is a decision, not a transport fault**:
      a reply header carries no version, so the SERVER's range decides and answers
      `UnsupportedVersion`, a refusal that arrived; only bytes that cannot be framed at all are
      `Transport`.
    - **Who reads an outcome is a COLUMN**: `CliOutcomeTable`'s `reader` (`ExitReader`:
      `Supervisor`, `Operator`, `Prober`) for the daemon, `EarlyVerbs` for the node, and a
      pre-verb refusal answers `RefusalExitCode(reader, stage)`. `RefuseUnderService` takes the
      daemon's whole `CliResult`, never an outcome beside it, so no site can hand it one the
      command line did not name. After a parse that FAILED, the verb is read from the WHOLE
      argv (`ApplyRecognisedOptions`, through the option rows themselves -- the one spelling of
      every flag), so `--no-such-flag --install-service` is an install's refusal, in both binaries.
    - `Usage` is ONE `ProcessExit` row with `endsAStart` false: no `StartStage` answers it and the
      systemd units' derived `RestartPreventExitStatus` does not exempt it.
    - `exit-codes-e2e` drives the routing through both real binaries (neither `main` is in a test
      target): each one-shot decline at 2, a start's 1 and 78 behind a bait the start refuses
      after its file, a probe's 1, both argv orders, and every network verb against a port nobody
      answers (1) and refused locally (2); a refusal a PEER replied is asserted at each runner's
      seam. `node-config-file-e2e` covers the node's files.
  - **The node's serving body by the same rule, per REFUSAL rather than per step**: a tier's
    refusals are of several kinds, so each `*OrExplain` refusal carries a `NodeRefusalCause`
    (`NodeRefusal.hpp`) and `main` ends with that cause's exit. The census names the cause
    every refusal site spells, one site per arm; `NodeRefusal_test` holds each cause to its
    exit. A credential file that was read and cannot be used is `Refused`; one that could
    not be read (`CredentialIo`), a port, a store, TLS
    material, a scratch root and the toolchain survey are `Failed`. **An identity file that is
    there and cannot be read is not an absent one**: it used to be read as absent and MINTED
    over.
  - **systemd**: every shipped unit says `RestartPreventExitStatus=78` and keeps
    `Restart=on-failure` under the DEFAULT start limit. A unit start limit of its own is gone:
    it counted an operator's restarts with the refusals, and the fourth `systemctl restart` in
    ten minutes left the service STOPPED. Measured on systemd 259: a refusal runs once and stays
    failed; a failure is restarted; restarts at a human pace are all honoured, and only five
    starts inside ten seconds meet the default limit.
  - **Windows**: the SCM runs its recovery actions for every stop whose Win32 code is not zero,
    so a refusal it did not restart would have to report zero -- hiding 1066 and 78 from
    `sc query`. It is bounded instead (`ServiceRestartAttempts`): three restarts in ten minutes,
    and `ServiceRecoverySteps` ends in no action, since the SCM repeats the LAST step forever.
  - **launchd** can tell an exit only from a crash, so `{Crashed:true}` restarts neither exit and
    a crash at every start forever; `BuildLaunchdPlist` states both costs.

- **The supervisor's launch arguments must not pass `--daemon`.** The POSIX
  daemonize path double-forks and sends stdout/stderr to `/dev/null`, which
  silences journald; its pidfile is also written after both parents exit, racing
  `Type=forking`. launchd has the identical problem — it reaps the forked job
  instantly as "exited" — which is why `BuildServiceArgv` takes an
  `EmitDaemonFlag` rather than always emitting it.
- **`--install-service` registers the *command-line* config, not the merged
  one.** A flag in `ProgramArguments` outranks the same key in YAML for the life
  of the registration, so baking merged values in froze every configured key at
  install time and made later edits to that same file silent no-ops — and copied
  `requirepass:` out of a mode-0640 file into a world-readable plist. Hence
  `main.cpp` hands `parsed->config` to `InstallService`, and
  `InlineCredentialRejection` refuses a `--requirepass` typed on the install
  command line rather than dropping or publishing it — *including* alongside
  `--config`, since nothing there can tell whether the named file carries the
  secret, and accepting it was the silent drop under another name.
- **What reaches a supervisor must survive its own parser.** Every registration
  flag is re-read by the daemon at the next start, so a value that cannot be
  spelled back is a service that registers cleanly and then fails forever:
  `--listen=[::]:11211` came back as `--listen=:::11211`, which the CLI rejects,
  and a Windows path ending in `\` escaped its own closing quote and swallowed
  the flags after it. `FormatListenHost` and `MaybeQuote` are where that round
  trip is kept honest. `ServiceNameRejection` covers the other direction: the
  name is concatenated into the directory launchd scans, so a separator writes a
  root-owned plist nothing knows how to remove.
- **PROVENANCE is not VALUE: whether an operator NAMED a setting is a fact the
  parse records, never one a comparison against the default recovers.** The two
  agree everywhere except on the one input that matters — an operator typing the
  default — and that is not an exotic input, it is what somebody does after
  reading the value off the startup line to pin it. Where the answer decides
  anything, `OptionSpec::explicitBit` records it at the parse and the decision
  reads the bit.

  Both sides of a flag ask this question, and getting one right is not getting the
  flag right. `--listen-node` had it wrong on both
  ([#286](https://github.com/LASTRADA-Software/fastcached/issues/286)): the tier
  compared `cfg.cacheListen` against `NodeConfig{}.cacheListen` to decide whether a
  bind failure was **fatal**, so a pinned default port was read as a convenience
  nobody asked for and the node started healthy serving no cache — and
  `MakeNodeServiceSpec`'s `emitIfSet` compares the same two values to decide what to
  register, so the same pinned port was dropped from the unit and the service came
  back classified as defaulted, warning past a taken port at every boot. Fixing only
  the startup half leaves the reported failure reachable through the install path,
  which is the way this software actually runs.

  So: a flag whose provenance decides anything is emitted **on the bit, never on
  difference** — `emitIfExplicit`, a named sibling of `emitIfSet` rather than an `if`
  per flag, because *reaching for `emitIfSet` is the mistake* and a named alternative
  is what makes the choice visible where it is made. `emitIfSet` stays right for a
  flag whose default is a constant the next start re-derives identically; it is wrong
  the moment the default is host-derived (`--cache-memory` follows RAM) or the moment
  being defaulted *means* something at startup (`--listen-node`'s warn-versus-refuse).

  The guard is mechanical, because the failure is an **omission** and every other
  case in the file passes a row that regressed: a case walks `NodeOptions()`, and for
  each row carrying an `explicitBit` sets the bit while leaving the field at its
  **default** — the one shape no value comparison can tell from silence — and requires
  the flag to be emitted. It asserts the converse over the same walk. A new row
  therefore cannot go back to `emitIfSet` by omission, and nobody has to remember this
  paragraph. Note the emission itself stays hand-written per binary for the reason
  already recorded above: an `OptionSpec` says how to *parse* a flag and carries no
  way to read a value back out.

  Its converse is why "always emit it" is not the fix: a setting nobody named must
  stay unnamed through the registration, or the machine's default is frozen at
  install time and a node that should follow a memory upgrade or a moved default
  silently does not.

  **The paragraph above was written before the code it governs obeyed it**, and the
  daemon did the opposite for as long as it existed
  ([#349](https://github.com/LASTRADA-Software/fastcached/issues/349)): every one of
  `BuildServiceArgv`'s thirty-one provenance-bearing flags was emitted by value
  comparison, `--max-memory` following host RAM among them. A rule nothing checks
  cannot make code fail, which is the general finding — and it is why the fix landed
  the mechanical guard here too rather than the one line the ticket named.

  Two things about the daemon's shape that the node's does not have to answer. Its
  parse result is a `CliResult` **wrapping** a `Config`, so the bits are not on the
  configuration at all — `BuildServiceArgv` and `MakeDaemonServiceSpec` therefore take
  the **parse**. Moving the bits onto `Config` instead would have been worse than a
  wider signature: `Config` is what the YAML merge fills and what `ConfigReloader`
  compares, and `FileOptions` sets an `explicitBit` too, so a key in a file would have
  become a flag baked into a registration — the precise thing "registers the
  command-line-only parse" forbids. Taking the parse is also the guard, since a
  function handed only the merge's output cannot obey a rule about the command line.

  And the daemon's audit moved the whole table rather than the five settings that
  could lose a pin. **Eighteen** of its rows were safe only because their default is a
  **compile-time constant** — which is exactly what `logTimestamps` was until #496
  made it platform-dependent, at which point `--no-log-timestamps` began registering
  nothing on a host that defaults it off. "Safe because the default happens to be a
  constant" is a property of this build, not of the flag; the two other safe shapes
  (a sentinel `0` meaning *follow the host*, and a one-sided switch whose default is
  the value it cannot express) are properties of the flag and stay safe. So on the
  daemon `emitIfSet` is gone entirely, and one `emitSwitch` serves both kinds of
  switch: the two were separate because a value comparison needs a platform default
  for the two-sided one, and provenance consults no default at all.

  **An explicitly EMPTIED value is a pin, and an empty default is not a licence to
  drop it.** The first pass excused `--storage`, `--tls-cert` and `--tls-key` on the
  grounds that empty is the flag's own way of saying "off" and there is therefore
  nothing to lose. There is: `ParseText` never fails, so `--storage=` parses, and
  under CLI-over-file precedence it means *no persistence whatever `--config`'s file
  says*. Deciding by presence dropped it, let the file win at every start, and left
  the daemon persisting to disk — #349's shape inside #349's own fix. What the empty
  default really constrains is the **absolutizer**, not the decision:
  `std::filesystem::absolute("")` is the installing shell's working directory, so an
  explicitly empty value is emitted verbatim. `WithScopeDefaults` then leaves it
  alone for the same reason it leaves a named `--config` alone.

  Only `--config` and `--pidfile` keep a presence test, and now for an exact reason
  rather than an approximate one: they carry **no explicit bit**, so they cannot be
  asked. That is the one shape the node's `--cache-dir` bullet above describes.

  **And a coverage sweep that asks only whether a flag APPEARED cannot see a line
  naming the wrong field.** `emitIfExplicit("metrics-port", cfg.port,
  cli.metricsPortExplicit)` emits a token under the right spelling forever, while
  every registration pins the cache port as the metrics port. So the daemon's sweep
  drives each value row a second time, with a value distinct from that row's default,
  and requires the emitted token to **move**. Movement is a value row's question
  only: a valueless flag's own `apply` may produce the platform default —
  `--no-log-timestamps` on a host that already defaults off emits the same token
  either way — so demanding it there would demand a contradiction on one platform,
  and a wrong field on a switch is caught by the presence half instead, since the
  emission follows the other field and no token under this spelling appears at all.

  A flag needs no bit when its default is **empty**. There is then no address to
  arrive at without asking, so every failure on it is unconditionally fatal —
  `--admin-listen` and `--cache-dir` are that shape, and the asymmetry with
  `--listen-node` is the default, not the surface.
- **Teardown must address every domain, not re-probe for one.** Which launchd
  domain a user agent lives in is decided at install time — `gui/<uid>` needs an
  Aqua session, so an SSH install lands in `user/<uid>`. Re-probing at uninstall
  booted out a job that was never there and reported success while the real one
  kept the port. `BootOutEverywhere` walks the whole `ScopeTraits::domains` row,
  and `pace-uninstall` mirrors it.
- **How a registration STARTS is part of it.** `ServiceSpec::startMode`, one
  `ServiceStartTable()` row per mode: the SCM start type (`auto` is 2, `manual` 3), launchd's
  `RunAtLoad`, and whether a launchd install kickstarts the job at once. There is no systemd
  column, because this project registers no systemd unit and the packaged units carry their own
  enable policy. `--service-start` is install-time only and never replayed into the registered
  command line: the start mode is the supervisor's record, and the running process never reads
  it. A Windows install leaves the service STOPPED in either mode; only a launchd `auto` install
  starts the job.
- **Registering over an existing service RE-APPLIES it.** `CreateRefusalTable()` maps what
  `CreateService` refused with to ONE step. 1073 (it exists) re-applies the registration through
  `ChangeServiceConfig` -- start type, command line, account -- and the service then gets
  everything a fresh install gives it: description, restart policy, SID type, the owned-path
  handover, the event source and, from the binary's `main`, the firewall. 1072 (marked for
  deletion) is waited out for `MarkedForDeletionCeiling`, asked every 250 ms. 1078 (another
  service displays that name) and any error with no row are refused. A re-applied registration
  takes effect at the service's next start, and the message says so rather than "start it now".
  - An uninstall stops the service and waits, bounded by `UninstallStopCeiling`, for
    `SERVICE_STOPPED`, and then deletes it WHATEVER the wait said: one still running is only
    marked, goes when it exits, and the message says that. The wait is why the next install
    rarely meets 1072; the 1072 row is why it survives one that does -- the row's own reason is
    an older MSI that deleted without waiting for the stop.
- **An MSI upgrade never deletes the registration of a feature it keeps.** Removal through the
  binary's `--uninstall-service` runs only for a feature being removed AND outside the old
  product's half of a major upgrade (`NOT UPGRADINGPRODUCTCODE`). The old product's
  `ServiceControl Stop="both" Wait="yes"` rows stop each service, waiting, before its files are
  replaced. CPack's own WiX template schedules `MajorUpgrade` `afterInstallInitialize` and this
  project does not override it, so there is no slot before `RemoveExistingProducts` for a stop
  of our own.
  - **Nor for anything else that writes to the execution script**: with `RemoveExistingProducts`
    directly after `InstallInitialize`, a deferred, rollback or commit action between them is
    Error 2613 and the upgrade aborts before it starts (round 7, after round 6 put the
    registration copies there; ICE63 reports it, as a WARNING). What must be read before the
    old product's half runs is read by AppSearch into properties, and what must be WRITTEN from
    those properties is written by the installer itself through the Registry table
    (`RegistrationCopy` components): `[PROPERTY]` carries an `ImagePath`'s TEXT verbatim, quotes
    included, which no custom action's command line can carry. Its registry TYPE is not carried
    -- the raw search returned the bare text and the copy is a `REG_SZ` -- and is immaterial,
    since a restore re-applies the image path through `Win32_Service.Change` rather than copying
    the value. `msi-custom-action-commands` refuses the order, and the MSI job runs ICE63 on the
    built package and fails on it.
  - **The exact restores are ARMED before anything that can fail**: the clear, both stashes and
    both restores run directly after `WriteRegistryValues`, and `msi-custom-action-commands`
    refuses a `Return="check"` deferred action scheduled ahead of either restore, since 0.3.0's
    uninstall deleted both services and ships no rollback to bring them back. The RESIDUAL is
    EVERY action from `RemoveExistingProducts` through `WriteRegistryValues` -- the removal
    itself, `StopServices`, `DeleteServices`, `RemoveRegistryValues`, `RemoveFiles`,
    `CreateFolders`, `InstallFiles`, `WriteRegistryValues` -- where nothing that restores can run
    yet; `PaceAwaitServiceExit` is the one of ours, a stated row of `ChecksBeforeTheRestores`.
    A failure there rolls an upgrade from 0.3.0 back with no service registered, and the remedy
    is to run the upgrade again.
  - **A rollback that STARTS a service is scheduled BEFORE `InstallFiles`**, and the rollback
    state's undo before it: a rollback runs in reverse, so a start scheduled after the files runs
    before `InstallFiles`' rollback restores them, starting the new binary over the old one being
    put back. Step 10 of `msi-custom-action-commands` refuses it. That restores "the files that
    were there" in a MAINTENANCE transaction only; in an upgrade the old files return with
    `RemoveExistingProducts`' rollback, after the restarts, and it is harmless only because an
    upgrade writes no was-running mark (`StopServices` stopped both services first).
  - **With rollback DISABLED** (the `DisableRollback` policy, `DISABLEROLLBACK=1`) no rollback
    custom action runs, so a failed upgrade from 0.3.0 leaves both services unregistered. That is
    not refused: an administrator who disabled rollback opted out of it, and the runbook names
    running the upgrade again as the remedy.
  - **The rollback state is discarded in the COMMIT phase** (`PaceDiscardRollbackState`,
    `Execute="commit"`), never deferred: a deferred discard runs inside the script, so any failure
    after it -- a later checked action, a standard action, the leftover deletes -- rolls back with
    the saved state already deleted and every exact restore reads a missing key and does nothing
    (#1629). A commit action runs only after the whole script succeeded and never in a rollback.
    Step 11 of `msi-custom-action-commands` derives the actions that delete the key from their
    command lines -- those spelling `reg.exe delete HKLM\SOFTWARE\Pace\InstallerRollback`
    on the whole key, the one spelling the fragment uses -- refuses a deferred one that is not a
    stated `$DeferredStateDeleters` row, and refuses to pass unless a SCHEDULED commit action is
    among them. It fails OPEN for a deleter spelled any other way (`Remove-Item`,
    `HKEY_LOCAL_MACHINE\`, a quoted path, a subkey, a `<RemoveRegistryKey>` element), as its own
    text states. The CI step `A failed upgrade restores the previous installation exactly` proves
    the behaviour end to end, with THREE controls on patched copies: (A) every rollback row that
    rewrites pace-kv's registration off -- the exact restore, its re-registration twin
    `PaceRestoreRegistration` and the undo -- must differ in pace-kv's registration;
    (B) only the twin off must differ in NOTHING, the exact restore working alone, and red there
    is a defect in the exact restore rather than a weak control; (C) the twin off and the discard
    deferred again must differ in pace-kv's registration. B and C differ only in the
    discard's phase, which is what isolates this fix. **Switching off the exact restore ALONE
    could not discriminate while N's registration matched what the twin rebuilds**: CI run
    37452107865 MEASURED an empty difference with both exact restores off. The twin is the
    INFERRED restorer, since it re-registers from what AppSearch captured before the transaction
    and reads no rollback state, and control A now pins that inference. **And an upgrade KEEPS the install root** (CPack's `FindInstallLocation`
    RegistrySearch reads it from the old product's `InstallLocation`), so the executable path
    alone is something any re-registration puts back. N's registration therefore carries what
    only the exact restore restores: one extra flag on its command line (`--log-level=info`),
    which the twin's `--install-service` does not build, so the twin alone can no longer put N
    back. With rollback DISABLED
    no commit action runs either, so the key survives that transaction; the next transaction's
    `PaceClearRollbackState` empties it before it writes any.
  - **`PACE_FAIL_FOR_TEST="1"` is a shipped, property-gated late failure**
    (`PaceFailForTest`, `Before="InstallFinalize"`, so behind every other script action): it
    exists for the CI step that proves a failed upgrade restores the previous installation
    exactly, and it is shipped rather than built apart so CI tests the package that ships. Only
    the exact value `1` runs it; an administrator who sets it fails their own install and nothing
    else.
  - A feature an upgrade no longer installs has its leftover registration deleted by the NEW
    product (`sc delete`, the `DeleteLeftover` rows), because the old half never removes one and
    the new product has no binary left to run `--uninstall-service` with. Only a registration
    whose image path starts with this install root, quoted (`"[INSTALL_ROOT]`, in both spellings
    the raw registry search returns), is ours to delete; any other shape fails the test CLOSED
    and is left alone. The same transaction removes the feature's firewall GROUP
    (`Remove-NetFirewallRule -Group`, the `DeleteLeftoverFirewall` rows, W-11), named as the
    binary files it, and CI asserts the node's group is empty after a deselecting upgrade. Its
    event source stays -- an accepted residual: it belongs to a program that is no longer
    installed, so nothing writes to it.
  - Deselecting a feature outside an upgrade (`REMOVE=CM_C_Node`, Settings > Apps > Modify, an
    uninstall) removes its service through its own binary, firewall rules included.
  - **A maintenance transaction resolves `INSTALL_ROOT` from the product's OWN install location**
    (`SetPaceInstallRootFromInstallLocation`: when `Installed`, before `CostFinalize`, from
    `Uninstall\[ProductCode]`'s `InstallLocation`). CPack's `FindInstallLocation` reads only
    `Uninstall\[WIX_UPGRADE_DETECTED]`, which is empty outside an upgrade, so a repair, a feature
    change or an uninstall of a custom root resolved the DEFAULT root. CI run 37456507637
    MEASURED the uninstall: it ran the default root's `pace-kv.exe --uninstall-service`
    (Info 1721, ignored), removed the files, and left pace-kv registered over a deleted
    binary, while the log showed the installed component's own directory (`CM_DP_Daemon.bin`)
    correct. The fix is one property rather than a component directory per action, because a
    feature that a change ADDS, every `Directory="INSTALL_ROOT"`, the PATH entry and
    `ARPINSTALLLOCATION` all resolve from it as well (INFERRED, none of them measured). It is a
    type 51 action before `CostFinalize`. "Changing the Target Location for a Directory" forbids
    changing a target directory during a maintenance installation, and that restriction covers
    EVERY option it lists, type 51 included. This row complies because it does not CHANGE the
    path: it re-states where the product already is, its own `InstallLocation`. A product
    installed by a build without the row keeps the old behaviour for its own repair or `/x`,
    which runs its own package, until it has been upgraded once. That is accepted, because no
    backwards compatibility is owed before production ready. Step 12 of `msi-custom-action-commands`
    refuses the package without it while any scheduled action names `INSTALL_ROOT`, and
    `wix-service-table` pins the rows.
- **The MSI's service table decides every start mode**, and is applied on every transaction that
  leaves a feature installed -- a first install, a repair, a feature change and an upgrade. With
  the node installed, the node is registered `auto` and started, and pace-kv stopped through
  `net stop`, which waits, and DISABLED (both would answer on 6674; below for why not `manual`);
  with pace-kv alone it
  is `auto` and started unless `PACE_START_SERVICE=0`. The node is re-registered on EVERY
  such transaction and needs no property -- a node that serves is refused `--scheduler`, and a
  registration kept as found would replay the one an earlier package wrote and fail at every
  start -- so the OPTIONAL properties are REMEMBERED (the WiX remember-property pattern: saved
  before `AppSearch`, read back from `HKLM\SOFTWARE\Pace\Installer`, restored, written
  again by a deferred `PaceRemember*` action on every transaction that registers; a root-feature
  component only OWNS the key, since a feature change reinstalls no component). Three of them:
  `PACE_FIREWALL_ALLOW`, `PACE_FLEET_SEED` and `PACE_FLEET_ID` (passed VERBATIM, a pin
  being security material), each a row of `check-wix-service-table` and of the
  remember case. **The node's sequence is ONE: validate, register, remember, start**, every step
  `Return="check"`. Validate is `PaceNodeCheckArguments`, the node's own `--check-arguments`
  over the registration's own argument list: a pin its parse refuses fails the transaction with
  nothing registered or remembered (batch 3 review, B3-1; before it the registration was
  `Return="ignore"`, so the OLD registration was started and the refused pin remembered, replayed by
  every later transaction and clearable by no empty property). The registration and the waiting
  start, with its RUNNING recheck, are checked so an upgrade cannot succeed over a node that will
  not start (ci-fix2). **And a failed step leaves nothing behind from the steps before it**, because
  Windows Installer undoes no custom action: each registration and each remember write has a
  ROLLBACK twin scheduled just before it -- a registration the transaction created is removed, one
  it re-applied is registered again from the values it found remembered (`Pace*Before`, read by
  searches of their own, since AppSearch leaves a stated property alone where it finds nothing), and
  each value is written back or deleted as found. Without the twins, remembering after registering
  was R-B's defect: a failed write rolled the files back under services it had registered. The node's
  two properties are remembered only by a transaction that keeps the node, so nothing the check
  did not see is ever written; the `[msi]` refusal and rollback cases and the MSI job's refused
  repair assert it. Not remembering them failed OPEN: a repair that left out
  `PACE_FIREWALL_ALLOW` opened the rules to any address. The `[msi]` remember case runs the
  fragment's own rows across install, repair, upgrade and repair. **There is no advertised-endpoint
  property** (W-10): an IP literal remembered across upgrades vetoed the dial hint for good on a
  roaming laptop, so the registration carries no `--advertise`, the node advertises its own name,
  and `PaceForgetNodeAdvertise` deletes the value an earlier package remembered; the MSI
  names no `--cluster-dir` either, since a registered value outranks the file's `cluster_dir`.
  `DocumentedCommandLines_test`'s `[msi]` case reads the `ExeCommand` out of the fragment and
  round-trips every shape, the no-property one first. The
  inputs are `PACE_NODE_SELECTED` / `PACE_SELECTED`, derived once from the feature
  states after `MigrateFeatureStates`, so no condition restates the feature-state expression.
  NOT after `CostFinalize`: on a major upgrade `MigrateFeatureStates` runs later and carries the
  old product's selection over, so a state read before it is the new package's default.
- **Windows Installer's Restart Manager takes no part in a transaction** (`MSIRESTARTMANAGERCONTROL`
  is `Disable`, one `Property` row of the fragment), because the service table and the
  `ServiceControl` rows own every stop and every start, and their rollback every restart. A silent
  install otherwise ALWAYS uses Restart Manager ("Silent UI level installations always shut down
  applications and services, and ... always use Restart Manager"): at `InstallValidate` it shuts
  down each service holding a file the transaction replaces, and at the end of the install it starts
  it again, WHATEVER the table decided (`MSIDISABLERMRESTART`'s own page: at `0` "all system
  services that were shut down to install the update are restarted").
  - **What PR 1634's CI MEASURED, and what is INFERRED.** MEASURED: in the upgrade from 0.3.0, with
    pace-kv running, pace-kv stopped one second in (InstallValidate time) and was started
    again at 12:12:47, after the table had made it manual and stopped it for the node; it could not
    bind 6674, which the node holds exclusively, terminated three times before msiexec returned, and
    its 30-second recovery restart took 6674 while "an upgrade deselecting pace-kv" had the node
    stopped, failing that transaction with 1603. The row assertion after the upgrade read `Manual`
    and `Stopped`, between two restarts. That Restart Manager made that start was INFERRED then, and
    the run with the printed log MEASURED it (the bullet "An OLD package's removal keeps its own
    Restart Manager", below).
    `Invoke-Msiexec` prints every `RESTART MANAGER` line of each verbose log (up to a stated cap of
    100), and a refused judgement adds the actions from 10 s before to 5 s after each finding.
  - **And it cost the rollback its restart.** `PaceStopForFiles` and
    `PaceNodeStopForFiles` (`Stop="both" Wait="yes"`) stop each service before its files
    are replaced, and `StopServices` records a rollback start only for a service it found RUNNING.
    Restart Manager's shutdown came first, so `StopServices` found nothing to stop and a failed
    transaction had no rollback start for it (INFERRED from the order; that a failed upgrade still
    ended with pace-kv running under Restart Manager was its end-of-install restart, equally
    INFERRED). With it disabled, the OLD product's `PaceStopForFiles`, run inside
    `RemoveExistingProducts`, stops a running pace-kv and records the start, which the rollback
    replays last, after the node's registration is undone.
  - **`Disable`, not the other two answers.** `DisableShutdown` keeps Restart Manager detecting
    which files are in use, and its documented scope ("a package that has not been authored to use
    the Restart Manager") leaves which shutdowns it stops a reading rather than a statement.
    `MSIDISABLERMRESTART=1` alone stops the RESTART and keeps the SHUTDOWN at `InstallValidate`, and
    with it the lost rollback start. The property is read from the package's `Property` table; a
    custom action changing it has no effect, so `msi-custom-action-commands` step 13 refuses a
    `SetProperty` of it as well as a missing row or another value, and `wix-service-table` pins the
    row. Both refusals name the defect. Both read the FRAGMENT, so a transform or a command line
    setting the property is seen by neither (they fail OPEN there); the per-transaction judgement
    below is what would see its effect.
  - **What `Disable` gives up.** Restart Manager offered to close a NON-service process holding a
    file the transaction replaces, and now nothing does, in full UI either: `pace-cc` inside a
    running build or a `pacectl` in a console has no window, so the FilesInUse dialog never
    lists it, and its file is replaced at the next boot (exit 3010). The services cannot raise it
    (no window) and are stopped before `InstallFiles`. And a MAINTENANCE transaction that removes a
    service (`REMOVE=CM_C_Node`, `/x`) now relies on the service PROCESS having exited between its
    stop (`StopServices`, `--uninstall-service`) and `RemoveFiles`: `PaceAwaitServiceExit` runs
    on an upgrade only, and Restart Manager's shutdown at `InstallValidate` used to give that margin.
    Both show as 3010 rather than as a failure: watch "removing the node feature" and the uninstall
    legs for it.
  - **This build's package must PROMISE it, and its log must keep the promise**: `Invoke-Msiexec`
    refuses a package whose Property table does not set `Disable`, unless the call names it
    `-Released` (0.3.0, the latest release), and refuses a log of a `Disable` package that lacks
    "RESTART MANAGER: Disabled by MSIRESTARTMANAGERCONTROL property" (the wording MEASURED on the
    Server 2025 runner). A skip would read as a pass: the static checks read the FRAGMENT, and a
    built MSI that lost the row is exactly what only this sees.
  - **Every transaction is JUDGED, inside `Invoke-Msiexec`**, because a row is read after the
    transaction and a service started and killed inside it passes the row. A call names the row the
    transaction leaves (`-Leaves <row>`) or, where no row honestly describes it, a named expectation
    with its reason (`-Expect`, `$script:TransactionExpectations`: `RollsBack` for a transaction that
    fails on purpose, `NodeCannotBind` for the step that holds 6674 so the node it adds cannot bind);
    a call naming neither, both or an unknown one is refused before msiexec starts, and the start
    seam asserts it never ran. Nothing defaults: every `Invoke-Msiexec` in `build.yml` states one. A
    named expectation is `MustFail`, so a transaction stating one that returns 0 is refused: the
    exemption is bound to the outcome it is named for, not to the call site's `-Accept`.
    Three witnesses, each a pure verdict over records: an unexpected-termination event (7031, 7034)
    of either service since the transaction began, unless the expectation is built to cause it; a 7036
    for a service the expectation leaves NOT RUNNING (stopped or unregistered) -- "running", or a
    "stopped" past the one stop the process it ran under at the start allows, since a start that dies
    before RUNNING still ends in a stop (PR 1634's logged three and no "running"); and a process the
    watch saw such a service run under, other than the one it ran under when the transaction began.
    The watch polls both services every 250 ms while msiexec runs; a failed poll is counted and named,
    and msiexec is waited for on every way out.
  - **And every transaction is judged TWICE**: at msiexec's exit, and once more by
    `Assert-TransactionSettled`, over a window reaching at least 10 s past the exit
    (`$script:TransactionSettleSeconds`), because a restore's own restart is an unwaited
    `sc.exe start` and a start that cannot serve dies about a second later (PR 1634: started
    12:12:47, 7031 at 12:12:48), after the exit's read. `Assert-ServiceTable` runs it after its
    stability interval; the failed upgrade, every control, the successful upgrade beside them and the
    two repairs with no row assertion call it themselves. It is SELF-ENFORCING but one transaction
    short: `Invoke-Msiexec` refuses to BEGIN while the previous transaction has not been settled, so
    only a step's LAST transaction relies on its call site -- every step ends in an
    `Assert-ServiceTable` today, and that blind spot fails OPEN.
  - **7036 is a witness only where the host writes it**, MEASURED on two hosts: PR 1634's runner
    (Windows Server 2025) writes it -- its log printed "The pace-kv service entered the running
    state" -- and this repository's Windows 11 26200 development host wrote none among 50,978 System
    records. The node's own start is the positive control: every transaction whose row leaves the
    node running starts it, and the pass line says `7036 live`, `7036 NOT SEEN` (no 7036 at all was
    read: a host that writes none, or a reader that fails on all of them -- the watch is then the
    only start witness, and a start that lives and dies between two polls without terminating
    unexpectedly is unseen: fails OPEN there) or `7036 unchecked` (the transaction starts no node).
    The witness cannot die behind a green line: a node start whose 7036 is missing while other
    services' 7036s were read is REFUSED (the reader or its matcher failed), and so is a `NOT SEEN`
    once an earlier transaction of the same process read `live`.
  - **The node's OWN 7036s never count as "other services'"** (PR 1645): its own `stopped` with no
    `running` proves the reader reads the node's, so it is `node stopped`, the node's outcome, never
    a dead witness. Whether the restart was AWAITED decides it: a transaction that COMMITTED
    (`$script:MsiCommittedExitCodes`) passed `PaceNodeStartService`, which waits for RUNNING, so
    a missed `running` is the witness failing on the STATE and is refused at the exit; one that ROLLED
    BACK restarts the node with Windows Installer's own unawaited StartServices, so the exit DEFERS it
    (`7036 DEFERRED`, the transaction's `Deferred`), and the settled judgement refuses a node that
    never came back -- `Assert-ServiceTable`'s own wait names the deferred outcome. Every refusal
    SHOWS its evidence first (`Show-TransactionEvidence`): the verbose log, each service's state,
    process and exit codes, and the SCM events of `$script:ServiceControlEventMeanings` since the
    transaction began, from the read the verdict was taken from.
  - **An OLD package's removal keeps its own Restart Manager, and Windows Installer restarts what it
    shut down AFTER the whole transaction**, so pace-kv beside the node is `disabled`, never
    `manual`. MEASURED in PR 1634's CI, the upgrade from 0.3.0 (whose package sets no such property):
    this package logged "Disabled by MSIRESTARTMANAGERCONTROL property"; 0.3.0's removal, which
    `RemoveExistingProducts` runs as a nested installation with 0.3.0's properties, opened a session
    of its own and "Successfully shut down all applications in the service's session that held files
    in use" (pace-kv); and the OUTER engine, after "Installation completed successfully" and after
    every action of this package, commit actions included, logged "Failed while restarting
    applications. Error: 352", with pace-kv started and crashing on 6674 between the two lines.
    Nothing reaches that session: `RemoveExistingProducts` sets only `ProductCode` and `REMOVE` for
    the removal ("RemoveExistingProducts Action"), the Upgrade table has no column for a property,
    nothing of ours may run before it (Error 2613), moving it before `InstallInitialize` takes the old
    product's removal out of the transaction (#1629), an immediate action runs unelevated under UAC,
    and `DisableAutomaticApplicationShutdown` is a machine POLICY. And it cannot be followed: the
    restart comes after the last action. So it is answered where it lands --
    `PaceDisableForNode` (`sc config pace-kv start= disabled`, `Return="check"`) leaves a
    start of pace-kv beside the node failing at the service control manager, with no process, no
    recovery restart and no race for 6674; the 352 is that refused start, and the upgrade still exits
    0 (MEASURED: it did with the crash too). Not the binary: a bind conflict is an I/O arm, `Failed`
    and restarted by design (`ProcessExit`, above), so a start that may not run must not be STARTABLE.
    Removing the node re-applies pace-kv `auto`, and a failed transaction puts back the start type
    it found. The CI leg asserts the nested shutdown line beside the judgement, so "no start" cannot
    pass for want of a restart attempt.
    - **Only a registration that EXISTS is disabled, and the disable is `Return="check"`.**
      `PaceInstallService` is `Return="ignore"` on purpose, so pace-kv may be ABSENT there,
      which is no more startable than disabled; a checked disable of it failed the node's whole install
      over a step that was not the cause (rm-nested review, I-1). `sc.exe` answers 1060
      (ERROR_SERVICE_DOES_NOT_EXIST, MEASURED) for exactly that, and that one answer ends the action
      with 0; every other answer goes on to the disable. `msi-custom-action-commands` step 14 runs the
      command for real against a name nothing registers, both ways, and changes no service.
    - **The binary's own restore cannot spell `disabled`**: `ServiceStart` has no such row, so a
      failed transaction's re-registration twin re-applies `#4` as `manual`, and the EXACT restore
      after it puts `disabled` back. Only a transaction whose stash ALSO failed (the stash is
      `Return="ignore"`) is left `manual`: the state before PR 1634, harmful only on a later upgrade
      from a package whose removal still has its own Restart Manager, so accepted rather than given a
      start mode the command line would never use.
    - The RESIDUAL is pace-kv WITHOUT the node: Windows Installer's restart of a pace-kv that ran
      before the upgrade succeeds, so `PACE_START_SERVICE=0` on an upgrade from 0.3.0 leaves it
      running; harmless (nothing else wants its port), and install.md says to stop it first. Every
      package from PR 1634 on disables Restart Manager, so the hazard is an upgrade FROM 0.3.0 or
      from a build before it -- dev builds carry 0.3.0's ProductVersion, so no version range can tell.
- **A stop states its drain.** `StopPendingPlanFor(--drain-timeout)` is the wait hint -- the drain
  plus `StopTeardownMargin`, clamped to what the SCM can carry -- and the checkpoint advances
  every `StopCheckpointInterval` until the body returns. A fixed hint shorter than the drain reads
  as a hung service to the SCM and to an MSI waiting on the stop. pace-kv has no drain of its
  own and passes none.
- **Which ports an install OPENS follows the MERGED configuration, not the `ServiceSpec`**, which
  carries no port and no rule. Each binary's `main` derives the rules from the configuration the
  service will run with (`NodeFirewallRules`, `DaemonFirewallRules`) and hands them to
  `WithRegistrationFirewall` beside the registration. On a registration that succeeded, that
  replaces the service's firewall group (`FirewallGroupFor`, `pace-kv: <service>`) with one
  inbound allow rule per non-loopback endpoint the configuration binds -- the node's from
  `NodeSurfaceTable()` rows, so a surface or a default that turns one on is opened by its row
  alone; pace-kv's from its listeners and, with `--metrics`, its metrics endpoint. Replace,
  never append: a repair and an upgrade run the install again, and a surface that has since
  become loopback must lose its rule. A surface bound to the NAME `localhost` gets a rule, since
  `IsLoopbackHost` does not take a name to be loopback, and the install says why.
  - Every network profile, scoped to the program AND the service SID (set `UNRESTRICTED` so the
    condition matches): a VPN adapter is usually Public, and a Domain- or Private-scoped rule
    never reaches the office's VPN population. `--firewall-allow` (IPv4 or IPv6, optional
    `/prefix`, repeatable, install-time only) narrows the remote side; `/0` is refused by name,
    because "any address" is spelled by omitting the flag.
  - **A port the KERNEL chooses is an endpoint of its own kind, never a missing one.**
    Discovery SENDS from an exclusive reply socket (a unicast to a shared port reaches only one
    of the sockets sharing it, so answering from the beacon port breaks two co-hosted nodes),
    and without `--discovery-reply-port` the kernel picks that port, so every challenge and
    proof arrives where no port-scoped rule can reach. The discovery row therefore resolves the
    reply endpoint on every configuration, as `SurfacePortKind::KernelChosen` when unpinned, and
    `NodeFirewallRules` maps the kind through a table to `FirewallPortKind::Any`: inbound UDP on
    every local port (`LocalPorts = "*"`, set explicitly, which is also what a new UDP rule reads
    back), named `... discovery-reply udp/any`, scoped to the program AND the service and to
    `--firewall-allow` like every other rule. What it exposes is only the UDP sockets this
    program opens: discovery's, which are the only ones that RECEIVE, and the route probe's
    (`Platform/RouteProbe.cpp`), which only `connect()`s to read the kernel's source-address
    choice, sends and receives nothing and is closed at once -- and `ctest -R udp-opener` is what
    keeps that true: it refuses a first-party UDP opener outside its permitted rows, and a new
    row is a decision about this rule. A pinned port gets exactly that port and no
    any-port rule. The uninstall removes it with the GROUP, never by re-deriving the rules.
    **The MSI pins it and the node does not**: `PACE_DISCOVERY_REPLY_PORT` (default `6682`,
    empty for the kernel's) reaches `--discovery-reply-port`, and the rule DERIVES from the
    surface table given that flag -- never spelled in the fragment. The node's own default stays
    kernel-chosen for the multi-instance rule (#126, consensus-and-cluster.md): two co-hosted
    nodes need two reply ports, and the package installs one node per machine.
  - **The rules are what the SERVICE opens at its next start, derived after the install secured
    its state directory.** The formation decides whether consensus and discovery run, and `main`
    HOLDS a record it cannot judge -- a 0.3.0 directory other accounts could write in, or any
    directory the service wrote, judged from the INSTALLER's account -- leaving the configuration
    unshaped, which opens the node port alone. So `InstallWithServiceFirewall` registers first,
    then reads the record (`StateDirectoryFormationReader`, without the owner judgement whose
    answer depends on who asks; the start judges again as the service), applies it as the start
    will, JUDGES that configuration by the install's rules (`NodeInstallRejection` -- an unshaped
    one runs no consensus, so the rows about an admitting node stay silent and the install would
    pass what the start refuses), and only then derives the rules. A record still unreadable, or
    a shaped configuration refused, REFUSES the install by name and opens nothing. `[firewall][install]`, and the MSI job's `Assert-NodeFirewall` after the
    0.3.0 upgrade.
  - "Any" is a KIND on `FirewallLocalPort`, never a port of 0 that one layer reads as every
    port and the next as port 0: a `Fixed` rule on 0 and an `Any` rule carrying a number are
    both refused before the firewall is touched, and the worksheet prints a kernel-chosen port
    as `*`, never as `:0`, which an operator would copy into a rule that admits nothing.
  - `--uninstall-service` always ATTEMPTS the delete, whatever the stop wait said, and removes
    the group once the delete succeeded or found no service (`WithRemovalFirewall`) -- including
    a service that had not stopped within `UninstallStopCeiling` and is only MARKED, whose rules
    go while it runs on until it exits. After a delete Windows refused it touches no rule, since
    that service is still registered and may be running, and says so: "any rules of this service
    are left in place, since the service may still be registered; they are removed by an
    uninstall that succeeds".
  - A rule name that matches one OUTSIDE the group, ignoring case, is refused before anything
    changes (`FirewallNameCollision`): the firewall removes rules by name, so the other rule
    could be the one removed. And the firewall never decides an install's or an uninstall's exit
    code: its refusal is appended as a warning to an outcome that stays the registration's.
  - The seam is `Platform/IFirewall`, the fake `src/tests/FirewallFakes.hpp`. Only Windows has a
    firewall this project manages; elsewhere `MakeSystemFirewall()` is null and the install
    names the surfaces that need a rule of the operator's own. The real Windows Firewall is
    asserted in the `package-windows` job.
## Finding and trusting a configuration file

<!-- agent-tripwire: A machine-wide config is obeyed only when only an administrator could have written it -->

- **A candidate config location names an application, not `pace-kv`.** Every row
  of `DefaultConfigCandidates()` hardcoded the daemon's file name, so a second
  binary had nothing to generalize onto. The rows carry `{app}` now, and two things
  about that are deliberate: the table stays `constexpr` so its four `static_assert`s
  keep stopping the *build* rather than waiting for `ctest`, and the substitution is
  a literal replace rather than `std::format` -- a display form already contains
  `%VAR%` on Windows and `$VAR` on POSIX, so a third meta-syntax whose braces are
  also `std::format`'s own grammar is how a path containing a brace becomes a thrown
  exception at startup.
- **A config the operator named is strict; one the daemon found is not.**
  Without `--config`, `DefaultConfigPath` walks a per-platform candidate table
  (user location before machine-wide) and takes the first entry that exists *and
  opens for reading* — `Config/DefaultConfigPath.cpp` is the single source of
  truth for that order, for what `--help` lists, and for where `--seed-config`
  writes. Readability, not mere existence, is the test: the macOS system config
  is mode `0640 root:_pace-kv`, so a per-user agent has to fall through it
  rather than fail to start. A discovered file that is absent or unreadable is
  skipped silently; one that parses badly is still fatal, as is a missing file
  named with `--config`. The resolved path goes into a *local* in `main.cpp` and
  never back into `parsed->config` — that object is what `InstallService`
  registers, and a discovered path baked into `ProgramArguments` would outrank
  the file itself forever (see the next bullet) and make
  `InlineCredentialRejection` name a path nobody typed.
- **The lookup's two rules both turn on one question: is this process the
  machine-wide daemon, or somebody's own?** `probe.IsPrivilegedProcess()` (root; on
  Windows an elevated administrator OR a service logon, `NT AUTHORITY\SERVICE` -- the
  virtual-account service is no administrator and IS the machine-wide instance, #860 --
  via `CheckTokenMembership`, which is false for the unelevated half of a split token)
  decides both halves,
  and neither is driven by the platform or by the row alone:
  - **Unprivileged runs skip every `ConfigScope::System` row.** The machine-wide
    file describes the system service, whose cache only the service account can
    write, so a `systemctl --user` instance that adopted its `storage_path:`
    would fail to open that directory and be respawned until the start limit
    tripped — the out-of-the-box restart loop the user unit's header says it
    exists to prevent. Readability is not enough of a filter here: the packaged
    `/etc/pace/pace-kv.yaml` is `0644 root:root` and readable by all.
  - **Privileged runs trust-check *every* row, per-user ones included.** `$HOME`
    and `$XDG_CONFIG_HOME` are inputs an unprivileged account often controls and
    sudo does not always reset, so checking only `System` rows would leave
    `sudo -E pace-kv` taking root's `storage_path:` from a file that account
    wrote. A path named with `--config` is never checked — that is the operator's
    assertion to make, and it is the escape hatch when a location is refused.
- **A machine-wide config is only obeyed when only an administrator could have
  written it.** `C:\ProgramData` grants `BUILTIN\Users` create-file on every
  subdirectory it hands down to, so moving the Windows config there made the
  configuration of the service — which then ran as *LocalSystem* — plantable by
  any standard account —
  `storage_path:` alone turns that into arbitrary directory creation and file
  writes as SYSTEM. Two halves, and both are needed: the MSI owns
  `%ProgramData%\pace` and gives it a protected access list of its own
  (`PermissionEx`, not `Permission` or `util:PermissionEx` — those take an
  account *name* and are wrong on a non-English Windows), and `DefaultConfigPath`
  refuses a candidate whose directory fails `Platform/FileTrust`. The test there
  is the containing directory's owner and entries, never the file's owner: on
  Windows a new object belongs to its *creator*, so a config seeded by hand from
  an elevated shell is owned by that administrator's own account, while a file
  planted by a standard account is granted to that account's own SID through the
  inherited `CREATOR OWNER` entry — an owner whitelist rejects the first and an
  entry scan misses the second. A rejection goes to stderr *and* through the
  logger once there is one: a service started by the SCM has no console, so
  stderr alone would put the message nowhere in the one deployment where a
  machine-wide config is the norm, and a file that is present, readable and
  ignored anyway is the silent no-op this list exists to prevent.
- **`--seed-config` secures the directory before it looks for the file, not
  after.** The whole point of the repair is the case where something is *already*
  there: any standard account can create a `%ProgramData%` subdirectory and drop
  a config into it long before the installer runs, and the MSI cannot undo that
  on its own — `PermissionEx` replaces the access list but not the owner, who
  keeps `WRITE_DAC` regardless. So seeding secures the parent first (repairing a
  squat), then decides what to do about the file: seed-once keeps an operator's
  edits, but a file found in a directory that until that moment anybody could
  write is not established to be an operator's, and is reported rather than
  blessed by silence or destroyed by overwriting. Seeding refuses outright when
  it has the rights for none of this, and deletes a directory it created but
  could not secure — which would otherwise be the very shape being defended
  against, authored by the defence.
- **The directory answers integrity; the FILE has to answer secrecy, and the
  directory's list cannot.** `%ProgramData%\pace` grants `BUILTIN\Users`
  read *inheritably* and must — the daemon runs as the virtual account
  `NT SERVICE\pace-kv`, an ordinary `BUILTIN\Users` member, and that grant is
  how it reached its own configuration. `OICI` then handed the same read to the one
  file `InlineCredentialRejection` tells operators to move `requirepass:` into,
  *because* a command line is world-readable — so the documented remedy relocated
  the secret rather than protecting it, and #384's readability check correctly fires
  on the shipped default (#741). The file therefore carries a **protected** list of
  its own: SYSTEM and Administrators in full, `NT AUTHORITY\SERVICE` read. Five
  things follow and each was a wrong turn first.
  - **Not `PermissionEx` in the MSI**, which is what the ticket proposed:
    `PermissionEx` targets a component the installer *installs*, and the live config
    is deliberately not payload. `--seed-config` writes it, so that is the only place
    the list can be applied — and it is one implementation for the custom action and
    a hand-run seed alike.
  - **`SU` (S-1-5-6, every service logon), not `NT SERVICE\<name>`.** The
    per-service trustee resolves only once the service exists — `GrantPathAccess`
    says so at its own call site — and the MSI seeds *before* it registers anything,
    so naming it would grant nothing on the one path this exists for. It also
    survives `--service-name`. It is a real widening over the per-service SID and is
    written down as one rather than presented as the tight answer: `SERVICE` is every
    principal logged on as a service, which takes an administrator to arrange and
    excludes every interactive account, but it is not only this daemon.
  - **Repair on upgrade only when the file is currently broadly readable.**
    Seed-once finds an existing file, and one seeded by an older build carries the
    inherited grant; a narrower delegation is an administrator's own and an
    undetermined answer is not an exposure anybody established. The repair is its own
    `SeedOutcome`, because a seed-once action modifying something silently is what it
    exists to avoid. Content is never touched.
  - **A comment that vouches for a grant moves with it, and it had TWO homes.**
    `MakeDaemonServiceSpec` cited the `BU` ACE as how the account reads its config —
    true when written, and this change deletes exactly that ACE's role. The
    `windowsLogon` bullet in *this file* said the same sentence, and was found only
    because #867's `## Open work` entry was being added a few lines below it. **A
    claim with two homes is corrected once and survives**, which is worse than one
    that is simply wrong: the surviving copy reads as independent corroboration. It
    is also #860's whole shape — a sentence outliving the change that falsified it —
    so when a comment vouches for something, grep the rulebook for it too.
  - Windows is the platform this is *about* and no test on a POSIX host can
    construct a DACL, so the evidence is the `package-windows` job asserting the
    installed file's access list — no broad principal may read, `S-1-5-6` may, and
    the list is protected. **Both directions**: a config nothing can read is not a
    fix, it is a daemon that silently starts on built-in defaults.
- **A directory a SERVICE mints a credential in is secured by the INSTALL, and adding a
  grant to it is not securing it.** The node's identity key is written by the service at
  its first start, under its virtual account, into `--cluster-dir` -- so no per-file list
  can be applied beforehand, and the directory's own list is the only place the answer can
  live. `GrantPathAccess` ADDS the account to what the path already has, and what
  `%ProgramData%\pace-node` already has is `BUILTIN\Users:(I)(OI)(CI)(RX)` (read on
  a hand-deployed directory, 2026-09-26): the key inherited every local account's read,
  and any local account could impersonate the machine to the fleet. So an owned path
  carries a `PathPrivacy`, and `MakeNodeServiceSpec` marks the state directory `Private`.
  - **A `Private` path gets a protected list of its own** (`SecureDirectoryForService`):
    SYSTEM, Administrators and the service's SID, inherited by what is created inside,
    nothing inherited from the parent -- and `OWNER RIGHTS` held to `READ_CONTROL`,
    because `%ProgramData%` lets any account create the directory first, and an owner
    keeps `WRITE_DAC` unless an OWNER RIGHTS entry says otherwise. Measured on this host:
    a non-elevated owner of a file whose protected list named only SYSTEM and
    Administrators granted itself full control with `icacls /grant`.
  - **That OWNER RIGHTS entry is the DIRECTORY's alone, never inherited**, or the service
    cannot mint anything there. A principal whose only grant is the service's Modify entry --
    no `WRITE_DAC`, by design -- is refused `ERROR_ACCESS_DENIED` on every create that SUPPLIES
    a security descriptor once an inheritable OWNER RIGHTS entry withholds `WRITE_DAC`; a create
    that inherits one still succeeds, which is why nothing but the key and the owner-only
    directories failed. Measured (2026-10-04, NTFS and ReFS, unelevated): the same create
    succeeds with the entry on the directory alone. The 0.3.0 upgrade's node died on exactly
    this ("cannot create ...\node-key: Access is denied"), and the elevated test that asserted
    the list never saw it, because an elevated process creates through Administrators' full
    control. `FileTrust: the service's own entry lets it create owner-only state in its
    directory` creates as a token with Administrators DENY-ONLY, with a control proving it.
    The residual, stated: the service keeps `WRITE_DAC` over every entry it creates there, so
    its own entry holding no `WRITE_DAC` constrains the DIRECTORY's list only.
  - **What is already inside is covered by inheritance, then CHECKED.** Setting a
    directory's list recomputes the inherited entries of everything under it, and a key
    the old service minted with default security carries only inherited entries -- the
    upgrade from today's MSI. Each entry is then asked `SecretFileExposure`, because
    Windows lets every account bypass traverse checking; one with an explicit broad grant
    is NAMED with its `icacls /reset` remedy rather than rewritten, somebody's decision or
    somebody's plant. POSIX removes the group and other bits, which hides the contents
    without visiting them.
  - **A failure REFUSES the install; it is never a warning** (`HandOverOwnedPaths`, one
    rule for every supervisor), because a readable key is a credential exposure while a
    `Shared` path that cannot be handed over is a service failing loudly at its first
    write. On Windows the registration is already made by then -- the trustee resolves only
    once the service exists -- and the MSI starts the node straight after
    `--install-service` whatever it returned (`Return="ignore"`), so a registration THIS
    install created is deleted again and a re-applied one is left and said to be
    (`RefusedRegistration`). launchd refuses before the plist is written.
  - **A directory that already exists is JUDGED before it is trusted**, because a standard
    account can arrange one before the installer runs, with no privilege. Refused, naming the
    entry: a reparse point (junction or symlink) on the directory or anywhere below it, which
    would redirect the key; an entry owned by anybody but SYSTEM, Administrators or the service,
    whose planter still knows its contents; a non-directory entry with a second hard link, whose
    list is shared with a file outside; and an entry keeping an explicit broad grant of its own.
    The owner becomes Administrators, and the checks run read-only BEFORE the list is applied and
    again AFTER it, once no new open by anybody else can change anything there. An exposed
    identity key is refused with a DELETE remedy rather than `icacls /reset`, which would keep a
    disclosed key in service.
  - **One residual is named, not hidden**: a handle opened BEFORE the apply keeps the access it
    was granted, since an access list is checked at open and not at each write. Refusing while
    other handles are open would refuse every re-apply with the service holding its key open.
  - The evidence on a real install is the `package-windows` job's feature-change step:
    after the node starts, no broad principal may read or plant in the directory or read
    the key, the list is protected, OWNER RIGHTS holds nothing beyond reading the list, and
    the service's SID still reaches its key. Windows Sandbox was not enabled on the host
    this was written on, so no before-and-after of an MSI install was measured locally.
- **A secret reached BY PATH is not provenance-gated, and which flags those are is a
  TABLE on both binaries.** #384's rule asks whether the `--requirepass` in force came
  out of the configuration file, because it can also arrive in argv — where the
  exposure is `ps` and belongs to `InlineCredentialRejection`. A key FILE has no such
  second route: the path is not the secret and the file is, so a world-readable key is
  exposed however its path was named, and asking whether it was typed answers a
  question nobody has (#752). That rule was never specific to the worker, and the
  daemon went on carrying its own for one file
  ([#864](https://github.com/LASTRADA-Software/fastcached/issues/864)): `--tls-key`,
  the private key terminating TLS on the **cache** port — so a loose one lets any local
  account impersonate the daemon to its clients or decrypt the session `--requirepass`
  itself travels over, which is the earlier exposure composed with this one.
  - **Classification is mandatory with a named opt-out**, never an opt-in list. Every
    `=<path>` row of a binary's option table sits in exactly one of two tables — the
    secret-file table or `PublicPathFlag`, which carries a per-row *why* — because a
    list that is exact about the flags it knows and silent about the ones it does not
    reads identically to complete coverage (#492). `--tls-cert` is classified as
    PUBLIC by name rather than left off: a certificate goes to every client during the
    handshake, and warning about a file that is *meant* to be readable is the alarm
    that teaches operators to ignore the one that matters. Measured by
    `grep -c 'operand = "=<path>"'`: **6** such rows in `CliOptions()`, one of them
    secret, and **9** in `NodeOptions()`, five of them secret. `--cluster-dir` is the fifth
    since #178, and its row is why a row's path is a PROJECTION of the configuration
    rather than a member pointer: the flag names a directory, and the secret is the
    identity key the node minted inside it (`NodeKeyPath`).
  - **One join, asked of two option tables.** `Testing::ClassifyPathFlags` is the
    guard, and it reports three lists rather than a verdict — unclassified, claimed by
    both, and naming no row at all — because those are three different repairs. It
    also returns how many `=<path>` rows it *saw*: with all three lists empty, a scan
    that matched nothing is indistinguishable from complete coverage, so the caller
    asserts the count is non-zero.
  - **A named file is reported whether or not a tier reads it.** `--tls-key` with
    `--tls` off is still a key on disk, and whether a surface exists is not a fact
    about the configuration — a rule whose premise is "somebody will read this" cannot
    state its premise without guessing. It is the same narrowing the worker's
    `--cluster-key-file` refusal had to be talked out of twice.
  - The subject list is one function per binary (`DaemonSecretFiles`,
    `Node::NodeSecretFiles`) and **both moments read it**, so a row added there reaches
    the start and every reload for free. That is what makes the guard worth having: the
    thing an author must remember is a table row, not a call site.
  - **Those two moments are ONE `SecretExposureWatcher`, and it re-asks the
    FILESYSTEM.** A file's MODE is in no configuration, so an implementation reasoning
    from the reloader's previous-and-current candidate pair covers half of #753 and
    **looks right** while doing it: a `requirepass:` that never moved produces two
    byte-identical snapshots, the diff concludes nothing changed, and the file is never
    looked at — which is exactly the transition an accepted reload exists to catch,
    somebody having widened the mode underneath a path that stayed the same. The other
    transition, a secret appearing in a file whose mode was always loose, IS visible in
    the snapshots, and that is what makes the snapshot-diffing version pass a review.
    `Config/SecretExposureWatcher.hpp` states both halves at the type; the startup
    observation and every accepted reload stat every row of the subject list, whether
    or not a value moved.
  - **What is remembered is `(path, exposure)`, not a rendered sentence**, so a file
    whose exposure changes KIND — group-readable, then world-readable, two different
    remedies — is a transition and is reported. A standing exposure is said ONCE, a
    clearing one is silent, and a path that leaves the set is FORGOTTEN: this reports
    what an operator must act on, never a status line. `Transitions` publishes the
    memory rule alone so it is testable where `chmod` is not, which is the same
    acquisition-versus-decision split `Platform/FileTrust` draws one level up.
- **`ExecStart` still passes `--config` on Linux and macOS — by choice, not
  necessity.** It predates the lookup, where its absence made `ConfigReloader`
  have nothing to re-read and `systemctl reload` a silent no-op; the lookup now
  closes that hole for every daemon started without the flag. The packaged units
  keep it because the path is unambiguous there and CI asserts it. Windows goes
  the other way: its custom action registers *no* `--config`, so a seed that did
  not happen degrades to built-in defaults instead of a service that fails at
  every start. The per-user launchd agent and the systemd user unit pass none —
  the packaged config describes the system daemon, whose cache only the service
  account can write.
## A configuration FILE through the option table

<!-- agent-tripwire: A configuration FILE reaches the same fields through the SAME appliers, in that order -->

- **The file's values and the command line's reach the same fields through the
  SAME appliers, in that order, so "the command line wins" is which loop runs
  second.** Both binaries do: `ReadYamlSettings` then `ApplyFileSettings` over the
  binary's own table, then `ClearListsNamedOn`, then argv. `Config/FileOptions.hpp`.
  The daemon did the other thing until #1437 — a second parser filled a `Config`
  and `Merge` copied field by field against a per-field explicit bit and a per-field
  presence bit, four lists none derived from the others — and **its KEYS agreed with
  the table while its VALUES did not**: measured on 0.2.0-568, the file accepted
  `port: 0x50`, `port: +80`, `bind: ""` and `metrics: yes`, every one refused on
  argv. A census of keys against rows came back 34 = 34 and could not see it, which
  is why the acceptance is a PARITY test driving every keyed row through the file
  and argv with the same text, not a key count.
- **And a RELOAD rebuilds the candidate the way the START built the live
  configuration, or the command line silently stops applying.** The daemon's SIGHUP
  path was `ReadYamlConfig(path)` and nothing else, so a setting in force because
  somebody typed a flag — or set `PACE_METRICS_PORT`, which is the same half
  of it — arrived at the immutability check as a setting being changed back to its
  default. **The two directions fail differently and the reloadable one is the
  dangerous one**: an immutable setting refuses the reload by name, forever, until
  the file is edited to agree with a flag it should have outranked; a *reloadable*
  one is **published**, so `--max-memory=8g` became a fraction of host RAM at the
  first logrotate hook, `InMemoryLruStorage::Resize` evicted down to it, and nothing
  in the logs connected any of that to a flag nobody re-read
  ([#622](https://github.com/LASTRADA-Software/fastcached/issues/622)). There is one
  `AssembleEffectiveConfig` — file, then command line, then environment — and
  `main()` and `ConfigReloader` both call it. The sources besides the file are held
  for the life of the process in a `ConfigSources`, which the reloader takes as a
  **required** constructor argument: a parameter that can be defaulted is this defect
  re-entering by omission. And the environment fallback travels as a resolved VALUE
  rather than as a reader, deliberately — a process's environment does not change
  under it, so replaying what the start resolved makes the two assemblies identical
  by construction rather than by inspection.
  - **And a REFORM shapes its body from the configuration IN FORCE, never the one the
    process started with.** `pace-node` replaces its serving body in-process
    when its formation mode changes (`RunNodeBodies`), and PUBLISHES the reformed
    configuration into the reloader as the one in force. Shaped from the start's `cfg`,
    which no reload changes, it reverted every accepted reload at the next yield,
    approval, forget or dissolve: an admission the operator removed (`--fleet-member`, since
    retired; `--fleet-open` today) was admitted again, a rotated `--requirepass` went back to
    the old secret, and nothing
    logged either. Removal is the direction that fails OPEN, so this is the dangerous
    reading of the rule above, one level later. Every body is adopted from
    `INodeConfigSource::Current()` — `LiveNodeConfig`, the reloader's snapshot, or the
    start's configuration only when there is no file — the seam the move judge reads, so
    the judge, the reform and a restart read one configuration.
- **A setting a FILE can carry and argv cannot is a defect, not a category.** Three
  `memory_compression*` keys were exactly that: accepted by `ReadYamlConfig`,
  documented in the shipped reference, live-wired at startup by `main.cpp`, and in no
  row of `CliOptions()`. So everything the table drives was blind to them — the
  reloadability column could not answer for them at all, which is #406 reading
  *complete* while a documented setting slipped past — and no `--install-service`
  could carry them, because a registration replays a command line. They have rows now
  and the second source is deleted
  ([#623](https://github.com/LASTRADA-Software/fastcached/issues/623)). Note that the
  two AREAS move together: giving a key a row forces `BuildServiceArgv` to emit it, or
  `ServiceControl_test`'s mechanical sweep goes red — so splitting such a change
  across lanes leaves either a flag the installer drops or a sweep nobody can make
  pass.
- **Which key a row answers to is a COLUMN, never a derivation.** Measured on the
  daemon when #1437 keyed every setting row: 48 flag rows, 36 of which carry a key,
  diverging three ways — `--storage` is `storage_path`, `--expiry-scan` is
  `active_expiry_scan`, `--expiry-interval` is `active_expiry_interval` (renamed, and
  until #1402 also carrying a unit the flag did not). There is no rule with exceptions there,
  only a mapping, and a convention derived from flag names would silently rename
  those three keys the day somebody generalised it. A NESTED key cannot be a column
  at all: the daemon's `listeners:` block became `listen:` and `listen_tls:`, lists
  of `host:port`, rather than teaching the shallow reader a second grammar.
- **A key naming no row is REFUSED, never ignored.** A file is read at every
  start, so a key nothing reads is a setting an operator believes is in force
  forever — the exact failure the file exists to remove, and a typo is the common
  way to reach it. **So is a key written twice**: the parser hands over both entries,
  so a scalar row kept the last and a list row would append both — a value the
  operator wrote silently discarded or doubled. And a key that is not a scalar is a
  refusal, not a yaml-cpp exception: `? [a, b]` ended a 0.2.0-568 worker with
  0xC0000409.
- **A row a file may not carry is on a named list with a per-row reason, and a
  compile-time guard reads that list rather than restating it.** Two kinds live
  there and they are not the same objection: a one-shot verb (`--install-service`,
  `--cluster-forget`, `--migrate-cache`) is a decision taken once, and a file would
  replay it at every start; the rest (`--config`, `--service-name`, `--daemon`)
  describe how this process was STARTED, so reading them out of the file the start
  already found is circular. Both directions are asserted — a row with neither a key
  nor a reason, and a reason naming a row that has a key.
- **A flag whose meaning is its PRESENCE is a boolean in the file, and `apply` runs
  on `true` alone.** The key spells the flag, so the reading is exact for both
  polarities: `raft_join: true` passes `--raft-join`, and `no_toolchain_discovery:
  false` passes nothing, which is discovery left on. **So a presence setting whose
  DEFAULT is on somewhere needs its negative row keyed too**: `log_timestamps: false`
  passes nothing, and on macOS nothing is ON — the daemon's file says off with
  `no_log_timestamps: true` (#1437). A positively-named key would
  need an applier no flag has — a setting reachable from a file and not from argv,
  which is the second mechanism the whole arrangement removes. Only `true` and
  `false` are accepted: YAML 1.1's `yes`/`on` are a schema this reader would have to
  reproduce exactly to be trusted.
- **A repeatable row's applier APPENDS, so the command line must EMPTY the list
  before it is applied over a file-seeded result.** Otherwise `--toolchain` extends
  the file's set instead of replacing it, and the worker serves a compiler the
  operator was pinning it away from. Replacement is the rule because mixing partial
  file values with partial command-line values makes precedence depend on
  declaration order. Driven off the table's own `clear` column, so a fourth
  repeatable flag is a column value rather than an edit somebody has to remember —
  and it walks argv through the parser's own `TakeValue`, because a VALUE is not a
  flag: `--advertise --toolchain` gives `--advertise` the value `--toolchain`, and a
  scan of every token would read that as naming the list and silently empty what the
  file declared.
- **A file that failed halfway is DECLINED, not half-applied.** "Some of the
  settings, up to the bad line" is a configuration nobody wrote; the command line
  then stands alone.
- **An error a value parser raised is re-attributed to the FILE and names the KEY.**
  `ApplyOneOption` stamps the row's `primary` for the same reason a shared parser
  cannot name a flag — but stamping `--cache-memory` on a bad `cache_memory:` sends
  an operator to look at a command line they never typed.
- **`--install-service` registers the command-line-only parse, and what it carries
  about the file is the PATH.** Baking in what the file said freezes one reading of
  it into launch arguments that then outrank the file forever: the operator edits it,
  restarts, and nothing changes with no error anywhere. Emitting a *resolved* default
  path is the same mistake one step down — it pins the service to whatever the lookup
  found on the day somebody ran the installer.
- **A missing file is `FileNotFound`, not `ParseError`.** `YAML::BadFile` derives
  from `YAML::Exception`, so catching only the general case sent an operator who
  mistyped `--config` hunting for a syntax mistake in a file that is not there. And
  a file that IS there and cannot be read is `FileUnreadable`, asked of the filesystem
  since yaml-cpp cannot tell the two apart. They are two answers to an OPERATOR (a path, a
  permission) and ONE to a supervisor: both are I/O arms, exit 1, restarted
  (`ConfigurationIoCodes`).
- **The shipped reference configuration is checked against the table.** Nothing else
  connects them: the flag parses, the file parses, and a build in which they describe
  different products passes everything. A setting with no commented block is one
  nobody can find; a block for a key the table dropped is worse, because uncommenting
  it makes the worker refuse to start. `ctest -R node-config-reference`, which also
  fails when either scan matches nothing — two empty lists agree perfectly.

## The CLI option table

<!-- agent-tripwire: Every flag is one row of `CliOptions()`, which drives parsing **and** help -->

- **A flag is one row, and every binary's row table drives both parsing and
  help.** The daemon used to declare flags four ways — hand-written `if (arg ==
  …)`, a descriptor array, two inline `initializer_list<tuple<…>>` tables, and
  seventeen copy-pasted blocks in `HandleTypedFlag` — and then spell every name
  again in a separate help table, so a flag could be accepted but undocumented
  or documented but rejected. `CliOptions()` is now the single source of truth,
  and the help column is *derived* from `primary`/`alias`/`operand` rather than
  restated. Rendering lives in `Cli/UsageDoc`, which must stay dependency-free:
  `pace-cc` compiles it in rather than linking `Pace`, so an include
  of anything from `Config/` there breaks the launcher's link, not just its
  build. Two remaining hand-written spellings are guarded by tests rather than
  generated: `BuildServiceArgv` (a `ServiceControl_test` case walks
  `CliOptions()` and requires each non-excluded flag to be emitted — the
  exclusions, `--requirepass` above all, are listed with their reasons) and the
  launcher's `PACE_*` oracle list in `LauncherCli_test`.

- **Which flags carry text OTHER MACHINES will read is a column of the table.**
  `ParseUtf8Text` rather than `ParseText`, and the rows in it are the ones whose
  value leaves the machine: `--advertise` becomes the endpoint clients dial, `--node-id` and `--raft-peer` a member's identity and the address its peers
  open a socket to, `--cluster-id` rides every discovery beacon, and
  `--cluster-admit`/`--cluster-set` commit their operand through consensus — where
  an entry is applied *after* it is committed, with nobody left to refuse it, so the
  CLI is the last place a person can be told. Since #141 the scheduler refuses a
  registration whose fields are not valid UTF-8, and a value that gets past the CLI
  is refused there on every heartbeat, forever, with the operator's only recovery
  being to rename the thing.

  Three rows are deliberately OUT of the column, and each omission is load-bearing:

  - **`--cluster-forget`.** Its operand *is* the offending id. A check covering it
    would make a member admitted by an older peer impossible to remove, and it would
    count towards quorum forever — the trap
    [#159](https://github.com/LASTRADA-Software/fastcached/issues/159) records.
  - **Every path-valued flag.** On a host that transcodes nothing a legacy filename
    is a perfectly good filename; refusing one would break a working node over a
    rule about a field it is not.
  - **The compiler half of `--toolchain=<fingerprint>=<compiler>`.** Only the
    fingerprint travels, so `ParseToolchain` checks what is before the first `=` and
    nothing after it. Asked by the PARSE rather than where the halves are used,
    which is the difference between a refusal and a trap: `--install-service`
    returns before a toolchain is ever resolved, bakes the command line into a
    registration, and replays it at every boot with nobody watching.

- **A value parser does not know which flag it was reached through, so it CANNOT
  name one.** It is a free function shared by every row that uses it, and a
  hand-written field is one that drifts when a flag is renamed. That used to be a
  convention -- `ApplyOneOption` stamped only an EMPTY field -- and a dozen parsers in
  both binaries broke it: `bind` for a bad host inside `--listen`, which the operator
  never typed, and `raft-peer`, `max-memory`, `log-level` without the dashes every row
  carries. **Now it is structural**: `ArgvError` takes no field parameter, so a literal
  one does not compile, and `ApplyOneOption` stamps the row's `primary` UNCONDITIONALLY,
  so a field a parser builds by hand into a `ConfigError` is overwritten rather than
  trusted. The one constructor that still names a field, `UnrowedArgvError`, is for a
  refusal about NO row -- an argument that matched none, a sub-command -- and every call
  is a row of `Options_test`'s census. A configuration file stamps its key, as before.

- **A flag rename is not a no-op when the flag's DEFAULT was doing the work**, and
  the rename is silent precisely where prose depended on the value rather than the
  name. Renaming a flag is a mechanical change — the compiler finds every use, the
  option table finds every row, and nobody re-reads the paragraphs around them,
  because there is nothing in a rename that looks like a behaviour change.

  Measured while #290 stage 3 replaced `--bind`/`--port` with `--listen-node`.
  `cluster-e2e.sh`'s cluster-key rationale said its nodes *"leave `--bind` at the
  wildcard ... so another machine genuinely could dial their compile ports"*. True as
  written: `--bind` defaulted to `0.0.0.0`. The conversion rewrote it to
  `--listen-node=127.0.0.1:<port>` and the paragraph, now naming the new flag,
  asserted the opposite of what the fixture did — and it was the *justification* for
  that fixture carrying a cluster key at all, so the reasoning for a deliberate
  choice had quietly inverted while every test stayed green.

  It was found by accident: `fleet-dashboard-e2e.sh` carried the same paragraph and
  had to be converted for an unrelated reason, which put the two side by side. Nothing
  would otherwise have looked.

  This is the *citation loses its conditions* family (see
  [`AGENT.md`](../../AGENT.md)'s caching principle) with a mechanism attached — there, a
  measured figure travelled without the word *warm*; here, a claim travelled without
  the default that made it true. **So when a flag is renamed, re-read the prose that
  names it for a claim about its VALUE**, and treat a default that changed as a
  behaviour change even though no code did. The clue is a sentence that reads as an
  argument rather than as a label: "leaves X at the wildcard" is a claim, "set X"
  is not.

## The daemon host, and what a machine IS

<!-- agent-tripwire: untriaged: #1567 the architecture-is-what-the-compiler-built-for rule has no AGENT.md bullet, and the nearest one is about a different subject -->

- **A daemon host wraps the body, so what must reach a terminal has to happen
  first.** `WorkerBody` is separate from `main` because `IDaemonHost` double-forks on
  POSIX or hands control to the SCM, and neither can wrap a `main` that has already
  parsed, validated and registered. The cheap, fallible checks stay in `main`
  deliberately: run inside the body they would print their diagnosis to a stdout the
  POSIX host has already redirected to `/dev/null`, so a misconfigured worker would
  exit in silence.

- **An architecture is what the compiler built for, not what the kernel is running.**
  `QueryHostFacts` reads the architecture from the compiler's own macros rather than
  from `uname`/`GetNativeSystemInfo`, because an x86-64 process under Rosetta or
  WOW64 executes x86-64 code on a machine that truthfully reports `arm64`. A
  scheduler weighing this node has to be told what the binary that will run a compile
  is, not what silicon is under it. Windows's version comes from `RtlGetVersion` and
  not `GetVersionEx`, which reports 6.2 for every release since Windows 8 unless the
  caller ships a compatibility manifest. And free space is `space.available`, not
  `space.free`: the difference is the root-reserved portion, which an unprivileged
  worker cannot write and must not offer to a scheduler as room it has.

## Which supervisor stamps a log line, and which does not

<!-- agent-tripwire: untriaged: #1567 the log-default-cannot-be-picked-per-binary rule has no AGENT.md bullet -->

Measured while closing #485, and expensive to rediscover — the ticket that raised it
guessed, and guessed wrong in both directions. **A binary's console logger is not the
sink in every deployment, and the supervisors do not agree about times.** For
`pace-node`, which is the shape both binaries have:

<!-- table-total: none -->
| deployment | the sink | who stamps |
|---|---|---|
| systemd | `ConsoleLogger` → stderr → journald. The unit is `Type=simple` and deliberately passes **no** `--daemon` — a double-fork silences journald | **journald** |
| launchd (macOS) | `ConsoleLogger` → stderr → **a plain file**: `BuildLaunchdPlist` writes `StandardOutPath`/`StandardErrorPath` at `<label>.{out,err}.log` | **nobody** |
| Windows SCM | `--daemon` selects `MakeWindowsEventLogger`; the console logger is **never reached** | the event record |
| foreground / redirected | `ConsoleLogger` → tty or file | **nobody** |

Three consequences, and none is obvious from either end:

- **A timestamp flag changes nothing on the Windows service.** It is the one
  deployment where the console logger is not the sink, so a default reasoned from "a
  supervisor stamps for us" is reasoning about a path the flag cannot reach.
- **launchd stamps nothing**, and that plist is built by the shared
  `ServiceControl.cpp` — so it is the same gap in `pace-kv`. A per-binary default
  chosen to work around it papers over one packaging defect in whichever binary
  noticed and leaves the other writing timeless files.
- **So a log default cannot be picked per binary.** Two binaries with the same flag
  and opposite defaults is a vocabulary split over a bug that lives in neither of
  them. One spelling, one default, and fix the gap where the gap is.

**The gap is the platform's, so the default is the platform's**
([#496](https://github.com/LASTRADA-Software/fastcached/issues/496)).
`Core/Logger.hpp` carries `DefaultLogTimestamps`, true under `__APPLE__` and false
everywhere else, and both binaries' config structs initialise from it. Two things
about that placement:

- **It is wider than launchd, deliberately.** A default injected into the plist would
  reach launchd only, and would then be a *value* recorded in a registration — which
  overrides a configuration file forever, because the command line wins, and kills the
  documented `log_timestamps:` key for every macOS operator. A default is the one
  form of "on unless you say otherwise" that a file can still outrank. The price is
  that a macOS operator running the binary in a terminal also gets stamps; that is the
  price and it is stated in the help text rather than hidden.
- **The reason lives beside the constant**, pointing here. A platform `#if` with no
  rationale reads as an accident, and the table above is the measurement that makes
  it defensible.

**A two-sided flag needs a two-sided emitter**
([#507](https://github.com/LASTRADA-Software/fastcached/issues/507), a prerequisite
for the above rather than a follow-up from it). `emitSwitchIfSet` emits the POSITIVE
flag whenever a value differs from its default, which spells *on* — correct while
every default is false, and **inverted** the moment one is not. Under the macOS
default an operator's explicit `--no-log-timestamps` differs from the default and was
registered as `--log-timestamps`: the thing they turned off, turned back on, at every
boot, silently, because a registration replays its command line forever. So:

- **A flag whose default is platform-dependent needs a negative spelling** and
  `SwitchSpellingFor`, which emits whichever of the pair PRODUCES the value.
  *This bullet used to end "`--log-source` and `--log-everything` default false
  everywhere, so `emitSwitchIfSet` stays right — do not unify the two", and that
  was correct exactly while the rule was a value comparison*: the two-sided switch
  needed a platform default the one-sided ones did not. Provenance consults no
  default at all (#349), so on the daemon the only thing left separating them is
  **whether a negative spelling exists** — an argument, not a second emitter — and
  one `emitSwitch` serves both. The node still has both helpers, and the sentence
  stays true there.
- **The negative spelling gets no `yamlKey`.** A file already says both things with
  `log_timestamps: true|false`; a second key for the same field would be two ways to
  spell one setting, with a precedence question nobody asked for. It is on
  `notFromFile` with that reason.
- **The defect lives in a COMBINATION, so the test must drive one.** On a false
  default the old emitter is correct, and with one value driven the wrong spelling is
  still A spelling. Both values against both axes — which needs the decision extracted
  as a pure function, since a host runs one default and cannot be asked for the other.
  The daemon's second axis is now provenance rather than the platform default, which
  strictly widens it: a typed `--log-timestamps` on a true-defaulting host used to
  register nothing, correct for that build and a pin the next one could move.
- **A coverage sweep cannot hold a mutually-exclusive pair — unless it drives ONE ROW
  at a time.** "one configuration, every flag appears in it" is a shape that demands a
  contradiction for two spellings of one field; excluding just the negative one passed
  on Windows and silently dropped `--log-timestamps` from the sweep on macOS. The
  daemon's sweep no longer has that shape: per row, both spellings are ordinary cases
  and neither needs excluding. Per row is stronger for a second reason — a whole-config
  sweep cannot see a line naming the wrong field or the wrong bit, because a
  neighbour's emission covers it.

## Open work

<!-- agent-tripwire: none: deferred work, tracked as GitHub issues; AGENT.md tripwires rules, not residuals -->

- **[#1567](https://github.com/LASTRADA-Software/fastcached/issues/1567)** — two sections here have
  no `AGENT.md` tripwire: `## The daemon host, and what a machine IS` — an
  architecture is what the compiler BUILT FOR and not what the kernel is running, so a
  scheduler weighing an x86-64 process under Rosetta or WOW64 is told `arm64` — and
  `## Which supervisor stamps a log line, and which does not`, whose rule is that a log
  default cannot be picked per binary. Both marked `untriaged:` and not `none:`, and
  `ctest -R rulebook-tripwires` prints the count against this issue on every run.

- **[#867](https://github.com/LASTRADA-Software/fastcached/issues/867)** — the seeded
  config grants read to `NT AUTHORITY\SERVICE` (S-1-5-6), which is every principal
  logged on as a service and not only this daemon. It is far narrower than the
  `BUILTIN\Users` grant it replaced and is what the seed can name — the per-service
  trustee `NT SERVICE\<name>` resolves only once the service exists, and the MSI
  seeds before it registers anything. Tightening it means granting at
  `--install-service` time, after `CreateService`, the way `GrantPathAccess` already
  does for `ownedPaths`; the obstacle is that the MSI passes no `--config`, so
  `ServiceSpec::configPath` is empty there and the machine-wide path would have to be
  resolved from `applicationName`. Since #860 closed, the service DOES read this file
  (`IsPrivilegedProcess` accepts a service logon), so a narrower grant is observable:
  `package-windows` seeds `port: 6699` and requires an answer there, which is what
  would show it working or breaking.


