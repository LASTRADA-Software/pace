// SPDX-License-Identifier: Apache-2.0
#include <Pace/Platform/CpuAffinity.hpp>
#include <Pace/Platform/DaemonControls.hpp>
#include <Pace/Server/Connection.hpp>
#include <Pace/Server/ReactorServerLoop.hpp>
#include <Pace/Server/Server.hpp>
#include <Pace/Transport/AcceptLoopReporter.hpp>
#include <Pace/Transport/NativeListen.hpp>

#include <algorithm>
#include <atomic>
#include <chrono>
#include <cstddef>
#include <cstdint>
#include <cstdlib>
#include <expected>
#include <format>
#include <memory>
#include <optional>
#include <ranges>
#include <span>
#include <stop_token>
#include <string>
#include <string_view>
#include <thread>
#include <tuple>
#include <vector>

#include <core/Profiling.hpp>
#include <core/async/Task.hpp>
#include <core/async/ThreadPoolExecutor.hpp>
#include <core/net/BlockingSocket.hpp>
#include <core/net/PlatformLoop.hpp>
#include <core/net/SocketAddress.hpp>
#include <core/net/Sockets.hpp>
#include <core/platform/Clock.hpp>

#if defined(_WIN32)
    #include <core/async/ResumeOn.hpp>
#endif

#include <core/net/ITlsContext.hpp>

namespace Pace
{

namespace
{

    /// Poll DaemonControls for a stop request and invoke `onStop` once seen.
    /// @param quit Set true by the caller to retire the watchdog.
    /// @param onStop Teardown callback (close listeners, stop reactors).
    template <typename StopFn>
    std::jthread MakeWatchdog(std::atomic<bool>& quit, StopFn onStop)
    {
        return std::jthread { [&quit, onStop = std::move(onStop)] {
            auto& controls = DaemonControls::Instance();
            while (!quit.load(std::memory_order_acquire))
            {
                if (controls.StopRequested())
                {
                    onStop();
                    return;
                }
                std::this_thread::sleep_for(std::chrono::milliseconds { 100 });
            }
        } };
    }

