//! `MessageService` (plan.md §111 send flow / §112 receive flow), scoped
//! to what Phase 1 needs: one-to-one text messages, no groups, no
//! multi-device fanout yet (plan.md §124's "Alice ↔ Bob text messaging").

use crate::events::MessagingEvent;
use crate::projections::{
    ConversationSummary, ConversationSummaryProjection, ConversationSummaryQuery,
};
use crate::stoolap_projections::StoolapConversationSummaryProjection;
use crate::PeerTicket;
use siar_crypto::{DeviceIdentity, Session};
use siar_domain::{
    backoff_millis, with_jitter, AttachmentReference, BlobSize, CallControlEvent, ConversationId,
    DeliveryState, DeviceId, MediaType, MessageContent, MessageId, MessageText,
};
use siar_event_log::projection::{
    InMemoryCheckpointStore, ProjectionCheckpointStore, ProjectionRunner,
};
use siar_event_log::StoolapCheckpointStore;
use siar_event_log::{
    append_with_retry, CorrelationId, EventId, EventOrigin, EventStore, DEFAULT_CATCH_UP_BATCH_SIZE,
};
use siar_protocol::v1::{Envelope, EnvelopeKind, CURRENT_VERSION};
use siar_protocol::{MailboxCheckIn, WireMessage};
use siar_storage::{BlobRepository, MessageRepository, OutboxRepository, StoredMessage};
use siar_transport::{PeerTransport, SiarEndpoint};
use std::collections::HashMap;
use std::sync::{Arc, Mutex};
use std::time::{SystemTime, UNIX_EPOCH};
use thiserror::Error;

/// §33/Phase 3's own append retry budget for this crate's real call
/// sites — see `siar_event_log::retry`'s own doc comment for why
/// blind retry with the same event is safe. Small: a single
/// conversation being written from two places in the same process at
/// once (a send racing an incoming-message's own append) is the only
/// realistic contention this crate has right now, not a real
/// multi-writer workload.
const EVENT_LOG_APPEND_MAX_ATTEMPTS: u32 = 5;

/// plan.md §46: how long we wait for a `DeliveryAck` before treating a
/// transport-accepted send as due for retry. Not part of the failure
/// backoff schedule (`siar_domain::backoff_millis`) — this is the "it
/// probably got there but we haven't heard back" timeout, not "it
/// failed".
const ACK_TIMEOUT_MILLIS: u64 = 5_000;

/// plan.md §33: jitter fraction applied to every scheduled retry, so many
/// queued sends across a reconnect don't all fire in the same instant.
const RETRY_JITTER_FRACTION: f64 = 0.2;

