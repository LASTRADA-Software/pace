// SPDX-License-Identifier: Apache-2.0
#pragma once

#include "ExchangeLog.hpp"
#include "NodeSurfaces.hpp"
#include "PeerIdentity.hpp"

#include <Pace/Core/EnumTable.hpp>
#include <Pace/Core/Logger.hpp>
#include <Pace/Core/Nonce.hpp>
#include <Pace/Core/SecureBytes.hpp>
#include <Pace/Distributed/NodeProof.hpp>
#include <Pace/Metrics/IMetricsSink.hpp>
#include <Pace/Protocol/CompileCacheAuth.hpp>
#include <Pace/Protocol/CompileCacheWire.hpp>
#include <Pace/Protocol/LiveStream.hpp>
#include <Pace/Protocol/SurfaceRefusal.hpp>

#include <algorithm>
#include <atomic>
#include <chrono>
#include <cstddef>
#include <cstdint>
#include <expected>
#include <memory>
#include <optional>
#include <span>
#include <string>
#include <string_view>
#include <vector>

#include <core/async/Task.hpp>
#include <core/net/IListener.hpp>

namespace Pace::Node
{

class NodeIoLoop;

/// A refusal the endpoint decides and the surface owning the verb answers.
///
/// Its own enum rather than more `CompileCacheWire::PrePayloadDecision` enumerators,
/// because that one is a WIRE enum: it describes a frame's own header, both binaries
/// compile it in, and the daemon reaches the same decisions from the same
/// `DecidePrePayload`. These describe **this process** -- the memory it is already
/// holding, and what this connection has proved -- so a peer cannot compute them and
/// there is nothing for the daemon to agree about. Widening a shared header to carry
/// a local decision would be a wire change bought for nothing.
///
/// Every one of these was answered in the accept loop with `Wire::EncodeErrorReply`
/// and counted nothing, which is
/// [#447](https://github.com/LASTRADA-Software/fastcached/issues/447): the merged
/// listener refused correctly on the wire while the only thing an operator can see
/// stayed flat.
///
/// **The endpoint's refusal for a connection it has no room for is deliberately not
/// here.** That one is decided at accept, before a header exists, so it names no verb
/// and no owner can be asked for it; `FrameServer` counts it itself. See
/// `IFrameResponder::EndpointRefusalReply`.
enum class EndpointRefusal : std::uint8_t
{
    /// A slot was free and the memory was not: this request's declared length does
    /// not fit in what the surface is already holding in flight.
    ///
    /// Answered `EndpointBusy`, which it shares on the wire with the endpoint's
    /// own at-capacity refusal and must never share a counter with: this says one
    /// request is too big *right now* and that one says the surface is full. A
    /// client does the same thing about both, an operator does not.
    InFlightBudget,

    /// An `AUTH` payload that would not decode into a credential at all.
    CredentialMalformed,

    /// An `AUTH` payload that decoded and did not verify.
    ///
    /// **The credential-guessing signal**, and it is the one refusal here that is not
    /// merely bookkeeping: a peer presenting a wrong token is exactly what an
    /// operator asking "is my scheduler port being probed" is looking for, and until
    /// #447 it answered `Unauthenticated` on the wire and moved nothing at all.
    CredentialRejected,

    /// The surface was still answering when the verb's own window ran out.
    ///
    /// **The one refusal here that is decided by a clock rather than by a frame**,
    /// and the only one the connection writes on its own initiative rather than in
    /// answer to something the peer just sent. `FrameServer::CloseOverdue` decides
    /// it; `ServeConnection` writes it, from the one place that owns the write side.
    ///
    /// Reachable only for a connection parked INSIDE the responder. A peer swept
    /// while the connection is parked on the socket -- dribbling a header, dribbling
    /// a declared payload -- is ended by the close, because the close is the only
    /// thing that ends a parked read and it is the write side gone. See
    /// `FrameServer::CloseOverdue` for why that asymmetry is the design rather than
    /// a shortfall ([#523](https://github.com/LASTRADA-Software/fastcached/issues/523)).
    ///
    /// **Counted by the ENDPOINT, not by the surface**, which is why every responder
    /// answers it through `Cc::RefuseWithoutCounter`. The deadline is the endpoint's
    /// fact: `FrameAnswerDeadlineSweeps` already tallies the sweep and
    /// `FrameDeadlineRefusalsSent` tallies how many of those peers were told why.
    /// Three per-surface copies of one endpoint fact would be three things to drift.
    AnswerDeadline,

    /// A `ProveNode` arrived with no challenge outstanding on this connection.
    ///
    /// **The endpoint's own fact, and the ONLY node-proof refusal here**: the challenge lives in
    /// the serve loop, because it is connection state and the prover is shared by every
    /// connection on the surface. Never asked for one, or already spent one -- a challenge
    /// answers exactly one proof whatever that proof's outcome.
    ///
    /// Every other way a proof can fail -- a payload that will not decode, a signature that does
    /// not verify, a key the roster does not hold or has revoked -- is the PROVER's to decide, and
    /// `INodeProver::Verify` hands those back already encoded and already counted. They are not
    /// rows here, because a row here obliges all seven surfaces to say why they do not count a
    /// refusal only one of them can ever produce.
    NodeProofUnchallenged,

