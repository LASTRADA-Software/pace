// SPDX-License-Identifier: Apache-2.0
#include <Pace/Cache/StorageTier.hpp>
#include <Pace/Distributed/NodeLoadTestUtils.hpp>
#include <Pace/Distributed/WorkerRegistry.hpp>
#include <Pace/Protocol/CompileCacheWire.hpp>

#include <catch2/catch_test_macros.hpp>

#include <algorithm>
#include <array>
#include <chrono>
#include <cstddef>
#include <format>
#include <optional>
#include <ranges>
#include <string>
#include <string_view>
#include <vector>

#include <core/platform/Clock.hpp>
#include <tests/Unwrap.hpp>

using namespace Pace;
using namespace Pace::Distributed;
using namespace Pace::Distributed::Testing;
using Pace::Testing::Unwrap;

namespace
{

/// A registry over a clock the test drives, so every expiry assertion is exact
/// rather than a race against wall time.
struct Fixture
{
    core::platform::ManualClock clock;
    WorkerRegistry registry { clock, std::chrono::milliseconds { 1000 } };
};

/// A registration with no codec preferences, which is what most of these cases
/// care about. Named so the field list is spelled once rather than at every call.
[[nodiscard]] WorkerRegistration Announce(std::string_view fingerprint, std::string_view endpoint, std::uint32_t slots)
{
    return { .fingerprint = fingerprint, .endpoint = endpoint, .slots = slots, .codecs = {} };
}

constexpr std::string_view Gcc13 = "gcc-13-abcdef";
constexpr std::string_view Gcc14 = "gcc-14-123456";

} // namespace

TEST_CASE("A registered worker is picked for its own fingerprint", "[distributed][registry]")
{
    Fixture fix;
    auto const id = fix.registry.Register(Announce(Gcc13, "10.0.0.1:6676", 4));

    auto const picked = fix.registry.Pick(Gcc13);
    REQUIRE(picked.has_value());
    CHECK(picked->id == id);
    CHECK(picked->endpoint == "10.0.0.1:6676");
}

TEST_CASE("A job is never dispatched across fingerprints", "[distributed][registry]")
{
    // The single most important property here. An over-strict match costs a local
    // compile; an over-loose one produces a silently wrong object that is then
    // stored under a key other machines fetch. There is no symmetry between those
    // two errors, which is why no configuration can loosen this.
    Fixture fix;
    (void) fix.registry.Register(Announce(Gcc13, "10.0.0.1:6676", 4));

    auto const picked = fix.registry.Pick(Gcc14);
    REQUIRE_FALSE(picked.has_value());
    CHECK(picked.error() == PickError::NoWorker);
}

TEST_CASE("A near-miss fingerprint is still a miss", "[distributed][registry]")
{
    // Byte-identical means byte-identical: a prefix, a suffix, and a case
    // difference are all different toolchains as far as this is concerned.
    Fixture fix;
    (void) fix.registry.Register(Announce(Gcc13, "10.0.0.1:6676", 4));

    for (auto const& near:
         { std::string { Gcc13 } + "x", std::string { "x" } + std::string { Gcc13 }, std::string { "GCC-13-ABCDEF" } })
    {
        INFO("fingerprint " << near);
        CHECK_FALSE(fix.registry.Pick(near).has_value());
    }
}

TEST_CASE("An empty fleet and a busy fleet are different answers", "[distributed][registry]")
{
    // Both end in a local compile at the client, but they are different operator
    // problems -- one is a configuration mistake, the other is capacity -- and the
    // client reports the scheduler's own words.
    Fixture fix;
    CHECK(fix.registry.Pick(Gcc13).error() == PickError::NoWorker);

    auto const id = fix.registry.Register(Announce(Gcc13, "10.0.0.1:6676", 1));
    fix.registry.JobStarted(id);
    CHECK(fix.registry.Pick(Gcc13).error() == PickError::NoCapacity);
}

TEST_CASE("The least-loaded matching worker wins", "[distributed][registry]")
{
    // Not round-robin: compile times vary by an order of magnitude within one
    // build, so distributing arrivals rather than load queues a long translation
    // unit behind another while a worker idles.
    Fixture fix;
    auto const busy = fix.registry.Register(Announce(Gcc13, "10.0.0.1:6676", 4));
    auto const idle = fix.registry.Register(Announce(Gcc13, "10.0.0.2:6676", 4));

    fix.registry.JobStarted(busy);
    fix.registry.JobStarted(busy);

    auto const picked = fix.registry.Pick(Gcc13);
    REQUIRE(picked.has_value());
    CHECK(picked->id == idle);
}

TEST_CASE("A worker that stops heartbeating stops being dispatched to", "[distributed][registry]")
{
    // A worker that dies mid-job would otherwise hold its slots forever and the
    // fleet would shrink to nothing with no diagnostic.
    Fixture fix;
    (void) fix.registry.Register(Announce(Gcc13, "10.0.0.1:6676", 4));
    REQUIRE(fix.registry.Pick(Gcc13).has_value());

    fix.clock.advance(std::chrono::milliseconds { 1001 });
    auto const picked = fix.registry.Pick(Gcc13);
    REQUIRE_FALSE(picked.has_value());
    CHECK(picked.error() == PickError::NoWorker);
    CHECK(fix.registry.LiveWorkers().empty());
}

TEST_CASE("A heartbeat keeps a worker alive and corrects its load", "[distributed][registry]")
{
    Fixture fix;
    auto const id = fix.registry.Register(Announce(Gcc13, "10.0.0.1:6676", 4));

    fix.clock.advance(std::chrono::milliseconds { 900 });
    // The worker's own count is authoritative: the registry's drifts whenever a
    // client dies between leasing and compiling, and only the worker knows what it
    // is actually running.
    CHECK(fix.registry.Heartbeat(id, Busy(3)));
    fix.clock.advance(std::chrono::milliseconds { 900 });

    auto const picked = fix.registry.Pick(Gcc13);
    REQUIRE(picked.has_value());
    CHECK(picked->inFlight == 3);
}

TEST_CASE("A heartbeat from an unknown worker is refused", "[distributed][registry]")
{
    // So the worker learns to register again rather than heartbeating into a void.
    Fixture fix;
    CHECK_FALSE(fix.registry.Heartbeat("w999", NodeLoad {}));
}

TEST_CASE("A worker that restarts keeps one identity, not two", "[distributed][registry]")
{
    // Re-registration is keyed on (fingerprint, endpoint). Issuing a second id
    // would leave the first pointing at a dead port until it expired, and half the
    // leases for that toolchain would go there in the meantime.
    Fixture fix;
    auto const first = fix.registry.Register(Announce(Gcc13, "10.0.0.1:6676", 4));
    fix.registry.JobStarted(first);

    auto const second = fix.registry.Register(Announce(Gcc13, "10.0.0.1:6676", 8));
    CHECK(second == first);
    CHECK(fix.registry.LiveWorkers().size() == 1);

    auto const picked = fix.registry.Pick(Gcc13);
    REQUIRE(picked.has_value());
    CHECK(picked->slots == 8);
    // A restarted worker is running nothing; carrying the old count forward would
    // make it look busy until its first heartbeat.
    CHECK(picked->inFlight == 0);
}

TEST_CASE("The same toolchain on two hosts is two workers", "[distributed][registry]")
{
    Fixture fix;
    auto const a = fix.registry.Register(Announce(Gcc13, "10.0.0.1:6676", 1));
    auto const b = fix.registry.Register(Announce(Gcc13, "10.0.0.2:6676", 1));
    CHECK(a != b);
    CHECK(fix.registry.LiveWorkers().size() == 2);
}