    /// Single-reactor server: one event loop multiplexes every connection on
    /// this thread. No connection-concurrency ceiling and no cross-thread
    /// coroutine migration. This is the default (reactorCount == 1).
    /// Iterates `options.binds` so multiple endpoints (e.g. plaintext + TLS)
    /// share the same reactor when only one is requested.
    int RunSingleReactor(ReactorServerOptions const& options,
                         CacheEngine& engine,
                         ILogger& logger,
                         core::net::AcceptLoopHealth& acceptLoops,
                         core::net::IAdmissionControl* admission,
                         IMetricsSink* metrics)
    {
        if (int const r = Detail::VerifyTlsContextForTlsBinds(options, logger); r != EXIT_SUCCESS)
            return r;
        CORE_THREAD_NAME("fc-reactor");
        core::platform::SteadyClock ownClock;
        core::platform::IClock& clock = options.clock != nullptr ? *options.clock : ownClock;

        // **Declared FIRST, so destroyed LAST, and since
        // [#1025](https://github.com/LASTRADA-Software/fastcached/issues/1025) that
        // ordering carries a requirement it did not before.** It must outlive the
        // listeners and servers, which hold references to it -- but its destructor now
        // FREES the coroutine chains still parked on it, so their frames' destructors
        // run after `servers`, `expiryPool`, the reaper and the per-bind `core::net::ITlsContext`
        // are already gone. Before that change those frames were never destroyed at
        // all, so nothing depended on what they touch.
        //
        // It holds as written, and the reasoning is the requirement: such a frame owns
        // its `Connection`, whose destruction reaches only the socket -- and
        // `~EpollSocket` / `~IocpSocket` call back into THIS reactor, which is alive
        // because it is the object being destroyed and a destructor body runs before
        // its members. Everything else `Connection` holds is a reference or a raw
        // pointer with a trivial destructor, and `core::net::IAdmissionControl::OnConnectionEnded`
        // sits on the `co_return` path, which a destroyed frame does not run.
        //
        // So: anything handed to a connection whose destructor does more than nothing
        // must outlive this reactor. **That sentence has a reader now, and it is not
        // this comment** ([#1051](https://github.com/LASTRADA-Software/fastcached/issues/1051)).
        // It is `ConnectionHoldings` in `Server/Connection.hpp`: everything a connection
        // is handed other than its socket goes through one type, and one
        // `static_assert` refuses that type the moment anything in it grows a
        // destructor. A comment stating an invariant nothing checks is a claim that
        // cannot fail, which is what this paragraph was until the guard existed.
        //
        // What the guard cannot see is the DECLARATION ORDER below, and that is
        // deliberate rather than a gap left open: it does not have to, because no local
        // declared here reaches a connection except by being handed to it. The guard
        // sits on the handing over, which is the narrow door, instead of on the wide
        // set of things that merely happen to be declared nearby.
        core::net::PlatformLoop reactor { clock };

        // Declared before the servers it counts and before anything that arms one,
        // so it outlives every caller and is destroyed last -- which is also what
        // makes its "readiness was never announced" line reachable on the bind-failure
        // path below.
        ReadinessAnnouncer announcer { logger, std::format("{} bind(s)", options.binds.size()), options.onServing };

        std::vector<std::unique_ptr<core::net::IListener>> listeners;
        std::vector<std::unique_ptr<Server>> servers;
        listeners.reserve(options.binds.size());
        servers.reserve(options.binds.size());
        for (auto const& bind: options.binds)
        {
            auto listener = core::net::listen(
                reactor,
                ClientListenOptions(bind.address, bind.port, options.listenBacklog, core::net::PortSharing::Exclusive));
            if (!listener.has_value())
            {
                logger.Logf(LogLevel::Error,
                            "fastcached: cannot bind {}:{} : {}",
                            bind.address,
                            bind.port,
                            listener.error().toString());
                return EXIT_FAILURE;
            }
            listeners.push_back(std::move(*listener));
            // Per-bind tls flag: a plaintext bind passes nullptr so accepted
            // sockets bypass the TLS wrapper; a TLS bind reuses the single
            // shared TlsContext (no per-bind cert/SNI in this iteration).
            auto* const perBindTls = bind.tls ? options.tlsContext : nullptr;
            // The endpoint's own policy travels with every connection it accepts.
            // Without this a handler cannot tell which listener a frame arrived on,
            // and "which surfaces are exposed where" stops being configurable.
            auto session = options.session;
            session.reactor = &reactor;
            // The same sink the connection counters already use, so a dispatch
            // outcome and the connection it arrived on land in one place. Null is
            // ordinary (no metrics endpoint configured) and every use is guarded.
            session.metrics = metrics;
            servers.push_back(std::make_unique<Server>(*listeners.back(),
                                                       engine,
                                                       logger,
                                                       acceptLoops,
                                                       Detail::BindSurface(bind),
                                                       admission,
                                                       metrics,
                                                       session,
                                                       perBindTls,
                                                       options.logSource ? LogSource::Yes : LogSource::No));
            // Registered where the participant is created, so the readiness count
            // and the thing being counted cannot disagree. See `ExpectAcceptor`.
            announcer.ExpectAcceptor();
        }
        announcer.AcceptorsAllSpawned();

        // Arm first, announce second. The readiness line used to be logged HERE,
        // above the loop that starts the acceptors (#646) -- a marker naming a fact
        // weaker than the bind a caller already had. `ReadinessAnnouncer` emits it,
        // and it emits it only once every accept loop is parked in `Accept()`.
        Detail::ArmAcceptLoops(servers, announcer, logger);

        // **Declared BEFORE the reaper, and that ordering is the mechanism.** Locals
        // are destroyed in reverse, so `~ExpiryReaper` -- which cancels the cycle and
        // waits out any sweep still on this pool -- runs before `~ThreadPoolExecutor`
        // joins its thread. Reversed, the pool would be torn down under a sweep it is
        // still running. This is the shape `main.cpp` already relies on for the
        // compile pool, stated there as "~WorkerServer runs before
        // ~ThreadPoolExecutor because `server` is declared after the pool".
        //
        // One thread: the sweep is a single cycle, and a second would only let two
        // sweeps overlap on one store.
        core::async::ThreadPoolExecutor expiryPool { 1 };
        auto const expiry = Detail::StartExpiryCycle(reactor, expiryPool, engine, logger, options, metrics);

        std::atomic<bool> watchdogQuit { false };
        // **`Stop()` and NOTHING else, because this runs on the watchdog's own thread**
        // ([#1208](https://github.com/LASTRADA-Software/fastcached/issues/1208)).
        // `Server::Shutdown()` closes the listener, which reaches
        // `EpollReactor::Detach` and walks the batch `RunLoop` is dispatching -- so
        // shutting the servers down from here raced the loop by construction rather
        // than in a narrow window, since `Shutdown()` ran BEFORE `Stop()`.
        //
        // `Stop()` is the one call that is safe from another thread: it sets a flag and
        // writes the wake fd, touching nothing the loop walks.
        auto watchdog = MakeWatchdog(watchdogQuit, [&] { reactor.stop(); });

        reactor.run();
        watchdogQuit.store(true, std::memory_order_release);

        // **The other half, and REORDERING ALONE would not have been it.** Moving
        // `Stop()` above `Shutdown()` inside the watchdog leaves both on the watchdog's
        // thread, and `Stop()` only posts a wakeup and returns -- so the loop can still
        // be mid-batch when `Shutdown()` closes the listener. That is the gap
        // `~FrameEndpoint` fell into in #840. What makes this safe is the THREAD and the
        // moment: `Run()` has returned here, so `TeardownIsSerialisedWithDispatch()`
        // holds on its `!Running()` term, which is what `Detach` now asserts.
        //
        // It is also tidier than leaving the accept loops parked for the reactor's
        // destructor to abandon (#1025): closing the listener completes each parked
        // accept, and the turn below resumes it on this thread, where it ends through its
        // own `co_return`.
        //
        // **The turn is not optional** (#1596). core-cpp's loop resumes a completed
        // operation on its NEXT turn rather than inside `close()`, and `run()` has already
        // returned -- so without it every accept loop stays queued until `~EventLoop`
        // frees it, which is after `servers` are gone, and `~AcceptingScope` then writes
        // to a destroyed `Server`. ThreadSanitizer reported exactly that as a
        // heap-use-after-free.
        for (auto& s: servers)
            s->Shutdown();
        std::ignore = reactor.runUntilIdle();

        std::uint64_t total = 0;
        for (auto const& s: servers)
            total += s->AcceptedCount();
        logger.Logf(LogLevel::Info, "served {} connection(s)", total);
        return EXIT_SUCCESS;
    }

#if defined(_WIN32)
    /// Drive one accepted connection to completion on a specific reactor's
    /// thread. The connection is handed off from the acceptor thread: it first
    /// reschedules onto `reactor` (so the socket is adopted and all its I/O
    /// completions land on that one thread — no coroutine migration), then
    /// adopts the raw handle and runs the protocol session.
    ///
    /// `core::net::adoptSocket` is the adoption, and it is called on `reactor`'s own
    /// thread, after the hop, because that is its contract. It owns the handle from
    /// the call on, including when it refuses, and it leaves socket options alone --
    /// which is why `AcceptRaw` has already applied them.
    ///
    /// The collaborators arrive by POINTER because this frame is detached and outlives the call: a
    /// reference parameter reads as borrowed for the call alone. Each outlives every reactor.
    /// @param reactor The reactor that serves the connection; never null.
    /// @param engine What the connection serves; never null.
    /// @param logger Where the connection logs; never null.
    /// @param lease The connection's admission slot, held for as long as this frame lives.
    core::async::DetachedTask RunHandedOffConnection(core::net::PlatformLoop* reactor,
                                                     AcceptedSocket raw,
                                                     CacheEngine* engine,
                                                     ILogger* logger,
                                                     std::optional<core::net::AdmissionLease> lease,
                                                     SessionContext session,
                                                     core::net::ITlsContext* tls,
                                                     LogSource logSource)
    {
        co_await core::async::ResumeOn { *reactor };
        // This connection now runs on `reactor`; pin pub/sub delivery to it so a
        // message published elsewhere wakes this subscriber via reactor.submit.
        session.reactor = reactor;
        // Firewall: this is a DetachedTask (unhandled_exception -> std::terminate),
        // so a handler exception must drop only this connection, not the daemon.
        try
        {
            auto socket = core::net::adoptSocket(*reactor, raw.handle, std::move(raw.peer));
            if (!socket.has_value())
            {
                // Refused -- the completion port would not take it, say -- and the handle is
                // already closed by the refusal. Awaiting would hang the connection; drop it.
                logger->Logf(
                    LogLevel::Error, "handed-off connection: adoption failed ({}); dropping", socket.error().toString());
            }
            else
            {
                Connection connection {
                    core::net::wrapTls(std::move(*socket), tls, *reactor),
                    ConnectionHoldings { .engine = *engine, .logger = *logger, .session = session, .logSource = logSource }
                };
                co_await connection.Run();
            }
        }
        catch (...)
        {
            LogConnectionFirewallException(*logger);
        }
        static_cast<void>(lease);
        co_return;
    }