    /// The count. See `Core/EnumTable.hpp`.
    Last,
};

/// One row per `EndpointRefusal`, in enumerator order.
struct EndpointRefusalCode
{
    EndpointRefusal refusal;          ///< Which endpoint decision this describes.
    CompileCacheWire::ErrorCode code; ///< What every surface tells the client about it.
};

/// What the client is told, per refusal.
///
/// **A property of the refusal, not of the surface**, which is why it is one table
/// here rather than an arm in each responder: three surfaces answering the same
/// question separately is three answers that agree today, and a divergence between
/// two of them would be one listener telling a client different things about one
/// decision, which nothing could see. The COUNTER is the half that legitimately
/// differs -- the scheduler moves one for a wrong credential, the cache cannot
/// produce that refusal at all -- so it stays with the surface.
///
/// The direct counterpart of `CompileCacheWire::ErrorCodeFor(PrePayloadDecision)`,
/// which the same call sites ask two lines away.
inline constexpr EnumTable<EndpointRefusal, EndpointRefusalCode> EndpointRefusalCodes { {
    { .refusal = EndpointRefusal::InFlightBudget, .code = CompileCacheWire::ErrorCode::EndpointBusy },
    { .refusal = EndpointRefusal::CredentialMalformed, .code = CompileCacheWire::ErrorCode::MalformedFrame },
    { .refusal = EndpointRefusal::CredentialRejected, .code = CompileCacheWire::ErrorCode::Unauthenticated },
    { .refusal = EndpointRefusal::AnswerDeadline, .code = CompileCacheWire::ErrorCode::RequestDeadlineExceeded },
    { .refusal = EndpointRefusal::NodeProofUnchallenged, .code = CompileCacheWire::ErrorCode::NodeProofUnchallenged },
} };

static_assert(RowsInEnumeratorOrder(EndpointRefusalCodes, &EndpointRefusalCode::refusal),
              "EndpointRefusalCodes must hold one row per EndpointRefusal, in enumerator order");

/// Why no surface counts `EndpointRefusal::AnswerDeadline`, stated once for all three.
///
/// Beside the enumerator rather than in any one responder, exactly as
/// `EndpointRefusalCodes` is: this is a property of the refusal, not of the surface
/// that happens to answer it. Three surfaces stating one fact separately is three
/// sentences that agree today, and the divergence would be invisible.
///
/// The deadline belongs to the ENDPOINT. It decides the sweep and it already carries
/// both halves: `FrameAnswerDeadlineSweeps` for the sweep, and
/// `FrameDeadlineRefusalsSent` for the peer that was told why. A surface counting it
/// again would be a third tally of one event, summed by whoever met two of them first.
inline constexpr std::string_view AnswerDeadlineIsTheEndpointsRationale =
    "the answer deadline is the endpoint's decision and the endpoint counts it, in the sweep row and the "
    "refusal-sent row; a per-surface copy would be a third tally of one event";

/// What an `AUTH` frame established on one connection.
///
/// A verdict rather than a `CredentialOutcome`, because an accepted `AUTH` on a node says WHO:
/// a verified ticket speaks for a machine, and that machine is what admission folds as
/// `ConnectionFacts::authenticatedMachine`. The endpoint clears it on every `AUTH` it reads a
/// header for and ASSIGNS it on every one it answers, so a refused one -- at the header or by
/// its verdict -- clears whatever an earlier one established.
///
/// **A refused ticket grants no admission, and one refused for a REVOKED key says so**: its
/// `revokedMachine` is recorded on the connection and never cleared, because the connection is the
/// forgotten machine's and every later verb on it is refused as that machine's
/// (`ConnectionFacts::revokedMachine`) -- on a `--fleet-open` node too, where its address alone
/// would admit it.
struct CredentialVerdict
{
    CredentialOutcome outcome { CredentialOutcome::Malformed }; ///< Only Accepted admits anything.
    /// The machine a VERIFIED ticket speaks for; engaged only when `outcome == Accepted`.
    std::optional<ProvenIdentity> machine {};
    /// The revoked key a refused ticket verified under; engaged only when it was refused for that.
    std::optional<RevokedKeyEvidence> revokedMachine {};
    /// The refusal the surface already encoded AND counted; empty unless it refused.
    std::vector<std::byte> refusalReply {};
};

/// Why no surface but the session component counts a credential refusal, stated once for
/// every surface that has to say it.
///
/// Here rather than beside one responder for `EndpointRefusalCodes`' reason: this is a
/// property of the ROUTING -- `AUTH` is `VerbFamily::Session`, which `MergedResponder` sends
/// to the session component -- so no other surface is ever asked to check a credential.
inline constexpr std::string_view CredentialIsTheSessionsRationale =
    "AUTH is the Session family, which MergedResponder routes to the session component; no credential outcome is "
    "ever decided against this surface";

/// Why no node surface counts `PrePayloadDecision::Unauthenticated`, stated once.
///
/// The node checks no password, so the endpoint asks `DecidePrePayload` with `authRequired`
/// false for every verb -- and that is the only road to this decision. A surface counting it
/// would own a row no event can move.
inline constexpr std::string_view NodeChecksNoPasswordRationale =
    "the node checks no password: the endpoint asks DecidePrePayload with authRequired false for every verb, which "
    "is the only road to this decision";

/// The answer every surface but the session component gives an `AUTH` it is never routed.
/// @return `NoPolicy`, establishing nothing.
[[nodiscard]] inline CredentialVerdict NotTheSessionSurface() noexcept
{
    return CredentialVerdict { .outcome = CredentialOutcome::NoPolicy };
}

/// Why no surface but the identity prover's counts a node-proof refusal, stated once for
/// every surface that has to say it.
///
/// `CredentialIsTheSessionsRationale`'s exact counterpart, and it is here rather than beside
/// one responder for `EndpointRefusalCodes`' reason: this is a property of the ROUTING -- the
/// two proof verbs are `VerbFamily::NodeProof`, which `MergedResponder` sends to the one
/// component that verifies identities -- so no other surface can ever be asked about them. Six
/// surfaces stating that separately is six sentences that agree today.
inline constexpr std::string_view NodeProofIsTheProversRationale =
    "the node-proof verbs are the NodeProof family, which MergedResponder routes to the identity prover; no "
    "proof outcome is ever decided against this surface";

/// Answer an endpoint-decided refusal the way its row decided, counted or not.
///
/// The one door both the scheduler and the compile surface reach their
/// `EndpointRefusalReply` through, so the counted and uncounted spellings are chosen
/// from data rather than remembered at two call sites. `CacheResponder` has had this
/// shape since #491 (`Detail::AnswerCacheRefusal`); the other two hand-wrote the same
/// three-line branch, which is the one branch
/// [`metrics-and-observability.md`](../../../.agent/rules/metrics-and-observability.md)
/// singles out -- *"deliberately uncounted must not be spelled like forgot"* -- and so
/// the one that least deserves three independent implementations.
///
/// The code is taken rather than re-derived, because both callers already hold it from
/// `ErrorCodeFor(refusal)` and passing it keeps this function from needing to know
/// which enumeration it is answering about.
/// @param metrics Where a counted refusal is recorded.
/// @param code What the client is told.
/// @param answer The counted row, or nothing where this surface counts none.
/// @param rationale Why nothing is counted; read only when @p answer is absent.
/// @param detail Words for a person, or empty when there are none to add.
/// @return The encoded reply. Never empty.
[[nodiscard]] inline std::vector<std::byte> AnswerEndpointRefusal(IMetricsSink& metrics,
                                                                  CompileCacheWire::ErrorCode code,
                                                                  std::optional<Cc::SurfaceRefusal> const& answer,
                                                                  std::string_view rationale,
                                                                  std::string_view detail)
{
    if (!answer.has_value())
        return Cc::RefuseWithoutCounter({ .code = code, .rationale = rationale }, detail);
    return Cc::Refuse(metrics, *answer, detail);
}

/// The wire code @p refusal is answered with.
/// @param refusal Any enumerator but `Last`.
/// @return The code every surface tells the client.
[[nodiscard]] constexpr CompileCacheWire::ErrorCode ErrorCodeFor(EndpointRefusal refusal) noexcept
{
    return EndpointRefusalCodes[static_cast<std::size_t>(refusal)].code;
}

/// Something a reply keeps held until the endpoint has finished with it.
///
/// **The endpoint writes a reply AFTER the responder has returned it**, so whatever must
/// last until the reply has been delivered cannot be released by the responder's own
/// scope -- that scope has ended by the time the first byte is written. The compile
/// worker's slot is the case that needs it (#1303): a cordon's drained report and a stop's
/// drain both read the slot count as *nothing this worker owes anybody*, and a slot
/// released at the responder's `co_return` made that claim while a multi-megabyte object
/// was still going out, so stopping on it abandoned the one compile the wait was for.
///
/// So the hold travels WITH the reply, and the endpoint destroys it once the write has
/// finished or been abandoned. That is every path out of one request, and none of them
/// carries a release of its own to forget.
class IReplyHold
{
  public:
    IReplyHold() = default;
    IReplyHold(IReplyHold const&) = delete;
    IReplyHold(IReplyHold&&) = delete;
    IReplyHold& operator=(IReplyHold const&) = delete;
    IReplyHold& operator=(IReplyHold&&) = delete;
    /// Releases whatever was held.
    virtual ~IReplyHold() = default;
};

/// What a responder answers with: the reply, and what stays held until it is written.
struct FrameReply
{
    /// A reply that holds nothing, which is every surface's but the compile worker's.
    ///
    /// Implicit on purpose, so a surface that holds nothing goes on answering
    /// `co_return bytes;`. The conversion cannot lose anything, because there is nothing
    /// on the other side of it to lose.
    /// @param reply The encoded reply, or empty to close without answering.
    FrameReply(std::vector<std::byte> reply = {}) noexcept:
        bytes { std::move(reply) }
    {
    }

    /// A reply that holds something until it has been written.
    /// @param reply The encoded reply, or empty to close without answering.
    /// @param held Released once the endpoint has written or abandoned the reply.
    FrameReply(std::vector<std::byte> reply, std::unique_ptr<IReplyHold> held) noexcept:
        bytes { std::move(reply) },
        hold { std::move(held) }
    {
    }

    /// The encoded reply, or empty to close without answering.
    std::vector<std::byte> bytes;

    /// What stays held until the reply has been written or abandoned; null for nothing.
    std::unique_ptr<IReplyHold> hold;

    /// Whether this answer is the connection's LAST: the endpoint writes it, then closes.
    ///
    /// For a verb answered once per connection by design -- FLEET-SUMMARY, whose every answer is a
    /// signature a stranger asked for -- so that pipelining questions on one connection cannot keep
    /// a reactor signing: each signature then costs a handshake and a slot of the port's pool. The
    /// close LINGERS, so a request pipelined behind this one is drained rather than answered by a
    /// reset that could destroy this reply in the peer's receive queue.
    bool endsConnection { false };
};

/// Serves one subscription for as long as it lasts.
///
/// **A verb answered by a stream is NOT answered by `IFrameResponder::Answer`**, and the split is
/// an interface rather than a longer `Answer` because the two have opposite shapes: an answer is
/// one reply the endpoint writes after the surface returns, while a stream writes for as long as
/// the subscription lasts and the endpoint has to be the writer throughout.
class IFrameStream
{
  public:
    IFrameStream() = default;
    IFrameStream(IFrameStream const&) = delete;
    IFrameStream(IFrameStream&&) = delete;
    IFrameStream& operator=(IFrameStream const&) = delete;
    IFrameStream& operator=(IFrameStream&&) = delete;
    virtual ~IFrameStream() = default;

    /// Serve a subscription until it ends.
    /// @param frame The whole request, header included; outlives the returned task, as
    ///        `IFrameResponder::Answer`'s does.
    /// @param peer Who is at the other end, as `IFrameResponder::Answer` receives it -- the
    ///        proof included, because a stream is re-gated on every tick and a gate that could
    ///        not see the proof would revoke a proven subscriber at its first one.
    /// @param sink Where every push goes and what the peer has done; never null, and it outlives
    ///        the returned task. A pointer because a coroutine parameter must not be a reference.
    /// @return The terminal reply, or empty to close without one -- the answer for a peer that
    ///         has left, and for a push that will never leave.
    [[nodiscard]] virtual core::async::Task<std::vector<std::byte>> Serve(std::span<std::byte const> frame,
                                                                          PeerIdentity peer,
                                                                          IPushSink* sink) = 0;
};

/// One connection's half-finished node handshake: what the caller opened with, what this server
/// answered, and the ephemeral secret only this server holds (#178).
///
/// Connection state, held by the serve loop and spent by the next proof whatever its outcome. The
/// secret lives in `SecureByteBuffer` and dies with the handshake.
struct NodeHandshake
{
    CompileCacheWire::NodeChallengeRequest request; ///< The caller's nonce and ephemeral key.
    CompileCacheWire::NodeChallengeReply reply;     ///< This server's half, signed.
    SecureByteBuffer ephemeralSecret;               ///< This server's ephemeral secret.
};

/// A challenge issued: the state to keep on the connection, and the reply to send.
struct NodeChallengeIssued
{
    NodeHandshake handshake;      ///< Kept by the serve loop until the proof.
    std::vector<std::byte> reply; ///< The encoded `Ok`.
};

/// What one proof established, and what to answer it with.
struct NodeProofVerdict
{
    /// The identity the proof's signature verified under, when the roster holds that key LIVE or
    /// REVOKED -- the second so every later verb on the connection is refused as the forgotten
    /// machine's. Disengaged for a proof that did not verify, or verified under a key the roster
    /// does not know: those connections have established nothing.
    std::optional<ProvenIdentity> identity;

