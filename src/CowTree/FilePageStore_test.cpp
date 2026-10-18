// SPDX-License-Identifier: Apache-2.0
#include <catch2/catch_test_macros.hpp>

#include <algorithm>
#include <cstddef>
#include <cstdint>
#include <expected>
#include <filesystem>
#include <fstream>
#include <memory>
#include <optional>
#include <ranges>
#include <span>
#include <string>
#include <string_view>
#include <tuple>
#include <vector>

#include <CowTree/Bytes.hpp>
#include <CowTree/CowTree.hpp>
#include <CowTree/Errors.hpp>
#include <CowTree/FilePageStore.hpp>
#include <CowTree/Meta.hpp>
#include <CowTree/PageId.hpp>
#include <tests/MetaLayoutBuilders.hpp>
#include <tests/ScratchPath.hpp>
#include <tests/Unwrap.hpp>

// The lock-classifier case below asserts over the platform's own error
// constants: `errno` values on POSIX, `GetLastError()` values on Windows.
#if defined(_WIN32)
    #include <windows.h>
#else
    #include <sys/stat.h>

    #include <cerrno>

    #include <fcntl.h>
#endif

namespace
{

CowTree::BytesView B(std::string_view s) noexcept
{
    return CowTree::AsBytes(s);
}

std::string Decode(std::vector<std::byte> const& v)
{
    return std::string(CowTree::AsStringView({ v.data(), v.size() }));
}

/// Allocate a fresh tmp path that gets cleaned up by the destructor.
struct TempFile
{
    std::filesystem::path path;

    TempFile()
    {
        // `UniqueScratchPath`, never a random draw: `std::random_device` returns zero for
        // most draws on the host #1507 was reproduced on, so every process here agreed on
        // one filename and contended for its `flock`. See `StorageTestUtils.hpp`'s
        // `TempFile`, which carries the measurement.
        path = Pace::Testing::UniqueScratchPath("cowtree-test");
        path += ".cow";
        std::filesystem::remove(path);
    }
    ~TempFile()
    {
        std::error_code ec;
        std::filesystem::remove(path, ec);
    }
    TempFile(TempFile const&) = delete;
    TempFile& operator=(TempFile const&) = delete;
    TempFile(TempFile&&) = delete;
    TempFile& operator=(TempFile&&) = delete;
};

/// Page size the free-list cases below build their store with.
constexpr std::size_t FreeListPageSize = 4096;

/// Data pages the free-list fixture allocates: 1 and 2 become the chain, 3
/// stays live so a walk that erased too much is visible as well as one that
/// erased too little.
constexpr std::uint64_t FreeListFixturePages = 3;

/// Store `value` little-endian into the first 8 bytes of `page`.
///
/// Written out rather than memcpy'd because that is what the walk in
/// `RecoverExistingFile` decodes: a raw copy would agree with it on a
/// little-endian host and disagree on every other one.
/// @param page Destination page buffer; must hold at least 8 bytes.
/// @param value Next-page id to encode.
void PutNextLink(std::span<std::byte> page, std::uint64_t value) noexcept
{
    for (auto const i: std::views::iota(std::size_t { 0 }, sizeof(value)))
        page[i] = static_cast<std::byte>((value >> (8 * i)) & 0xFFU);
}

/// Write a free-list page's id count, which follows its `next` link.
void PutFreeListCount(std::span<std::byte> page, std::uint64_t count) noexcept
{
    for (auto const i: std::views::iota(std::size_t { 0 }, sizeof(count)))
        page[8 + i] = static_cast<std::byte>((count >> (8 * i)) & 0xFFU);
}

/// Write the `slot`-th page id of a free-list page.
void PutFreeListId(std::span<std::byte> page, std::size_t slot, std::uint64_t id) noexcept
{
    auto const at = 16 + (slot * sizeof(id));
    for (auto const i: std::views::iota(std::size_t { 0 }, sizeof(id)))
        page[at + i] = static_cast<std::byte>((id >> (8 * i)) & 0xFFU);
}

/// Open -- or reopen -- the free-list fixture's store at `path`.
///
/// One options block for both directions, because a seed and a reopen that
/// disagreed about `pageSize` would not fail: `RecoverExistingFile` takes the
/// on-disk value and carries on.
///
/// `Fsync` rather than the default `Batched` is historical: the seed used to put
/// its meta on disk through `WriteMeta`, which `Batched` buffers until a flush
/// boundary this fixture never reaches. Since #1624 the seed patches the meta
/// into the closed file instead (see `SeedFreeListChain`), so the durability no
/// longer decides whether the reopen finds a chain to walk.
/// @param path Filesystem path of the store file.
/// @return Whatever `FilePageStore::Open` answered.
auto OpenFreeListStore(std::filesystem::path const& path)
{
    CowTree::FilePageStore::Options opts;
    opts.path = path;
    opts.pageSize = FreeListPageSize;
    opts.durability = CowTree::FilePageStore::Durability::Fsync;
    return CowTree::FilePageStore::Open(opts);
}

// ---------------------------------------------------------------------------
// One damaged meta slot, in a real file (#632).
//
// The two-slot alternation is what makes an interrupted meta write survivable,
// and it is the CowTree library's own promise rather than Pace's --
// `src/CowTree/` is a standalone sibling any project can pick up, so a
// guarantee asserted only from the Pace suite would not travel with it.
//
// `CowTreeStorage_test.cpp` asks the OPERATOR's version of this question -- a
// daemon's store opens, serves the surviving commit and says nothing -- and it
// pins the surviving-slot property too, in "Recovering onto the surviving meta
// slot does not spend it". So that property is pinned in BOTH suites, for two
// different reasons, and this case is not the only place it lives: `_lastDurableSlot`
// is a `FilePageStore` member, so the LIBRARY's own guarantee has to be
// assertable without Pace present, while the other suite asserts what the
// same behaviour costs an operator.
//
// The fixtures are separate because a TEST helper cannot be shared: `src/tests/`
// and `src/Pace/` are off `CowTreeTests`' include path, which is the
// boundary that keeps this library standalone. That is narrower than "nothing
// can be shared" -- `src/CowTree/CowTree/` is on BOTH suites' paths under the
// same `<CowTree/...>` spelling.
//
// And what is duplicated is more than file I/O, which an earlier draft claimed:
// `MetaDamageOffset`, `SlotBytes`, `DecodeSlot` and `DamageMetaSlot` all exist
// twice, and three of those encode the on-disk LAYOUT (the slot offset and where
// the CRC'd payload is) rather than test plumbing. By the argument above they
// would belong in `src/CowTree/CowTree/` if they earned a public helper. They
// have not -- two call sites in two test binaries is not a public contract, and
// putting a damage helper in the shipped library to serve them would be worse.
//
// `OtherSlot` WAS on that list and has come off it: #726 needed "the slot we did
// not last make durable" in two production paths, so it is now
// `CowTree::OtherSlot` in `PageId.hpp` and both copies here are gone. That is
// the test of whether one of these earns promotion -- a production caller, not a
// second test.
//
// Damaged meta bytes have no API route -- `WriteMeta` encodes and CRCs whatever
// it is handed -- so the file is patched directly, at `Meta.hpp`'s own
// documented layout ("slot A at offset 0, slot B at offset PageSize"). The
// injection is asserted rather than assumed, so a layout that moved fails here
// instead of quietly damaging nothing.
//
// Watched refusing, one break at a time, measured on `gcc-debug`:
//
//   * reading the `CorruptMetas` condition as "EITHER slot failed" turns this
//     case red in `FilePageStore::RecoverExistingFile` (at `Open`) and again in
//     `CowTree::Open` (at `tree.Open()`);
//   * recording the DAMAGED slot as `_lastDurableSlot` turns it red at the
//     byte comparison below -- and turned only the Pace suite red before
//     that assertion was moved in here, which is why it was moved;
//   * inverting the both-valid `txnId` tie-break does NOT, correctly, since only
//     one slot is valid here; eight existing cases cover that comparison.
// ---------------------------------------------------------------------------

/// Page size the meta-damage case builds its store with.
///
/// The named minimum rather than the literal 512 it happens to equal: a bare
/// literal becomes an INVALID page size the day `MinPageSize` rises, and `Open`
/// would then refuse the store in a case whose whole point is that it opens.
constexpr std::size_t MetaDamagePageSize = CowTree::MinPageSize;

/// Byte the damage flips, as an offset inside an encoded meta page.
///
/// It has to land in the CRC'd payload -- the leading
/// `MetaEncodedSize - sizeof(u32)` bytes. Half way in is inside the payload for
/// any layout the encoder can grow into.
///
/// The region a decoder genuinely cannot see is NOT the trailing CRC word, which
/// is the tempting guess: `DecodeMeta` recomputes the CRC over the payload and
/// compares it against the stored word, so flipping the STORED word leaves the
/// recomputed one unchanged and the comparison always mismatches -- measured
/// `Corrupt` at both ends of it. What nothing reads is the zero PADDING past
/// `MetaEncodedSize`, where a flip decodes clean (measured at `pageSize - 1`, and
/// at offset 60 under meta layout 1 -- an offset layout 2 now spends on `dataPages`). `DamageMetaSlot` asserts detection
/// rather than trusting either claim.
constexpr std::size_t MetaDamageOffset = CowTree::MetaEncodedSize / 2;

/// Read a whole file into memory.
/// @param path The file to read.
/// @return Its bytes.
[[nodiscard]] std::vector<std::byte> ReadWholeFile(std::filesystem::path const& path)
{
    std::ifstream f { path, std::ios::binary | std::ios::ate };
    REQUIRE(f.good());
    auto const size = static_cast<std::size_t>(f.tellg());
    f.seekg(0);
    std::vector<std::byte> bytes(size);
    f.read(reinterpret_cast<char*>(bytes.data()), static_cast<std::streamsize>(size));
    REQUIRE(f.good());
    return bytes;
}

/// The bytes of one meta slot, out of a store file read whole.
/// @param file The whole store file.
/// @param slot Which slot.
/// @return A view over that slot's page.
[[nodiscard]] std::span<std::byte const> SlotBytes(std::span<std::byte const> file, CowTree::MetaSlot slot)
{
    REQUIRE(file.size() >= 2 * MetaDamagePageSize);
    return file.subspan(static_cast<std::size_t>(slot) * MetaDamagePageSize, MetaDamagePageSize);
}

/// Decode one meta slot out of a store file read whole.
/// @param file The whole store file.
/// @param slot Which slot.
/// @return Whatever `DecodeMeta` answered for it.
[[nodiscard]] std::expected<CowTree::Meta, CowTree::CowTreeError> DecodeSlot(std::span<std::byte const> file,
                                                                             CowTree::MetaSlot slot)
{
    auto const page = SlotBytes(file, slot);
    return CowTree::DecodeMeta(CowTree::BytesView { page.data(), page.size() });
}

/// Replace a file's contents wholesale.
/// @param path  The file to write.
/// @param bytes What it should hold afterwards.
void WriteWholeFile(std::filesystem::path const& path, std::span<std::byte const> bytes)
{
    std::ofstream f { path, std::ios::binary | std::ios::trunc };
    REQUIRE(f.good());
    f.write(reinterpret_cast<char const*>(bytes.data()), static_cast<std::streamsize>(bytes.size()));
    REQUIRE(f.good());
}

/// Build a store at `path` whose durable meta names a free-list chain rooted
/// at page 1, and close it. Page 3 is left live.
///
/// The chain's shape is the caller's, so a case that wants a damaged one says
/// so in data. The pages go in through the store's API, so this fixture restates no
/// data-page offset -- the thing the neighbouring sweep in `CowTreeStorage_test.cpp`
/// argues a fixture must not do -- but the META that names the chain is patched into the
/// closed file, as the `[meta][corrupt]` case below does: `WriteMeta` now stamps the
/// store's own free list on every durability (#1624), so no caller's `freeRoot` can ride
/// through it. That rule is about the DATA-page offset, which is private; `Meta.hpp`
/// documents the meta slots as the on-disk contract.
///
/// Both pages are written BEFORE the meta that names `freeRoot`, so this store
/// walks nothing while it is open -- the injection route is invisible in the
/// file, which is the same one a patch-the-closed-file route would leave.
///
/// It is NOT a file any writer in this tree produces, and that is deliberate
/// rather than an oversight: a real store's list is the store's own, written by
/// every meta write since #1624, so no caller chooses its shape -- and a case
/// that wants a damaged chain has no other route to one. The block comment
/// above the cases carries the whole argument.
/// @param path Filesystem path to create the store at.
/// @param nextOfOne What page 1 chains to.
/// @param nextOfTwo What page 2 chains to.
void SeedFreeListChain(std::filesystem::path const& path, CowTree::PageId nextOfOne, CowTree::PageId nextOfTwo)
{
    auto store = OpenFreeListStore(path);
    REQUIRE(store.has_value());

    for (auto const expected: std::views::iota(std::uint64_t { 1 }, FreeListFixturePages + 1))
    {
        auto const id = (*store)->Allocate();
        REQUIRE(id.has_value());
        REQUIRE(id->value == expected);
    }

    // Two free-list PAGES. Since #990 the list lives in dedicated pages rather than
    // being threaded through the free pages themselves -- a page holds `next`, a
    // count, and that many ids -- so the fixture writes that shape. The two damage
    // cases below are unchanged by it: an out-of-range `next` and a cycle are both
    // still expressed by the `next` field, which is what they seed.
    //
    // Page 1 names nothing and page 2 names page 3, so a walk that RAN is visible as
    // page 3 having become free while the list pages themselves stay live.
    std::vector<std::byte> page(FreeListPageSize, std::byte { 0 });
    PutNextLink(page, nextOfOne.value);
    PutFreeListCount(page, 0);
    REQUIRE((*store)->Write(CowTree::PageId { 1 }, CowTree::BytesView { page.data(), page.size() }).has_value());

    std::ranges::fill(page, std::byte { 0 });
    PutNextLink(page, nextOfTwo.value);
    PutFreeListCount(page, 1);
    PutFreeListId(page, 0, 3);
    REQUIRE((*store)->Write(CowTree::PageId { 2 }, CowTree::BytesView { page.data(), page.size() }).has_value());

    CowTree::Meta meta;
    meta.pageSize = static_cast<std::uint32_t>(FreeListPageSize);
    meta.txnId = 1;
    meta.root = CowTree::PageId::None();
    meta.freeRoot = CowTree::PageId { 1 };
    meta.itemCount = 0;
    meta.dataPages = FreeListFixturePages;

    // Patched into the closed file, in the slot a commit would have chosen: every commit's
    // `WriteMeta` now writes the STORE's own free list (#1624), so the caller's `freeRoot` can no
    // longer ride through it. The slot is the other one from the durable meta (#726), and a fresh
    // store's is A. Nothing here needs a particular slot anyway: `RecoverExistingFile` tie-breaks
    // on `txnId`, and the chain is the only thing about this file that is meant to be unusual.
    REQUIRE((*store)->LastDurableSlot() == CowTree::MetaSlot::A);
    store->reset();
    auto file = ReadWholeFile(path);
    REQUIRE(CowTree::EncodeMeta(std::span { file }.subspan(FreeListPageSize * static_cast<std::size_t>(CowTree::MetaSlot::B),
                                                           FreeListPageSize),
                                meta)
                .has_value());
    WriteWholeFile(path, file);
}

/// Flip one byte inside meta slot `slot` of the closed store file at `path`.
///
/// Both directions of the injection are asserted: the named slot must stop
/// decoding -- as `Corrupt`, since `DecodeMeta` checks the CRC before magic and
/// version, so damage never presents as a store of another vintage -- and the
/// other slot must still decode.
/// @param path Store file to damage in place.
/// @param slot Which meta slot to damage.
void DamageMetaSlot(std::filesystem::path const& path, CowTree::MetaSlot slot)
{
    auto bytes = ReadWholeFile(path);
    REQUIRE(bytes.size() >= 2 * MetaDamagePageSize);
    bytes[(static_cast<std::size_t>(slot) * MetaDamagePageSize) + MetaDamageOffset] ^= std::byte { 0xFF };
    WriteWholeFile(path, bytes);

    auto const after = ReadWholeFile(path);
    auto const damaged = DecodeSlot(after, slot);
    REQUIRE_FALSE(damaged.has_value());
    REQUIRE(damaged.error() == CowTree::CowTreeError::Corrupt);
    REQUIRE(DecodeSlot(after, CowTree::OtherSlot(slot)).has_value());
}

/// Open -- or reopen -- the meta-damage case's store at `path`.
/// @param path Filesystem path of the store file.
/// @return Whatever `FilePageStore::Open` answered.
auto OpenMetaDamageStore(std::filesystem::path const& path)
{
    CowTree::FilePageStore::Options opts;
    opts.path = path;
    opts.pageSize = MetaDamagePageSize;
    // `Batched` is STATED, though it is also the default, so the fixture goes on
    // describing its own store if the default ever moves -- cheaper than a runtime
    // assertion, which would fire for a precondition rather than for the property.
    //
    // It pins WHICH WRITER runs -- `FlushBatchLocked`, which the last assertion
    // below is about -- and nothing more than that. It does NOT select a different
    // slot rule: `WriteMeta` takes the identical `OtherSlot(_lastDurableSlot)`
    // branch under `Fsync` and `Batched`, and there is no `txnId mod 2` parity
    // anywhere (see `Meta.hpp`, which says so in as many words). This comment used
    // to claim that `Fsync` derived the slot from `CommitTxn`'s `txnId % 2`; that
    // expression was deleted in the very commit the claim was written in (#808).
    //
    // Measured, so the strength of the pin is not overstated: flipping this to
    // `Fsync` leaves the whole `[filestore]` suite green -- 503 assertions, 21
    // cases. The pin buys determinism about the path, not a passing assertion.
    opts.durability = CowTree::FilePageStore::Durability::Batched;
    return CowTree::FilePageStore::Open(opts);
}

} // namespace