    /// `Detail::IRawAcceptor` over a blocking listening socket: `AcceptRaw`, which the teardown's close
    /// wakes with `Cancelled`.
    class ListeningSocketAcceptor final: public Detail::IRawAcceptor
    {
      public:
        /// @param listening A bound, listening, blocking socket; not owned.
        explicit ListeningSocketAcceptor(core::platform::NativeHandle listening) noexcept:
            _listening { listening }
        {
        }

        [[nodiscard]] std::expected<AcceptedSocket, core::net::NetError> Accept() override
        {
            return AcceptRaw(_listening);
        }

      private:
        core::platform::NativeHandle _listening;
    };

    /// Where the Windows acceptor threads hand what they took. Every member outlives the threads.
    struct ReactorHandOff
    {
        std::span<std::unique_ptr<core::net::PlatformLoop> const> reactors; ///< Round-robin targets.
        std::atomic<std::size_t>& nextReactor;                              ///< Shared by every acceptor thread.
        std::atomic<std::uint64_t>& accepted;                               ///< Connections admitted.
        CacheEngine& engine;                                                ///< What each connection serves.
        ILogger& logger;                                                    ///< Handed to each connection.
        core::net::IAdmissionControl* admission { nullptr };                ///< Admission gate, or nullptr.
        IMetricsSink* metrics { nullptr };                                  ///< Connection counters, or nullptr.
        ReactorServerOptions const& options;                                ///< Session and log settings.
    };