    /// The session keys, engaged whenever the handshake agreed one -- whatever the verdict. The
    /// connection is sealed with them before `reply` is written, so the answer to a proof, an `Ok`
    /// or a refusal alike, is always the first sealed frame: the caller engages its receiving seal
    /// before it sends the proof, and a grammar that depended on the verdict would leave it reading
    /// a refusal as the head of a sealed frame. Sealing a connection proves nothing about who is on
    /// it; `identity` is what admission reads.
    std::optional<Distributed::NodeSessionKeys> keys;

    /// What to answer: `Ok`, or the refusal, already encoded and counted.
    std::vector<std::byte> reply;
};

/// Proves, one connection at a time, WHICH machine a caller is (#178).
///
/// **A seam of its own rather than two more methods on `IFrameResponder`**, for
/// `IFrameStream`'s reason: only the surface that owns `VerbFamily::NodeProof` has anything to
/// say here, and every other one would write two bodies that refuse. One pure virtual returning
/// a pointer says *this surface offers no prover* once, which is a decision rather than two
/// omissions.
///
/// **The endpoint terminates both verbs rather than passing them to `Answer`**, exactly as it
/// does `AUTH` and for the same reason: what they change is CONNECTION state -- the handshake
/// outstanding, the identity proved and the seal -- and the responder is shared by every
/// connection on the surface. So the handshake lives in the serve loop and this object holds none.
class INodeProver
{
  public:
    INodeProver() = default;
    INodeProver(INodeProver const&) = delete;
    INodeProver(INodeProver&&) = delete;
    INodeProver& operator=(INodeProver const&) = delete;
    INodeProver& operator=(INodeProver&&) = delete;
    virtual ~INodeProver() = default;

    /// Answer a `NodeChallenge`: draw this connection's nonce and ephemeral key, and sign the reply.
    ///
    /// Drawn HERE rather than in the endpoint, because the randomness seam belongs with the
    /// component that holds the key: `FrameServer` serves six surfaces that have no use for an
    /// `ISecureRandom&`. **A draw can fail, and the refusal comes back ENCODED**, for `Verify`'s
    /// reason below; a challenge that cannot be drawn is never replaced by a weak one (#1527).
    /// @param payload The `NodeChallenge` request payload.
    /// @return The handshake to keep and the reply to send, or the encoded refusal.
    [[nodiscard]] virtual std::expected<NodeChallengeIssued, std::vector<std::byte>> Challenge(
        std::span<std::byte const> payload) = 0;

    /// Judge a `ProveNode` against the connection's handshake.
    ///
    /// **Every refusal comes back ENCODED and already counted**, which is this endpoint's standing
    /// division of labour -- the endpoint owns WHEN the question is asked, the surface owns the
    /// answer, its wording and its counter. The four ways a proof fails do not share a diagnosis:
    /// a payload that will not decode is a client-library mismatch, a signature that does not
    /// verify is a forgery or a bug, an unknown key is a machine nobody admitted, and a revoked
    /// key is a machine the cluster forgot.
    /// @param handshake The connection's handshake, spent by this call whatever its outcome.
    /// @param payload The `ProveNode` request payload.
    /// @return What was established and what to answer.
    [[nodiscard]] virtual NodeProofVerdict Verify(NodeHandshake const& handshake, std::span<std::byte const> payload) = 0;
};

/// Who is at the other end of a connection, as an admission policy sees it.
///
/// Two facts rather than one string, and the second is why this type exists: admission used to
/// be decided from the peer's ADDRESS alone, which is a stand-in for *this is one of our nodes*
/// and stops being one the moment an address is not stable
/// ([#1428](https://github.com/LASTRADA-Software/fastcached/issues/1428),
/// [#178](https://github.com/LASTRADA-Software/fastcached/issues/178) item 1).
///
/// Answers one framed request.
///
/// The seam that lets one accept loop serve every framed surface this node exposes.
/// A node runs a scheduler, a cache tier and a compile worker; each speaks the same
/// `0xFC` framing and differs only in what it answers and how much it will buffer.
/// A second accept loop per surface would be three near-copies of a listener, a
/// shutdown order and a poll timeout -- the copy-paste this codebase treats as a
/// defect rather than a coincidence.
///
/// An interface rather than a `std::function`, deliberately: a responder outlives
/// the endpoint and a closure would keep its whole enclosing scope alive with it.
class IFrameResponder
{
  public:
    virtual ~IFrameResponder() = default;

    IFrameResponder() = default;
    IFrameResponder(IFrameResponder const&) = default;
    IFrameResponder& operator=(IFrameResponder const&) = default;
    IFrameResponder(IFrameResponder&&) = default;
    IFrameResponder& operator=(IFrameResponder&&) = default;

    /// Answer one complete request frame.
    ///
    /// A `core::async::Task` because answering may now have to reach the network -- the cache
    /// surface consults an upstream, and that dial suspends rather than blocking
    /// the loop every other connection on this reactor is sharing. A responder
    /// that needs nothing is still free to `co_return` without suspending, which
    /// the scheduler's does; that costs a frame allocation and no round trip.
    ///
    /// @param frame The whole request, header included. A span rather than an
    ///        owning vector because a cache STORE carries an object file and
    ///        copying it here would double the peak footprint on the hot path of
    ///        a parallel build. It must outlive the returned task -- the same
    ///        contract `core::net::sendAll` states, and true by construction at the one call
    ///        site, where the backing vector is a local of the calling coroutine.
    /// @param peer Who is at the other end, for the surfaces whose policy needs it.
    ///        Owned rather than a view: it is short, and every policy-bearing
    ///        responder holds it across a suspension, so a view would make its
    ///        lifetime a rule at each implementation instead of a fact.
    ///        **It carries what the connection proved as well as its address, since
    ///        #1428**, and it has to reach HERE rather than only the door: this is
    ///        where the authoritative gate runs, so a proof the door honoured and
    ///        `Answer` could not see would refuse the caller one line later.
    /// @return The encoded reply, or empty to close without answering -- which is
    ///         only ever right when the peer is not speaking this protocol at all --
    ///         and whatever must stay held until the endpoint has written it.
    [[nodiscard]] virtual core::async::Task<FrameReply> Answer(std::span<std::byte const> frame, PeerIdentity peer) = 0;

    /// May this peer send at all, before a byte of its payload is taken?
    ///
    /// **The point is WHEN this is asked, not that it is asked.** Both surfaces
    /// already refused the peers this refuses -- but from inside `Answer`, which runs
    /// after the whole declared payload has been read and charged against the byte
    /// budget. So a caller the surface was always going to refuse could still make
    /// this process allocate for it, which is the cheapest denial there is: the
    /// refusal cost exactly what serving would have
    /// ([#285](https://github.com/LASTRADA-Software/fastcached/issues/285),
    /// [#377](https://github.com/LASTRADA-Software/fastcached/issues/377)).
    ///
    /// **Only decisions that depend on the PEER alone belong here.** That is what
    /// makes the question answerable before the frame exists. A surface's membership
    /// or locality rule qualifies; anything reading the verb, the payload or a
    /// credential does not, and stays in `Answer` where the request is.
    ///
    /// **The responder owns the predicate; the endpoint only asks it earlier.** The
    /// refusal is returned already encoded, so the wording, the wire code and the
    /// counter stay with the surface that decided -- rather than the endpoint growing
    /// its own copy of a rule that would then have two places to drift.
    ///
    /// **The gate inside `Answer` stays, and is still the authority.** This is an
    /// early-out, not a replacement: `Answer` is reachable directly, and a predicate
    /// enforced only at the door is one a later caller can walk around.
    ///
    /// Pure virtual rather than defaulted to "admit everyone", deliberately. A
    /// default would let a surface added later inherit an open door by saying
    /// nothing, which is the shape this codebase records as reopening a hole by
    /// omission. A surface with no peer policy returns `std::nullopt` and says so.
    ///
    /// **Takes the verb as well as the peer, since #290.** Each surface today serves
    /// one verb family, so the surface *is* the policy and every implementation
    /// ignores `opRaw` -- nothing observable changes. It is here because a merged
    /// 0xFC listener cannot express its own acceptance criterion without it: *a cache
    /// FETCH from another machine is refused while a compile from that same peer
    /// succeeds*. Same peer, two verbs, two answers, and a peer-only predicate has
    /// nowhere to put the difference.
    ///
    /// The verb costs nothing to supply. `ServeConnection` decodes the request header
    /// well before it asks this, so the opcode is already in hand at the one call
    /// site -- the earlier note that a peer-only shape is what "lets it be asked
    /// before a frame exists" described an option nobody takes, and it was the
    /// sentence that would have argued against this.
    ///
    /// Raw rather than an `Op`, for the reason `DecidePrePayload` is total over every
    /// byte value: an unknown opcode still has to be refusable, and a policy that
    /// could only be asked about verbs this build knows would admit the ones it does
    /// not.
    ///
    /// **Takes what the connection PROVED as well as its address, since #1428.** That is a
    /// `PeerIdentity` rather than a second parameter, and the widening is what makes a machine at
    /// an address on no list admissible at all -- and a REVOKED machine refusable from any address
    /// (#178): the address routes answer the same as before, and the identity is folded onto them
    /// per connection by `Distributed::ExplainConnection`. A surface that ignores the field
    /// answers exactly what it answered, because *nothing was proved* is a disengaged identity and
    /// the fold returns the oracle's own decision for it.
    ///
    /// @param peer Who is at the other end: the kernel's host, and what this connection proved.
    /// @param opRaw The third header byte, as received; not necessarily a known verb.
    /// @return The encoded refusal to send back, or nullopt to go on and read the
    ///         payload. A refusal is answered as a **reply and a resynchronization**
    ///         by the caller -- never a close, because the frame declared its length
    ///         and a peer that cannot tell a policy refusal from a dead host retries
    ///         forever.
    [[nodiscard]] virtual std::optional<std::vector<std::byte>> RefusePeer(PeerIdentity const& peer,
                                                                           std::uint8_t opRaw) const = 0;