TEST_CASE("FilePageStore opens a fresh file and reports the page size", "[filestore]")
{
    TempFile tmp;
    CowTree::FilePageStore::Options opts;
    opts.path = tmp.path;
    opts.pageSize = 4096;

    auto store = CowTree::FilePageStore::Open(opts);
    REQUIRE(store.has_value());
    REQUIRE((*store)->PageSize() == 4096U);
}

TEST_CASE("Allocated page survives close + reopen", "[filestore][persist]")
{
    TempFile tmp;
    CowTree::FilePageStore::Options opts;
    opts.path = tmp.path;
    opts.pageSize = 4096;

    {
        auto store = CowTree::FilePageStore::Open(opts);
        REQUIRE(store.has_value());
        CowTree::CowTree tree { **store };
        REQUIRE(tree.Open().has_value());

        auto txn = tree.BeginWrite();
        REQUIRE(txn.Put(B("persist"), B("yes")).has_value());
        REQUIRE(txn.Commit().has_value());
    }

    {
        auto store = CowTree::FilePageStore::Open(opts);
        REQUIRE(store.has_value());
        CowTree::CowTree tree { **store };
        REQUIRE(tree.Open().has_value());

        auto r = tree.BeginRead();
        auto got = r.Get(B("persist"));
        REQUIRE(got.has_value());
        REQUIRE(got->has_value());
        REQUIRE(Decode((*got).value_or(std::vector<std::byte> {})) == "yes");
    }
}

TEST_CASE("Durability=Fsync issues fsync calls per write", "[filestore][durability]")
{
    TempFile tmp;
    CowTree::FilePageStore::Options opts;
    opts.path = tmp.path;
    opts.durability = CowTree::FilePageStore::Durability::Fsync;

    auto store = CowTree::FilePageStore::Open(opts);
    REQUIRE(store.has_value());

    auto const before = (*store)->FsyncCallCount();
    CowTree::CowTree tree { **store };
    REQUIRE(tree.Open().has_value());
    auto txn = tree.BeginWrite();
    REQUIRE(txn.Put(B("k"), B("v")).has_value());
    REQUIRE(txn.Commit().has_value());

    REQUIRE((*store)->FsyncCallCount() > before);
}