TEST_CASE("Finishing a job at zero outstanding does not wrap the counter", "[distributed][registry]")
{
    // `inFlight` is unsigned. A decrement at zero would report four billion jobs
    // outstanding, taking the worker out of rotation permanently and silently --
    // and reaching zero here is not even a bug, since a heartbeat can correct the
    // count downwards between a job starting and finishing.
    Fixture fix;
    auto const id = fix.registry.Register(Announce(Gcc13, "10.0.0.1:6676", 1));

    fix.registry.JobFinished(id);
    fix.registry.JobFinished(id);

    auto const picked = fix.registry.Pick(Gcc13);
    REQUIRE(picked.has_value());
    CHECK(picked->inFlight == 0);
}

TEST_CASE("Expiring the stale names what it dropped", "[distributed][registry]")
{
    // Expiry was a filter and nothing else: `IsLive` hid a dead worker from `Pick`
    // while its entry stayed in the map forever, so a machine going away was never
    // an EVENT anything could act on -- and whatever was held against that worker
    // was held until it timed out on its own.
    Fixture fix;
    auto const alive = fix.registry.Register(Announce(Gcc13, "10.0.0.1:6676", 4));
    auto const dying = fix.registry.Register(Announce(Gcc14, "10.0.0.2:6676", 4));

    CHECK(fix.registry.ExpireStale().empty()); // a live fleet drops nothing

    fix.clock.advance(std::chrono::milliseconds { 1001 });
    REQUIRE(fix.registry.Heartbeat(alive, NodeLoad {}));

    CHECK(fix.registry.ExpireStale() == std::vector { dying });

    // Erased, not merely filtered: a second call has nothing left to report, and
    // the survivor is untouched.
    CHECK(fix.registry.ExpireStale().empty());
    CHECK(fix.registry.Pick(Gcc13).has_value());
    CHECK_FALSE(fix.registry.Pick(Gcc14).has_value());
}

TEST_CASE("A clock that moves backwards does not expire the fleet", "[distributed][registry]")
{
    // Not paranoia about the steady clock: a ManualClock in a test can be set
    // backwards, and treating a negative age as enormous would expire everything.
    Fixture fix;
    fix.clock.advance(std::chrono::milliseconds { 5000 });
    (void) fix.registry.Register(Announce(Gcc13, "10.0.0.1:6676", 4));

    fix.clock.advance(std::chrono::milliseconds { -2000 });
    CHECK(fix.registry.Pick(Gcc13).has_value());
}

TEST_CASE("A big machine with more running jobs still wins on headroom", "[distributed][registry]")
{
    // The correction. `Pick` compared `inFlight` in ABSOLUTE terms, which treats
    // every worker as an identical box: a 64-slot server running 8 jobs looked
    // busier than a 4-slot laptop running 2, when the server had 56 slots free and
    // the laptop had 2. Across a fleet of mixed machines -- the ordinary case, not
    // an exotic one -- that sends work to the smallest machines first and leaves the
    // big ones idle.
    Fixture fix;
    auto const server = fix.registry.Register(Announce(Gcc13, "10.0.0.1:6676", 64));
    auto const laptop = fix.registry.Register(Announce(Gcc13, "10.0.0.2:6676", 4));

    // The server is carrying four times the laptop's load and is still the better
    // place for the next job.
    for ([[maybe_unused]] auto const job: std::views::iota(0, 8))
        fix.registry.JobStarted(server);
    for ([[maybe_unused]] auto const job: std::views::iota(0, 2))
        fix.registry.JobStarted(laptop);

    auto const picked = fix.registry.Pick(Gcc13);
    REQUIRE(picked.has_value());
    CHECK(picked->id == server);
}

TEST_CASE("Equal headroom is broken by which machine has more of itself left", "[distributed][registry]")
{
    // Where the headroom ties, the proportionally emptier machine takes it: 4 free
    // of 8 has more of itself left than 4 free of 64, and is the better place to put
    // a job that will occupy a core for seconds.
    Fixture fix;
    auto const big = fix.registry.Register(Announce(Gcc13, "10.0.0.1:6676", 64));
    auto const small = fix.registry.Register(Announce(Gcc13, "10.0.0.2:6676", 8));

    for ([[maybe_unused]] auto const job: std::views::iota(0, 60))
        fix.registry.JobStarted(big);
    for ([[maybe_unused]] auto const job: std::views::iota(0, 4))
        fix.registry.JobStarted(small);

    auto const picked = fix.registry.Pick(Gcc13);
    REQUIRE(picked.has_value());
    CHECK(picked->id == small);
}

TEST_CASE("A full machine is never picked however large it is", "[distributed][registry]")
{
    // Headroom is a preference; the slot cap is not. A worker at its limit is out of
    // the running entirely, or the fleet would be fuller and slower than it believes
    // at the same moment.
    Fixture fix;
    auto const big = fix.registry.Register(Announce(Gcc13, "10.0.0.1:6676", 64));
    auto const small = fix.registry.Register(Announce(Gcc13, "10.0.0.2:6676", 2));

    for ([[maybe_unused]] auto const job: std::views::iota(0, 64))
        fix.registry.JobStarted(big);

    auto const picked = fix.registry.Pick(Gcc13);
    REQUIRE(picked.has_value());
    CHECK(picked->id == small);
}

TEST_CASE("A worker whose machine is busy elsewhere is passed over", "[distributed][registry]")
{
    // The end-to-end shape of the live-load rule, through the registry rather than
    // against the policy function: this is the path that would silently keep sending
    // work to a saturated developer machine if the heartbeat's load were recorded
    // and then never consulted.
    Fixture fix;
    auto const desk = fix.registry.Register(
        WorkerRegistration { .fingerprint = Gcc13,
                             .endpoint = "10.0.0.1:6676",
                             .slots = 0,
                             .codecs = {},
                             .capacity = NodeCapacity { .logicalCores = 8, .nodeClass = NodeClass::Workstation } });
    auto const server = fix.registry.Register(
        WorkerRegistration { .fingerprint = Gcc13,
                             .endpoint = "10.0.0.2:6676",
                             .slots = 0,
                             .codecs = {},
                             .capacity = NodeCapacity { .logicalCores = 4, .nodeClass = NodeClass::Dedicated } });

    // Six slots against four: with nothing else known, the bigger machine wins.
    auto const idle = fix.registry.Pick(Gcc13);
    REQUIRE(idle.has_value());
    CHECK(idle->id == desk);

    // Its owner then starts using it. Eight busy cores of eight, none of them ours,
    // so it withdraws entirely and the small dedicated node takes the work.
    REQUIRE(fix.registry.Heartbeat(desk, WithCpu(0, 1000)));
    auto const shifted = fix.registry.Pick(Gcc13);
    REQUIRE(shifted.has_value());
    CHECK(shifted->id == server);

    // And it comes back when they stop, rather than being written off.
    REQUIRE(fix.registry.Heartbeat(desk, WithCpu(0, 0)));
    auto const recovered = fix.registry.Pick(Gcc13);
    REQUIRE(recovered.has_value());
    CHECK(recovered->id == desk);
}