    /// Check an `AUTH` payload.
    ///
    /// The endpoint terminates `AUTH` rather than passing it to `Answer`, because
    /// what the verb changes is **connection state**, and the responder is shared by
    /// every connection on this surface -- exactly as the daemon's handler keeps
    /// `credentialAccepted` in its own loop rather than in the policy.
    ///
    /// **The node checks no password.** There is no credential to require before a verb, so
    /// nothing here gates a frame: admission is `RefusePeer`'s. What an `AUTH` can still
    /// establish is which MACHINE a verified ticket speaks for, and only the session
    /// component -- the `Session` family's owner -- can answer that; every other surface is
    /// never routed an `AUTH` and says so.
    ///
    /// @param payload The `AUTH` request payload, already bounded by `MaxAuthPayload`
    ///        through the pre-payload gate.
    /// @return What was established. Only `Accepted` carries a machine -- `NoPolicy` is
    ///         answered `Ok` and establishes nothing.
    [[nodiscard]] virtual CredentialVerdict CheckCredential(std::span<std::byte const> payload) const = 0;

    /// Encode -- and count -- a pre-payload refusal `DecidePrePayload` decided.
    ///
    /// The same division of labour as `RefusePeer`: one predicate decides, and the
    /// surface owns the wording, the wire code and the counter, so a refusal cannot
    /// be worded one way here and another way in `Answer`. The endpoint deliberately
    /// does not encode this itself -- it would then own a counter belonging to a
    /// policy it does not implement.
    ///
    /// Pure virtual rather than defaulted for the reason `RefusePeer` is: a surface
    /// that says nothing would silently stop counting its own refusals, and a
    /// security counter reading zero because nobody wired it is indistinguishable
    /// from one reading zero because nothing was refused.
    ///
    /// **Takes the verb, since #290**, for the counter rather than for the wording.
    /// A merged 0xFC listener routes each verb to the surface that owns it, and a
    /// refusal has to be counted against that surface: a cache STORE that overran its
    /// ceiling attributed to the scheduler is a counter that names the wrong
    /// subsystem, which is the one thing an operator uses these to do. The wording
    /// stays verb-blind on purpose -- a peer that failed to authenticate learns
    /// nothing from being told which verb it failed to reach.
    ///
    /// **Takes the wording, since #447**, because the endpoint now reaches this from
    /// the surface-wide frame ceiling as well as from `DecidePrePayload`'s per-verb
    /// one, and that refusal names both numbers: "too large" without the ceiling
    /// tells an operator nothing about the limit they are up against. The two
    /// ceilings are one fact at two heights and share one counter -- an operator does
    /// the same thing about both -- so they are one `PayloadTooLarge` rather than a
    /// second enumerator. Empty where the caller has nothing to add, which is every
    /// pre-payload decision: a peer that failed to authenticate learns nothing from
    /// being told which verb it failed to reach.
    ///
    /// @param decision Any value other than `Serve`.
    /// @param opRaw The third header byte, as received; not necessarily a known verb.
    /// @param detail Words for a person, or empty when there are none to add.
    /// @return The encoded refusal to send back. Never empty.
    [[nodiscard]] virtual std::vector<std::byte> RefusalReply(CompileCacheWire::PrePayloadDecision decision,
                                                              std::uint8_t opRaw,
                                                              std::string_view detail) const = 0;

    /// Encode -- and count -- a refusal the ENDPOINT decided about a known verb.
    ///
    /// The companion to `RefusalReply`, and separate from it because the two answer
    /// about different things. `PrePayloadDecision` is a wire enum: it describes the
    /// frame's own header, both binaries compile it in, and the daemon reaches the
    /// same decisions from the same function. These are about **this process** -- the
    /// memory it is already holding, and what this connection has proved -- so they
    /// are decided here and cannot be expressed there.
    ///
    /// What they share is the division of labour, which is the whole point: the
    /// endpoint owns WHEN the question is asked, the surface owns the answer,
    /// including which counter moves. Every one of these used to be encoded in the
    /// accept loop with `Wire::EncodeErrorReply` and counted nothing, so a merged
    /// listener answered them correctly and left the series flat
    /// ([#447](https://github.com/LASTRADA-Software/fastcached/issues/447)).
    ///
    /// **A verb is always known here**, which is what separates these from the
    /// endpoint's one verbless refusal. A connection turned away because the surface
    /// already holds every connection it will is decided before a byte is read, so
    /// there is no owner to route it to and no responder is asked -- `FrameServer`
    /// counts that one itself, against its own row. Splitting them that way is also
    /// what keeps the two `EndpointBusy` refusals apart: `InFlightBudget` says one
    /// request is too big *right now* and `OpenConnections` says the surface is full,
    /// an operator acts on them oppositely, and they share a wire code. Two
    /// categories, so they cannot reach one counter by anybody forgetting.
    ///
    /// @param refusal Which refusal the endpoint decided.
    /// @param opRaw The third header byte, as received; not necessarily a known verb.
    /// @param detail Words for a person, or empty when there are none to add.
    /// @return The encoded refusal to send back. Never empty.
    [[nodiscard]] virtual std::vector<std::byte> EndpointRefusalReply(EndpointRefusal refusal,
                                                                      std::uint8_t opRaw,
                                                                      std::string_view detail) const = 0;

    /// How long serving @p opRaw may take before the socket is abandoned.
    ///
    /// **Per responder and per VERB, because one number cannot bound both things this
    /// endpoint now carries.** A cache exchange is bounded by a round trip; a
    /// dispatched compile is bounded by how long a COMPILER runs. That is #223,
    /// recorded in `distributed-compilation.md` for the client side -- and it arrived
    /// on the server side the moment a compile could reach a reactor surface (#290).
    ///
    /// The endpoint's own `HeaderTimeout` covers everything before a verb is named,
    /// which is where the slow-loris property lives: a peer that connects and sends
    /// half a header is swept on that short window whatever it might have been about
    /// to ask for. This one is armed only once the header has decoded, so a surface
    /// generous to compiles gives a stranger nothing.
    ///
    /// **A missing hop here is silent in the worst way.** `ServeConnection` is not
    /// parked on the socket while a responder answers, so a sweep closes it without
    /// waking anything: the compile runs to completion, hops home, and its `WriteAll`
    /// fails. Every translation unit worth distributing would be compiled, paid for
    /// and thrown away, while short ones succeeded -- so a smoke test passes.
    ///
    /// Pure virtual for the reason the ceilings below are: a surface that inherits
    /// this answer inherits five seconds, and five seconds is exactly the value that
    /// makes the failure above.
    ///
    /// @param opRaw The third header byte, as received; not necessarily a known verb.
    /// @return The window covering the payload read and the answer.
    [[nodiscard]] virtual std::chrono::milliseconds RequestTimeout(std::uint8_t opRaw) const noexcept = 0;

    /// Largest request this surface will buffer.
    ///
    /// Per-responder rather than one constant, and the spread is the point: a
    /// scheduler verb carries a fingerprint and a key, while a cache STORE carries a
    /// whole object file. Sizing both for the larger would hand an unauthenticated
    /// peer a way to make the scheduler allocate megabytes.
    ///
    /// **Zero here refuses every payload-bearing frame, and that is the OPPOSITE of what
    /// zero means for the two ceilings below**, where the endpoint reads it as *no ceiling*
    /// (`concurrent != 0`, `budget != 0`). The reader is built with this as its cap, so
    /// nothing a zero declares is buffered. The difference would surface through
    /// `MergedResponder`, whose fold answers 0 for all three when it folds no owner. No
    /// node builds that shape today -- `main.cpp` always hands it a compile owner -- so a
    /// case in `NodeFrameSurface_test.cpp` pins what each ceiling answers there (#1338).
    [[nodiscard]] virtual std::size_t MaxRequestBytes() const noexcept = 0;

    /// How many connections this surface will hold open at once.
    ///
    /// This counts CONNECTIONS, not requests, and the distinction became load-bearing
    /// when the endpoint learned to serve a connection until the peer stops (#176).
    /// While each connection was one request, the two were the same number and the
    /// cap read as a request cap; once a connection is long-lived, a slot held for
    /// its lifetime is held across the peer's idle time as well. Naming it for
    /// requests and sizing it for requests -- eight, on the cache surface -- would
    /// have let eight attached peers lock out every other client while barely
    /// sending anything.
    ///
    /// So what it bounds is descriptors and coroutine frames, and it is sized for
    /// those. Memory is NOT what this bounds; `MaxInFlightBytes()` below is, which is
    /// why this can afford to be generous.
    ///
    /// **Zero means no ceiling**: the accept loop refuses only when this is non-zero. Not
    /// what zero means for `MaxRequestBytes()`, which see.
    [[nodiscard]] virtual std::size_t MaxOpenConnections() const noexcept = 0;