TEST_CASE("Durability=None makes no fsync calls during writes", "[filestore][durability]")
{
    TempFile tmp;
    CowTree::FilePageStore::Options opts;
    opts.path = tmp.path;
    opts.durability = CowTree::FilePageStore::Durability::None;

    auto store = CowTree::FilePageStore::Open(opts);
    REQUIRE(store.has_value());

    // The fresh-file bootstrap issues one fsync; reset the comparison from there.
    auto const baseline = (*store)->FsyncCallCount();

    CowTree::CowTree tree { **store };
    REQUIRE(tree.Open().has_value());
    auto txn = tree.BeginWrite();
    REQUIRE(txn.Put(B("k"), B("v")).has_value());
    REQUIRE(txn.Commit().has_value());

    REQUIRE((*store)->FsyncCallCount() == baseline);
}

TEST_CASE("Durability=Batched coalesces fsyncs across commits (group commit)", "[filestore][durability][batched]")
{
    TempFile tmp;
    CowTree::FilePageStore::Options opts;
    opts.path = tmp.path;
    opts.durability = CowTree::FilePageStore::Durability::Batched;

    auto store = CowTree::FilePageStore::Open(opts);
    REQUIRE(store.has_value());
    auto const baseline = (*store)->FsyncCallCount();

    CowTree::CowTree tree { **store };
    REQUIRE(tree.Open().has_value());
    for (auto const i: std::views::iota(0, 10)) // fewer than the group-commit flush interval
    {
        auto const key = "k" + std::to_string(i);
        auto txn = tree.BeginWrite();
        REQUIRE(txn.Put(B(key), B("v")).has_value());
        REQUIRE(txn.Commit().has_value());
    }
    // No fsync yet: Batched defers it to the flush boundary.
    REQUIRE((*store)->FsyncCallCount() == baseline);
}

TEST_CASE("Durability=Batched defers freed-page reuse until the flush boundary", "[filestore][durability][batched]")
{
    TempFile tmp;
    CowTree::FilePageStore::Options opts;
    opts.path = tmp.path;
    opts.pageSize = 4096;
    opts.durability = CowTree::FilePageStore::Durability::Batched;

    auto store = CowTree::FilePageStore::Open(opts);
    REQUIRE(store.has_value());
    auto& pages = **store;
    std::vector<std::byte> const page(4096, std::byte { 0 });

    auto p1 = pages.Allocate();
    REQUIRE(p1.has_value());
    REQUIRE(pages.Write(*p1, CowTree::BytesView { page.data(), page.size() }).has_value());
    REQUIRE(pages.Free(*p1).has_value());

    // p1 is pending (its freeing isn't durable yet), so the next Allocate must
    // NOT hand it back — it would let a crash-rollback read an overwritten page.
    auto p2 = pages.Allocate();
    REQUIRE(p2.has_value());
    REQUIRE(p2->value != p1->value);

    // Cross the flush interval (64 meta writes) so the freeing becomes durable
    // and the pending page graduates to the reusable free list.
    CowTree::Meta meta;
    for (auto const i: std::views::iota(std::uint64_t { 1 }, std::uint64_t { 65 }))
    {
        meta.txnId = i;
        REQUIRE(pages.WriteMeta(meta).has_value());
    }

    // Now the previously-freed page is reusable.
    auto p3 = pages.Allocate();
    REQUIRE(p3.has_value());
    REQUIRE(p3->value == p1->value);
}

/// Page size the free-list growth cases build their store with: 510 ids per list page.
constexpr std::size_t GrowthPageSize = 4096;

/// A batched store and the one thing these cases do to it: commit and flush.
///
/// The meta names no tree, because the page store does not read one -- what these cases
/// exercise is the flush, which writes the free list and makes the batch's frees durable.
struct FlushingStore
{
    std::unique_ptr<CowTree::FilePageStore> store;
    CowTree::Meta meta {};

    /// Open -- or reopen -- a batched store at `path`.
    /// @param path Filesystem path of the store file.
    /// @param pageSize Page size to create it with; a reopen keeps the file's own.
    explicit FlushingStore(std::filesystem::path const& path, std::size_t pageSize = GrowthPageSize)
    {
        CowTree::FilePageStore::Options opts;
        opts.path = path;
        opts.pageSize = pageSize;
        opts.durability = CowTree::FilePageStore::Durability::Batched;
        auto opened = CowTree::FilePageStore::Open(opts);
        REQUIRE(opened.has_value());
        store = std::move(*opened);
        meta.pageSize = static_cast<std::uint32_t>(store->PageSize());
    }

    /// Buffer one commit and flush it: one group commit, exactly what the interval does.
    void CommitAndFlush()
    {
        ++meta.txnId;
        REQUIRE(store->WriteMeta(meta).has_value());
        REQUIRE(store->Flush().has_value());
    }

    /// Allocate `count` pages and write each with its own id, so a read can tell them apart.
    /// @return The pages, in allocation order.
    [[nodiscard]] std::vector<CowTree::PageId> AllocateWritten(std::size_t count) const
    {
        std::vector<CowTree::PageId> ids;
        std::vector<std::byte> page(store->PageSize(), std::byte { 0 });
        for ([[maybe_unused]] auto const i: std::views::iota(std::size_t { 0 }, count))
        {
            auto const id = store->Allocate();
            REQUIRE(id.has_value());
            PutNextLink(page, id->value);
            REQUIRE(store->Write(*id, CowTree::BytesView { page.data(), page.size() }).has_value());
            ids.push_back(*id);
        }
        return ids;
    }
};

TEST_CASE("A batched store churning at a steady size keeps its page count flat",
          "[filestore][durability][batched][freelist]")
{
    // The page store's half of the unbounded-file defect, with no Pace present: a
    // store that frees what it allocates must stop growing. Each round allocates
    // `PagesPerRound` pages, frees the previous round's and flushes -- one group commit per
    // round, which a cache at its byte bound does every 64 commits.
    //
    // The free list's own pages used to be taken by EXTENDING the file, and the previous
    // list's pages went back to the free list. So every flush with anything free grew the
    // file by a page while F stayed under one list page's 510 ids, and geometrically after.
    // A 64 GiB disk tier measured 103 GB, 89 % free pages.
    //
    // The SLACK is what makes that reachable: more pages free than one round reallocates,
    // so the free list is never empty at a flush. Without it the old code wrote no list at
    // all, and this case could not fail.
    //
    // `Rounds` is sized to the defect, not to the diagnosis's 3000. The old code added one
    // page per flush from the first, so 200 rounds leave it ~200 pages over a settled
    // count; the 3000 would have asked for 6000 fsyncs to show the same line, longer.
    constexpr std::size_t PagesPerRound = 4;
    constexpr std::size_t SlackPages = 2 * PagesPerRound;
    constexpr std::size_t Rounds = 200;

    TempFile tmp;
    FlushingStore s { tmp.path };
    for (auto const id: s.AllocateWritten(SlackPages))
        REQUIRE(s.store->Free(id).has_value());
    s.CommitAndFlush();

    std::vector<CowTree::PageId> previous;
    std::vector<std::size_t> totals;
    for ([[maybe_unused]] auto const round: std::views::iota(std::size_t { 0 }, Rounds))
    {
        auto current = s.AllocateWritten(PagesPerRound);
        for (auto const id: previous)
            REQUIRE(s.store->Free(id).has_value());
        previous = std::move(current);
        s.CommitAndFlush();
        totals.push_back(s.store->TotalDataPages());
    }

    // Settled by round 2: round 1 still draws on the slack, and round 2's flush is the
    // first with nothing left in `_freeList` to write its list into, so it extends once.
    auto const settled = totals[1];
    auto const [lowest, highest] = std::ranges::minmax(totals | std::views::drop(1));
    INFO("pages after round 2: " << settled << ", after the last: " << totals.back() << ", range " << lowest << ".."
                                 << highest);
    CHECK(lowest == settled);
    CHECK(highest == settled);
    // The counter and the file agree, so the flatness is the FILE's and not a figure's.
    CHECK(std::filesystem::file_size(tmp.path) == (2 + s.store->TotalDataPages()) * GrowthPageSize);
}

TEST_CASE("A batched store cuts its free tail and reopens over the shorter file",
          "[filestore][durability][batched][freelist][persist]")
{
    // The file SHRINKS, so a store already past its bound converges with no operator
    // action. Free the upper three quarters of a written store and flush three times: the
    // first makes the freeing durable, the second still has the previous list's page at
    // the top (it is pending, the superseded meta's `freeRoot`), and the third cuts
    // everything above the two pages the alternating list lives in.
    constexpr std::size_t LivePages = 16;
    constexpr std::size_t FreedPages = 48;
    constexpr std::size_t ListPages = 2;

    TempFile tmp;
    std::vector<CowTree::PageId> live;
    std::size_t peak = 0;
    {
        FlushingStore s { tmp.path };
        live = s.AllocateWritten(LivePages);
        for (auto const id: s.AllocateWritten(FreedPages))
            REQUIRE(s.store->Free(id).has_value());
        s.CommitAndFlush();
        peak = s.store->TotalDataPages();
        s.CommitAndFlush();
        s.CommitAndFlush();

        INFO("pages at the peak: " << peak << ", after three flushes: " << s.store->TotalDataPages());
        REQUIRE(peak > LivePages + FreedPages);
        CHECK(s.store->TotalDataPages() == LivePages + ListPages);
        CHECK(std::filesystem::file_size(tmp.path) == (2 + LivePages + ListPages) * GrowthPageSize);
    }

    // The durable list was written BEFORE the cut and still names the ids above the new
    // end. Recovery skips such an ENTRY; refusing it as `Corrupt` would make every store
    // that ever shrank unopenable.
    FlushingStore s { tmp.path };
    CHECK(s.store->TotalDataPages() == LivePages + ListPages);
    for (auto const id: live)
    {
        auto const read = s.store->Read(id);
        REQUIRE(read.has_value());
        std::vector<std::byte> expected(GrowthPageSize, std::byte { 0 });
        PutNextLink(expected, id.value);
        CHECK(std::ranges::equal(*read, expected));
    }
    // The previous list's page is free in the reopened world, and it is the lowest free id.
    auto const next = s.store->Allocate();
    REQUIRE(next.has_value());
    CHECK(next->value == LivePages + 1);
}