TEST_CASE("A fleet that is unavailable is a different refusal from one that is small", "[distributed][registry]")
{
    // Three refusals rather than two, for the reason there were two rather than one:
    // they are different operator problems with different fixes. Told "no capacity",
    // an operator buys machines; the truth in the first section below is that the
    // machines they already own have filled their scratch disks, and 200 MB fixes it.
    Fixture fix;
    auto const id = fix.registry.Register(
        WorkerRegistration { .fingerprint = Gcc13,
                             .endpoint = "10.0.0.1:6676",
                             .slots = 4,
                             .codecs = {},
                             .capacity = NodeCapacity { .logicalCores = 8, .nodeClass = NodeClass::Dedicated } });

    SECTION("slots free on paper, withdrawn in practice")
    {
        REQUIRE(fix.registry.Heartbeat(id, WithScratch(0, 0)));

        auto const picked = fix.registry.Pick(Gcc13);
        REQUIRE_FALSE(picked.has_value());
        CHECK(picked.error() == PickError::Withdrawn);
    }

    SECTION("genuinely full of this fleet's own work")
    {
        // No live-load report at all, so nothing is withdrawn; the four slots are
        // simply taken. This is the case that really does mean "buy more machines".
        REQUIRE(fix.registry.Heartbeat(id, Busy(4)));

        auto const picked = fix.registry.Pick(Gcc13);
        REQUIRE_FALSE(picked.has_value());
        CHECK(picked.error() == PickError::NoCapacity);
    }

    SECTION("both at once reports the actionable one")
    {
        // A second worker full of our own work, beside the first with a full disk.
        // `Withdrawn` wins: "some of your machines are unavailable" is fixable today,
        // where "the fleet is small" is a purchase -- and reporting the purchase
        // would hide the full disk behind a number that looks like growth.
        auto const busy = fix.registry.Register(Announce(Gcc13, "10.0.0.2:6676", 2));
        REQUIRE(fix.registry.Heartbeat(busy, Busy(2)));
        REQUIRE(fix.registry.Heartbeat(id, WithScratch(0, 0)));

        auto const picked = fix.registry.Pick(Gcc13);
        REQUIRE_FALSE(picked.has_value());
        CHECK(picked.error() == PickError::Withdrawn);
    }
}

TEST_CASE("A cordoned worker is passed over, stays visible, and returns when the cordon lifts",
          "[distributed][registry][cordon]")
{
    // #1303, through the registry rather than the policy function: the path that would go
    // on sending work to a machine an operator is draining if the heartbeat's cordon were
    // recorded and never consulted.
    Fixture fix;
    auto const desk = fix.registry.Register(
        WorkerRegistration { .fingerprint = Gcc13,
                             .endpoint = "10.0.0.1:6676",
                             .slots = 4,
                             .codecs = {},
                             .capacity = NodeCapacity { .logicalCores = 8, .nodeClass = NodeClass::Dedicated } });
    auto const server = fix.registry.Register(
        WorkerRegistration { .fingerprint = Gcc13,
                             .endpoint = "10.0.0.2:6676",
                             .slots = 2,
                             .codecs = {},
                             .capacity = NodeCapacity { .logicalCores = 4, .nodeClass = NodeClass::Dedicated } });

    // Four free against two: with nothing cordoned, the bigger machine wins.
    auto const idle = fix.registry.Pick(Gcc13);
    REQUIRE(idle.has_value());
    CHECK(idle->id == desk);

    // Cordoned with one compile still running and three slots free on paper -- which is
    // exactly the state a slot count alone would keep handing work.
    REQUIRE(fix.registry.Heartbeat(desk, Cordoned(1)));
    auto const shifted = fix.registry.Pick(Gcc13);
    REQUIRE(shifted.has_value());
    CHECK(shifted->id == server);

    // Still registered and still reported, with what it is draining: a cordon is not a
    // withdrawal, and a machine that vanished from the page could not be watched drain.
    auto const reports = fix.registry.LiveWorkerReports();
    auto const drained = std::ranges::find_if(reports, [&desk](WorkerReport const& r) { return r.info.id == desk; });
    REQUIRE(drained != reports.end());
    CHECK(drained->info.load.cordoned);
    CHECK(drained->info.inFlight == 1);

    // With only the cordoned machine left serving this toolchain, the refusal is the
    // actionable one -- some machines are unavailable -- not a fleet too small.
    REQUIRE(fix.registry.Heartbeat(server, Busy(2)));
    auto const refused = fix.registry.Pick(Gcc13);
    REQUIRE_FALSE(refused.has_value());
    CHECK(refused.error() == PickError::Withdrawn);

    // And lifting it is a heartbeat like any other.
    REQUIRE(fix.registry.Heartbeat(desk, Busy(0)));
    auto const recovered = fix.registry.Pick(Gcc13);
    REQUIRE(recovered.has_value());
    CHECK(recovered->id == desk);
}

TEST_CASE("One machine serving two toolchains is one node's cache", "[distributed][registry][cache]")
{
    // The registry keys on (fingerprint, endpoint), so a node started with two
    // `--toolchain` flags is two entries against one machine -- deliberately, and
    // documented at the node. Both heartbeat the SAME cache figures, because a cache
    // is per node and not per toolchain. So anything summing a cache field across
    // `LiveWorkers()` counts one node's objects and bytes twice, which on a fleet
    // page reads as a cache holding double what it holds.
    Fixture fixture;

    NodeCacheCapacity budget {};
    budget.tierBytesLimit[static_cast<std::size_t>(StorageTier::Memory)] = 256ULL << 20;
    auto announce = Announce("gcc-14", "10.0.0.2:7100", 4);
    announce.capacity.cache = budget;

    auto const gcc = fixture.registry.Register(announce);
    announce.fingerprint = "clang-20";
    auto const clang = fixture.registry.Register(announce);
    CHECK(gcc != clang);
    CHECK(fixture.registry.LiveWorkers().size() == 2);

    NodeLoad load {};
    load.cache.tiers[static_cast<std::size_t>(StorageTier::Memory)] =
        CacheTierUsage { .itemCount = 900, .bytesUsed = 100ULL << 20, .evictions = 3 };
    load.cache.hits = 4000;
    load.cache.misses = 100;
    CHECK(fixture.registry.Heartbeat(gcc, load));
    CHECK(fixture.registry.Heartbeat(clang, load));

    auto const caches = fixture.registry.NodeCaches();
    REQUIRE(caches.size() == 1);
    CHECK(caches[0].endpoint == "10.0.0.2:7100");
    auto const& memory = caches[0].load.tiers[static_cast<std::size_t>(StorageTier::Memory)];
    REQUIRE(memory.has_value());
    // 900 and not 1800, which is the whole point.
    CHECK(Unwrap(memory).itemCount == 900);
    CHECK(Unwrap(memory).bytesUsed == 100ULL << 20);
    CHECK(caches[0].load.hits == 4000);
    CHECK(caches[0].capacity.tierBytesLimit == budget.tierBytesLimit);
}

TEST_CASE("Two machines are two node caches", "[distributed][registry][cache]")
{
    // The other direction, so the dedup above cannot pass by collapsing everything:
    // different endpoints are different nodes, whatever toolchains they serve.
    Fixture fixture;
    (void) fixture.registry.Register(Announce("gcc-14", "10.0.0.2:7100", 4));
    (void) fixture.registry.Register(Announce("gcc-14", "10.0.0.3:7100", 4));

    auto const caches = fixture.registry.NodeCaches();
    REQUIRE(caches.size() == 2);
    // Ordered by endpoint, so a snapshot is reproducible -- the property
    // `LiveWorkers()` sorts for, applied to the key this view groups on.
    CHECK(caches[0].endpoint == "10.0.0.2:7100");
    CHECK(caches[1].endpoint == "10.0.0.3:7100");
}