    /// How many declared payload bytes may be in flight across all connections.
    ///
    /// The connection cap alone does not bound memory -- N connections each
    /// declaring `MaxRequestBytes()` is still N times that. This is what actually
    /// bounds it, and it is checkable at exactly the right moment: the header
    /// declares its length before a single payload byte is read.
    ///
    /// It is therefore also the throttle on concurrent WORK, which is the job the
    /// connection cap above stopped being able to do: a surface serving megabyte
    /// objects limits how many move at once by choosing a budget worth about one of
    /// them, and does not need a second count to say the same thing less precisely.
    /// A refusal here is a reply on a kept connection, so a peer that arrives during
    /// a busy moment is told to come back rather than made to reconnect.
    ///
    /// **Zero means no budget**: a header is refused for its declared length only when
    /// this is non-zero. Not what zero means for `MaxRequestBytes()`, which see -- and a
    /// surface whose request cap is also zero admits no payload to spend a budget on.
    [[nodiscard]] virtual std::size_t MaxInFlightBytes() const noexcept = 0;

    /// Whether this verb's owner accounts for the request's bytes itself.
    ///
    /// The budget above is charged when the header declares its length and released
    /// when `Answer` returns, which is right for a verb whose answer is a round trip
    /// and wrong for one whose answer is a COMPILE. A compile runs for seconds to
    /// minutes, and `CompileResponder` charges the same frame against
    /// `CompileCapacity` -- the accounting the worker advertises and the dedicated
    /// port already uses. Held in both, one buffer is counted in two pools for the
    /// whole compile, and the endpoint's pool is shared per LISTENER: compiles
    /// filling it refuse a 64 KiB `REGISTER` with `EndpointBusy`, which carries no
    /// redirect and is not followed by the worker half, so a peer expires out of the
    /// registry and every lease answers `NoWorker` -- a fleet outage caused by this
    /// node's own compile load (#448).
    ///
    /// So a verb that answers `true` is charged by the endpoint only while its
    /// payload is READ -- which nothing else can account for, since the owner has no
    /// frame yet -- and by its owner from there on. One buffer, one pool, and the
    /// figure both doors charge is the one the worker advertises.
    ///
    /// **The handoff is tight by construction, and rests on two invariants stated
    /// here because neither is visible at the release site.** `core::async::Task` is lazy
    /// (`Async/Task.hpp`: `initial_suspend` is `suspend_always`, with symmetric
    /// transfer at the final one), so `co_await Answer(...)` runs the body on the
    /// awaiting thread with no return to the loop; and the node's framed surfaces
    /// share exactly one reactor thread (`NodeIoLoop`). Between the release and the
    /// owner's charge there is therefore no suspension point and no other thread
    /// serving this pool, so nothing can observe the lowered figure. Were either
    /// invariant broken, `DeclaredRequestFootprint` floors at the payload length, so
    /// the owner always charges at least what was released -- the error would be
    /// bounded by one frame per reactor thread and would err towards over-admission.
    ///
    /// Pure virtual for the reason the ceilings above are: a surface that says
    /// nothing would answer `false` by inheritance and silently double-charge, which
    /// is precisely the defect this column exists to close.
    ///
    /// @param opRaw The third header byte, as received; not necessarily a known verb.
    /// @return True when the owner of @p opRaw charges the request's bytes itself.
    [[nodiscard]] virtual bool HoldsOwnByteBudget(std::uint8_t opRaw) const noexcept = 0;

    /// Whether a peer that disconnects while @p opRaw is being answered should be
    /// noticed before the answer is written, and where that is recorded.
    ///
    /// **Only worth asking where the answer is long.** A cache round trip is answered
    /// out of memory, so a client cannot realistically vanish inside one and the write
    /// that would discover it is the very next statement. A COMPILE runs for seconds
    /// to minutes, and today nothing observes the disconnect at all: the worker
    /// compiles to completion, encodes the object, and writes it into a socket nobody
    /// is reading -- 84 MB of it for a single translation unit, measured at #223.
    ///
    /// A surface that answers `true` gets a read-only watcher for the duration of the
    /// answer. **It never writes**, which is what keeps `ServeConnection`'s
    /// exactly-one-writer property structural rather than a rule somebody has to
    /// remember; see the loop's own note where the reply is written.
    ///
    /// ## The lifetime property, and why it is a property rather than a line of code
    ///
    /// The watcher parks in `core::net::ISocket::WaitReadable`, and **a parked wait can only be
    /// cancelled by `Close()`** -- there is no other cancellation on the interface. So
    /// a watch that was armed and did not fire ends the connection after that reply,
    /// because the alternative is to issue the loop's next `Read` while the watcher is
    /// still parked. That is not merely undefined: `EpollSocket::Read` and
    /// `WaitReadable` share one read-op slot and each begins by nulling the parked
    /// awaitable, so the second arm drops the first coroutine's resume handle and
    /// leaks its frame, silently and permanently, with no assertion and no log
    /// (`IocpSocket` has the same shape;
    /// [#663](https://github.com/LASTRADA-Software/fastcached/issues/663) is about
    /// making that loud rather than leaving it as prose in another file).
    ///
    /// Stated here as the *reason* rather than left at the close itself, because an
    /// undocumented lifetime change is how the next reader "fixes" it back into the
    /// leak.
    ///
    /// ## It is unobservable today, and here is the check that would falsify that
    ///
    /// `Cc::RunOneExchange` is documented as "once per verb" (`ReactorExchange.hpp`)
    /// and dials fresh on every call, so **no client in this tree reuses a compile
    /// connection** -- the launcher pipelines AUTH and COMPILE into one connection and
    /// then closes it. The cost of this concession is therefore currently zero.
    ///
    /// If someone adds connection reuse, the check is exactly that sentence: does any
    /// client send a second request on a connection that carried a COMPILE? The moment
    /// one does, it pays one extra connect per compile -- which is a fair price for
    /// not double-arming the slot above, but it must not be a mystery. A concession
    /// justified by a fact about the tree has to name the fact, or it stops being
    /// justified the moment the fact changes and nobody notices.
    ///
    /// ## What EOF is taken to mean, and the case that reading costs
    ///
    /// **A peer that has sent FIN is treated as gone, and that is a decision rather
    /// than a deduction.** EOF says the peer closed its WRITE side; whether its read
    /// side is still open is not observable from here, and the only way to find out is
    /// to write -- which is the cost this exists to avoid. So a half-close, where a
    /// client says "I will send nothing more" and still waits for its reply, is read
    /// here as a client that left: its object is not written and the counter names it
    /// as abandoned.
    ///
    /// **The cache surface one directory away applies the SAME rule and reaches a
    /// different outcome**, which is worth stating precisely because this paragraph
    /// used to claim the opposite. It said `RedisResp`'s `ArmDisconnect` counted only
    /// a socket ERROR as a disconnect, and offered that contrast as the REASON the
    /// compile surface departs from it. #673 made that false: `ArmDisconnect` is
    /// `if (!readable.has_value() || *readable == 0)` (`RedisResp.cpp`), because an
    /// error is an abortive close while `0` is EOF -- the ORDINARY way a client leaves
    /// -- so the error-only arm it used to have never once fired and leaked the socket
    /// it existed to free.
    ///
    /// So there is no disagreement between the surfaces to justify. Both read EOF as
    /// *this peer has finished sending*; what differs is what is already DETERMINED at
    /// that moment. A cache command's reply is determined, so it is answered; a
    /// compile's is not -- the object does not exist yet -- so there is nothing to
    /// serve and the delivery is abandoned. One rule, two outcomes, and the wire is
    /// what picks which.
    ///
    /// **The check that would falsify the trade-off**: does any client half-close after
    /// sending? None in this tree does -- and that is now an absence of exercise rather
    /// than an impossibility, which is a materially weaker guard than this paragraph
    /// used to claim.
    ///
    /// It said `core::net::ISocket` had no `ShutdownWrite` at all, so nothing here *could*
    /// half-close. #671 put `ShutdownWrite` on the interface itself
    /// (`ISocket.hpp`, virtual with a default no-op), precisely so the question would
    /// be askable in production rather than only over the in-memory transport. So every
    /// transport can half-close today; the reason this concession stays free is only
    /// that no client in this tree chooses to.
    ///
    /// A reader who checks the old sentence finds it satisfied and stops. The current
    /// check is the weaker one and has to be run rather than reasoned: does any caller
    /// of a `0xFC` client actually call `ShutdownWrite` before awaiting its reply? A
    /// third-party client speaking `0xFC` over a raw socket could, and would lose
    /// distribution silently while this counter blamed it. If one ever does, the answer
    /// is not to soften the rule -- it is that EOF-without-close needs a meaning this
    /// wire agrees on, in one place, for both surfaces.
    ///
    /// ## Why it answers a COUNTER rather than a bool
    ///
    /// An abandoned delivery is an event on the SURFACE, not on the endpoint: the
    /// endpoint owns when the question is asked and the surface owns what it means,
    /// which is the same split every refusal in this loop already makes. A bool would
    /// leave the endpoint incrementing `fastcache_worker_jobs_*` for whichever surface
    /// happened to arm a watch, so the day a second one does it would file its events
    /// under the worker's name and nothing would say so.
    ///
    /// So a surface that wants the watch names the row its abandoned deliveries belong
    /// to, and `std::nullopt` is "do not watch" -- the only two answers there are.
    ///
    /// Pure virtual for the reason every ceiling above is: a surface that says nothing
    /// would inherit an answer, and here the inherited answer would silently change
    /// when this connection ends.
    ///
    /// @param opRaw The third header byte, as received; not necessarily a known verb.
    /// @return The counter to raise when the peer is found gone, or nullopt not to
    ///         watch @p opRaw at all.
    [[nodiscard]] virtual std::optional<IMetricsSink::Counter> PeerWatchCounter(std::uint8_t opRaw) const noexcept = 0;