TEST_CASE("A flush writes its free list into no page the meta it supersedes still needs",
          "[filestore][durability][batched][freelist][meta][corrupt]")
{
    // The crash-safety argument of a free list written into free pages, made red-capable.
    // The list's pages may come only from `_freeList`, free in the durable meta's world AND
    // the next one's. Two kinds of page are NOT, and a flush that took either would damage
    // the meta it supersedes -- which is the meta a crash, or a damaged slot, falls back to:
    //
    //   - a PENDING free: the durable meta's tree still references it;
    //   - a page of the PREVIOUS list: the durable meta's `freeRoot` names it.
    //
    // A clean reopen never reads the superseded meta, so every other case here would pass
    // a build that broke either rule. This one reopens on it: commit k, free some of k's
    // tree, commit k+1, damage k+1's slot, and require k's world to come back intact --
    // every tree page reading back what it held, and no allocation handing one out.
    //
    // Small pages, because `DamageMetaSlot` addresses the slots at `MinPageSize`.
    constexpr std::size_t TreePages = 16;
    constexpr std::size_t FreedAtK1 = 8;
    constexpr std::size_t Spare = 8;

    TempFile tmp;
    std::vector<CowTree::PageId> tree;
    CowTree::MetaSlot damaged {};
    {
        FlushingStore s { tmp.path, MetaDamagePageSize };
        tree = s.AllocateWritten(TreePages);
        for (auto const id: s.AllocateWritten(Spare))
            REQUIRE(s.store->Free(id).has_value());
        s.CommitAndFlush(); // the spare pages' freeing becomes durable
        s.CommitAndFlush(); // k: the list moves into a free page; the first list's page is pending

        // Batch k+1 frees the upper half of k's tree: pending, and still k's.
        for (auto const id: tree | std::views::drop(TreePages - FreedAtK1))
            REQUIRE(s.store->Free(id).has_value());
        s.CommitAndFlush(); // k+1
        damaged = s.store->LastDurableSlot();
    }
    DamageMetaSlot(tmp.path, damaged);

    FlushingStore s { tmp.path };
    // The reopen landed on k, the slot that was not damaged.
    REQUIRE(s.store->LastDurableSlot() == CowTree::OtherSlot(damaged));

    // Every page of k's tree reads back what it held, the half k+1 freed included.
    for (auto const id: tree)
    {
        INFO("tree page " << id.value);
        auto const read = s.store->Read(id);
        REQUIRE(read.has_value());
        std::vector<std::byte> expected(s.store->PageSize(), std::byte { 0 });
        PutNextLink(expected, id.value);
        CHECK(std::ranges::equal(*read, expected));
    }

    // And k's free list names none of them: draining it hands out no tree page. Bounded by
    // the pages the file holds -- the first id past them is an extension, and ends the walk.
    auto const held = s.store->TotalDataPages();
    for ([[maybe_unused]] auto const i: std::views::iota(std::size_t { 0 }, held + 1))
    {
        auto const id = s.store->Allocate();
        REQUIRE(id.has_value());
        if (id->value > held)
            break;
        INFO("allocated " << id->value);
        CHECK(std::ranges::find(tree, *id) == tree.end());
    }
}

TEST_CASE("Durability=Batched flushes buffered writes on graceful close", "[filestore][durability][batched]")
{
    TempFile tmp;
    CowTree::FilePageStore::Options opts;
    opts.path = tmp.path;
    opts.durability = CowTree::FilePageStore::Durability::Batched;

    {
        auto store = CowTree::FilePageStore::Open(opts);
        REQUIRE(store.has_value());
        CowTree::CowTree tree { **store };
        REQUIRE(tree.Open().has_value());
        for (auto const i: std::views::iota(0, 5)) // fewer than the flush interval -> only the dtor flush persists these
        {
            auto const key = "k" + std::to_string(i);
            auto txn = tree.BeginWrite();
            REQUIRE(txn.Put(B(key), B("value")).has_value());
            REQUIRE(txn.Commit().has_value());
        }
    } // FilePageStore destructor flushes the buffered batch

    auto store = CowTree::FilePageStore::Open(opts);
    REQUIRE(store.has_value());
    CowTree::CowTree tree { **store };
    REQUIRE(tree.Open().has_value());
    auto reader = tree.BeginRead();
    auto got = reader.Get(B("k3"));
    REQUIRE(got.has_value());
    REQUIRE(got->has_value());
    REQUIRE(Decode((*got).value_or(std::vector<std::byte> {})) == "value");
}

TEST_CASE("Durability=Batched defers meta-slot writes until the flush boundary", "[filestore][durability][batched]")
{
    TempFile tmp;
    CowTree::FilePageStore::Options opts;
    opts.path = tmp.path;
    opts.pageSize = 4096;
    opts.durability = CowTree::FilePageStore::Durability::Batched;

    auto store = CowTree::FilePageStore::Open(opts);
    REQUIRE(store.has_value());
    CowTree::CowTree tree { **store };
    REQUIRE(tree.Open().has_value());

    for (auto const i: std::views::iota(0, 10)) // fewer than the flush interval
    {
        auto const key = "k" + std::to_string(i);
        auto txn = tree.BeginWrite();
        REQUIRE(txn.Put(B(key), B("v")).has_value());
        REQUIRE(txn.Commit().has_value());
    }

    // Crash-safety invariant: intermediate commits never overwrite a meta slot
    // in place, so both slots still hold the bootstrap txnId 0. (The old code
    // pwrote a fresh, un-fsynced txnId to an alternating slot on every commit,
    // so a torn write inside the window could leave NO recoverable slot.)
    auto const a = (*store)->ReadMeta(CowTree::MetaSlot::A);
    auto const b = (*store)->ReadMeta(CowTree::MetaSlot::B);
    REQUIRE(a.has_value());
    REQUIRE(b.has_value());
    REQUIRE(a->txnId == 0U);
    REQUIRE(b->txnId == 0U);
}

TEST_CASE("Durability=Batched: a crash inside the unflushed window reopens consistent",
          "[filestore][durability][batched][crash]")
{
    TempFile tmp;
    CowTree::FilePageStore::Options opts;
    opts.path = tmp.path;
    opts.pageSize = 4096;
    opts.durability = CowTree::FilePageStore::Durability::Batched;

    {
        auto store = CowTree::FilePageStore::Open(opts);
        REQUIRE(store.has_value());
        CowTree::CowTree tree { **store };
        REQUIRE(tree.Open().has_value());
        for (auto const i: std::views::iota(0, 10)) // < flush interval -> nothing durable yet
        {
            auto const key = "k" + std::to_string(i);
            auto txn = tree.BeginWrite();
            REQUIRE(txn.Put(B(key), B("v")).has_value());
            REQUIRE(txn.Commit().has_value());
        }
        (*store)->SimulateCrashForTest(); // hard crash: no flush
    }

    // Reopen MUST succeed (never CorruptMetas) and show the last durable state
    // -- here the empty bootstrap. The window is cleanly lost, not half-applied.
    auto store = CowTree::FilePageStore::Open(opts);
    REQUIRE(store.has_value());
    CowTree::CowTree tree { **store };
    REQUIRE(tree.Open().has_value());
    auto r = tree.BeginRead();
    auto got = r.Get(B("k0"));
    REQUIRE(got.has_value()); // a clean miss, not an error / corruption
    REQUIRE_FALSE(got->has_value());
}

TEST_CASE("Durability=Batched: commits flushed before a crash survive it", "[filestore][durability][batched][crash]")
{
    TempFile tmp;
    CowTree::FilePageStore::Options opts;
    opts.path = tmp.path;
    opts.pageSize = 4096;
    opts.durability = CowTree::FilePageStore::Durability::Batched;

    {
        auto store = CowTree::FilePageStore::Open(opts);
        REQUIRE(store.has_value());
        CowTree::CowTree tree { **store };
        REQUIRE(tree.Open().has_value());
        for (auto const i: std::views::iota(0, 80)) // > flush interval (64): the first window is made durable
        {
            auto const key = "k" + std::to_string(i);
            auto txn = tree.BeginWrite();
            REQUIRE(txn.Put(B(key), B("v")).has_value());
            REQUIRE(txn.Commit().has_value());
        }
        (*store)->SimulateCrashForTest();
    }

    auto store = CowTree::FilePageStore::Open(opts);
    REQUIRE(store.has_value());
    CowTree::CowTree tree { **store };
    REQUIRE(tree.Open().has_value());
    auto r = tree.BeginRead();
    // A key from the flushed first window survives the crash...
    auto early = r.Get(B("k0"));
    REQUIRE(early.has_value());
    REQUIRE(early->has_value());
    REQUIRE(Decode((*early).value_or(std::vector<std::byte> {})) == "v");
    // ...while a key written only in the unflushed tail is cleanly lost.
    auto tail = r.Get(B("k79"));
    REQUIRE(tail.has_value());
    REQUIRE_FALSE(tail->has_value());
}

// ============================================================================
// Exclusive claim on the backing file
//
// A second store on one path used to be silent data loss on POSIX: both opened,
// both wrote meta pages, and whichever committed last decided what the other
// one's transactions had never happened. Windows refused it, but as a generic
// open failure that named no cause.
//
// These run in ONE process on purpose. `flock` is per open file description
// and a Windows share mode is per handle, so a second `Open` from here meets
// exactly the kernel enforcement a second process would -- and unlike a second
// process, it runs on every platform in CI.
// ============================================================================