    /// Count one connection: @p all always, @p overTls as well when it arrived on a TLS bind.
    /// @param metrics The sink, or nullptr.
    /// @param all The counter every connection moves.
    /// @param overTls The counter only a TLS bind's connection moves.
    /// @param tls Whether the connection arrived on a TLS bind.
    void CountConnection(IMetricsSink* metrics, IMetricsSink::Counter all, IMetricsSink::Counter overTls, bool tls)
    {
        if (metrics == nullptr)
            return;
        metrics->Increment(all);
        if (tls)
            metrics->Increment(overTls);
    }

    /// Admit one accepted connection, count it and hand it to the next reactor -- or refuse it.
    ///
    /// Admitted and counted in one step, as `Server::Run` does it.
    /// @param to The reactors and the collaborators each connection is handed.
    /// @param raw The connection; owned from here on.
    /// @param tls The bind's TLS context, or nullptr for a plaintext bind.
    void HandOffToReactor(ReactorHandOff const& to, AcceptedSocket raw, core::net::ITlsContext* tls)
    {
        auto lease = to.admission != nullptr ? to.admission->tryAdmit() : std::nullopt;
        if (to.admission != nullptr && !lease.has_value())
        {
            CountConnection(to.metrics,
                            IMetricsSink::Counter::ConnectionsAdmissionRejected,
                            IMetricsSink::Counter::ConnectionsAdmissionRejectedTls,
                            tls != nullptr);
            CloseNativeSocket(raw.handle);
            return;
        }
        to.accepted.fetch_add(1, std::memory_order_relaxed);
        CountConnection(
            to.metrics, IMetricsSink::Counter::ConnectionsTotal, IMetricsSink::Counter::ConnectionsTotalTls, tls != nullptr);
        auto const idx = to.nextReactor.fetch_add(1, std::memory_order_relaxed) % to.reactors.size();
        // Per-bind copy for the same reason the other two platform paths make one: this connection
        // carries its endpoint's role mask, not the daemon's.
        auto session = to.options.session;
        RunHandedOffConnection(to.reactors[idx].get(),
                               std::move(raw),
                               &to.engine,
                               &to.logger,
                               std::move(lease),
                               session,
                               tls,
                               to.options.logSource ? LogSource::Yes : LogSource::No);
    }