TEST_CASE("A node that stopped heartbeating stops reporting a cache", "[distributed][registry][cache]")
{
    // A stale figure is worse than none: an operator reading a fleet page cannot
    // tell "this node holds 900 objects" from "this node held 900 objects when it
    // was last heard from, an hour ago".
    Fixture fixture;
    (void) fixture.registry.Register(Announce("gcc-14", "10.0.0.2:7100", 4));
    CHECK(fixture.registry.NodeCaches().size() == 1);

    fixture.clock.advance(std::chrono::milliseconds { 2000 });
    CHECK(fixture.registry.NodeCaches().empty());
}

TEST_CASE("A node with no cache reports no tiers rather than empty ones", "[distributed][registry][cache]")
{
    // Absent all the way through. A node running with `--cache-memory 0` and no
    // `--cache-dir` has no cache at all, and a leader drawing zeroes for it would
    // show a member whose cache is doing nothing -- a different claim, and one an
    // operator would act on.
    Fixture fixture;
    (void) fixture.registry.Register(Announce("gcc-14", "10.0.0.2:7100", 4));

    auto const caches = fixture.registry.NodeCaches();
    REQUIRE(caches.size() == 1);
    for (auto const& tier: caches[0].capacity.tierBytesLimit)
        CHECK_FALSE(tier.has_value());
    for (auto const& tier: caches[0].load.tiers)
        CHECK_FALSE(tier.has_value());
    CHECK_FALSE(caches[0].load.hits.has_value());
}

TEST_CASE("A sibling that just re-registered does not blank the node's cache", "[distributed][registry][cache]")
{
    // The entries of one node do NOT always agree, which is why picking between
    // them arbitrarily is wrong. `Register` clears a worker's load -- a
    // re-registering worker has restarted, so what it last reported is a reading
    // from before that -- so a node whose gcc entry has just re-registered holds
    // nothing there while its clang entry still holds last round's figures.
    //
    // Choosing the empty one reports that node as having no cache until the next
    // heartbeat, and "no cache" is a claim an operator acts on. Worse, which entry
    // got chosen depended on an unordered_map's iteration order, so it would have
    // been intermittent.
    Fixture fixture;
    auto announce = Announce("gcc-14", "10.0.0.2:7100", 4);
    auto const gcc = fixture.registry.Register(announce);
    announce.fingerprint = "clang-20";
    auto const clang = fixture.registry.Register(announce);

    NodeLoad load {};
    load.cache.tiers[static_cast<std::size_t>(StorageTier::Memory)] = CacheTierUsage { .itemCount = 900 };
    load.cache.hits = 4000;
    CHECK(fixture.registry.Heartbeat(gcc, load));
    CHECK(fixture.registry.Heartbeat(clang, load));

    // One entry re-registers, and its load is reset. It is also now the most
    // recently seen, so "newest wins" alone would pick exactly the wrong one.
    fixture.clock.advance(std::chrono::milliseconds { 10 });
    announce.fingerprint = "gcc-14";
    CHECK(fixture.registry.Register(announce) == gcc);

    auto const caches = fixture.registry.NodeCaches();
    REQUIRE(caches.size() == 1);
    auto const& memory = caches[0].load.tiers[static_cast<std::size_t>(StorageTier::Memory)];
    REQUIRE(memory.has_value());
    CHECK(Unwrap(memory).itemCount == 900);
    CHECK(caches[0].load.hits == 4000);
}

TEST_CASE("How long ago a worker was heard from is measured on the injected clock", "[distributed][registry][heartbeat-age]")
{
    // The age has to come from the clock the registry was given, not from
    // `steady_clock::now()`. Handed a raw `core::platform::SteadyTimePoint`, a consumer would reach for
    // the latter -- right in production and wrong under every one of these cases,
    // silently, because the two clocks agree about nothing.
    Fixture fix;
    auto const id = fix.registry.Register(Announce(Gcc13, "10.0.0.1:6676", 4));

    auto const fresh = fix.registry.LiveWorkerReports();
    REQUIRE(fresh.size() == 1);
    CHECK(fresh[0].info.id == id);
    CHECK(fresh[0].heartbeatAge == std::chrono::milliseconds { 0 });

    fix.clock.advance(std::chrono::milliseconds { 400 });
    auto const aged = fix.registry.LiveWorkerReports();
    REQUIRE(aged.size() == 1);
    CHECK(aged[0].heartbeatAge == std::chrono::milliseconds { 400 });

    // A heartbeat is what resets it -- that is what the number is reporting.
    CHECK(fix.registry.Heartbeat(id, Busy(1)));
    CHECK(fix.registry.LiveWorkerReports()[0].heartbeatAge == std::chrono::milliseconds { 0 });
}

TEST_CASE("A worker past its timeout is absent rather than very old", "[distributed][registry][heartbeat-age]")
{
    // The distinction a dashboard would otherwise get wrong in the dangerous
    // direction: an expired worker must not appear at all, because a row showing a
    // large age reads as a machine that is merely slow to report.
    Fixture fix;
    (void) fix.registry.Register(Announce(Gcc13, "10.0.0.1:6676", 4));

    fix.clock.advance(std::chrono::milliseconds { 1001 });
    CHECK(fix.registry.LiveWorkerReports().empty());
    CHECK(fix.registry.NodeReports().empty());
}

TEST_CASE("A clock set backwards reports no age rather than an enormous one", "[distributed][registry][heartbeat-age]")
{
    // A `core::platform::ManualClock` can legitimately go backwards in a test, and an unsigned
    // duration would then read as several hundred million years.
    Fixture fix;
    fix.clock.advance(std::chrono::milliseconds { 500 });
    (void) fix.registry.Register(Announce(Gcc13, "10.0.0.1:6676", 4));

    fix.clock.advance(std::chrono::milliseconds { -200 });
    auto const reports = fix.registry.LiveWorkerReports();
    REQUIRE(reports.size() == 1);
    CHECK(reports[0].heartbeatAge == std::chrono::milliseconds { 0 });
}

TEST_CASE("One machine serving two toolchains is one node, and its cores are not doubled",
          "[distributed][registry][node-report]")
{
    // The double count a fleet page exists to avoid. This registry keys on
    // (fingerprint, endpoint), so a node with two `--toolchain` flags is two
    // entries carrying ONE machine's cores -- and summing them across
    // `LiveWorkers()` reports a fleet twice the size of the one an operator owns.
    //
    // Deliberately different slot counts per entry, so a max/sum transposition in
    // `registeredSlots` fails rather than passing on equal numbers. The job count
    // is checked by the two cases below, which is where the grain lives now.
    Fixture fix;
    auto gcc = Announce(Gcc13, "10.0.0.2:7100", 6);
    gcc.capacity = NodeCapacity { .logicalCores = 32, .totalMemoryBytes = 64ULL << 30 };
    auto const gccId = fix.registry.Register(gcc);

    auto clang = Announce(Gcc14, "10.0.0.2:7100", 4);
    clang.capacity = gcc.capacity;
    auto const clangId = fix.registry.Register(clang);

    CHECK(fix.registry.LiveWorkers().size() == 2);
    fix.registry.JobStarted(gccId);
    fix.registry.JobStarted(gccId);
    fix.registry.JobStarted(clangId);

    auto const nodes = fix.registry.NodeReports();
    REQUIRE(nodes.size() == 1);
    CHECK(nodes[0].endpoint == "10.0.0.2:7100");
    // 32, not 64: the entries describe one machine.
    CHECK(nodes[0].capacity.logicalCores == 32);
    // The maximum, because both were derived from the same cores.
    CHECK(nodes[0].registeredSlots == 6);
    // Three jobs on one machine, counted once. `JobStarted` moves every entry at
    // the endpoint, so both siblings read 3 and the fold takes it once.
    CHECK(nodes[0].fleetJobsInFlight == 3);
    // Both toolchains named, sorted so the column order cannot move between reads.
    REQUIRE(nodes[0].fingerprints.size() == 2);
    CHECK(nodes[0].fingerprints[0] == Gcc13);
    CHECK(nodes[0].fingerprints[1] == Gcc14);
}