TEST_CASE("A second store on one path is refused as InUse", "[filestore][lock]")
{
    TempFile tmp;
    CowTree::FilePageStore::Options opts;
    opts.path = tmp.path;

    auto first = CowTree::FilePageStore::Open(opts);
    REQUIRE(first.has_value());
    REQUIRE((*first)->StoreLockState() == CowTree::FilePageStore::LockState::Held);

    auto second = CowTree::FilePageStore::Open(opts);
    REQUIRE_FALSE(second.has_value());
    REQUIRE(second.error().cause == CowTree::CowTreeError::InUse);

    // #1507: the refusal carries the system error it was classified FROM. Asserted as a
    // ROUND TRIP through the classifier rather than against a named errno, because the two
    // platforms report this condition with different values -- EWOULDBLOCK/EAGAIN against
    // ERROR_SHARING_VIOLATION -- and what the acceptance clause asks is that the code which
    // PRODUCED this arm is the code reported. Naming one errno would make the case a
    // statement about the host it was written on.
    REQUIRE(second.error().systemCode.has_value());
    auto const systemCode = Pace::Testing::Unwrap(second.error().systemCode);
    INFO("system code: " << systemCode);
    CHECK(CowTree::FilePageStore::ClassifyLockFailure(systemCode) == CowTree::FilePageStore::LockFailure::Contended);
}

TEST_CASE("A store refused as InUse leaves the first one writable", "[filestore][lock]")
{
    TempFile tmp;
    CowTree::FilePageStore::Options opts;
    opts.path = tmp.path;

    auto first = CowTree::FilePageStore::Open(opts);
    REQUIRE(first.has_value());
    CowTree::CowTree tree { **first };
    REQUIRE(tree.Open().has_value());

    // The refusal must touch nothing: a guard that costs the incumbent its
    // store would be worse than the corruption it prevents.
    REQUIRE_FALSE(CowTree::FilePageStore::Open(opts).has_value());

    auto txn = tree.BeginWrite();
    REQUIRE(txn.Put(B("survivor"), B("yes")).has_value());
    REQUIRE(txn.Commit().has_value());

    auto reader = tree.BeginRead();
    auto got = reader.Get(B("survivor"));
    REQUIRE(got.has_value());
    REQUIRE(got->has_value());
    REQUIRE(Decode((*got).value_or(std::vector<std::byte> {})) == "yes");
}

TEST_CASE("Closing a store releases the file for the next one", "[filestore][lock]")
{
    TempFile tmp;
    CowTree::FilePageStore::Options opts;
    opts.path = tmp.path;

    {
        auto first = CowTree::FilePageStore::Open(opts);
        REQUIRE(first.has_value());
    }

    // Every restart depends on this, so it is asserted rather than assumed:
    // the claim is released by the close in the destructor, not held to the
    // end of the process.
    auto second = CowTree::FilePageStore::Open(opts);
    REQUIRE(second.has_value());
}

TEST_CASE("A crashed store releases the file", "[filestore][lock][crash]")
{
    TempFile tmp;
    CowTree::FilePageStore::Options opts;
    opts.path = tmp.path;

    auto crashed = CowTree::FilePageStore::Open(opts);
    REQUIRE(crashed.has_value());
    (*crashed)->SimulateCrashForTest();

    // What the kernel does for a process that dies: the descriptor goes, and
    // the claim goes with it. A recovering daemon must not have to clear
    // anything by hand -- that is the failure mode a lock FILE would have.
    auto next = CowTree::FilePageStore::Open(opts);
    REQUIRE(next.has_value());
}

TEST_CASE("ClassifyLockFailure maps this platform's lock errors", "[filestore][lock]")
{
    using LockFailure = CowTree::FilePageStore::LockFailure;

    struct Row
    {
        int systemError;
        LockFailure expected;
        char const* what;
    };

    // Asserted as a table because the arms differ per platform and the one
    // that matters most cannot be provoked: no filesystem CI runs on reports
    // "cannot lock", so `Unsupported` would otherwise be reasoning nobody ever
    // checks.
#if defined(_WIN32)
    auto const rows = std::vector<Row> {
        { .systemError = ERROR_SHARING_VIOLATION,
          .expected = LockFailure::Contended,
          .what = "another handle holds the file" },
        { .systemError = ERROR_LOCK_VIOLATION, .expected = LockFailure::Contended, .what = "a byte-range lock refuses us" },
        { .systemError = ERROR_FILE_NOT_FOUND, .expected = LockFailure::Fatal, .what = "the open itself failed" },
        { .systemError = ERROR_ACCESS_DENIED, .expected = LockFailure::Fatal, .what = "no rights to the file" },
    };
#else
    auto const rows = std::vector<Row> {
        { .systemError = EWOULDBLOCK, .expected = LockFailure::Contended, .what = "another descriptor holds the file" },
        { .systemError = EAGAIN, .expected = LockFailure::Contended, .what = "the same condition, other spelling" },
        { .systemError = EBADF, .expected = LockFailure::Fatal, .what = "our own bug, not the filesystem's limit" },
        { .systemError = ENOLCK, .expected = LockFailure::Fatal, .what = "transient, not a capability statement" },
        { .systemError = EINVAL, .expected = LockFailure::Unsupported, .what = "this descriptor cannot be flocked" },
        { .systemError = EOPNOTSUPP, .expected = LockFailure::Unsupported, .what = "the filesystem does not implement it" },
    };
#endif

    for (auto const& row: rows)
    {
        INFO(row.what);
        CHECK(CowTree::FilePageStore::ClassifyLockFailure(row.systemError) == row.expected);
    }
}

TEST_CASE("An empty file that already existed is not blanked into a fresh store", "[filestore][open]")
{
    TempFile tmp;
    {
        std::ofstream created { tmp.path, std::ios::binary };
        REQUIRE(created.good());
    }
    REQUIRE(std::filesystem::file_size(tmp.path) == 0U);

    CowTree::FilePageStore::Options opts;
    opts.path = tmp.path;

    // Whether to bootstrap is decided from the pre-open `exists()` AND the
    // length read back under the claim, so this pins the conservative half of
    // that pair: a file the operator put there is never silently initialised
    // just because it happens to be empty. It is refused, exactly as before.
    auto const store = CowTree::FilePageStore::Open(opts);
    REQUIRE_FALSE(store.has_value());
    REQUIRE(store.error().cause == CowTree::CowTreeError::CorruptMetas);

    // The CONTROL for #1507's system code, and the reason it is an optional rather than an
    // int. This refusal is decided from meta-page bytes already read, so there is no system
    // call behind it and nothing to report -- and *absent* must not be spelled `0`, which is
    // `errno`'s own value for success. Without this assertion a build that stamped the last
    // errno it happened to see onto every refusal would satisfy the case that asserts the
    // lock refusal carries one.
    CHECK_FALSE(store.error().systemCode.has_value());
}

// ---------------------------------------------------------------------------
// The free-list walk at Open.
//
// `docs/operations/corrupt-store.md` tells an operator that opening a store
// "reads the two meta slots, walks the free list, and looks up two reserved
// keys", and that damage anywhere in that reach refuses the process to start
// with `Corrupt`. Two of those three are pinned by `CowTreeStorage_test`
// against an `InMemoryPageStore`; the free-list walk is not reachable from
// there at all, because it lives in `FilePageStore::RecoverExistingFile` and
// has no in-memory equivalent (#580). These three cases are that third one,
// and they need a real file for it.
//
// The chain is seeded through `FilePageStore`'s own API so a case can choose its
// shape -- a damaged link has no other route. It is not the only writer: a store writes a
// real list at every meta write under every durability (a batched flush since #990, every
// Fsync and None commit since #1624), so these refusals ARE reachable by damage in the field. What none of them covers is an
// ENTRY past the end of the file, which is not damage at all once the store cuts its free tail -- the reopen half of "A
// batched store cuts its free tail" pins that one.
// ---------------------------------------------------------------------------

TEST_CASE("An intact free-list chain is walked at Open and its pages are recycled", "[filestore][open][freelist]")
{
    TempFile tmp;
    SeedFreeListChain(tmp.path, CowTree::PageId { 2 }, CowTree::PageId::None());

    auto const store = OpenFreeListStore(tmp.path);
    REQUIRE(store.has_value());

    // The control direction, and the one that makes the two damage cases below
    // mean anything: an Open that never walked the chain would leave pages 1
    // and 2 live and would also, trivially, never refuse. `Read` rejects a page
    // that is not live, so this says the walk ran and consumed exactly the two
    // pages the chain named.
    REQUIRE((*store)->TotalDataPages() == FreeListFixturePages);
    // The list's own pages stay LIVE -- that is what makes the layout safe, since
    // nothing hands them out for `Allocate` to overwrite. What the walk consumed is
    // page 3, the one the list NAMED. `Read` rejects a page that is not live, so this
    // says the walk ran and freed exactly what it was told to.
    REQUIRE((*store)->Read(CowTree::PageId { 1 }).has_value());
    REQUIRE((*store)->Read(CowTree::PageId { 2 }).has_value());
    REQUIRE_FALSE((*store)->Read(CowTree::PageId { 3 }).has_value());
}

TEST_CASE("A free-list link pointing past the end of the file refuses the store at Open",
          "[filestore][open][freelist][corrupt]")
{
    TempFile tmp;
    // Page 1 chains to a page the file does not have. This is the shape a
    // truncated or partially-rewritten store takes, and it is the one an
    // unguarded walk would follow into a `ReadAt` past the end.
    SeedFreeListChain(tmp.path, CowTree::PageId { 1'000'000 }, CowTree::PageId::None());

    auto const store = OpenFreeListStore(tmp.path);
    REQUIRE_FALSE(store.has_value());
    // `Corrupt`, which `CowTreeStorage::TranslateError` carries out to the
    // operator as `StorageErrorCode::Corrupt` with `context=FilePageStore::Open`
    // -- the exact line the operator page quotes. Not `CorruptMetas`: both meta
    // slots read back fine, and it is the structure beneath them that did not
    // hold. Not `OutOfRange` or `IoError` either, both of which say the caller
    // asked for something silly rather than that the store is damaged.
    REQUIRE(store.error().cause == CowTree::CowTreeError::Corrupt);
}

TEST_CASE("A free-list chain that loops refuses the store at Open", "[filestore][open][freelist][corrupt]")
{
    TempFile tmp;
    // Page 2 links back to page 1. Every id in the loop is in range, so the
    // bounds check above cannot see this one: without the visited set `Open`
    // never returns and `_freeList` grows without bound, which is an unbounded
    // answer rather than a wrong one and is why it is a separate case.
    SeedFreeListChain(tmp.path, CowTree::PageId { 2 }, CowTree::PageId { 1 });

    auto const store = OpenFreeListStore(tmp.path);
    REQUIRE_FALSE(store.has_value());
    REQUIRE(store.error().cause == CowTree::CowTreeError::Corrupt);
}