    /// Windows multi-core: one blocking acceptor thread *per BindConfig*
    /// distributes raw sockets round-robin across N independent
    /// single-threaded IOCP reactors (Windows has no SO_REUSEPORT
    /// load-balancing). Each connection is pinned to the reactor it was
    /// handed to and wrapped with the bind's TLS flag.
    int RunMultiReactorWindows(ReactorServerOptions const& options,
                               CacheEngine& engine,
                               ILogger& logger,
                               core::net::AcceptLoopHealth& acceptLoops,
                               core::net::IAdmissionControl* admission,
                               IMetricsSink* metrics,
                               unsigned reactorCount)
    {
        if (int const r = Detail::VerifyTlsContextForTlsBinds(options, logger); r != EXIT_SUCCESS)
            return r;
        core::platform::SteadyClock ownClock;
        core::platform::IClock& clock = options.clock != nullptr ? *options.clock : ownClock;
        // Readiness on this platform takes TWO kinds of participant, and both are
        // load-bearing. An acceptor thread parked in `AcceptRaw` takes the socket; an
        // IOCP reactor's `Run()` is what ever serves it, because every accepted handle
        // is handed off. Counting only the acceptor threads would announce readiness
        // while every handed-off connection sat on a completion port nobody was
        // draining -- #646's own defect one layer in.
        //
        // Both are registered where they are CREATED rather than added up, because a
        // total stated as `binds + reactors` that came out too high would stop the
        // line ever being emitted, on the platform this cannot be executed on. See
        // `ExpectAcceptor`.
        ReadinessAnnouncer announcer { logger,
                                       std::format("{} bind(s) x {} reactors", options.binds.size(), reactorCount),
                                       options.onServing };

        std::vector<std::unique_ptr<core::net::PlatformLoop>> reactors;
        reactors.reserve(reactorCount);
        for ([[maybe_unused]] auto const i: std::views::iota(0U, reactorCount))
        {
            reactors.push_back(std::make_unique<core::net::PlatformLoop>(clock));
            announcer.ExpectAcceptor();
        }

        // One listening socket per BindConfig; each acceptor thread owns one.
        std::vector<core::platform::NativeHandle> listenSocks;
        std::vector<bool> bindTls; // parallel to listenSocks
        listenSocks.reserve(options.binds.size());
        bindTls.reserve(options.binds.size());
        for (auto const& bind: options.binds)
        {
            auto bound = BindAndListen(core::net::defaultAddressResolver(), bind.address, bind.port, options.listenBacklog);
            if (!bound.has_value())
            {
                logger.Logf(LogLevel::Error, "fastcached: cannot bind {}:{} : {}", bind.address, bind.port, bound.error());
                for (core::platform::NativeHandle const sock: listenSocks)
                    CloseNativeSocket(sock);
                return EXIT_FAILURE;
            }
            listenSocks.push_back(bound->handle);
            bindTls.push_back(bind.tls);
        }
        std::atomic<std::uint64_t> accepted { 0 };
        std::atomic<bool> stopping { false };
        // ONE round-robin counter shared across all acceptor threads. The
        // previous per-acceptor `std::size_t next = 0` per lambda meant
        // every bind's first connections landed on reactors[0], because
        // each acceptor's counter was independent — under steady low-rate
        // multi-bind load, reactors 0 and 1 silently received ~2x the
        // connections of reactors 2 and 3. A single atomic counter
        // restores the round-robin contract the leading comment promises.
        std::atomic<std::size_t> nextReactor { 0 };

        ReactorHandOff const handOff { .reactors = reactors,
                                       .nextReactor = nextReactor,
                                       .accepted = accepted,
                                       .engine = engine,
                                       .logger = logger,
                                       .admission = admission,
                                       .metrics = metrics,
                                       .options = options };
        std::vector<std::jthread> acceptors;
        acceptors.reserve(options.binds.size());
        for (auto const bindIdx: std::views::iota(std::size_t { 0 }, options.binds.size()))
        {
            announcer.ExpectAcceptor();
            auto* const perBindTls = bindTls[bindIdx] ? options.tlsContext : nullptr;
            acceptors.push_back(Detail::StartAcceptorThread(
                Detail::AcceptorThreadOptions { .surface = Detail::BindSurface(options.binds[bindIdx]),
                                                .threadName = std::format("fc-acceptor-{}", bindIdx),
                                                .acceptor = std::make_unique<ListeningSocketAcceptor>(listenSocks[bindIdx]),
                                                .logger = logger,
                                                .acceptLoops = acceptLoops,
                                                .wait = DefaultDrainWait(),
                                                .stopping = stopping,
                                                .announcer = announcer },
                [&handOff, perBindTls](AcceptedSocket raw) { HandOffToReactor(handOff, std::move(raw), perBindTls); }));
        }

        // Both spawn loops have run, so the set is complete. The reactor arms land
        // later, on their own threads, and the last of them announces.
        announcer.AcceptorsAllSpawned();

        std::atomic<bool> watchdogQuit { false };
        // Single-shot guard: stopAll is invoked both by the watchdog (on
        // SIGINT/SIGTERM) and unconditionally at the function tail. Without
        // a guard, every listenSock would be closed twice — and on Windows
        // SOCKET handles are recyclable, so a second closesocket on a stale
        // handle could tear down a freshly-accepted unrelated socket that
        // happened to receive the same numeric value. test_and_set is
        // atomic and idempotent — exactly one stopAll path actually runs
        // the teardown.
        //
        // **Closing these while an acceptor thread is parked in `AcceptRaw` is
        // deliberate, and it is the only thing that ends those threads.** The comment
        // above addresses double-close and says nothing about close-under-accept, which
        // reads like the second hazard went unexamined — it was
        // ([#1238](https://github.com/LASTRADA-Software/fastcached/issues/1238)), and
        // this paragraph is here because the next reader will arrive at the same
        // suspicion from the same comment.
        //
        // Measured on Windows, 3 runs: `closesocket` under a parked `::accept` returns
        // `WSAEINTR` → `core::net::NetErrorCode::Cancelled`, the acceptor's `!raw.has_value()`
        // breaks its loop, and `~jthread` joins. It is NOT the hazard #1207 fixed on
        // `BlockingListener`: that remedy is *stop, JOIN, then close*, and it rests on
        // POSIX NOT waking a parked `accept` (measured by `scripts/probes/accept-close-wakeup.cpp`:
        // still parked past a 12 s ceiling after the close, 12002-12045 ms of MEASURED
        // elapsed -- never the sum of the sleeps a wait asked for), so closing early buys
        // nothing there. Here the close is the wakeup, so
        // joining first would hang forever. The POSIX sibling below can join-then-close
        // only because its acceptors are loop-driven `core::net` listeners. Pinned by
        // `ctest -R AcceptRaw`, which had no equivalent when #1238 was filed.
        //
        // What is NOT closed by this: an acceptor that has just passed its `stopping`
        // check can still call `AcceptRaw` on a handle `stopAll` closed a moment later.
        // No flag can remove that window — there is always a gap between the check and
        // the syscall — which is why the close, not the flag, is the stop mechanism;
        // the flag only saves a doomed syscall. The outcome there is `WSAENOTSOCK` →
        // `BadFileHandle`, so the loop breaks anyway, which is the intended end.
        std::atomic_flag stopRun = ATOMIC_FLAG_INIT;
        auto stopAll = [&] {
            if (stopRun.test_and_set(std::memory_order_acq_rel))
                return; // another caller already ran the teardown.
            stopping.store(true, std::memory_order_release);
            for (core::platform::NativeHandle const sock: listenSocks)
                CloseNativeSocket(sock);
            for (auto& reactor: reactors)
                reactor->stop();
        };
        auto watchdog = MakeWatchdog(watchdogQuit, stopAll);

        // **Declared BEFORE the reaper, and that ordering is the mechanism.** Locals
        // are destroyed in reverse, so `~ExpiryReaper` -- which cancels the cycle and
        // waits out any sweep still on this pool -- runs before `~ThreadPoolExecutor`
        // joins its thread. Reversed, the pool would be torn down under a sweep it is
        // still running. This is the shape `main.cpp` already relies on for the
        // compile pool, stated there as "~WorkerServer runs before
        // ~ThreadPoolExecutor because `server` is declared after the pool".
        //
        // One thread: the sweep is a single cycle, and a second would only let two
        // sweeps overlap on one store.
        core::async::ThreadPoolExecutor expiryPool { 1 };
        auto const expiry = Detail::StartExpiryCycle(*reactors[0], expiryPool, engine, logger, options, metrics);

        std::vector<std::jthread> threads;
        threads.reserve(reactorCount - 1);
        for (auto const i: std::views::iota(1U, reactorCount))
            threads.emplace_back([&reactors, &announcer, i] {
                [[maybe_unused]] auto const threadName = std::format("fc-reactor-{}", i);
                CORE_THREAD_NAME(threadName.c_str());
                announcer.AcceptorArmed(std::format("reactor {}", i));
                reactors[i]->run();
            });
        CORE_THREAD_NAME("fc-reactor-0");
        announcer.AcceptorArmed("reactor 0");
        reactors[0]->run();
        threads.clear();

        // Unconditional cleanup: if reactors[0]->Run() returned through any
        // path other than the watchdog firing (test calls Stop() directly,
        // an unhandled exception unwinds, the IOCP completion port is
        // externally closed), the watchdog quits via watchdogQuit without
        // ever invoking onStop — leaving listenSocks open and the acceptor
        // jthreads blocked in AcceptRaw forever. Calling stopAll() here
        // closes the sockets so AcceptRaw returns WSAEINTR and the acceptor
        // lambdas exit; ~jthread joins cleanly. (This said `WSAEINTR/EBADF`;
        // the POSIX half describes neither this block, which is Windows-only,
        // nor a parked accept, which POSIX does not wake at all — #1238.)
        stopAll();
        watchdogQuit.store(true, std::memory_order_release);
        logger.Logf(LogLevel::Info, "served {} connection(s)", accepted.load(std::memory_order_relaxed));
        return EXIT_SUCCESS;
    }

#else