TEST_CASE("A heartbeat's job count is one machine's, not one per toolchain", "[distributed][registry][node-report]")
{
    // Exactly what a node does: `main.cpp` samples one `WorkerServer::InFlight()`
    // per round -- there being only one worker server per node, whatever it serves
    // -- and sends that ONE number to every registrar. Summing it across siblings
    // reported this machine's four jobs as eight, which is more work than it
    // registered slots for, and `TotalsFor` then rendered the difference as
    // capacity withheld by somebody else.
    //
    // This is the case that fails against a `+=` fold. The one above cannot: its
    // numbers arrive through `JobStarted`, which moves every sibling together, so
    // max and sum agree there by construction.
    Fixture fix;
    auto const gcc = fix.registry.Register(Announce(Gcc13, "10.0.0.2:7100", 6));
    auto const clang = fix.registry.Register(Announce(Gcc14, "10.0.0.2:7100", 6));

    REQUIRE(fix.registry.Heartbeat(gcc, Busy(4)));
    REQUIRE(fix.registry.Heartbeat(clang, Busy(4)));

    auto const nodes = fix.registry.NodeReports();
    REQUIRE(nodes.size() == 1);
    CHECK(nodes[0].fleetJobsInFlight == 4);
}

TEST_CASE("A job occupies the machine, not the toolchain it was leased against", "[distributed][registry][node-report]")
{
    // A lease names one entry, but the cores it consumes are the host's. Counting
    // it against that entry alone left the machine's OTHER toolchain advertising a
    // full complement of slots it was already using -- the "a worker accepts more
    // jobs than the scheduler believes it has" failure `SlotCeilingsFor` exists to
    // prevent, reached from the registry side.
    Fixture fix;
    auto const gcc = fix.registry.Register(Announce(Gcc13, "10.0.0.3:7100", 4));
    auto const clang = fix.registry.Register(Announce(Gcc14, "10.0.0.3:7100", 4));
    // A second machine, so the walk cannot pass by moving every entry it has.
    (void) fix.registry.Register(Announce(Gcc13, "10.0.0.4:7100", 4));

    fix.registry.JobStarted(gcc);

    auto const live = fix.registry.LiveWorkers();
    REQUIRE(live.size() == 3);
    for (auto const& worker: live)
    {
        INFO("worker " << worker.id << " at " << worker.endpoint);
        CHECK(worker.inFlight == (worker.endpoint == "10.0.0.3:7100" ? 1U : 0U));
    }

    // And back down again, on the same entries. A pair that moved different ones
    // would drift by a toolchain per job.
    fix.registry.JobFinished(clang);
    for (auto const& worker: fix.registry.LiveWorkers())
    {
        INFO("worker " << worker.id);
        CHECK(worker.inFlight == 0U);
    }
}

TEST_CASE("Two machines are two node reports", "[distributed][registry][node-report]")
{
    // The other direction, so the grouping above cannot pass by collapsing
    // everything: different endpoints are different machines.
    Fixture fix;
    (void) fix.registry.Register(Announce(Gcc13, "10.0.0.2:7100", 4));
    (void) fix.registry.Register(Announce(Gcc13, "10.0.0.3:7100", 4));

    auto const nodes = fix.registry.NodeReports();
    REQUIRE(nodes.size() == 2);
    // Ordered by endpoint, so a snapshot is reproducible.
    CHECK(nodes[0].endpoint == "10.0.0.2:7100");
    CHECK(nodes[1].endpoint == "10.0.0.3:7100");
}

TEST_CASE("A node cache report carries how stale its figures are", "[distributed][registry][cache]")
{
    // "This cache is empty" and "this node stopped answering and these are its last
    // figures" look identical without an age, and lead to opposite conclusions.
    Fixture fix;
    auto const id = fix.registry.Register(Announce(Gcc13, "10.0.0.2:7100", 4));
    NodeLoad load {};
    load.cache.hits = 10;
    CHECK(fix.registry.Heartbeat(id, load));

    fix.clock.advance(std::chrono::milliseconds { 250 });
    auto const caches = fix.registry.NodeCaches();
    REQUIRE(caches.size() == 1);
    CHECK(caches[0].heartbeatAge == std::chrono::milliseconds { 250 });
    CHECK(caches[0].load.hits == 10);
}

TEST_CASE("A machine's software version reaches its report, and a restart refreshes it", "[distributed][registry][version]")
{
    core::platform::ManualClock clock;
    WorkerRegistry registry { clock };

    (void) registry.Register(WorkerRegistration { .fingerprint = "gcc-14",
                                                  .endpoint = "10.0.0.1:7100",
                                                  .version = "1.4.2",
                                                  .slots = 4,
                                                  .codecs = {},
                                                  .capacity = NodeCapacity { .logicalCores = 8 } });

    auto const first = registry.NodeReports();
    REQUIRE(first.size() == 1);
    CHECK(first[0].version == "1.4.2");

    // The path a machine takes when it restarts -- and restarting on a new build is
    // exactly what an upgrade looks like. A version held over from the first
    // registration would leave the page reporting the old binary for as long as the
    // process stayed up, which is the one thing this column must never do.
    (void) registry.Register(WorkerRegistration { .fingerprint = "gcc-14",
                                                  .endpoint = "10.0.0.1:7100",
                                                  .version = "1.5.0",
                                                  .slots = 4,
                                                  .codecs = {},
                                                  .capacity = NodeCapacity { .logicalCores = 8 } });

    auto const second = registry.NodeReports();
    REQUIRE(second.size() == 1);
    CHECK(second[0].version == "1.5.0");
}

TEST_CASE("One machine serving two toolchains reports one version", "[distributed][registry][version]")
{
    core::platform::ManualClock clock;
    WorkerRegistry registry { clock };

    // Two registry entries, one process. They cannot disagree about the version, and
    // the report is one machine's row -- so this asserts the grain rather than a
    // blend of the two entries.
    for (auto const* fingerprint: { "gcc-14", "clang-20" })
        (void) registry.Register(WorkerRegistration { .fingerprint = fingerprint,
                                                      .endpoint = "10.0.0.1:7100",
                                                      .version = "1.4.2",
                                                      .slots = 4,
                                                      .codecs = {},
                                                      .capacity = NodeCapacity { .logicalCores = 8 } });

    auto const reports = registry.NodeReports();
    REQUIRE(reports.size() == 1);
    CHECK(reports[0].fingerprints.size() == 2);
    CHECK(reports[0].version == "1.4.2");
}