#if !defined(_WIN32)
TEST_CASE("The store descriptor does not survive an exec", "[filestore][lock]")
{
    TempFile tmp;
    CowTree::FilePageStore::Options opts;
    opts.path = tmp.path;

    auto const store = CowTree::FilePageStore::Open(opts);
    REQUIRE(store.has_value());

    struct stat target {};
    REQUIRE(::stat(tmp.path.c_str(), &target) == 0);

    // A `flock` lives on the open file description and is released only when
    // the LAST descriptor on it closes, so a copy inherited by a compiler child
    // would keep the store claimed after this process exits -- and the next
    // start would blame a second node that does not exist. Found by scanning
    // rather than by asking the store, because the point is what any inherited
    // copy would look like, not what the member happens to hold.
    bool found = false;
    for (auto const fd: std::views::iota(0, 256))
    {
        struct stat here {};
        if (::fstat(fd, &here) != 0)
            continue;
        if (here.st_dev != target.st_dev || here.st_ino != target.st_ino)
            continue;
        auto const descriptorFlags = ::fcntl(fd, F_GETFD);
        REQUIRE(descriptorFlags != -1);
        CHECK((descriptorFlags & FD_CLOEXEC) != 0);
        found = true;
    }
    // Without this the case passes by finding nothing at all.
    REQUIRE(found);
}
#endif

TEST_CASE("One damaged meta slot opens on the surviving slot's commit", "[filestore][open][meta][corrupt]")
{
    // Two durable commits, so BOTH slots carry a real one. With a single commit
    // the other slot still holds the blank `txnId == 0` meta `BootstrapNewFile`
    // wrote, and "recovered onto the previous commit" would be
    // indistinguishable from "recovered onto nothing".
    TempFile tmp;
    {
        auto store = OpenMetaDamageStore(tmp.path);
        REQUIRE(store.has_value());
        CowTree::CowTree tree { **store };
        REQUIRE(tree.Open().has_value());
        for (auto const* const key: { "first", "second" })
        {
            auto txn = tree.BeginWrite();
            REQUIRE(txn.Put(B(key), B("value")).has_value());
            REQUIRE(txn.Commit().has_value());
            // The default `Batched` durability buffers the meta until a flush
            // boundary, so without this both commits would collapse into the
            // one write the destructor makes and only one slot would move.
            REQUIRE((*store)->Flush().has_value());
        }
    }

    auto const seeded = ReadWholeFile(tmp.path);
    auto const seededA = DecodeSlot(seeded, CowTree::MetaSlot::A);
    auto const seededB = DecodeSlot(seeded, CowTree::MetaSlot::B);
    REQUIRE(seededA.has_value());
    REQUIRE(seededB.has_value());
    REQUIRE(seededA->txnId != seededB->txnId);
    // Which slot the alternation left the newest commit in is read off the file
    // rather than assumed: it follows from how many flushes happened, and a
    // hard-coded slot would silently stop damaging the live one the day that
    // changed. `>=` is what `RecoverExistingFile` and `CowTree::Open` both
    // spell, so this mirrors them rather than paraphrasing them -- the tie is
    // unreachable here, the two ids being asserted different above, but a
    // fixture that reads differently from the code it models has to be
    // re-proved by hand every time somebody compares the two.
    auto const live = seededA->txnId >= seededB->txnId ? CowTree::MetaSlot::A : CowTree::MetaSlot::B;

    /// One row of the table below.
    ///
    /// The survivor is derived (`CowTree::OtherSlot(damaged)`) while `secondKeyReadable`
    /// is stated, and the two are not in tension even though the sibling fixture
    /// argues against deriving a column: what must not be derived from the
    /// discriminator is the EXPECTATION, or the assertion agrees with itself
    /// whatever the code does. "Which slot is the other one" is a definition, not
    /// an expectation -- deriving it cannot make a wrong build pass.
    struct Row
    {
        CowTree::MetaSlot damaged; ///< Which slot to damage; the survivor is `OtherSlot` of it.
        bool secondKeyReadable;    ///< Whether the newest commit's key survives.
        std::string_view what;     ///< What the row is about.
    };

    // Both directions, because only the pair says the SURVIVING slot was
    // chosen: damage the live slot alone and a build that always took the older
    // valid slot would pass, damage the stale one alone and one that always
    // took the newer would.
    auto const rows = std::vector<Row> {
        { .damaged = CowTree::OtherSlot(live),
          .secondKeyReadable = true,
          .what = "the stale slot is damaged: the newest commit still serves" },
        { .damaged = live,
          .secondKeyReadable = false,
          .what = "the live slot is damaged: the store falls back to the previous commit" },
    };

    for (auto const& row: rows)
    {
        INFO(row.what);
        // Every row starts from the seeded bytes, so one row's damage is not
        // still in the file when the next one runs.
        WriteWholeFile(tmp.path, seeded);
        DamageMetaSlot(tmp.path, row.damaged);

        auto const survivorSlot = CowTree::OtherSlot(row.damaged);
        // The survivor's meta and page bytes are already in hand from the seed:
        // the file has just been restored from those very bytes and
        // `DamageMetaSlot` touched only the other slot, so there is nothing to
        // re-read here.
        auto const& survivor = survivorSlot == CowTree::MetaSlot::A ? seededA : seededB;
        auto const survivorPage = SlotBytes(seeded, survivorSlot);

        // `Corrupt` at open means BOTH slots failed, and one is not both. This
        // is the whole claim, and `CorruptMetas` is what a build reading that
        // condition as "either" would answer here instead.
        auto const store = OpenMetaDamageStore(tmp.path);
        REQUIRE(store.has_value());

        {
            CowTree::CowTree tree { **store };
            REQUIRE(tree.Open().has_value());
            // Which meta the tree came up on, asked directly. The key
            // assertions below would also pass over a default-constructed
            // `Meta`, whose empty root reads as a tree that simply has no keys
            // in it.
            REQUIRE(tree.ItemCount() == survivor->itemCount);

            auto const reader = tree.BeginRead();
            auto const first = reader.Get(B("first"));
            REQUIRE(first.has_value());
            REQUIRE(first->has_value());
            auto const second = reader.Get(B("second"));
            // A key from a commit the surviving slot never saw is a MISS and
            // not a failure: the store is consistent, just with an earlier
            // moment.
            REQUIRE(second.has_value());
            REQUIRE(second->has_value() == row.secondKeyReadable);

            // And the store must not spend the one slot it has left. Recovery
            // records the SURVIVING slot as `_lastDurableSlot`, so
            // `FlushBatchLocked` writes the OTHER one -- the damaged one -- and
            // ordinary use repairs the file instead of leaving it one torn write
            // from unopenable. That member lives in `FilePageStore` and nowhere
            // else, which is why the assertion belongs in THIS suite: a build
            // that recovered correctly and then wrote over the good slot passes
            // every assertion above it.
            //
            // What this does NOT say, because an earlier draft said it and it was
            // false: it is not that `Fsync` would break this. THIS fixture's seed
            // -- raw `CowTree`, one `Flush()` per commit -- leaves the `txnId`
            // parity INTACT (measured: A at txn 2, B at txn 1), and under `Fsync`
            // such a store preserves its survivor in both damage directions too.
            // #726 needs a parity-BROKEN store, which only a `CowTreeStorage`-shaped
            // seed produces, so it is pinned in `CowTreeStorage_test` and named in
            // the storage rulebook -- not here. Citing that measurement here was a
            // measurement of a different store shape read as one about this one,
            // which is the defect `build-and-toolchain.md` gained a section for in
            // the same change.
            auto txn = tree.BeginWrite();
            REQUIRE(txn.Put(B("after-recovery"), B("value")).has_value());
            REQUIRE(txn.Commit().has_value());
            REQUIRE((*store)->Flush().has_value());
        }

        auto const after = ReadWholeFile(tmp.path);
        // Byte-for-byte, not "still decodes": a slot rewritten with an equally
        // valid meta would decode fine and would still have been the one spent.
        REQUIRE(std::ranges::equal(survivorPage, SlotBytes(after, survivorSlot)));
        // The other half, which is what makes the first mean something: the
        // commit did land somewhere, in the slot that was already damaged, and
        // it is newer than what the store recovered from. Without this a build
        // that wrote no meta at all would pass.
        auto const repaired = DecodeSlot(after, row.damaged);
        REQUIRE(repaired.has_value());
        REQUIRE(repaired->txnId > survivor->txnId);
    }
}

namespace
{
/// The meta with the higher txnId in a store file written at `GrowthPageSize`.
/// A slot sits one such page apart, not one `MinPageSize`.
/// @param path The store file.
/// @return The newest decodable slot's meta.
CowTree::Meta NewestMetaOnDisk(std::filesystem::path const& path)
{
    auto const file = ReadWholeFile(path);
    auto const decode = [&](CowTree::MetaSlot slot) {
        auto const page = std::span { file }.subspan(static_cast<std::size_t>(slot) * GrowthPageSize, GrowthPageSize);
        return CowTree::DecodeMeta(CowTree::BytesView { page.data(), page.size() });
    };
    auto const a = decode(CowTree::MetaSlot::A);
    auto const b = decode(CowTree::MetaSlot::B);
    REQUIRE(a.has_value());
    REQUIRE(b.has_value());
    return a->txnId > b->txnId ? *a : *b;
}
} // namespace

TEST_CASE("A crash's extensions are free in the recovered world", "[filestore][durability][batched][crash][freelist]")
{
    // L3 of #1624: pages `ExtendLocked` added after the last durable meta are in the file but in no
    // tree and no list. Recovery used to mark them live, so every crash leaked them for good.
    TempFile tmp;
    std::size_t inUseAtFlush = 0;
    std::size_t extendedTo = 0;
    {
        FlushingStore s { tmp.path };
        std::ignore = s.AllocateWritten(8);
        s.CommitAndFlush();
        inUseAtFlush = s.store->PagesInUse();
        std::ignore = s.AllocateWritten(16); // extends: nothing is free
        extendedTo = s.store->TotalDataPages();
        s.store->SimulateCrashForTest();
    }
    FlushingStore s { tmp.path };
    INFO("in use at the flush: " << inUseAtFlush << ", file extended to " << extendedTo << " data pages");
    REQUIRE(s.store->TotalDataPages() == extendedTo); // the file still holds them
    CHECK(s.store->PagesInUse() == inUseAtFlush);
    // And the next flush cuts them: they are the free tail.
    s.CommitAndFlush();
    CHECK(s.store->TotalDataPages() < extendedTo);
}