    /// POSIX multi-core: N independent single-threaded reactors, each with
    /// one listener per BindConfig (all bound with SO_REUSEPORT so the
    /// kernel load-balances connections across listeners on the same
    /// {address, port}). Every connection is accepted, owned, and served
    /// entirely by one reactor — no handoff.
    int RunMultiReactorPosix(ReactorServerOptions const& options,
                             CacheEngine& engine,
                             ILogger& logger,
                             core::net::AcceptLoopHealth& acceptLoops,
                             core::net::IAdmissionControl* admission,
                             IMetricsSink* metrics,
                             unsigned reactorCount)
    {
        if (int const r = Detail::VerifyTlsContextForTlsBinds(options, logger); r != EXIT_SUCCESS)
            return r;
        core::platform::SteadyClock ownClock;
        core::platform::IClock& clock = options.clock != nullptr ? *options.clock : ownClock;
        std::vector<std::unique_ptr<core::net::PlatformLoop>> reactors;
        // Listeners and servers are laid out as `[reactor * binds + bind]`
        // — a flat array indexed by `reactor * binds.size() + bindIdx`. This
        // keeps the lifetime simple and lets the watchdog tear them down with
        // a single pass.
        std::vector<std::unique_ptr<core::net::IListener>> listeners;
        std::vector<std::unique_ptr<Server>> servers;
        reactors.reserve(reactorCount);
        auto const bindCount = options.binds.size();
        listeners.reserve(reactorCount * bindCount);
        servers.reserve(reactorCount * bindCount);

        // Declared before the servers it counts and before any reactor thread, so it
        // outlives every caller of `AcceptorArmed`.
        ReadinessAnnouncer announcer { logger,
                                       std::format("{} bind(s) x {} reactors", bindCount, reactorCount),
                                       options.onServing };

        for (auto const i: std::views::iota(0U, reactorCount))
        {
            reactors.push_back(std::make_unique<core::net::PlatformLoop>(clock));
            for (auto const& bind: options.binds)
            {
                auto listener = core::net::listen(
                    *reactors[i],
                    ClientListenOptions(bind.address, bind.port, options.listenBacklog, core::net::PortSharing::Shared));
                if (!listener.has_value())
                {
                    logger.Logf(LogLevel::Error,
                                "fastcached: cannot bind {}:{} on reactor {}: {}",
                                bind.address,
                                bind.port,
                                i,
                                listener.error().toString());
                    return EXIT_FAILURE;
                }
                listeners.push_back(std::move(*listener));
                auto* const perBindTls = bind.tls ? options.tlsContext : nullptr;
                // The endpoint's own policy travels with every connection it accepts.
                // Without this a handler cannot tell which listener a frame arrived on,
                // and "which surfaces are exposed where" stops being configurable.
                auto session = options.session;
                session.reactor = reactors[i].get();
                session.metrics = metrics;
                servers.push_back(std::make_unique<Server>(*listeners.back(),
                                                           engine,
                                                           logger,
                                                           acceptLoops,
                                                           std::format("{} on reactor {}", Detail::BindSurface(bind), i),
                                                           admission,
                                                           metrics,
                                                           session,
                                                           perBindTls,
                                                           options.logSource ? LogSource::Yes : LogSource::No));
                // One participant per (reactor, bind) pair, registered where the
                // pair is created rather than multiplied out afterwards.
                announcer.ExpectAcceptor();
            }
        }
        // The set is complete before any reactor thread exists. The arms land later,
        // each on its own reactor's thread, and the last one announces -- which used
        // to be logged HERE, before a single reactor thread had been created (#646).
        announcer.AcceptorsAllSpawned();

        std::atomic<bool> watchdogQuit { false };
        // `Stop()` and nothing else -- the same rule as the single-reactor path, and
        // this is the second of the two sites #1208 reported. The servers are shut
        // down after every loop has returned, below.
        auto watchdog = MakeWatchdog(watchdogQuit, [&] {
            for (auto& reactor: reactors)
                reactor->stop();
        });

        auto const onlineCpus = OnlineCpuCount();
        auto runReactor = [&](unsigned index) {
            // Pin this reactor to its own core (best-effort) so its connections
            // and storage shards stay cache-resident on one core.
            if (options.pinReactorsToCpu && onlineCpus > 0)
            {
                if (!PinCallingThreadToCpu(index % onlineCpus))
                    logger.Logf(LogLevel::Warn, "reactor {}: CPU affinity not applied", index);
            }
            // Run one accept loop per bind on this reactor, and report them armed.
            // Arming happens on THIS thread and immediately before `Run()`, which is
            // why the readiness line cannot be emitted from the calling thread: it
            // would have to be emitted before the last reactor even started.
            Detail::ArmAcceptLoops(
                std::span<std::unique_ptr<Server> const> { servers }.subspan(index * bindCount, bindCount),
                announcer,
                logger);
            reactors[index]->run();
        };

        // **Declared BEFORE the reaper, and that ordering is the mechanism.** Locals
        // are destroyed in reverse, so `~ExpiryReaper` -- which cancels the cycle and
        // waits out any sweep still on this pool -- runs before `~ThreadPoolExecutor`
        // joins its thread. Reversed, the pool would be torn down under a sweep it is
        // still running. This is the shape `main.cpp` already relies on for the
        // compile pool, stated there as "~WorkerServer runs before
        // ~ThreadPoolExecutor because `server` is declared after the pool".
        //
        // One thread: the sweep is a single cycle, and a second would only let two
        // sweeps overlap on one store.
        core::async::ThreadPoolExecutor expiryPool { 1 };
        auto const expiry = Detail::StartExpiryCycle(*reactors[0], expiryPool, engine, logger, options, metrics);

        std::vector<std::jthread> threads;
        threads.reserve(reactorCount - 1);
        for (auto const i: std::views::iota(1U, reactorCount))
            threads.emplace_back([&runReactor, i] {
                // Hoist into a stack local; Tracy's SetThreadName does not
                // copy and would dangle on a `std::format(...).c_str()`.
                [[maybe_unused]] auto const threadName = std::format("fc-reactor-{}", i);
                CORE_THREAD_NAME(threadName.c_str());
                runReactor(i);
            });
        CORE_THREAD_NAME("fc-reactor-0");
        runReactor(0);
        threads.clear();

        watchdogQuit.store(true, std::memory_order_release);

        // Every loop has returned -- `runReactor(0)` above and `threads.clear()`, which
        // joins -- so no reactor is `Running()` and closing a listener here cannot walk
        // a batch anybody is dispatching. See the single-reactor path for why the order
        // rather than the thread was never the fix (#1208).
        //
        // And each loop takes the turn that resumes its accept loops, for the single-reactor
        // path's reason: nothing else will before `~EventLoop`, which runs after `servers`.
        for (auto& server: servers)
            server->Shutdown();
        for (auto& reactor: reactors)
            std::ignore = reactor->runUntilIdle();

        std::uint64_t total = 0;
        for (auto& server: servers)
            total += server->AcceptedCount();
        logger.Logf(LogLevel::Info, "served {} connection(s)", total);
        return EXIT_SUCCESS;
    }

#endif

} // namespace

int RunReactorServer(ReactorServerOptions const& options,
                     CacheEngine& engine,
                     ILogger& logger,
                     core::net::AcceptLoopHealth& acceptLoops,
                     core::net::IAdmissionControl* admission,
                     IMetricsSink* metrics)
{
    if (options.binds.empty())
    {
        logger.Log(LogLevel::Error, "fastcached: no listener configured (set --bind or --listen)");
        return EXIT_FAILURE;
    }
    auto const reactorCount = std::max(1U, options.reactorThreads);
    if (reactorCount == 1)
        return RunSingleReactor(options, engine, logger, acceptLoops, admission, metrics);
#if defined(_WIN32)
    return RunMultiReactorWindows(options, engine, logger, acceptLoops, admission, metrics, reactorCount);
#else
    return RunMultiReactorPosix(options, engine, logger, acceptLoops, admission, metrics, reactorCount);
#endif
}

namespace Detail
{
    std::unique_ptr<ExpiryReaper> StartExpiryCycle(core::net::EventLoop& reactor,
                                                   core::async::IExecutor& sweepOn,
                                                   CacheEngine& engine,
                                                   ILogger& logger,
                                                   ReactorServerOptions const& options,
                                                   IMetricsSink* metrics)
    {
        auto reaper = std::make_unique<ExpiryReaper>(engine.Storage(), logger, options.expiry, metrics);
        reaper->Start(reactor, sweepOn);
        return reaper;
    }