TEST_CASE("A node too old to report a version leaves it empty", "[distributed][registry][version]")
{
    core::platform::ManualClock clock;
    WorkerRegistry registry { clock };

    (void) registry.Register(WorkerRegistration { .fingerprint = "gcc-14",
                                                  .endpoint = "10.0.0.1:7100",
                                                  .slots = 4,
                                                  .codecs = {},
                                                  .capacity = NodeCapacity { .logicalCores = 8 } });

    auto const reports = registry.NodeReports();
    REQUIRE(reports.size() == 1);
    // Empty is the fact, not a value to be tidied into "unknown" here: what to show
    // for it is the renderer's decision, and it renders as the page's dash.
    CHECK(reports[0].version.empty());
}

// ---------------------------------------------------------------------------
// #1297: a worker that registered and is never chosen has no signal anywhere.
//
// The shape is #226's: one driver family fingerprints differently from the
// clients', so the scheduler never selects it, so NOTHING ARRIVES to be refused --
// and a refusal is the only thing either machine counts. Every reading on both ends
// stays healthy. The registry is the one place that knows a selection happened, so
// it is the one place the absence of one can be recorded.
// ---------------------------------------------------------------------------

namespace
{

/// A registry whose workers do not expire while a case advances the clock by minutes.
///
/// `Fixture` above times a worker out after one second, which is right for the
/// expiry cases it was written for and wrong for these: the fact under test is an
/// entry that has been sitting registered and unchosen for a long time, and it has to
/// still be IN the registry to report anything at all. Under the shorter timeout
/// these cases do not fail at the property -- the reports come back EMPTY and the
/// assertions are about a worker that is no longer there.
struct AgeFixture
{
    core::platform::ManualClock clock;
    WorkerRegistry registry { clock, std::chrono::hours { 1 } };
};

} // namespace

TEST_CASE("A worker nothing has been sent to reports no last-picked age", "[distributed][registry][lastpicked]")
{
    AgeFixture fix;
    (void) fix.registry.Register(Announce(Gcc13, "10.0.0.1:6676", 4));
    fix.clock.advance(std::chrono::milliseconds { 2'400'000 });

    auto const reports = fix.registry.LiveWorkerReports();
    REQUIRE(reports.size() == 1);
    // ABSENT, never zero. The two are opposite claims: zero says a job went here a
    // moment ago, which is the healthiest reading there is, and it would be printed
    // for the worker in the worst state in the fleet.
    CHECK_FALSE(reports[0].lastPickedAge.has_value());
    // The other half of the one-line answer. Without it an absence above cannot be
    // told from a node that came up a second ago, and "registered 40 minutes, never
    // picked" is the sentence this pair exists to render.
    CHECK(reports[0].registeredAge == std::chrono::milliseconds { 2'400'000 });
}