TEST_CASE("A recorded page count above the file's length reclaims nothing and refuses nothing",
          "[filestore][open][freelist]")
{
    // The truncation after a flush may leave the file SHORTER than a surviving meta's count.
    // That is not damage, and there is nothing past the end to free.
    TempFile tmp;
    std::size_t inUse = 0;
    {
        FlushingStore s { tmp.path };
        std::ignore = s.AllocateWritten(4);
        for (auto const id: s.AllocateWritten(12))
            REQUIRE(s.store->Free(id).has_value());
        s.CommitAndFlush(); // meta records the full count
        s.CommitAndFlush();
        s.CommitAndFlush(); // the tail is cut below the count an older meta recorded
        inUse = s.store->PagesInUse();
    }
    auto const recovered = NewestMetaOnDisk(tmp.path);
    FlushingStore s { tmp.path };
    // The premise, asserted rather than traced: the meta recovery lands on records MORE pages than
    // the file now holds. A fixture whose cut fell short of it would test the ordinary range instead.
    REQUIRE(recovered.dataPages.has_value());
    auto const recorded = Pace::Testing::Unwrap(recovered.dataPages);
    INFO("recorded " << recorded << " data pages, the file holds " << s.store->TotalDataPages());
    REQUIRE(recorded > s.store->TotalDataPages());
    CHECK(s.store->PagesInUse() == inUse);
}

namespace
{

/// Page size of the version-1 conversion fixtures: the smallest, so the files stay small.
constexpr std::size_t V1PageSize = CowTree::MinPageSize;

/// Rewrite meta slot @p slot of the closed store at @p path in the version-1 layout, from its own contents.
void DowngradeSlotToV1(std::filesystem::path const& path, CowTree::MetaSlot slot)
{
    auto bytes = ReadWholeFile(path);
    auto const meta = DecodeSlot(bytes, slot);
    REQUIRE(meta.has_value());
    auto const v1 = CowTree::Testing::EncodeMetaV1(*meta, V1PageSize);
    std::ranges::copy(v1, bytes.begin() + static_cast<std::ptrdiff_t>(static_cast<std::size_t>(slot) * V1PageSize));
    WriteWholeFile(path, bytes);
    auto const after = ReadWholeFile(path);
    auto const decoded = DecodeSlot(after, slot);
    REQUIRE(decoded.has_value());
    REQUIRE(decoded->version == 1U);
}

/// Open the tree over a Batched store at @p path, put @p key, commit, and close gracefully.
void PutAndClose(std::filesystem::path const& path, std::string const& key)
{
    CowTree::FilePageStore::Options opts;
    opts.path = path;
    opts.pageSize = V1PageSize;
    opts.durability = CowTree::FilePageStore::Durability::Batched;
    auto store = CowTree::FilePageStore::Open(opts);
    REQUIRE(store.has_value());
    CowTree::CowTree tree { **store };
    REQUIRE(tree.Open().has_value());
    auto txn = tree.BeginWrite();
    REQUIRE(txn.Put(B(key), B("value")).has_value());
    REQUIRE(txn.Commit().has_value());
}

/// Whether the tree serves @p key.
bool ServesKey(CowTree::CowTree& tree, std::string const& key)
{
    auto reader = tree.BeginRead();
    auto const got = reader.Get(B(key));
    return got.has_value() && got->has_value();
}

} // namespace

TEST_CASE("A store whose slots are both version 1 opens and serves, and its next meta is version 2",
          "[filestore][open][meta]")
{
    // Every store in service today was written with layout 1. Both binaries treat a store that will
    // not open as fatal, so this is the upgrade path, not a courtesy.
    TempFile tmp;
    PutAndClose(tmp.path, "first");
    PutAndClose(tmp.path, "second");
    DowngradeSlotToV1(tmp.path, CowTree::MetaSlot::A);
    DowngradeSlotToV1(tmp.path, CowTree::MetaSlot::B);

    CowTree::FilePageStore::Options opts;
    opts.path = tmp.path;
    opts.pageSize = V1PageSize;
    opts.durability = CowTree::FilePageStore::Durability::Batched;
    auto store = CowTree::FilePageStore::Open(opts);
    REQUIRE(store.has_value());
    {
        CowTree::CowTree tree { **store };
        REQUIRE(tree.Open().has_value());
        CHECK(ServesKey(tree, "first"));
        CHECK(ServesKey(tree, "second"));
        auto txn = tree.BeginWrite();
        REQUIRE(txn.Put(B("third"), B("value")).has_value());
        REQUIRE(txn.Commit().has_value());
    }
    REQUIRE((*store)->Flush().has_value());
    auto const slot = (*store)->LastDurableSlot();
    auto const file = ReadWholeFile(tmp.path);
    auto const written = DecodeSlot(file, slot);
    REQUIRE(written.has_value());
    CHECK(written->version == 2U);
    REQUIRE(written->dataPages.has_value());
    CHECK(Pace::Testing::Unwrap(written->dataPages) == (*store)->TotalDataPages());
}

TEST_CASE("A store with one slot in each layout opens on the higher txnId, whichever layout that is",
          "[filestore][open][meta]")
{
    // Review focus 3: the choice between the slots is the txnId's, never the layout's.
    TempFile tmp;
    PutAndClose(tmp.path, "first");
    PutAndClose(tmp.path, "second");
    auto const file = ReadWholeFile(tmp.path);
    auto const a = DecodeSlot(file, CowTree::MetaSlot::A);
    auto const b = DecodeSlot(file, CowTree::MetaSlot::B);
    REQUIRE(a.has_value());
    REQUIRE(b.has_value());
    REQUIRE(a->txnId != b->txnId);
    auto const higher = a->txnId > b->txnId ? CowTree::MetaSlot::A : CowTree::MetaSlot::B;

    for (auto const downgraded: { higher, CowTree::OtherSlot(higher) })
    {
        INFO("slot rewritten as version 1: " << (downgraded == CowTree::MetaSlot::A ? "A" : "B") << ", higher txnId is in "
                                             << (higher == CowTree::MetaSlot::A ? "A" : "B"));
        TempFile copy;
        WriteWholeFile(copy.path, file);
        DowngradeSlotToV1(copy.path, downgraded);

        CowTree::FilePageStore::Options opts;
        opts.path = copy.path;
        opts.pageSize = V1PageSize;
        opts.durability = CowTree::FilePageStore::Durability::Batched;
        auto store = CowTree::FilePageStore::Open(opts);
        REQUIRE(store.has_value());
        CowTree::CowTree tree { **store };
        REQUIRE(tree.Open().has_value());
        CHECK(ServesKey(tree, "second"));
    }
}

TEST_CASE("A fresh Batched store that crashes before its first flush reclaims every page it extended",
          "[filestore][durability][batched][crash][freelist]")
{
    // #1624, L3 at birth: the blank metas `BootstrapNewFile` writes name no page, so they must say
    // so (`dataPages == 0`). Left unknown, recovery reclaims nothing until the first flush, which
    // is `BatchedFlushInterval` commits away.
    TempFile tmp;
    std::size_t emptyInUse = 0;
    {
        FlushingStore s { tmp.path };
        emptyInUse = s.store->PagesInUse();
        REQUIRE(emptyInUse == CowTree::MetaSlotCount);
        std::ignore = s.AllocateWritten(20);
        s.store->SimulateCrashForTest();
    }
    FlushingStore s { tmp.path };
    CHECK(s.store->TotalDataPages() == 20);
    CHECK(s.store->PagesInUse() == emptyInUse);
}

TEST_CASE("A version-1 meta restated through EncodeMeta decodes as version 2, never Corrupt", "[filestore][meta]")
{
    // A recovered version-1 meta is kept and restated; `EncodeMeta` writes the layout-2 bytes, so it
    // must stamp version 2 too, or the slot decodes under the v1 row with its CRC in the wrong place.
    CowTree::Meta meta;
    meta.pageSize = static_cast<std::uint32_t>(V1PageSize);
    meta.txnId = 5;
    auto const v1 = CowTree::Testing::EncodeMetaV1(meta, V1PageSize);
    auto const decoded = CowTree::DecodeMeta({ v1.data(), v1.size() });
    REQUIRE(decoded.has_value());
    REQUIRE(decoded->version == 1U);

    std::vector<std::byte> page(V1PageSize);
    REQUIRE(CowTree::EncodeMeta({ page.data(), page.size() }, *decoded).has_value());
    auto const again = CowTree::DecodeMeta({ page.data(), page.size() });
    REQUIRE(again.has_value());
    CHECK(again->version == 2U);
    CHECK(again->txnId == 5U);
}