    void ArmAcceptLoops(std::span<std::unique_ptr<Server> const> servers, ReadinessAnnouncer& announcer, ILogger& logger)
    {
        // A DetachedTask has a `suspend_never` initial suspend, so calling this runs
        // `Server::Run()` up to its first real suspension point -- which is the
        // listener's `Accept()`. That is what turns "started" into "armed", and it
        // is the whole reason the readiness line can be emitted below rather than
        // above.
        auto runAccept = [](Server* s) -> core::async::DetachedTask {
            co_await s->Run();
            co_return;
        };

        for (auto const& owned: servers)
        {
            auto* const server = owned.get();
            runAccept(server);
            if (!server->IsAccepting())
            {
                // Not counted, deliberately. The loop ended before parking, so there
                // is no acceptor here -- and a readiness line that counted it would
                // be exactly the claim #646 is about, made one level deeper.
                logger.Logf(
                    LogLevel::Error, "{}: accept loop did not arm; this endpoint is not being served", server->Surface());
                continue;
            }
            // Under the loop's own name, the one its warnings and `/healthz` use, so the
            // three agree about which bind a line is about.
            announcer.AcceptorArmed(server->Surface());
        }
    }

    std::jthread StartAcceptorThread(AcceptorThreadOptions options, AcceptedHandOff handOff)
    {
        return std::jthread { [options = std::move(options),
                               handOff = std::move(handOff)](std::stop_token const& stopToken) {
            // `options` lives as long as this thread, so the name Tracy keeps a pointer to does too.
            CORE_THREAD_NAME(options.threadName.c_str());
            // Armed the moment this thread is about to block in its first accept.
            options.announcer.AcceptorArmed(options.surface);
            AcceptLoopReporter acceptErrors { options.surface, options.surface, options.logger, options.acceptLoops };
            auto const stopRequested = [&] {
                return options.stopping.load(std::memory_order_acquire) || stopToken.stop_requested();
            };
            while (!stopRequested())
            {
                auto raw = options.acceptor->Accept();
                if (raw.has_value())
                {
                    acceptErrors.OnAccepted(options.wait.Now());
                    handOff(std::move(*raw));
                    continue;
                }
                // A dead listener ends this thread as a closed one does. `EndAndClose` is NOT carried
                // out here -- this thread does not own the listening socket, which is the teardown's
                // to close once every acceptor thread has returned -- so a dead listener on a node
                // that goes on serving stays open until then. Harmless while `BadHandle` is the only
                // code the policy calls dead: a handle that is no socket queues no handshake.
                auto const step = acceptErrors.OnError(raw.error(), options.wait.Now(), stopRequested());
                if (step.next != AcceptLoopNext::AcceptAgain)
                    return;
                // There is no reactor timer on this thread to suspend on, so a backoff BLOCKS.
                if (step.delay > std::chrono::milliseconds {})
                    options.wait.Sleep(step.delay);
            }
            acceptErrors.OnLoopEnded();
        } };
    }

    std::string BindSurface(BindConfig const& bind)
    {
        // An IPv6 literal is bracketed, or its colons run into the port's.
        auto const host = bind.address.contains(':') ? std::format("[{}]", bind.address) : bind.address;
        return std::format("cache {}:{}{}", host, bind.port, bind.tls ? " (TLS)" : "");
    }

    int VerifyTlsContextForTlsBinds(ReactorServerOptions const& options, ILogger& logger)
    {
        for (auto const& bind: options.binds)
        {
            if (bind.tls && options.tlsContext == nullptr)
            {
                logger.Logf(LogLevel::Fatal,
                            "fastcached: TLS bind {}:{} requested but no TLS context configured",
                            bind.address,
                            bind.port);
                return EXIT_FAILURE;
            }
        }
        return EXIT_SUCCESS;
    }

} // namespace Detail

} // namespace Pace