    /// How often this surface pulses `Status::Progress` while answering @p opRaw, or
    /// nullopt not to pulse it at all.
    ///
    /// **The liveness signal a long verb owes its client**
    /// ([#245](https://github.com/LASTRADA-Software/fastcached/issues/245)). A client
    /// bounds a dispatched compile with one flat deadline, which has to be as long as
    /// the slowest translation unit anybody compiles -- so that same number is how long
    /// a worker whose process has stopped making progress goes unnoticed. TCP keepalive
    /// answers the case where the HOST goes away and cannot see the case where the
    /// kernel answers every probe while nothing above it does. Only a periodic *I am
    /// still here* separates the two, and only the party doing the work can send it.
    ///
    /// **Per verb, and answered by the SURFACE, for `PeerWatchCounter`'s reason**: the
    /// endpoint owns *when* -- it holds the socket and it is the only writer on it --
    /// and the surface owns *whether this verb is the kind of work worth reporting on*.
    /// Every verb here but `Compile` is answered from a table in microseconds, so a
    /// pulse on one would be a frame no client could ever observe and a second reply
    /// shape every reader would have to handle for nothing.
    ///
    /// **An interval, not a bool**, because the number has to agree with the client's
    /// idle bound: they measure one silence from opposite sides. Neither end can pick
    /// its own without describing a fleet the other is not running, which is why both
    /// values sit in `CompileCacheWire` with the relation between them asserted there.
    ///
    /// Pure virtual for the reason every question above it is: a surface that says
    /// nothing would inherit an answer, and inheriting *pulse* would put a frame on a
    /// wire whose client has no reason to expect one.
    ///
    /// @param opRaw The third header byte, as received; not necessarily a known verb.
    /// @return How long between pulses, or nullopt not to pulse @p opRaw at all. A
    ///         non-positive interval is treated as nullopt, the same way every ceiling
    ///         in this tree spells *no bound*.
    [[nodiscard]] virtual std::optional<std::chrono::milliseconds> ProgressInterval(std::uint8_t opRaw) const noexcept = 0;

    /// The stream that answers @p opRaw, or null when this verb is answered with one reply.
    ///
    /// **Per verb, and answered by the SURFACE, for `ProgressInterval`'s reason**: the endpoint
    /// owns the socket and the order of what leaves on it, and the surface owns whether this verb
    /// is a subscription. Only `Op::Subscribe` is (`CompileCacheWire::PushIsSubscribeOnly`).
    ///
    /// Pure virtual for the reason every question above is: a surface that inherited *stream*
    /// would be asked to serve a subscription it knows nothing about, and one that inherited
    /// *reply* for a stream verb would answer a single frame to a client waiting for a series.
    /// @param opRaw The third header byte, as received; not necessarily a known verb.
    /// @return The stream, which must outlive the endpoint, or null.
    [[nodiscard]] virtual IFrameStream* StreamFor(std::uint8_t opRaw) noexcept = 0;