TEST_CASE("A Fsync or None store keeps its free pages free across a restart", "[filestore][durability][freelist]")
{
    // L2 of #1624: only a batched flush used to write a free list, so a strict or unsynced store came
    // back with every free page marked live -- and under a disk budget that is capacity lost for good.
    for (auto const durability: { CowTree::FilePageStore::Durability::Fsync, CowTree::FilePageStore::Durability::None })
    {
        TempFile tmp;
        std::size_t inUse = 0;
        std::size_t pages = 0;
        {
            CowTree::FilePageStore::Options opts;
            opts.path = tmp.path;
            opts.pageSize = GrowthPageSize;
            opts.durability = durability;
            auto opened = CowTree::FilePageStore::Open(opts);
            REQUIRE(opened.has_value());
            auto store = std::move(*opened);
            CowTree::CowTree tree { *store };
            REQUIRE(tree.Open().has_value());
            // Enough keys to span many pages, then delete most: a purge-sized free set.
            {
                auto txn = tree.BeginWrite();
                for (auto const i: std::views::iota(0, 400))
                {
                    auto const key = "key-" + std::to_string(i);
                    auto const value = std::string(200, 'v');
                    REQUIRE(txn.Put(B(key), B(value)).has_value());
                }
                REQUIRE(txn.Commit().has_value());
            }
            {
                auto txn = tree.BeginWrite();
                for (auto const i: std::views::iota(0, 360))
                {
                    auto const key = "key-" + std::to_string(i);
                    REQUIRE(txn.Erase(B(key)).has_value());
                }
                REQUIRE(txn.Commit().has_value());
            }
            // A last, tiny commit: the list a commit writes describes what the commits BEFORE it
            // freed, because `CommitTxn` frees a transaction's pages after its meta is written. So
            // the purge above reaches the list through this commit, and only this commit's own few
            // pages are missing from it -- which a clean close persists (F1).
            {
                auto txn = tree.BeginWrite();
                REQUIRE(txn.Put(B("key-last"), B("v")).has_value());
                REQUIRE(txn.Commit().has_value());
            }
            inUse = store->PagesInUse();
            pages = store->TotalDataPages();
        }
        CowTree::FilePageStore::Options opts;
        opts.path = tmp.path;
        opts.durability = durability;
        auto opened = CowTree::FilePageStore::Open(opts);
        REQUIRE(opened.has_value());
        auto store = std::move(*opened);
        INFO("durability " << static_cast<int>(durability) << ": in use before close " << inUse);
        // Exactly: the last commit's own frees reach a list through the clean close (F1).
        CHECK(store->PagesInUse() == inUse);
        // And a second session's allocations reuse them: as many pages as the first session had
        // free, and the file does not grow. Counted from BEFORE the close, never from the reopened
        // store, whose own free count is zero exactly when the list was lost -- and allocating
        // nothing could not show growth at all.
        auto const freeBeforeClose = pages + CowTree::MetaSlotCount - inUse;
        REQUIRE(freeBeforeClose > 0);
        for ([[maybe_unused]] auto const i: std::views::iota(std::size_t { 0 }, freeBeforeClose))
            REQUIRE(store->Allocate().has_value());
        CHECK(store->TotalDataPages() <= pages);
    }
}

namespace
{
/// What a store looked like just before it closed.
struct ClosedStore
{
    /// `PagesInUse()` just before the close.
    std::size_t inUse = 0;
    /// The meta in the store's last durable slot just before the close.
    CowTree::Meta lastDurable {};
};

/// How `RewriteOneKeyAndClose` ends the store. Private to these cases: never stored or sent.
enum class Ending : std::uint8_t
{
    Clean, ///< the destructor runs its close-time work
    Crash, ///< `SimulateCrashForTest` first, so the destructor writes nothing
};

/// Run @p commits single-key rewrites on a fresh store under @p durability and close it.
/// @param path       The store file.
/// @param durability The policy to write under.
/// @param commits    How many commits.
/// @param ending     A clean close, or a simulated crash.
/// @return The pages in use and the last durable meta just before the close.
ClosedStore RewriteOneKeyAndClose(std::filesystem::path const& path,
                                  CowTree::FilePageStore::Durability durability,
                                  int commits,
                                  Ending ending = Ending::Clean)
{
    CowTree::FilePageStore::Options opts;
    opts.path = path;
    opts.pageSize = GrowthPageSize;
    opts.durability = durability;
    auto opened = CowTree::FilePageStore::Open(opts);
    REQUIRE(opened.has_value());
    auto store = std::move(*opened);
    CowTree::CowTree tree { *store };
    REQUIRE(tree.Open().has_value());
    for (auto const i: std::views::iota(0, commits))
    {
        auto const value = std::to_string(i);
        auto txn = tree.BeginWrite();
        REQUIRE(txn.Put(B("k"), B(value)).has_value());
        REQUIRE(txn.Commit().has_value());
    }
    auto const meta = store->ReadMeta(store->LastDurableSlot());
    REQUIRE(meta.has_value());
    if (ending == Ending::Crash)
        store->SimulateCrashForTest();
    return { .inUse = store->PagesInUse(), .lastDurable = *meta };
}
} // namespace

TEST_CASE("A clean close keeps the last commit's frees free", "[filestore][durability][freelist]")
{
    // L1 of #1624: `CowTree::CommitTxn` frees the replaced pages AFTER `WriteMeta`, and the 64th
    // batched commit flushes INSIDE it -- so its frees reach a store with nothing left to flush, and
    // the destructor flushed only when a meta was buffered. Fsync and None name them in no list at all.
    struct Shape
    {
        CowTree::FilePageStore::Durability durability;
        int commits;
        std::size_t newListPages; ///< list pages the close writes where no list existed before
    };
    for (auto const shape:
         { Shape { .durability = CowTree::FilePageStore::Durability::Batched, .commits = 64, .newListPages = 0 },
           Shape { .durability = CowTree::FilePageStore::Durability::Fsync, .commits = 2, .newListPages = 1 },
           Shape { .durability = CowTree::FilePageStore::Durability::None, .commits = 2, .newListPages = 1 } })
    {
        TempFile tmp;
        auto const closed = RewriteOneKeyAndClose(tmp.path, shape.durability, shape.commits);
        CowTree::FilePageStore::Options opts;
        opts.path = tmp.path;
        auto opened = CowTree::FilePageStore::Open(opts);
        REQUIRE(opened.has_value());
        auto store = std::move(*opened);
        INFO("durability " << static_cast<int>(shape.durability));
        // Nothing leaks: the pages in use are those before the close, plus the one page a list now
        // occupies where the store had never written one (commit 1 freed nothing, so commit 2's list was empty).
        CHECK(store->PagesInUse() == closed.inUse + shape.newListPages);
        // And the close really restated: the second commit's rewrite freed the first leaf, which only
        // the restate names (one commit frees nothing on a fresh store).
        store.reset();
        CHECK(NewestMetaOnDisk(tmp.path).txnId == closed.lastDurable.txnId + 1);
    }
}

TEST_CASE("Opening and closing a store with nothing freed leaves the file byte-identical", "[filestore][persist]")
{
    // The close-time restate must fire only for a free: a store merely opened must not grow a new
    // meta on the way out.
    TempFile tmp;
    // The seed's own close restated (its last commit freed a leaf), so this is the first open after
    // a restating close -- the one a one-shot write on the way back in would show up in.
    std::ignore = RewriteOneKeyAndClose(tmp.path, CowTree::FilePageStore::Durability::Fsync, 3);
    auto const before = ReadWholeFile(tmp.path);
    {
        CowTree::FilePageStore::Options opts;
        opts.path = tmp.path;
        auto opened = CowTree::FilePageStore::Open(opts);
        REQUIRE(opened.has_value());
        auto store = std::move(*opened);
    }
    CHECK(ReadWholeFile(tmp.path) == before);
}

TEST_CASE("A close-time restate takes the next txnId and keeps the last commit's root", "[filestore][meta]")
{
    TempFile tmp;
    auto const closed = RewriteOneKeyAndClose(tmp.path, CowTree::FilePageStore::Durability::Batched, 64);
    auto const newest = NewestMetaOnDisk(tmp.path);
    CHECK(newest.txnId == closed.lastDurable.txnId + 1);
    // A RESTATE: the same world, field by field, so a reopen serves what the last commit left.
    CHECK(newest.root == closed.lastDurable.root);
    CHECK(newest.itemCount == closed.lastDurable.itemCount);
    CHECK(newest.keyBytes == closed.lastDurable.keyBytes);
    CHECK(newest.valueBytes == closed.lastDurable.valueBytes);
    REQUIRE(closed.lastDurable.itemCount == 1); // a default-constructed meta would agree on zeros
}

TEST_CASE("A simulated crash skips the close-time restate", "[filestore][durability][crash][freelist]")
{
    // The crash tests mean a crash only while `SimulateCrashForTest` leaves the destructor's restate
    // out. The clean-close case's batched shape, crashed instead of closed: the 64th commit flushed
    // inside `WriteMeta` and freed its old leaf after it, so that leaf stays LIVE (no list names it)
    // and the newest meta is the flush's own, not a restatement of it.
    //
    // Batched rather than the Fsync two-commit shape, whose count cannot tell the two apart: there
    // the restate writes its list INTO the one free page, so a restated and an unrestated reopen
    // both report one page more than before the close.
    TempFile tmp;
    auto const crashed = RewriteOneKeyAndClose(tmp.path, CowTree::FilePageStore::Durability::Batched, 64, Ending::Crash);
    CHECK(NewestMetaOnDisk(tmp.path).txnId == crashed.lastDurable.txnId);
    CowTree::FilePageStore::Options opts;
    opts.path = tmp.path;
    auto opened = CowTree::FilePageStore::Open(opts);
    REQUIRE(opened.has_value());
    // A clean close of the same shape reopens at exactly `inUse` (the clean-close case's row).
    CHECK((*opened)->PagesInUse() == crashed.inUse + 1);
}

TEST_CASE("A Fsync commit with nothing free costs the fsyncs it did before", "[filestore][durability]")
{
    // F2 adds a fsync only when a list page was written. The first commit of a fresh store frees
    // nothing, so it must cost what it cost on master d2dd26622, where a probe measured a delta of
    // 3 for each of the first three commits: `Write`'s per-page fsync for the one leaf, `SyncData`
    // in `CommitTxn`, and the meta write's own; only the first of them has an empty free set.
    // Watched red: with the list fsync made unconditional, the delta is 4.
    constexpr std::size_t FsyncsPerCommitOnMaster = 3;
    TempFile tmp;
    CowTree::FilePageStore::Options opts;
    opts.path = tmp.path;
    opts.durability = CowTree::FilePageStore::Durability::Fsync;
    auto opened = CowTree::FilePageStore::Open(opts);
    REQUIRE(opened.has_value());
    auto store = std::move(*opened);
    CowTree::CowTree tree { *store };
    REQUIRE(tree.Open().has_value());
    auto const before = store->FsyncCallCount();
    auto txn = tree.BeginWrite();
    REQUIRE(txn.Put(B("k"), B("v")).has_value());
    REQUIRE(txn.Commit().has_value());
    CHECK(store->FsyncCallCount() - before == FsyncsPerCommitOnMaster);
}