#[derive(Debug, Error)]
pub enum MessageServiceError {
    #[error(transparent)]
    Storage(#[from] siar_storage::StorageError),
    #[error(transparent)]
    Transport(#[from] siar_transport::TransportError),
    #[error(transparent)]
    Crypto(#[from] siar_crypto::CryptoError),
    #[error("could not decode a decrypted message body")]
    Malformed,
    #[error("attachment is too large: {0}")]
    AttachmentTooLarge(#[from] siar_domain::BlobSizeError),
    /// A file-subsystem failure while preparing an imported attachment.
    #[error("file subsystem: {0}")]
    Files(#[from] siar_files::FilesError),
    #[error("requested blob was not found on the peer")]
    BlobNotFound,
}

/// What `handle_incoming` decoded off the wire, widened from a bare
/// `Option<MessageContent>` so call signaling (plan.md §48) can travel
/// the same decode path without pretending a ring/hangup event is a
/// chat message. `GroupEvent` frames are intentionally *not* listed
/// here — they're routed to `GroupService` separately since decoding
/// one needs the per-group `Session`/state `GroupService` owns, not
/// anything `MessageService` has (see `group_service.rs`).
#[derive(Debug, Clone)]
pub enum IncomingEvent {
    Content(MessageContent),
    CallSignal {
        from: DeviceId,
        event: CallControlEvent,
    },
}

/// Why a [`AttachmentFetcher`] could not produce the attachment — told
/// apart because they call for different follow-ups.
#[derive(Debug, Clone, Copy, PartialEq, Eq)]
pub enum AttachmentFetchError {
    /// The peer answered: it does not have the blob or will not serve it.
    /// The legacy path would be told the same, so it is not tried.
    Unavailable,
    /// The peer could not be spoken to over this protocol (not paired for
    /// it, no address, or it does not implement it). The legacy path may
    /// still work.
    Unsupported,
    /// It started and did not finish (timeout, cancelled, corrupt).
    Failed,
}

/// A chunked, resumable way to pull an attachment (`files/1`), offered to
/// [`MessageService::fetch_attachment`] as the preferred path.
pub trait AttachmentFetcher: Send + Sync {
    fn fetch<'a>(
        &'a self,
        peer: &'a PeerTicket,
        reference: &'a AttachmentReference,
    ) -> std::pin::Pin<
        Box<dyn std::future::Future<Output = Result<Vec<u8>, AttachmentFetchError>> + Send + 'a>,
    >;
}

pub struct MessageService {
    /// plan.md §7–8: `DeviceId` is our own stable local identifier,
    /// assigned once at provisioning — never derived from key bytes, so
    /// it stays stable across a future key-rotation (plan.md §40).
    device_id: DeviceId,
    identity: DeviceIdentity,
    endpoint: Arc<SiarEndpoint>,
    messages: Arc<dyn MessageRepository + Send + Sync>,
    outbox: Arc<dyn OutboxRepository + Send + Sync>,
    blobs: Arc<dyn BlobRepository + Send + Sync>,
    /// Preferred way to pull attachments, if the host wired one (see
    /// [`Self::with_attachment_fetcher`]).
    attachment_fetcher: Option<Arc<dyn AttachmentFetcher>>,
    /// `04-offline-event-log-architecture.md` §33's own real call
    /// sites — see [`Self::with_event_log`]'s own doc comment for why
    /// this is optional rather than a required constructor argument.
    event_log: Option<Arc<dyn EventStore + Send + Sync>>,
    /// §16/§18's own `conversation_summary` worked example — see
    /// [`Self::with_event_log`] and `crate::projections`'s own doc
    /// comment. Always present together with `event_log` (both `Some`
    /// or both `None`); kept as two separate `Option`s rather than one
    /// `Option<(..., ...)>` only because the query side
    /// ([`Self::conversation_summary`]) reads just this one field.
    /// Trait objects rather than a concrete type: [`Self::
    /// with_event_log`] wires the in-memory backend by default, but
    /// [`Self::with_durable_conversation_summary`] can swap both for
    /// their `stoolap`-backed counterparts without changing either
    /// field's own type.
    conversation_summary: Option<Arc<dyn ConversationSummaryQuery>>,
    summary_checkpoints: Option<Arc<dyn ProjectionCheckpointStore>>,
    /// §8 "Correlation and Causation" — see [`MessageCorrelation`]'s
    /// own doc comment for the real mechanism, and this field's own
    /// initialization in [`Self::with_event_log`] for why it always
    /// travels together with `event_log`.
    correlations: Option<Arc<Mutex<HashMap<MessageId, MessageCorrelation>>>>,
}

/// §8's own real mechanism: one row per message, tracking the
/// [`CorrelationId`] shared by every event in that message's own
/// lifecycle (`MessageCreated` → `MessageQueued` → ... →
/// `MessageDelivered`/`MessageRead`) and the [`EventId`] of whichever
/// of those events was most recently recorded — so the next one's own
/// `causation_id` can point to it. Keyed by [`MessageId`] because
/// that's the only identifier a later, unrelated call
/// (`handle_incoming`'s `DeliveryAck` branch, running long after
/// `send_text` returned, possibly on a different code path entirely)
/// actually carries; there is no `EventId` lying around to reference
/// directly at that point without looking one up somehow, and this
/// map IS that lookup.
///
/// In-memory only, same "not durable across a restart" status
/// `ConversationSummaryProjection`'s own materialized state already
/// has — a real, named consequence: if the process restarts between
/// `send_text` (which starts a message's correlation chain) and a
/// later `DeliveryAck` for that same message, the chain is lost and
/// `MessageDelivered` gets recorded with `correlation_id`/
/// `causation_id` both `None` rather than wrongly linked to nothing —
/// see [`MessageService::continue_correlation`]'s own doc comment for
/// exactly how that degrades.
#[derive(Debug, Clone, Copy)]
struct MessageCorrelation {
    correlation_id: CorrelationId,
    last_event_id: EventId,
}

impl MessageService {
    pub fn new(
        device_id: DeviceId,
        identity: DeviceIdentity,
        endpoint: Arc<SiarEndpoint>,
        messages: Arc<dyn MessageRepository + Send + Sync>,
        outbox: Arc<dyn OutboxRepository + Send + Sync>,
        blobs: Arc<dyn BlobRepository + Send + Sync>,
    ) -> Self {
        Self {
            device_id,
            identity,
            endpoint,
            messages,
            outbox,
            blobs,
            attachment_fetcher: None,
            event_log: None,
            conversation_summary: None,
            summary_checkpoints: None,
            correlations: None,
        }
    }

    /// Makes [`Self::fetch_attachment`] try `fetcher` (normally the
    /// `files/1` chunked pull) before the legacy whole-blob request. A
    /// peer that answers "unavailable" ends the attempt; one that cannot
    /// speak the protocol, or a transfer that does not finish, falls back
    /// to the legacy path, so nothing that worked before stops working.
    pub fn with_attachment_fetcher(mut self, fetcher: Arc<dyn AttachmentFetcher>) -> Self {
        self.attachment_fetcher = Some(fetcher);
        self
    }

    /// Opt-in wiring for `siar-event-log`'s per-conversation messaging
    /// event stream (`crate::events`) — additive, not a replacement for
    /// `siar-storage`: this crate's tables remain the system of record
    /// for message content/delivery state (see this type's private
    /// `record_messaging_event` method for exactly what "additive"
    /// means for a failed append). A separate builder method rather than a seventh `new(...)` argument, so existing
    /// callers that don't want the event log keep compiling unchanged
    /// — `new(...)`'s signature is otherwise untouched by this. Takes
    /// and returns `self` by value (not `&mut self`) because
    /// `MessageService` is typically wrapped in an `Arc` immediately
    /// after construction for sharing across async tasks; wiring has
    /// to happen before that `Arc` is taken, not after.
    ///
    /// Also wires §16/§18's own `conversation_summary` projection
    /// (`crate::projections`) and §8's own `MessageCorrelation`
    /// registry automatically — a caller that wants the event log at
    /// all gets a live, queryable summary view and real correlation/
    /// causation tracking for free, with no separate opt-in: see
    /// [`Self::conversation_summary`] for the query side and
    /// `record_messaging_event`'s own doc comment for how both stay
    /// caught up.
    ///
    /// Wires the IN-MEMORY `ConversationSummaryProjection`/
    /// `InMemoryCheckpointStore` pair specifically — call
    /// [`Self::with_durable_conversation_summary`] afterward to swap
    /// both for their durable `stoolap`-backed counterparts instead.
    pub fn with_event_log(mut self, event_log: Arc<dyn EventStore + Send + Sync>) -> Self {
        self.event_log = Some(event_log);
        self.conversation_summary = Some(
            Arc::new(ConversationSummaryProjection::new()) as Arc<dyn ConversationSummaryQuery>
        );
        self.summary_checkpoints =
            Some(Arc::new(InMemoryCheckpointStore::new()) as Arc<dyn ProjectionCheckpointStore>);
        self.correlations = Some(Arc::new(Mutex::new(HashMap::new())));
        self
    }

    /// Upgrades the `conversation_summary` projection wired by
    /// [`Self::with_event_log`] (which defaults to the in-memory
    /// backend) to the durable `stoolap`-backed
    /// `StoolapConversationSummaryProjection`/`StoolapCheckpointStore`
    /// pair instead — the first real caller either of those durable
    /// types gets (see `stoolap_projections`'s own doc comment).
    /// Meant to be called right after `with_event_log` in the same
    /// builder chain; calling it without `with_event_log` first is
    /// harmless, not unsafe — the projection this sets is simply never
    /// consulted, since `record_messaging_event` checks `event_log`
    /// first and returns immediately if that's `None` (same as
    /// `with_durable_conversation_summary` never having been called at
    /// all).
    ///
    /// `projection_db_path`/`checkpoint_db_path` are two SEPARATE
    /// `stoolap::Database` files (or, if the caller passes a fresh
    /// in-memory pair via [`StoolapConversationSummaryProjection::
    /// open_in_memory`]/[`siar_event_log::StoolapCheckpointStore::
    /// open_in_memory`] directly instead of this method, two separate
    /// in-memory instances) — same "no cross-store atomicity" honesty
    /// `siar_event_log::stoolap_store`'s own doc comment already
    /// states for the relationship between the event log and
    /// `siar-storage`'s tables; this projection and its checkpoint are
    /// a third and fourth database in the same category, not
    /// exempted from that limitation.
    pub fn with_durable_conversation_summary(
        mut self,
        projection: Arc<StoolapConversationSummaryProjection>,
        checkpoints: Arc<StoolapCheckpointStore>,
    ) -> Self {
        self.conversation_summary = Some(projection as Arc<dyn ConversationSummaryQuery>);
        self.summary_checkpoints = Some(checkpoints as Arc<dyn ProjectionCheckpointStore>);
        self
    }

    /// Starts (or restarts) `message_id`'s own §8 correlation chain,
    /// returning the fresh [`CorrelationId`] every later event in the
    /// same lifecycle should reuse (via [`Self::continue_correlation`]).
    /// Call this exactly once per message, at whichever event first
    /// proves the message exists locally
    /// (`MessageCreated`/`MessageReceived`). Returns `None` if
    /// [`Self::with_event_log`] was never called — same "no-op when
    /// there's no event log to correlate anything in" shape
    /// `record_messaging_event` itself already has.
    fn start_correlation(&self, message_id: MessageId, event_id: EventId) -> Option<CorrelationId> {
        let registry = self.correlations.as_ref()?;
        let correlation_id = CorrelationId::new();
        registry
            .lock()
            .expect("correlation registry lock poisoned")
            .insert(
                message_id,
                MessageCorrelation {
                    correlation_id,
                    last_event_id: event_id,
                },
            );
        Some(correlation_id)
    }

    /// Looks up `message_id`'s already-started correlation chain and
    /// advances its `last_event_id` to `event_id` for the next call —
    /// use for every event in a message's lifecycle after the one that
    /// called [`Self::start_correlation`]. Returns
    /// `(correlation_id, causation_id)`, where `causation_id` is
    /// whichever event was most recently recorded for this message
    /// before this call. Both come back `None` — not an error, just an
    /// absent correlation — if [`Self::with_event_log`] was never
    /// called, OR if this message's chain was never started (a real
    /// case, not just a hypothetical: a process restart between
    /// `send_text` and a later `DeliveryAck` for the same message loses
    /// the in-memory registry entirely — see [`MessageCorrelation`]'s
    /// own doc comment).
    fn continue_correlation(
        &self,
        message_id: MessageId,
        event_id: EventId,
    ) -> (Option<CorrelationId>, Option<EventId>) {
        let Some(registry) = self.correlations.as_ref() else {
            return (None, None);
        };
        let mut registry = registry.lock().expect("correlation registry lock poisoned");
        match registry.get_mut(&message_id) {
            Some(entry) => {
                let correlation_id = Some(entry.correlation_id);
                let causation_id = Some(entry.last_event_id);
                entry.last_event_id = event_id;
                (correlation_id, causation_id)
            }
            None => (None, None),
        }
    }

    /// §18 "read-your-writes", queryable: reflects every real append
    /// `record_messaging_event` has made so far for this conversation,
    /// synchronously — no separate background catch-up loop to wait
    /// on. Returns `None` if [`Self::with_event_log`] was never
    /// called, same as an unpopulated conversation would, OR if the
    /// query itself failed (logged, not propagated — same best-effort
    /// posture `record_messaging_event` itself already has; a real
    /// failure mode only the durable backend
    /// ([`Self::with_durable_conversation_summary`]) can actually hit,
    /// since the in-memory one's own lookup can't fail).
    pub async fn conversation_summary(
        &self,
        conversation_id: ConversationId,
    ) -> Option<ConversationSummary> {
        let projection = self.conversation_summary.as_ref()?;
        match projection.get(conversation_id).await {
            Ok(summary) => summary,
            Err(e) => {
                tracing::warn!(error = %e, "failed to query conversation_summary");
                None
            }
        }
    }

    /// Records one of `crate::events::MessagingEvent`'s nine §33
    /// variants to the event log, if one is wired
    /// ([`Self::with_event_log`]), then immediately catches up the
    /// `conversation_summary` projection against it — §18's own
    /// "critical projections update ... same transaction as the
    /// event" relaxed to "synchronously, right after," per
    /// `siar_event_log::projection`'s own doc comment on what this
    /// crate's single-process, no-concurrent-writer setting actually
    /// needs. Both steps are best-effort: a failure at either is
    /// logged and swallowed, never propagated to the caller. That's a
    /// deliberate scope choice, not an oversight — `siar-storage`'s
    /// tables are still this crate's actual system of record (see
    /// `MessageServiceError`'s own variants, none of which are about
    /// the event log or its projections), so a send or receive
    /// succeeding or failing should not hinge on whether an audit-trail
    /// write or a read-model refresh also landed. Making either
    /// authoritative enough that its own failure should fail the
    /// caller is Phase 5 territory, not this round's.
    ///
    /// `event_id`/`correlation_id`/`causation_id` are caller-supplied
    /// (§8) — see [`Self::start_correlation`]/[`Self::
    /// continue_correlation`]'s own doc comments for how a real call
    /// site gets them; this method just threads them through to
    /// [`MessagingEvent::into_new_event`] unchanged.
    async fn record_messaging_event(
        &self,
        event: MessagingEvent,
        event_id: EventId,
        origin: EventOrigin,
        correlation_id: Option<CorrelationId>,
        causation_id: Option<EventId>,
    ) {
        let Some(store) = self.event_log.as_deref() else {
            return;
        };
        let stream_id = event.stream_id();
        let new_event = event.into_new_event(event_id, origin, correlation_id, causation_id);
        match append_with_retry(store, stream_id, new_event, EVENT_LOG_APPEND_MAX_ATTEMPTS).await {
            Ok(_) => {
                if let (Some(projection), Some(checkpoints)) =
                    (&self.conversation_summary, &self.summary_checkpoints)
                {
                    let runner = ProjectionRunner::new(store, checkpoints.as_ref());
                    if let Err(e) = runner
                        .catch_up(projection.as_ref(), DEFAULT_CATCH_UP_BATCH_SIZE)
                        .await
                    {
                        tracing::warn!(
                            error = %e,
                            "failed to catch up the conversation_summary projection"
                        );
                    }
                }
            }
            Err(e) => {
                tracing::warn!(error = %e, "failed to record messaging event to the event log");
            }
        }
    }

    /// Builds a signed `MailboxCheckIn` for this device — see
    /// `siar_protocol::mailbox`'s own doc comment for exactly what
    /// signing does and doesn't close. Kept here rather than exposing
    /// `self.identity` to callers directly: `DeviceIdentity`'s own doc
    /// comment is explicit that raw key material shouldn't leave
    /// `siar-crypto`, and this is the one signing operation a mailbox-
    /// checking caller (`apps/cli`'s `check-mailbox` command today)
    /// actually needs.
    pub fn sign_mailbox_check_in(&self, now_millis: u64) -> MailboxCheckIn {
        MailboxCheckIn::new(&self.identity, self.device_id, now_millis)
    }

    /// The unlinkable counterpart to
    /// [`sign_mailbox_check_in`](Self::sign_mailbox_check_in) — same
    /// "build the check-in from this device's own identity, no
    /// separate accessor needed" shape, but derived against `peer`
    /// instead of signed with this device's own key (an anonymous
    /// check-in has no signature at all — see
    /// `siar_crypto::mailbox_token`'s doc comment for that
    /// bearer-capability tradeoff). Kept as a method here rather than
    /// exposing `self.identity` to callers: `identity: DeviceIdentity`
    /// stays exactly as private as it's always been, and every caller
    /// that needs a token derivation goes through this or
    /// [`send_text_anon`](Self::send_text_anon), never touching a raw
    /// `DeviceIdentity` itself.
    pub fn build_anonymous_check_in(
        &self,
        peer: &PeerTicket,
        now_millis: u64,
    ) -> siar_protocol::AnonymousMailboxCheckIn {
        let peer_x25519_public = x25519_dalek::PublicKey::from(peer.x25519_public);
        let token_secret =
            siar_crypto::MailboxTokenSecret::establish(&self.identity, &peer_x25519_public);
        siar_protocol::AnonymousMailboxCheckIn::new(&token_secret, now_millis)
    }

    /// plan.md §111: persist first, then attempt delivery. The message is
    /// visible to `timeline()` (and therefore the UI, in later phases)
    /// the instant this returns `Ok`, regardless of whether the network
    /// send below succeeds.
    pub async fn send_text(
        &self,
        conversation: ConversationId,
        peer: &PeerTicket,
        text: MessageText,
    ) -> Result<MessageId, MessageServiceError> {
        let message_id = MessageId::new();
        let now = now_millis();

        let content = MessageContent::Text(text);
        let plaintext = postcard::to_allocvec(&content).expect("MessageContent always serializes");

        let session = self.session_for(peer);
        let ciphertext = session.encrypt(&plaintext)?;

        let stored = StoredMessage {
            message_id,
            conversation_id: conversation,
            sender_device: self.device_id,
            // Phase-1 stand-in for a real per-conversation sequence
            // counter (plan.md §21) — fine for ordering within one
            // two-peer chat's local clock, not for the deterministic
            // distributed ordering groups will need in Phase 5.
            sequence: now,
            timestamp_millis: now,
            delivery_state: DeliveryState::Local,
            payload: ciphertext.clone(),
        };

        // Transactional outbox: message + outbox row commit together
        // (plan.md §16–17) before we ever touch the network.
        self.outbox.enqueue(&stored, &peer.encode())?;

        // §33's own first two named events, in the order they actually
        // happen here: the message existed (`MessageCreated`) the
        // instant its ciphertext was ready, and it was queued
        // (`MessageQueued`) the instant `enqueue` above actually
        // persisted it — both true by the time we reach this line,
        // hence both recorded together rather than split across two
        // separate call sites that would just be adjacent anyway.
        //
        // §8: `MessageCreated` starts this message's own correlation
        // chain (`start_correlation`); `MessageQueued` continues it
        // (`continue_correlation`), so its own `causation_id` points
        // back at `MessageCreated`'s real `EventId` and both share one
        // `CorrelationId` for the whole send lifecycle.
        let created_event_id = EventId::new();
        let correlation_id = self.start_correlation(message_id, created_event_id);
        self.record_messaging_event(
            MessagingEvent::MessageCreated {
                conversation_id: conversation,
                message_id,
                sender_device: self.device_id,
                sequence: stored.sequence,
                ciphertext: stored.payload.clone(),
            },
            created_event_id,
            EventOrigin::LocalDevice(self.device_id),
            correlation_id,
            None,
        )
        .await;
        let queued_event_id = EventId::new();
        let (queued_correlation, queued_causation) =
            self.continue_correlation(message_id, queued_event_id);
        self.record_messaging_event(
            MessagingEvent::MessageQueued {
                conversation_id: conversation,
                message_id,
            },
            queued_event_id,
            EventOrigin::LocalDevice(self.device_id),
            queued_correlation,
            queued_causation,
        )
        .await;

        let envelope = Envelope {
            version: CURRENT_VERSION,
            message_id,
            conversation_id: conversation,
            sender: self.device_id,
            timestamp_millis: now,
            sequence: stored.sequence,
            kind: EnvelopeKind::Text,
            payload: ciphertext,
        };

        match self
            .endpoint
            .send(peer.endpoint_addr.clone(), &WireMessage::V1(envelope))
            .await
        {
            Ok(()) => {
                // plan.md §46: transport accepting the bytes is `Sent`,
                // not `Delivered` — the outbox stays populated (so the
                // retry scheduler keeps resending) until a real
                // `DeliveryAck` comes back in `handle_incoming` and calls
                // `outbox.complete`. Marking complete here would silently
                // drop messages whose ACK never arrives. `reschedule`
                // (not `record_failure`) pushes the next retry out
                // without counting this as a failed attempt.
                self.messages
                    .update_delivery_state(message_id, DeliveryState::Sent)?;
                self.outbox
                    .reschedule(message_id, (now_millis() + ACK_TIMEOUT_MILLIS) as i64)?;
            }
            Err(e) => {
                tracing::warn!(error = %e, "send failed, left in outbox for retry");
                let delay = with_jitter(
                    backoff_millis(0),
                    pseudo_unit_random(message_id),
                    RETRY_JITTER_FRACTION,
                );
                self.outbox
                    .record_failure(message_id, (now_millis() + delay) as i64)?;
            }
        }

        Ok(message_id)
    }

    /// The unlinkable counterpart to [`send_text`](Self::send_text) —
    /// same session-encrypted payload, addressed and delivered
    /// completely differently: instead of a `V1::Envelope` sent
    /// directly to `peer.endpoint_addr`, this builds a
    /// `TokenMailboxEnvelope` addressed by a
    /// [`siar_crypto::mailbox_token::MailboxTokenSecret`] token and
    /// hands it to `relay` for pickup — see `siar_crypto::
    /// mailbox_token`'s and `siar_protocol::mailbox::
    /// TokenMailboxEnvelope`'s own doc comments for the full
    /// unlinkability picture and its real, named limits (the relay
    /// still sees *when* something moves and *how much*, and the
    /// bearer-capability model means no delivery signature).
    ///
    /// Deliberately NOT wired through the outbox/retry/ACK machinery
    /// `send_text` uses — this workspace has no `DeliveryAck` path for
    /// a token-addressed delivery to travel back on (that would need
    /// its own rotating-token addressing for the ack itself, which
    /// isn't designed here), so a caller gets a `MessageId` back and
    /// this crate's normal retry scheduler will NOT resend on this
    /// path if the relay drops it. Real follow-up work, named rather
    /// than silently downgraded to "good enough."
    pub async fn send_text_anon(
        &self,
        peer: &PeerTicket,
        relay: &PeerTicket,
        text: MessageText,
    ) -> Result<MessageId, MessageServiceError> {
        let message_id = MessageId::new();
        let now = now_millis();

        let content = MessageContent::Text(text);
        let plaintext = postcard::to_allocvec(&content).expect("MessageContent always serializes");

        // Same session-derived confidentiality as send_text — only the
        // addressing/delivery path differs, not the encryption.
        let session = self.session_for(peer);
        let ciphertext = session.encrypt(&plaintext)?;

        let peer_x25519_public = x25519_dalek::PublicKey::from(peer.x25519_public);
        let token_secret =
            siar_crypto::MailboxTokenSecret::establish(&self.identity, &peer_x25519_public);
        let destination_token = token_secret.token_for_epoch(siar_crypto::epoch_for(now));

        let envelope = siar_protocol::TokenMailboxEnvelope {
            id: message_id,
            destination_token,
            created_at: now,
            // A day is an approximation, not a measured value — same
            // "chosen conservatively, not tuned against real traffic"
            // status every other untuned constant in this workspace
            // carries (see e.g. `siar_crypto::mailbox_token::
            // EPOCH_LENGTH_MILLIS`'s own doc comment). Long enough that
            // a recipient checking in once a day still finds it; short
            // enough that an unclaimed message doesn't sit in a relay's
            // `TokenMailboxStore` forever.
            expires_at: now + 24 * 60 * 60 * 1000,
            hop_limit: 4,
            priority: siar_domain::MessagePriority::Normal,
            payload_hash: *blake3::hash(&ciphertext).as_bytes(),
            ciphertext,
        };

        self.endpoint
            .send(
                relay.endpoint_addr.clone(),
                &WireMessage::TokenMailboxDeposit(envelope),
            )
            .await?;

        Ok(message_id)
    }

    /// Decrypts one [`siar_protocol::TokenMailboxEnvelope`] received in
    /// answer to an anonymous check-in — the receive-side counterpart
    /// to [`send_text_anon`](Self::send_text_anon), using the exact
    /// same [`Session`] derivation (`session_for(peer)`) so decryption
    /// succeeds precisely when the envelope was really encrypted for
    /// this pairing. `peer` here is the *sender* the caller expects
    /// this item came from — an anonymous check-in has no sender field
    /// to read that from (the whole point), so the caller has to
    /// already know who it's checking mail from, same precondition
    /// `siar_crypto::mailbox_token::MailboxTokenSecret`'s own doc
    /// comment names ("a shared secret must already exist").
    pub fn decrypt_token_mailbox_envelope(
        &self,
        peer: &PeerTicket,
        envelope: &siar_protocol::TokenMailboxEnvelope,
    ) -> Result<MessageContent, MessageServiceError> {
        let session = self.session_for(peer);
        let plaintext = session.decrypt(&envelope.ciphertext)?;
        postcard::from_bytes(&plaintext).map_err(|_| MessageServiceError::Malformed)
    }

    /// plan.md §22–23's attachment send flow: encrypt the file under its
    /// own random key, publish the ciphertext to our local blob store
    /// (`BlobProtocolHandler` on `SiarEndpoint` serves it from there to
    /// whoever asks), and send only the small `AttachmentReference` —
    /// never the file bytes — inside the session-encrypted envelope.
    pub async fn send_attachment(
        &self,
        conversation: ConversationId,
        peer: &PeerTicket,
        plaintext: Vec<u8>,
        media_type: MediaType,
    ) -> Result<MessageId, MessageServiceError> {
        let size = BlobSize::parse(plaintext.len() as u64)?;
        let (blob, key) = siar_crypto::encrypt_attachment(&plaintext)?;
        self.blobs.put(blob.hash.as_bytes(), &blob.ciphertext)?;

        let reference = AttachmentReference {
            blob_hash: *blob.hash.as_bytes(),
            encrypted_size: size,
            media_type,
            attachment_key: key.to_bytes(),
            thumbnail: None, // plan.md §25 — thumbnail generation is a later refinement
        };

        self.send_attachment_reference(conversation, peer, reference)
            .await
    }

    /// spec 05 §204: send an attachment that already lives in the file
    /// subsystem's blob store (`siar_files::FilesService::import_attachment`).
    /// No bytes are copied into this service's own `BlobRepository`:
    /// serve the store to peers with `FilesBlobStore` (see `blob_bridge`)
    /// when binding the endpoint. Binding the blob to the returned
    /// message id (`FilesService::bind_to_object`) is the caller's next
    /// step, so the blob outlives its temporary import owner.
    pub async fn send_imported_attachment(
        &self,
        conversation: ConversationId,
        peer: &PeerTicket,
        imported: &siar_files::ImportedAttachment,
    ) -> Result<MessageId, MessageServiceError> {
        let reference = imported.reference()?;
        self.send_attachment_reference(conversation, peer, reference)
            .await
    }

    /// The part of an attachment send that does not care where the blob
    /// is stored: wrap the reference, encrypt it for the session, record
    /// it in the outbox, and try the wire once.
    async fn send_attachment_reference(
        &self,
        conversation: ConversationId,
        peer: &PeerTicket,
        reference: AttachmentReference,
    ) -> Result<MessageId, MessageServiceError> {
        let message_id = MessageId::new();
        let now = now_millis();
        let content = MessageContent::Attachment(reference);
        let envelope_plaintext =
            postcard::to_allocvec(&content).expect("MessageContent always serializes");

        let session = self.session_for(peer);
        let ciphertext = session.encrypt(&envelope_plaintext)?;

        let stored = StoredMessage {
            message_id,
            conversation_id: conversation,
            sender_device: self.device_id,
            sequence: now,
            timestamp_millis: now,
            delivery_state: DeliveryState::Local,
            payload: ciphertext.clone(),
        };
        self.outbox.enqueue(&stored, &peer.encode())?;

        let envelope = Envelope {
            version: CURRENT_VERSION,
            message_id,
            conversation_id: conversation,
            sender: self.device_id,
            timestamp_millis: now,
            sequence: stored.sequence,
            kind: EnvelopeKind::Attachment,
            payload: ciphertext,
        };

        match self
            .endpoint
            .send(peer.endpoint_addr.clone(), &WireMessage::V1(envelope))
            .await
        {
            Ok(()) => {
                self.messages
                    .update_delivery_state(message_id, DeliveryState::Sent)?;
                self.outbox
                    .reschedule(message_id, (now_millis() + ACK_TIMEOUT_MILLIS) as i64)?;
            }
            Err(e) => {
                tracing::warn!(error = %e, "attachment send failed, left in outbox for retry");
                let delay = with_jitter(
                    backoff_millis(0),
                    pseudo_unit_random(message_id),
                    RETRY_JITTER_FRACTION,
                );
                self.outbox
                    .record_failure(message_id, (now_millis() + delay) as i64)?;
            }
        }

        Ok(message_id)
    }

    /// plan.md §112: decode -> decrypt -> persist -> ACK. (Identity/replay
    /// verification is a further hardening item — plan.md §68–70 covers
    /// the idempotency half of that, handled here via `insert_if_new`;
    /// Phase 1's CLI trusts that `peer` really is who the transport says
    /// it is, which only holds because the harness pairs two known peers
    /// by hand.)
    ///
    /// Returns `None` for a `DeliveryAck`/`ReadReceipt` frame (nothing to
    /// show a user), `Some(IncomingEvent::Content(_))` for a text/
    /// attachment message worth displaying, `Some(IncomingEvent::CallSignal
    /// { .. })` for call control-plane events (plan.md §48) — the caller
    /// feeds those into `siar_domain::CallState::apply` to drive its own
    /// call UI state machine. `EnvelopeKind::GroupEvent` and the three
    /// `GroupMls*` frames are not handled here at all (see
    /// `IncomingEvent`'s doc comment); a caller wiring up groups
    /// dispatches those to `GroupService` before ever reaching this
    /// function.
    pub async fn handle_incoming(
        &self,
        peer: &PeerTicket,
        envelope: Envelope,
    ) -> Result<Option<IncomingEvent>, MessageServiceError> {
        match envelope.kind {
            EnvelopeKind::CallSignal(event) => {
                // Signaling is deliberately unencrypted-at-this-layer
                // (see `EnvelopeKind::CallSignal`'s doc comment on why
                // it rides as a plain field) — nothing to decrypt, just
                // hand the event to the caller's call-state machine.
                Ok(Some(IncomingEvent::CallSignal {
                    from: envelope.sender,
                    event,
                }))
            }
            EnvelopeKind::GroupEvent
            | EnvelopeKind::GroupMlsCommit
            | EnvelopeKind::GroupMlsWelcome
            | EnvelopeKind::GroupMlsApplication => {
                // Not this function's job — see the doc comment above.
                // A caller that hasn't routed group frames elsewhere
                // yet just doesn't see them; `apps/cli` does route them
                // (to `GroupService`, see that crate's `group_service.rs`)
                // but `apps/desktop` still doesn't have any group UI, so
                // for that caller this remains "a wiring gap in the
                // caller," not a silent drop of something it was
                // otherwise going to handle. The three MLS kinds join
                // `GroupEvent` here for the same reason they exist at
                // all — see `EnvelopeKind::GroupMlsCommit`'s doc
                // comment — `GroupService`'s MLS-path methods are the
                // ones that decode and process them.
                Ok(None)
            }
            EnvelopeKind::Text | EnvelopeKind::Attachment => {
                let session = self.session_for(peer);
                let plaintext = session.decrypt(&envelope.payload)?;
                let content: MessageContent =
                    postcard::from_bytes(&plaintext).map_err(|_| MessageServiceError::Malformed)?;

                let stored = StoredMessage {
                    message_id: envelope.message_id,
                    conversation_id: envelope.conversation_id,
                    sender_device: envelope.sender,
                    sequence: envelope.sequence,
                    timestamp_millis: envelope.timestamp_millis,
                    delivery_state: DeliveryState::Delivered,
                    payload: envelope.payload,
                };
                // plan.md §70: idempotent under duplicate delivery — only
                // ACK (and only surface to the caller) on a genuinely new
                // message, so a retransmitted envelope doesn't spam the
                // sender with redundant ACKs or the UI with a duplicate.
                let is_new = self.messages.insert_if_new(&stored)?;

                if is_new {
                    // §33 `MessageReceived` — real receipt of a
                    // genuinely new message (not a retransmit; see the
                    // comment above `insert_if_new` on why this is
                    // inside the `is_new` branch). `envelope.sender` is
                    // the remote peer's own device — this event is
                    // theirs, not ours, hence `RemoteDevice`.
                    //
                    // §8: this is a fresh correlation chain for THIS
                    // device's own receive-side lifecycle
                    // (`start_correlation`, not `continue_correlation`)
                    // — we didn't create this message, so there is no
                    // earlier local event to continue from; `causation`
                    // is `None` for the same reason.
                    let received_event_id = EventId::new();
                    let correlation_id =
                        self.start_correlation(envelope.message_id, received_event_id);
                    self.record_messaging_event(
                        MessagingEvent::MessageReceived {
                            conversation_id: envelope.conversation_id,
                            message_id: envelope.message_id,
                            sender_device: envelope.sender,
                        },
                        received_event_id,
                        EventOrigin::RemoteDevice(envelope.sender),
                        correlation_id,
                        None,
                    )
                    .await;

                    let ack = Envelope {
                        version: CURRENT_VERSION,
                        message_id: MessageId::new(),
                        conversation_id: envelope.conversation_id,
                        sender: self.device_id,
                        timestamp_millis: now_millis(),
                        sequence: 0,
                        kind: EnvelopeKind::DeliveryAck {
                            acked_message: envelope.message_id,
                        },
                        payload: Vec::new(),
                    };
                    let endpoint = self.endpoint.clone();
                    let ack_addr = peer.endpoint_addr.clone();
                    tokio::spawn(async move {
                        // Best-effort: a lost ACK just means the sender's
                        // outbox retries and we idempotently no-op the
                        // resend — not a reason to block or fail receive.
                        if let Err(e) = endpoint.send(ack_addr, &WireMessage::V1(ack)).await {
                            tracing::debug!(error = %e, "best-effort delivery ACK send failed");
                        }
                    });
                    Ok(Some(IncomingEvent::Content(content)))
                } else {
                    Ok(None)
                }
            }
            EnvelopeKind::DeliveryAck { acked_message } => {
                self.messages
                    .update_delivery_state(acked_message, DeliveryState::Delivered)?;
                self.outbox.complete(acked_message)?;
                // §33 `MessageDelivered` — the confirmation that this
                // message reached the recipient came from them
                // (`envelope.sender` here is whoever sent the ACK, i.e.
                // the original message's own recipient), so this is
                // their event to originate, not ours, even though it's
                // our own outbound message being confirmed.
                //
                // §8: continues the SAME correlation chain `send_text`
                // started for `acked_message` — `causation_id` points
                // back at whichever of `MessageCreated`/`MessageQueued`
                // was recorded last for it. Both come back `None`
                // instead if that chain was never started here (see
                // `continue_correlation`'s own doc comment on why
                // that's a real, not hypothetical, case).
                let delivered_event_id = EventId::new();
                let (correlation_id, causation_id) =
                    self.continue_correlation(acked_message, delivered_event_id);
                self.record_messaging_event(
                    MessagingEvent::MessageDelivered {
                        conversation_id: envelope.conversation_id,
                        message_id: acked_message,
                    },
                    delivered_event_id,
                    EventOrigin::RemoteDevice(envelope.sender),
                    correlation_id,
                    causation_id,
                )
                .await;
                Ok(None)
            }
            EnvelopeKind::ReadReceipt { .. } => {
                // Phase 3 (plan.md §45) — accepted on the wire already so
                // the format doesn't need to change later, not acted on
                // yet.
                Ok(None)
            }
        }
    }

    /// plan.md §22's receive-side fetch: given an `AttachmentReference`
    /// from an already-decrypted message, ask `peer` for the blob and
    /// decrypt it. Deliberately not called automatically from
    /// `handle_incoming` — plan.md §65's tiered cache / §67's bandwidth
    /// policy both assume attachments download on demand (or per a
    /// user's auto-download setting), not unconditionally the instant a
    /// reference arrives.
    pub async fn fetch_attachment(
        &self,
        peer: &PeerTicket,
        reference: &AttachmentReference,
    ) -> Result<Vec<u8>, MessageServiceError> {
        if let Some(cached) = self.blobs.get(&reference.blob_hash)? {
            let key = siar_crypto::AttachmentKey::from_bytes(reference.attachment_key);
            let hash = siar_crypto::BlobHash::from_bytes(reference.blob_hash);
            return Ok(siar_crypto::decrypt_attachment(&cached, hash, &key)?);
        }

        if let Some(fetcher) = &self.attachment_fetcher {
            match fetcher.fetch(peer, reference).await {
                Ok(plaintext) => return Ok(plaintext),
                Err(AttachmentFetchError::Unavailable) => {
                    return Err(MessageServiceError::BlobNotFound)
                }
                Err(e) => {
                    tracing::debug!(?e, "files/1 fetch did not succeed; using the legacy path")
                }
            }
        }

        let ciphertext = self
            .endpoint
            .fetch_blob(peer.endpoint_addr.clone(), reference.blob_hash)
            .await?
            .ok_or(MessageServiceError::BlobNotFound)?;

        // plan.md §73: verify (hash + AEAD tag) before trusting it, then
        // cache it locally so a second view of the same attachment
        // doesn't re-fetch over the network.
        let key = siar_crypto::AttachmentKey::from_bytes(reference.attachment_key);
        let hash = siar_crypto::BlobHash::from_bytes(reference.blob_hash);
        let plaintext = siar_crypto::decrypt_attachment(&ciphertext, hash, &key)?;
        self.blobs.put(&reference.blob_hash, &ciphertext)?;

        Ok(plaintext)
    }

    /// plan.md §48's signaling send: Offer/Ring/Accept/Reject/Hangup/etc
    /// travel as their own envelope kind, not through the outbox — a
    /// missed "Ring" a minute late is pointless (plan.md §44's
    /// ephemeral-event rule applies here too, not just typing), so this
    /// is fire-and-forget over the pooled connection rather than
    /// persisted-then-retried like a text message.
    pub async fn send_call_signal(
        &self,
        peer: &PeerTicket,
        event: CallControlEvent,
    ) -> Result<(), MessageServiceError> {
        let envelope = Envelope {
            version: CURRENT_VERSION,
            message_id: MessageId::new(),
            // Call signaling isn't scoped to a conversation the way chat
            // messages are; callers that need to correlate a signal to a
            // specific call use `message_id`/their own call-session id
            // at the application layer, same as any other correlation
            // this layer doesn't model.
            conversation_id: ConversationId::new(),
            sender: self.device_id,
            timestamp_millis: now_millis(),
            sequence: 0,
            kind: EnvelopeKind::CallSignal(event),
            payload: Vec::new(),
        };

        self.endpoint
            .send(peer.endpoint_addr.clone(), &WireMessage::V1(envelope))
            .await?;
        Ok(())
    }

    /// plan.md §33: the retry scheduler's core poll. Call this
    /// periodically (the CLI's background task does, every second or so)
    /// — reconstructs each due message from storage (no second copy of
    /// the ciphertext lives in `outbox`) and resends it.
    pub async fn retry_due(&self) -> Result<usize, MessageServiceError> {
        let due = self.outbox.due(now_millis() as i64, 50)?;
        let mut retried = 0;

        for op in due {
            let Some(stored) = self.messages.get(op.message_id)? else {
                // Shouldn't happen under the transactional-outbox
                // invariant (plan.md §17) — message and outbox rows
                // always commit together — but don't retry forever
                // against a row that no longer exists.
                self.outbox.complete(op.message_id)?;
                continue;
            };
            let peer = match PeerTicket::decode(&op.peer_ticket_hex) {
                Ok(p) => p,
                Err(e) => {
                    tracing::warn!(error = %e, "outbox row has an undecodable peer ticket; dropping");
                    self.outbox.complete(op.message_id)?;
                    continue;
                }
            };

            let envelope = Envelope {
                version: CURRENT_VERSION,
                message_id: stored.message_id,
                conversation_id: stored.conversation_id,
                sender: stored.sender_device,
                timestamp_millis: stored.timestamp_millis,
                sequence: stored.sequence,
                // `StoredMessage` doesn't currently persist which
                // `EnvelopeKind` a message originally used, so retries
                // always re-tag as `Text`. Harmless for correctness —
                // `handle_incoming` decodes `Text` and `Attachment`
                // identically, since the real discriminant lives inside
                // the decrypted `MessageContent`, not this outer tag —
                // but it would matter for a future traffic-priority
                // feature (plan.md §66) reading the outer tag without
                // decrypting. Fix: persist the kind alongside `payload`
                // if/when that lands.
                kind: EnvelopeKind::Text,
                payload: stored.payload,
            };

            match self
                .endpoint
                .send(peer.endpoint_addr.clone(), &WireMessage::V1(envelope))
                .await
            {
                Ok(()) => {
                    retried += 1;
                    self.outbox
                        .reschedule(op.message_id, (now_millis() + ACK_TIMEOUT_MILLIS) as i64)?;
                }
                Err(e) => {
                    tracing::warn!(error = %e, "retry send failed");
                    let delay = with_jitter(
                        backoff_millis(op.attempts),
                        pseudo_unit_random(op.message_id),
                        RETRY_JITTER_FRACTION,
                    );
                    self.outbox
                        .record_failure(op.message_id, (now_millis() + delay) as i64)?;
                }
            }
        }

        // plan.md §35: sweep dead pooled connections while we're already
        // on this periodic cadence, rather than adding a second timer.
        self.endpoint.evict_idle_connections();

        Ok(retried)
    }

    /// Static-key session (see siar-crypto's module docs on `Session`).
    /// Deliberately *not* cached: re-deriving from the same two static
    /// keys is a cheap ECDH + BLAKE3, and not caching means there is
    /// nothing here to invalidate when Phase 2 swaps this for a real
    /// ratchet — that swap becomes a one-function change in siar-crypto
    /// instead of also touching a cache-invalidation path here.
    fn session_for(&self, peer: &PeerTicket) -> Session {
        let x25519_public = x25519_dalek::PublicKey::from(peer.x25519_public);
        Session::establish(&self.identity, &x25519_public)
    }
}

fn now_millis() -> u64 {
    SystemTime::now()
        .duration_since(UNIX_EPOCH)
        .expect("system clock is before 1970")
        .as_millis() as u64
}

/// Cheap jitter source (plan.md §33 just needs "don't all retry in
/// lockstep", not cryptographic randomness) — avoids pulling in the
/// `rand` crate for one `f64` per retry. Seeded by the message ID plus
/// the current clock, so repeated retries of the same message don't get
/// identical jitter.
fn pseudo_unit_random(seed: MessageId) -> f64 {
    use std::collections::hash_map::DefaultHasher;
    use std::hash::{Hash, Hasher};

    let mut hasher = DefaultHasher::new();
    seed.hash(&mut hasher);
    now_millis().hash(&mut hasher);
    (hasher.finish() as f64) / (u64::MAX as f64)
}