    /// The identity prover this surface offers a connection, or null when it offers none.
    ///
    /// **Not per verb**, unlike every question above it: the two verbs of
    /// `VerbFamily::NodeProof` are one exchange and a surface that served half of it would be a
    /// connection that can be challenged and never proved. So the answer is the surface's, asked
    /// once, and the family's two rows are handled together or not at all.
    ///
    /// Pure virtual, and the reason is `StreamFor`'s rather than `RefusePeer`'s: null is the SAFE
    /// answer here -- a surface offering no prover admits nobody it would not have admitted
    /// before -- so what a default would cost is not an open door but a silence. It would let a
    /// surface that ought to verify proofs inherit *I verify none*, which is a family refused at
    /// the door with a sentence about this node running no cluster, on a node that runs one. A pure
    /// virtual makes the claim explicit at each surface.
    /// @return The prover, which must outlive the endpoint, or null.
    [[nodiscard]] virtual INodeProver* NodeProver() noexcept = 0;
};

/// How a refused request gets back to a frame boundary, so the connection stays
/// usable.
///
/// **A PRIVATE enum -- nothing transmits it and nothing stores it -- so it states no
/// ordinals.** An explicit `= N` here would assert a contract that does not exist.
enum class Resynchronize : std::uint8_t
{
    StepOver, ///< Read and discard exactly what the header declared.
    Oversize, ///< The declaration is past the cap, so the step-over is bounded too.
};

/// A refusal decided from a request HEADER, before a payload byte is read.
///
/// Returned by value and owning: the reply is bytes this endpoint will hand to a
/// write, not a view into anything the decision borrowed. `.agent/rules/wire-and-protocol.md`
/// is explicit that a struct a decoder returns by value must not borrow from what it
/// decoded, and the same reasoning governs a decision returned to a caller that then
/// suspends.
struct HeaderRefusal
{
    std::vector<std::byte> reply; ///< What to send. Encoded and counted by the surface.
    Resynchronize resynchronize;  ///< How to reach the next frame boundary afterwards.
};

/// What `DecideHeaderRefusal` reads of a surface.
struct HeaderGate
{
    IFrameResponder& responder; ///< What answers -- and encodes and counts -- every refusal.
    std::string_view what;      ///< The surface's name, for the messages that name it.
    std::size_t inFlightBytes;  ///< What the surface holds in flight now, read ONCE: the figure decided on.
};

/// Whether this header is refused, and with what.
///
/// **Four refusals, one question, and it writes nothing** -- which is what makes
/// lifting it out of `ServeConnection` legal at all (#675). That loop holds the
/// endpoint's exactly-one-writer property, so an extraction that takes a write with
/// it turns the property into an agreement between two functions; this takes the
/// DECISION and leaves every byte to the loop, which is why the four `WriteAll`
/// calls that used to sit in these branches are now one.
///
/// **The ORDER is the load-bearing part and it is now stated in one place.** Each
/// step's reasoning is on the step:
///
///  1. The surface-wide cap, on the DECLARED length, so nothing is allocated.
///  2. Admission, ahead of any resource decision -- a peer this surface will not
///     serve must not be able to reach one, or a flood of refusable frames exhausts
///     the budget and makes the surface answer `EndpointBusy` to the peers it does
///     serve, which is the denial reconstructed one step out (#285, #377).
///  3. The credential and the per-verb ceiling, through the same `DecidePrePayload`
///     the daemon's loop calls, so the two surfaces cannot disagree about which
///     verbs are open before authentication.
///  4. The in-flight byte budget, last, for the reason step 2 gives.
///
/// @param gate What the surface answers with, its name, and the bytes it holds in flight now.
/// @param peer Who is at the other end: the kernel's host, and what this connection has
///        proved. A source port is ephemeral and is not an identity, so the address is all an
///        admission policy had before #1428 -- and a proof is the second thing it now has.
/// @param decoded The request header, as it decoded.
/// @param cap The surface-wide request ceiling, read once by the caller.
/// @return The refusal, or nullopt when the request is to be served.
[[nodiscard]] std::optional<HeaderRefusal> DecideHeaderRefusal(HeaderGate const& gate,
                                                               PeerIdentity const& peer,
                                                               CompileCacheWire::RequestHeader const& decoded,
                                                               std::size_t cap);

/// Accepts connections and answers framed requests on each until the peer stops.
///
/// Shaped after `WorkerServer` rather than `Server`, and for the reason that governs
/// the whole node: `Connection` is built around a `CacheEngine`, and a scheduler has
/// no cache. Taking an `IListener&` and running its own loop keeps the node clear of
/// the cache stack while still reusing the reactor and the socket abstraction.
///
/// ## Many requests per connection
///
/// A connection is served until the peer stops sending, which is what the daemon
/// serving this same wire has always done (`Protocol/CompileCacheHandler`). This
/// endpoint answered exactly one request and closed, and that was issue #176 rather
/// than a simpler design: a worker dials once per heartbeat ROUND and then registers
/// every toolchain it found over that one connection, so a machine with two
/// toolchains registered one of them, every round, forever -- reported as a transport
/// failure, which named neither the cause nor the toolchain that lost.
///
/// There is still no per-connection state and no handshake; a loop is not a session.
/// What it buys is that a peer with two things to say may say both, which is a
/// property of the wire (a credential is a frame, so presenting one is two frames)
/// rather than an optimisation.
///
/// ## The payload cap is small on purpose
///
/// A scheduler verb carries a fingerprint, an endpoint and a key, none of which is
/// large, so the ceiling is kilobytes rather than the cache's megabytes. A frame over
/// it is refused with a *reply* naming both numbers, not a close.
///
/// It used to carry a second job: membership was checked inside the service, after
/// the frame had been read, so the small cap was what bounded what a stranger could
/// make this endpoint allocate. `IFrameResponder::RefusePeer` closes that directly
/// now (#285, #377) -- a peer the surface will refuse is refused before its payload
/// is read at all -- and the cap is back to being only what it says it is.
class FrameServer
{
  public:
    /// How long a peer may take to NAME a verb before its socket is abandoned.
    ///
    /// This used to be `SO_RCVTIMEO`, applied to every accepted socket by
    /// `BlockingListener::SetTimeouts`. A reactor socket has no such option -- its
    /// reads suspend rather than block -- so without a replacement a client that
    /// connects and sends half a header holds a descriptor and a coroutine frame
    /// until the process dies. A slow-loris on the node's cache port, free.
    ///
    /// Armed once per REQUEST rather than once per connection, so a conversation is
    /// not swept mid-flight. This window covers the idle gap before a request and its
    /// header -- so an attached peer that stops talking is still swept, which is what
    /// keeps the slow-loris property once a connection is long-lived.
    ///
    /// **It stops there, and it used to not.** It was `RequestTimeout` and it covered
    /// the answer as well, which is a five-second ceiling on how long a responder may
    /// take -- correct for a cache round trip and fatal for a compile, which runs for
    /// minutes. `IFrameResponder::RequestTimeout` is what covers the answer now, and
    /// the split is deliberate rather than cosmetic: everything decided BEFORE a verb
    /// is named is decided about a peer that has told this surface nothing, so it must
    /// stay short whatever the surface goes on to serve. Renamed rather than
    /// redocumented, because a name that has quietly stopped describing its own fact is
    /// how #365 happened.
    static constexpr std::chrono::milliseconds HeaderTimeout { 5'000 };

    /// How often the sweeper looks for connections past their deadline.
    ///
    /// ONE sweeper per server rather than one timer per connection, and that is the
    /// difference between a bounded cost and a parked frame per client.
    /// `core::net::EventLoop::Schedule` cannot be cancelled, so a per-connection timer would
    /// stay on the wheel for the full interval after its connection had already
    /// finished -- the leak `Async/DeadlineTimer` documents at length.
    static constexpr std::chrono::milliseconds SweepInterval { HeaderTimeout / 4 };

    /// How long a REFUSED connection is given to read its refusal and hang up.
    ///
    /// Shorter than `HeaderTimeout` because there is less to wait for: the peer has
    /// its answer already and has only to close, which is a round trip rather than a
    /// request. A refusal takes no connection slot, so nothing counts one -- and a
    /// surface that is refusing is one already at capacity, which is exactly when a
    /// flood must not be able to park a socket per attempt for as long as a real
    /// request gets.
    ///
    /// One sweep interval, because the sweeper's cadence is the floor on how promptly
    /// any deadline can be acted on: asking for less would be a number that reads like
    /// a guarantee and is not one. So a refused socket outlives its answer by at most
    /// two ticks, against the six a served request may take.
    static constexpr std::chrono::milliseconds RefusalTimeout { SweepInterval };

    /// How often a connection ending under a parked watch re-reads that watch.
    ///
    /// Short, because it is pure teardown latency on this side: the peer already has
    /// its answer, and the ordinary client hangs up within one step. Here rather than
    /// beside the loop it drives, so it sits with `RefusalTimeout` above, which is the
    /// ceiling that actually bounds that wait -- two halves of one bound in two files
    /// is how they come to disagree.
    static constexpr std::chrono::milliseconds GracefulCloseStep { 5 };

    /// How long a swept-but-not-closed connection is given to come back and explain
    /// itself before it is closed after all.
    ///
    /// A connection swept while parked INSIDE the responder is not closed: closing it
    /// there wakes nothing (`IFrameResponder::RequestTimeout` says why) and only
    /// destroys the write side the refusal has to leave by. It is marked instead, and
    /// the connection writes its own refusal when `Answer` returns.
    ///
    /// **This is what keeps that deferral from being unbounded.** `Answer` is an
    /// interface, so nothing here can promise it returns at all -- a wedged responder
    /// would otherwise hold the descriptor for the life of the process, where the old
    /// unconditional close released it. When this expires the sweeper closes as it
    /// always did, so the fix can only ever cost this much promptness and never the
    /// property it replaced.
    ///
    /// **Derived from the verb's own window, and it shipped once as a flat constant
    /// that was wrong by a factor of 120.** `SweepInterval * 4` resolves to five
    /// seconds; `CompileResponder::RequestTimeout` was `DefaultCompileLeaseTimeout` at
    /// the time, which is six hundred -- and is `MaxCompileLeaseLifetime` since #522,
    /// which is wider again. A translation unit that has just outrun a ten-minute
    /// grant does not return inside five seconds, so the deferral expired, the socket
    /// was closed, and the connection found nothing owed when `Answer` finally came
    /// back -- delivering the explanation reliably on the cache surface, where the
    /// problem is mild, and silently not at all on the compile surface, which is the
    /// one #523 was filed about. The constant's own justification was that its value
    /// is "a property of this mechanism and not of a site's workload", written three
    /// hundred lines below `IFrameResponder::RequestTimeout` arguing that ONE NUMBER
    /// CANNOT BOUND BOTH THINGS this endpoint carries -- and pure virtual so that no
    /// surface can inherit five seconds, because five seconds is exactly the value
    /// that makes this failure.
    ///
    /// So the rule is: **a responder gets at most twice its own budget before the
    /// socket goes.** Ten seconds on the cache, and twice `MaxCompileLeaseLifetime` on
    /// a compile -- two hours since #522 widened that ceiling, where it was twenty
    /// minutes before. Stated as the RULE rather than as a figure, because the figure
    /// moves with a constant this file does not own: both bounded, both proportional to
    /// what the surface itself said its work costs, and
    /// neither able to drift from `RequestTimeout` because it is the same number. No
    /// flag and no new virtual -- the value comes from a question the endpoint
    /// already asks at the point it arms the answer window.
    ///
    /// A pure function over the window rather than arithmetic inlined at the sweep,
    /// so the magnitude can be pinned on both sides without a case that waits out a
    /// wall-clock spread the instrument's own noise is comparable to.
    /// @param window The verb's answer window, as the responder named it.
    /// @return How long past the sweep the descriptor is held open.
    [[nodiscard]] static constexpr std::chrono::milliseconds ExplanationGraceFor(std::chrono::milliseconds window) noexcept
    {
        // Floored at the sweeper's cadence, which is the floor on how promptly any
        // deadline here can be acted on: a grace under one tick would be a number
        // that reads like a guarantee and is not one. The same argument
        // `RefusalTimeout` above makes for the same reason.
        return std::max(window, SweepInterval);
    }

    /// @param io The loop this server accepts and answers on.
    /// @param listener Bound listener; must outlive the run.
    /// @param responder Answers each request; must outlive the run.
    /// @param what Names this surface in log lines, so three endpoints in one
    ///        process are distinguishable when one of them stops accepting.
    /// @param metrics Where this endpoint's OWN refusal is recorded. Exactly one
    ///        refusal here belongs to the endpoint rather than to a surface: a
    ///        connection turned away because every connection slot is taken is
    ///        decided at accept, before a header exists, so it names no verb and
    ///        `MergedResponder` has nothing to route it by. Every other refusal is
    ///        the owning surface's and reaches its counter through `IFrameResponder`.
    /// @param logger Shared logger.
    FrameServer(NodeIoLoop& io,
                core::net::IListener& listener,
                IFrameResponder& responder,
                std::string_view what,
                IMetricsSink& metrics,
                ILogger& logger,
                Node::ToolchainNamer namer = {}) noexcept;

    FrameServer(FrameServer const&) = delete;
    FrameServer(FrameServer&&) = delete;
    FrameServer& operator=(FrameServer const&) = delete;
    FrameServer& operator=(FrameServer&&) = delete;
    ~FrameServer();

    /// Accept loop; returns when the listener is closed via `Shutdown()`.
    ///
    /// Each accepted connection is served by a `core::async::DetachedTask` of its own rather
    /// than inline, which is the entire point: the cache surface consults an
    /// upstream from inside its answer, and serving that inline is what made one
    /// slow dial stall every other client of this node.
    [[nodiscard]] core::async::Task<void> Run();

    /// Stop accepting, close what is open, and wait for the connections to end.
    ///
    /// Safe from any thread. The closes are POSTED onto the reactor rather than
    /// done here, and that is not caution: `core::net::ISocket::close` retires the
    /// socket's registration with the loop, which only the reactor's thread may touch.
    /// The connection tasks a close wakes resume in the loop's next drain, on the
    /// reactor, on every backend (core-cpp 0.2.1, guarantee G2); fastcached's own
    /// reactor used to run them inline on epoll and kqueue, on the closing thread.
    void Shutdown() noexcept;

    /// Report a loop that threw, without throwing. Called by the owning loop's
    /// exception firewall.
    void NoteLoopThrew() noexcept;

    /// @return How many connections are being served right now. For tests.
    [[nodiscard]] std::size_t OpenConnections() const noexcept;

    /// @return How many declared payload bytes are in flight. For tests.
    [[nodiscard]] std::size_t InFlightBytes() const noexcept;

    /// Implementation detail; public so the .cpp's connection tasks can name it.
    struct State;

  private:
    std::shared_ptr<State> _state;
};

/// The node's scheduler port: listener, server and the thread that serves them,
/// owned as one thing.
///
/// A class rather than three locals in `main()`, for the reason `AdminEndpoint`
/// records: the three have a *destruction order* -- the server must close its
/// listener before the thread serving it can be joined -- and holding them separately
/// expresses that as a `Shutdown()` somebody has to remember at every return path.
/// Here it is the destructor. And `main.cpp` in this binary is in no test target, so
/// wiring that lives there has no unit coverage at all.
class FrameEndpoint
{
  public:
    /// Bind the endpoint and start serving it.
    ///
    /// The error is a diagnostic string rather than one of the project's four error
    /// enums, the same deliberate departure `AdminEndpoint::Start` documents: this
    /// fails in two ways belonging to two taxonomies -- a malformed listen spec is a
    /// `ConfigError`, an address that will not bind is a `core::net::NetError` -- the caller's
    /// response is identical either way, and what it needs is the text.
    /// **A surface, never an address.** This used to take the listen spec, the host a
    /// bare port falls back to and the surface's name as three loose arguments, and
    /// every caller supplied its own -- so the port map lived here as well as in the
    /// four other places #288 found it, and a new surface could be opened without
    /// appearing on the map an operator is told to build a firewall from.
    ///
    /// Taking the enumerator makes that impossible rather than merely discouraged:
    /// there is no argument to pass a bare string to, so a port cannot be opened
    /// without a row, and a row cannot exist without `RowsInEnumeratorOrder`
    /// accepting it. A guard that fails the build beats one that fails a suite.
    /// @param io The loop this endpoint accepts and answers on. It must be
    ///        `Start()`ed after every endpoint has been created, so the listener is
    ///        bound and adopted before anything begins accepting.
    /// @param surface Which surface to serve. Its row supplies the address, the host
    ///        a bare port takes and the name used in log lines -- including the
    ///        asymmetry between them, which is the anti-leeching rule rather than a
    ///        caller's preference: a scheduler no peer can dial does nothing, while a
    ///        node's private cache reachable from the network is this machine's whole
    ///        build output served to strangers.
    /// @param cfg What the operator asked for; the row resolves the endpoint from it.
    /// @param responder Answers each request; must outlive the endpoint.
    /// @param metrics Where this endpoint's own at-capacity refusal is counted; see
    ///        the `FrameServer` constructor for why exactly one refusal is its own.
    /// @param logger Where to announce the bound address.
    /// @return The running endpoint, or why it could not be served.
    [[nodiscard]] static std::expected<std::unique_ptr<FrameEndpoint>, std::string> Start(NodeIoLoop& io,
                                                                                          NodeSurface surface,
                                                                                          NodeConfig const& cfg,
                                                                                          IFrameResponder& responder,
                                                                                          IMetricsSink& metrics,
                                                                                          ILogger& logger,
                                                                                          Node::ToolchainNamer namer = {});