TEST_CASE("Picking a worker records when it was picked", "[distributed][registry][lastpicked]")
{
    AgeFixture fix;
    (void) fix.registry.Register(Announce(Gcc13, "10.0.0.1:6676", 4));
    fix.clock.advance(std::chrono::milliseconds { 5'000 });
    REQUIRE(fix.registry.Pick(Gcc13).has_value());
    fix.clock.advance(std::chrono::milliseconds { 2'000 });

    auto const reports = fix.registry.LiveWorkerReports();
    REQUIRE(reports.size() == 1);
    REQUIRE(reports[0].lastPickedAge.has_value());
    // The VALUE, not merely that one arrived: measured from the pick rather than
    // from the registration five seconds before it. An age anchored on the wrong
    // instant is present, plausible and wrong, which is the failure a
    // `has_value()`-only assertion cannot see.
    CHECK(Unwrap(reports[0].lastPickedAge) == std::chrono::milliseconds { 2'000 });
    CHECK(reports[0].registeredAge == std::chrono::milliseconds { 7'000 });
}

TEST_CASE("Choosing one of a machine's toolchains leaves the other never picked", "[distributed][registry][lastpicked]")
{
    // The case the whole grain exists for, and the one that separates a per-ENTRY
    // record from the tempting per-machine one. `JobStarted` deliberately moves
    // every entry sharing an endpoint, because a job occupies the machine -- so a
    // pick recorded there, or recorded across siblings here, would mark the unused
    // toolchain as reached the instant a job ran on the used one. That is exactly
    // the state #1297 exists to make visible, so it would be erased by the fix.
    AgeFixture fix;
    auto const used = fix.registry.Register(Announce(Gcc13, "10.0.0.1:6676", 4));
    auto const unused = fix.registry.Register(Announce(Gcc14, "10.0.0.1:6676", 4));

    fix.clock.advance(std::chrono::milliseconds { 1'000 });
    auto const picked = fix.registry.Pick(Gcc13);
    REQUIRE(picked.has_value());
    CHECK(picked->id == used);
    // Exactly what the scheduler does next, so the machine-wide accounting is live
    // rather than assumed absent: if it touched the pick record this would pass for
    // the wrong reason and the assertion below would be vacuous.
    fix.registry.JobStarted(picked->id);

    auto const reports = fix.registry.LiveWorkerReports();
    REQUIRE(reports.size() == 2);
    std::optional<std::chrono::milliseconds> usedAge;
    std::optional<std::chrono::milliseconds> unusedAge;
    bool sawUsed = false;
    bool sawUnused = false;
    for (auto const& report: reports)
    {
        if (report.info.id == used)
        {
            sawUsed = true;
            usedAge = report.lastPickedAge;
        }
        if (report.info.id == unused)
        {
            sawUnused = true;
            unusedAge = report.lastPickedAge;
        }
    }
    REQUIRE(sawUsed);
    REQUIRE(sawUnused);
    CHECK(usedAge.has_value());
    CHECK_FALSE(unusedAge.has_value());
    // And the machine-wide count DID move on both, which is what makes the split
    // above a real one rather than an artefact of nothing having happened.
    for (auto const& report: reports)
        CHECK(report.info.inFlight == 1);
}

TEST_CASE("A refusal records no pick on anybody", "[distributed][registry][lastpicked]")
{
    // What is recorded is *this entry was chosen*, never *somebody asked about this
    // toolchain*. Stamping on the way in would make a fingerprint every worker
    // refused read as picked, and leave the toolchain nobody ever asks for -- the
    // one case this exists to find -- as the only absence left.
    AgeFixture fix;
    auto const id = fix.registry.Register(Announce(Gcc13, "10.0.0.1:6676", 1));
    // Full, so the fleet has this toolchain and cannot take the job.
    CHECK(fix.registry.Heartbeat(id, Busy(1)).has_value());

    CHECK(fix.registry.Pick(Gcc13).error() == PickError::NoCapacity);
    CHECK(fix.registry.Pick(Gcc14).error() == PickError::NoWorker);

    auto const reports = fix.registry.LiveWorkerReports();
    REQUIRE(reports.size() == 1);
    CHECK_FALSE(reports[0].lastPickedAge.has_value());
}

TEST_CASE("Re-registering keeps a worker's pick record and its registration age", "[distributed][registry][lastpicked]")
{
    // Re-registration is NOT a restart, which is the whole reason this case exists.
    // `NodeAnnounce::AnnounceOnce` falls through from a failed `Heartbeat` straight
    // to `Register` in the same round, so any refused heartbeat -- `EndpointBusy`, or
    // `NotLeader` during an election -- takes this path on a machine that never went
    // away. `SchedulerService::Register` already says so where it declines to release
    // leases on this path.
    //
    // Clearing here would therefore destroy the finding on a transient: an entry
    // reading "registered 40 minutes, never picked" would drop to "registered 0
    // seconds, never picked", which says nothing, and every entry that HAD been
    // picked would momentarily read never-picked and push the fleet count above zero
    // on a healthy building fleet. `inFlight` and `load` are reset on this path
    // because the next heartbeat corrects them; these two have no corrective.
    AgeFixture fix;
    (void) fix.registry.Register(Announce(Gcc13, "10.0.0.1:6676", 4));
    REQUIRE(fix.registry.Pick(Gcc13).has_value());
    fix.clock.advance(std::chrono::milliseconds { 3'000 });

    auto const before = fix.registry.LiveWorkerReports();
    REQUIRE(before.size() == 1);
    // A control: the record IS populated, so the assertions below are about it
    // SURVIVING rather than about a field that was never written.
    REQUIRE(Unwrap(before[0].lastPickedAge) == std::chrono::milliseconds { 3'000 });
    REQUIRE(before[0].registeredAge == std::chrono::milliseconds { 3'000 });

    (void) fix.registry.Register(Announce(Gcc13, "10.0.0.1:6676", 4));
    fix.clock.advance(std::chrono::milliseconds { 1'000 });

    auto const after = fix.registry.LiveWorkerReports();
    REQUIRE(after.size() == 1);
    // Both keep counting from where they were, rather than from the re-registration.
    REQUIRE(after[0].lastPickedAge.has_value());
    CHECK(Unwrap(after[0].lastPickedAge) == std::chrono::milliseconds { 4'000 });
    CHECK(after[0].registeredAge == std::chrono::milliseconds { 4'000 });
    // And the fields that SHOULD be reset on this path still are, so this case
    // pins the difference between the two groups rather than freezing the whole
    // re-registration path.
    CHECK(after[0].info.inFlight == 0);
}

TEST_CASE("An entry that expires and comes back is a new registration", "[distributed][registry][lastpicked]")
{
    // The other half of the rule above, and what makes keeping the record safe: the
    // registry does draw the restart distinction, on the one piece of evidence it
    // has. An entry that lapses is ERASED, so what returns is genuinely new and
    // starts with no pick recorded and a registration age of zero.
    Fixture fix; // The short heartbeat timeout, because this case is about expiry.
    (void) fix.registry.Register(Announce(Gcc13, "10.0.0.1:6676", 4));
    REQUIRE(fix.registry.Pick(Gcc13).has_value());

    fix.clock.advance(std::chrono::milliseconds { 5'000 });
    CHECK(fix.registry.ExpireStale().size() == 1);

    (void) fix.registry.Register(Announce(Gcc13, "10.0.0.1:6676", 4));

    auto const reports = fix.registry.LiveWorkerReports();
    REQUIRE(reports.size() == 1);
    CHECK_FALSE(reports[0].lastPickedAge.has_value());
    CHECK(reports[0].registeredAge == std::chrono::milliseconds { 0 });
}

TEST_CASE("A registration age counts from the registration, not from the last heartbeat",
          "[distributed][registry][lastpicked]")
{
    // The two ages answer different questions and a live worker keeps the heartbeat
    // one small by definition, so deriving this from `lastSeen` would make it agree
    // with `heartbeatAge` forever -- present, plausible, and unable to say whether
    // an entry has been sitting unpicked for forty minutes or forty milliseconds.
    AgeFixture fix;
    auto const id = fix.registry.Register(Announce(Gcc13, "10.0.0.1:6676", 4));
    fix.clock.advance(std::chrono::milliseconds { 5'000 });
    CHECK(fix.registry.Heartbeat(id, Busy(0)).has_value());
    fix.clock.advance(std::chrono::milliseconds { 900 });

    auto const reports = fix.registry.LiveWorkerReports();
    REQUIRE(reports.size() == 1);
    CHECK(reports[0].heartbeatAge == std::chrono::milliseconds { 900 });
    CHECK(reports[0].registeredAge == std::chrono::milliseconds { 5'900 });
}

TEST_CASE("An excluded worker is skipped, and a fleet of nothing but excluded ones says so",
          "[distributed][registry][exclusion]")
{
    Fixture fix;
    (void) fix.registry.Register(Announce(Gcc13, "laptop.corp:6676", 8)); // more headroom: preferred when allowed
    auto const other = fix.registry.Register(Announce(Gcc13, "desk.corp:6676", 2));

    std::array<std::string_view, 1> const laptop { "laptop.corp:6676" };
    auto const picked = fix.registry.Pick(Gcc13, laptop);
    REQUIRE(picked.has_value());
    CHECK(picked->id == other);

    std::array<std::string_view, 2> const both { "laptop.corp:6676", "desk.corp:6676" };
    auto const none = fix.registry.Pick(Gcc13, both);
    REQUIRE_FALSE(none.has_value());
    CHECK(none.error() == PickError::Excluded);

    // An exclusion narrows only a MATCHING fleet: a toolchain nobody serves is still
    // NoWorker, whatever the client listed -- the misconfiguration must not hide behind it.
    CHECK(fix.registry.Pick(Gcc14, both).error() == PickError::NoWorker);
}

TEST_CASE("A busy fleet with one worker excluded is busy, not excluded", "[distributed][registry][exclusion]")
{
    Fixture fix;
    auto const laptop = fix.registry.Register(Announce(Gcc13, "laptop.corp:6676", 1));
    auto const desk = fix.registry.Register(Announce(Gcc13, "desk.corp:6676", 1));
    (void) laptop;
    fix.registry.JobStarted(desk); // desk full of this fleet's own work
    std::array<std::string_view, 1> const excluded { "laptop.corp:6676" };
    CHECK(fix.registry.Pick(Gcc13, excluded).error() == PickError::NoCapacity);
}

TEST_CASE("An exclusion list at the wire's own cap still finds the one worker left out",
          "[distributed][registry][exclusion]")
{
    // `MaxLeaseExclusions` bounds what a DECODED request can carry (`CompileCacheWire.hpp`);
    // `Pick` itself takes a `span` and enforces no limit of its own. This proves the
    // widest list the wire actually delivers works end to end, rather than only the
    // one- and two-entry lists the other exclusion cases use.
    Fixture fix;
    std::vector<std::string> endpoints;
    endpoints.reserve(CompileCacheWire::MaxLeaseExclusions);
    for (auto const index: std::views::iota(std::size_t { 0 }, CompileCacheWire::MaxLeaseExclusions))
    {
        endpoints.push_back(std::format("worker{}.corp:6676", index));
        (void) fix.registry.Register(Announce(Gcc13, endpoints.back(), 1));
    }
    std::vector<std::string_view> excluded;
    excluded.reserve(endpoints.size());
    for (auto const& endpoint: endpoints)
        excluded.push_back(endpoint);
    REQUIRE(excluded.size() == CompileCacheWire::MaxLeaseExclusions);

    // Every worker registered so far is excluded, so the whole fleet is off limits.
    CHECK(fix.registry.Pick(Gcc13, excluded).error() == PickError::Excluded);

    // One more worker, not on the list: still found, so a full-width exclusion list
    // does not overrun, truncate or otherwise mis-scan.
    auto const survivor = fix.registry.Register(Announce(Gcc13, "survivor.corp:6676", 1));
    auto const picked = fix.registry.Pick(Gcc13, excluded);
    REQUIRE(picked.has_value());
    CHECK(picked->id == survivor);
}

TEST_CASE("A heartbeat records where the worker was seen and what it answers on", "[distributed][registry][dialhint]")
{
    Fixture fix;
    auto const id = fix.registry.Register(Announce(Gcc13, "laptop.corp:6676", 1));
    std::vector<std::string> const interfaces { "10.8.0.7", "fe80::1" };
    REQUIRE(fix.registry
                .Heartbeat(id, NodeLoad {}, WorkerAddresses { .observedHost = "10.8.0.7", .interfaceAddresses = interfaces })
                .has_value());

    auto const picked = fix.registry.Pick(Gcc13);
    REQUIRE(picked.has_value());
    CHECK(picked->observedHost == "10.8.0.7");
    CHECK(picked->interfaceAddresses == interfaces);

    // The laptop's VPN address moved: the next heartbeat REPLACES both facts.
    std::vector<std::string> const moved { "10.8.0.42" };
    REQUIRE(
        fix.registry.Heartbeat(id, NodeLoad {}, WorkerAddresses { .observedHost = "10.8.0.42", .interfaceAddresses = moved })
            .has_value());
    auto const after = fix.registry.Pick(Gcc13);
    REQUIRE(after.has_value());
    CHECK(after->observedHost == "10.8.0.42");
    CHECK(after->interfaceAddresses == moved);
}

TEST_CASE("A heartbeat that reports no addresses clears the list an earlier exchange left",
          "[distributed][registry][dialhint]")
{
    // The decision this pins: an empty list REPLACES, it does not keep. The wire cannot tell
    // "reported none" from "said nothing" -- an absent field decodes as empty -- and every
    // worker that sends a list at REGISTER sends one on every heartbeat from the same sample,
    // so an empty list is the worker's current statement. Keeping the earlier one would pair
    // this beat's observed host with another exchange's list in the NAT check, and the cost
    // of clearing is only a lease without a hint, which dials the name as before.
    Fixture fix;
    std::vector<std::string> const atRegistration { "10.8.0.7" };
    auto registration = Announce(Gcc13, "laptop.corp:6676", 1);
    registration.observedHost = "10.8.0.7";
    registration.interfaceAddresses = atRegistration;
    auto const id = fix.registry.Register(registration);

    auto const registered = fix.registry.Pick(Gcc13);
    REQUIRE(registered.has_value());
    CHECK(registered->observedHost == "10.8.0.7");
    CHECK(registered->interfaceAddresses == atRegistration);

    REQUIRE(fix.registry.Heartbeat(id, NodeLoad {}, WorkerAddresses { .observedHost = "10.8.0.7", .interfaceAddresses = {} })
                .has_value());
    auto const beat = fix.registry.Pick(Gcc13);
    REQUIRE(beat.has_value());
    CHECK(beat->observedHost == "10.8.0.7");
    CHECK(beat->interfaceAddresses.empty());
}

TEST_CASE("A re-registration refreshes where the worker was seen and what it answers on",
          "[distributed][registry][dialhint]")
{
    Fixture fix;
    std::vector<std::string> const before { "10.8.0.7" };
    auto first = Announce(Gcc13, "laptop.corp:6676", 1);
    first.observedHost = "10.8.0.7";
    first.interfaceAddresses = before;
    auto const id = fix.registry.Register(first);

    // Same (fingerprint, endpoint), so the same entry -- reached again after a reconnect.
    std::vector<std::string> const after { "10.8.0.42", "192.168.1.20" };
    auto second = Announce(Gcc13, "laptop.corp:6676", 1);
    second.observedHost = "10.8.0.42";
    second.interfaceAddresses = after;
    CHECK(fix.registry.Register(second) == id);

    auto const picked = fix.registry.Pick(Gcc13);
    REQUIRE(picked.has_value());
    CHECK(picked->observedHost == "10.8.0.42");
    CHECK(picked->interfaceAddresses == after);
}

TEST_CASE("What a heartbeat reported outlives the request that carried it", "[distributed][registry][dialhint]")
{
    // `WorkerAddresses` borrows; the entry must own. Arranged so a view would dangle: the
    // strings are longer than any small-string buffer, so their characters live in freed
    // HEAP storage once the scope ends, and that storage is churned before the read.
    constexpr std::string_view Unique = "fd00:1234:5678:9abc:def0:1234:5678:9abc";
    static_assert(Unique.size() > 23, "must exceed every standard library's small-string buffer");

    Fixture fix;
    auto const id = fix.registry.Register(Announce(Gcc13, "laptop.corp:6676", 1));
    {
        std::string const observed { Unique };
        std::vector<std::string> const interfaces { std::string { Unique } };
        REQUIRE(
            fix.registry
                .Heartbeat(id, NodeLoad {}, WorkerAddresses { .observedHost = observed, .interfaceAddresses = interfaces })
                .has_value());
    }
    constexpr int ChurnCount = 64;
    std::vector<std::string> churn;
    churn.reserve(ChurnCount);
    for (auto const index: std::views::iota(0, ChurnCount))
        churn.emplace_back(Unique.size(), static_cast<char>('a' + (index % 26)));

    auto const picked = fix.registry.Pick(Gcc13);
    REQUIRE(picked.has_value());
    CHECK(picked->observedHost == Unique);
    REQUIRE(picked->interfaceAddresses.size() == 1);
    CHECK(picked->interfaceAddresses.front() == Unique);
}

TEST_CASE("A worker whose compile byte budget is spent is passed over until it frees",
          "[distributed][registry][byte-budget]")
{
    // #1667: the scheduler granted by slots and the worker admitted by slots AND bytes, so a
    // worker out of bytes refused `EndpointBusy` every grant the scheduler went on issuing.
    // Thirty slots, ten running, and 250 of 256 MiB held: ten jobs of 25 MiB, room for none.
    constexpr std::uint64_t MiB = 1ULL << 20;
    Fixture fix;
    auto const worker = fix.registry.Register(Announce(Gcc13, "10.0.0.1:6676", 30));
    auto const spent =
        NodeLoad { .inFlight = 10,
                   .cpuBusyPermille = std::nullopt,
                   .availableMemoryBytes = std::nullopt,
                   .freeScratchBytes = std::nullopt,
                   .compileBudget = CompileBudgetLoad { .budgetBytes = 256 * MiB, .inFlightBytes = 250 * MiB } };
    REQUIRE(fix.registry.Heartbeat(worker, spent));
    auto const refused = fix.registry.Pick(Gcc13);
    REQUIRE_FALSE(refused.has_value());
    // Slots free on paper, and still `NoCapacity`, never `Withdrawn`: the bytes are held by
    // this fleet's own compiles, and "withdrawn" would read as a machine busy elsewhere.
    REQUIRE(refused.error() == PickError::NoCapacity);

    // It frees -- the next beat holds 100 MiB under the same ten jobs -- and is picked again.
    REQUIRE(fix.registry.Heartbeat(
        worker,
        NodeLoad { .inFlight = 10,
                   .cpuBusyPermille = std::nullopt,
                   .availableMemoryBytes = std::nullopt,
                   .freeScratchBytes = std::nullopt,
                   .compileBudget = CompileBudgetLoad { .budgetBytes = 256 * MiB, .inFlightBytes = 100 * MiB } }));
    CHECK(fix.registry.Pick(Gcc13).has_value());

    // The control: the same ten jobs with no budget reported take no ceiling from it.
    REQUIRE(fix.registry.Heartbeat(worker,
                                   NodeLoad { .inFlight = 10,
                                              .cpuBusyPermille = std::nullopt,
                                              .availableMemoryBytes = std::nullopt,
                                              .freeScratchBytes = std::nullopt }));
    CHECK(fix.registry.Pick(Gcc13).has_value());
}