    /// Serve a surface on a descriptor a supervisor already bound and listened.
    ///
    /// The socket-activation counterpart to `Start`, and everything after the
    /// listener is obtained is the same -- which is why they are two factories over
    /// one private constructor rather than one factory with a flag: what differs is
    /// exactly where the listener comes from, and nothing else.
    ///
    /// **No row is resolved and no address is read from `cfg`.** Under activation the
    /// unit owns the address; `--listen-node` holds a value that describes nothing,
    /// which is the whole of the rule that a flag naming a listener this process did
    /// not open cannot answer questions about that listener. The port comes back from
    /// the descriptor itself, and the HOST can only come from `--advertise` -- which
    /// is why activation makes that flag mandatory and refuses at startup without it.
    ///
    /// **The descriptor is handed on, never held.** `AdoptInheritedListener` takes
    /// ownership including on its own failure paths -- on Windows it refuses, and an `int`
    /// names no socket there to own -- so this function neither closes it on a refusal
    /// nor lets anything else do so. A failed adoption is a startup
    /// refusal exactly as a failed bind is: an activated node that cannot serve the
    /// descriptor it was given is in the position that refusal exists for, and
    /// warning past it would leave a worker registering an endpoint nothing answers.
    ///
    /// @param io The loop this endpoint accepts and answers on.
    /// @param surface Which surface to serve. Its row supplies the name used in log
    ///        lines; its address is not consulted, because the unit chose it.
    /// @param descriptor An already-bound, already-listening descriptor. Ownership
    ///        passes to the listener built here, whether or not that succeeds; Windows
    ///        refuses without one to own.
    /// @param advertisedHost The host clients are told to dial, from `--advertise`.
    ///        The only honest answer to "what address is this", since the process
    ///        cannot ask the unit and a wildcard bind names nothing dialable.
    /// @param responder Answers each request; must outlive the endpoint.
    /// @param metrics Where this endpoint's own at-capacity refusal is counted; see
    ///        the `FrameServer` constructor for why exactly one refusal is its own.
    /// @param logger Where to announce the adopted address.
    /// @return The running endpoint, or why the descriptor could not be served.
    [[nodiscard]] static std::expected<std::unique_ptr<FrameEndpoint>, std::string> StartAdopted(
        NodeIoLoop& io,
        NodeSurface surface,
        int descriptor,
        std::string_view advertisedHost,
        IFrameResponder& responder,
        IMetricsSink& metrics,
        ILogger& logger,
        Node::ToolchainNamer namer = {});

    /// Serve a surface on a listener the CALLER built.
    ///
    /// The one door `Start` and `StartAdopted` both arrive at once they have a bound
    /// listener, so the adopt-and-serve half exists once rather than twice, and the
    /// **test seam for the teardown rule**
    /// ([#840](https://github.com/LASTRADA-Software/fastcached/issues/840)). That
    /// defect is about *which thread* -- and with *what* running -- the listener this
    /// endpoint owns is destroyed on, and neither factory above lets a case supply a
    /// listener it can ask. Without this, a test can pin the defect's precondition and
    /// nothing else, which is what #668 shipped and deliberately did not call a fix.
    ///
    /// **It opens no port and can open none.** The listener arrives already bound, and
    /// the surface still arrives as a `NodeSurface`, so the row supplies the name in
    /// the log lines exactly as it does for the two factories -- there is still no
    /// argument to pass a bare address to, which is what `Start` documents at length.
    ///
    /// Infallible, and that is what separates it from the two above: everything that
    /// can fail is the bind, and this is reached after it.
    /// @param io The loop this endpoint accepts and answers on.
    /// @param surface Which surface to serve; its row supplies the name only.
    /// @param listener A bound listener belonging to `io.Reactor()`. Ownership passes
    ///        here, and `~FrameEndpoint` hands it to `io` rather than freeing it.
    /// @param boundEndpoint What `BoundEndpoint()` reports; the caller derives it,
    ///        because only it knows whether the host came from a row or `--advertise`.
    /// @param responder Answers each request; must outlive the endpoint.
    /// @param metrics Where this endpoint's own at-capacity refusal is counted.
    /// @param logger Shared logger.
    /// @return The running endpoint. Never null.
    [[nodiscard]] static std::unique_ptr<FrameEndpoint> StartWithListener(NodeIoLoop& io,
                                                                          NodeSurface surface,
                                                                          std::unique_ptr<core::net::IListener> listener,
                                                                          std::string boundEndpoint,
                                                                          IFrameResponder& responder,
                                                                          IMetricsSink& metrics,
                                                                          ILogger& logger,
                                                                          Node::ToolchainNamer namer = {});

    /// Stop serving. The loop's own thread is joined by `NodeIoLoop`.
    ///
    /// The listener is not freed here: it belongs to the reactor, which is typically
    /// still running at this point, so it is handed to `NodeIoLoop::Retire` -- see
    /// there for why deferring rather than posting is what closes #840.
    ~FrameEndpoint();

    FrameEndpoint(FrameEndpoint const&) = delete;
    FrameEndpoint& operator=(FrameEndpoint const&) = delete;

    // Neither movable, for the reason `AdminEndpoint` gives: the reactor holds
    // pointers into `_server`, and `_server` a reference to `_listener`.
    FrameEndpoint(FrameEndpoint&&) = delete;
    FrameEndpoint& operator=(FrameEndpoint&&) = delete;

    /// The address this endpoint actually bound.
    [[nodiscard]] std::string const& BoundEndpoint() const noexcept
    {
        return _boundEndpoint;
    }

    /// @return How many declared payload bytes are in flight. For tests.
    ///
    /// Forwarded from `FrameServer` rather than exposing the server itself: the one
    /// thing a case needs to read from outside is this figure, and the handoff in
    /// `IFrameResponder::HoldsOwnByteBudget` is an ORDERING that nothing else can
    /// observe (#448).
    [[nodiscard]] std::size_t InFlightBytes() const noexcept;

    /// @return How many connections are being served right now. For tests: forwarded for the same
    ///         reason as `InFlightBytes`, so a case can see a peer LEAVE rather than infer it.
    [[nodiscard]] std::size_t OpenConnections() const noexcept;

  private:
    FrameEndpoint(NodeIoLoop& io,
                  std::unique_ptr<core::net::IListener> listener,
                  IFrameResponder& responder,
                  std::string_view what,
                  std::string boundEndpoint,
                  IMetricsSink& metrics,
                  ILogger& logger,
                  Node::ToolchainNamer namer = {});

    /// The loop this endpoint accepts on, and what its listener is handed back to.
    ///
    /// Held rather than only borrowed at construction because `~FrameEndpoint` needs
    /// it: the listener is reactor-owned and must not be destroyed on this thread
    /// while the reactor turns. See `NodeIoLoop::Retire`.
    NodeIoLoop& _io;

    /// `core::net::IListener` and not the platform type, deliberately: naming the concrete one
    /// would drag `<windows.h>` into every header that includes this, and nothing
    /// here needs more than Accept, Close and BoundPort -- the last of which is on
    /// the interface now precisely so this could stop being concrete.
    std::unique_ptr<core::net::IListener> _listener;
    std::unique_ptr<FrameServer> _server;
    std::string _boundEndpoint;
};

} // namespace Pace::Node
