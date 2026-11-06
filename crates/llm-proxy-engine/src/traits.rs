//! The engine's extension points (audit conflict 13): every feature that
//! needs process-shared or backend-specific state implements one of these
//! traits instead of living in the axum layer. Each trait ships a local,
//! in-process default so a single node runs with no external services; the
//! Redis/Postgres-backed implementations arrive as optional crates and slot
//! in behind the same trait.
//!
//! [`EventBus`](llm_proxy_storage::EventBus) (usage events) and
//! [`Tokenizer`](llm_proxy_core::Counter) (token estimation) already existed
//! and are not duplicated here.

use std::collections::HashMap;
use std::fmt::Debug;
use std::sync::Arc;

use async_trait::async_trait;
use llm_proxy_core::{AffinityConfig, AppConfig, ProviderRegistry, ProviderRouteKind, RetryConfig};
use llm_proxy_protocol::core::{CoreEvent, CoreRequest, CoreResponse};
use secrecy::SecretString;

use crate::catalog::ModelCatalogService;

/// The ladder for a route that did not opt into retries: one attempt, no
/// backoff, no hold.
fn single_attempt() -> RetryConfig {
    RetryConfig {
        max_attempts: 1,
        backoff: std::time::Duration::ZERO,
        cooldown: std::time::Duration::from_secs(30),
        total_timeout: std::time::Duration::ZERO,
        hold: std::time::Duration::ZERO,
    }
}
use crate::error::EngineError;
use crate::health::AffinityTable;

/// Resolves a route to a plan of candidate targets (pipeline slot 3). The
/// default implementation is the TOML/config-loaded [`ProviderRegistry`]
/// plus catalog enforcement, and it understands pools: a pool route resolves
/// to its members in failover order with the pool's ladder policy.
#[async_trait]
pub trait Router: Debug + Send + Sync {
    /// Resolve `provider` + route kind + requested model to the candidate
    /// targets the attempt loop tries in order, plus the ladder policy that
    /// governs them.
    async fn resolve(&self, query: &RouteQuery<'_>) -> Result<RoutePlan, EngineError>;
}

/// Everything the router is asked per request.
#[derive(Debug, Clone, Copy)]
pub struct RouteQuery<'a> {
    /// The provider or pool named in the URL.
    pub provider: &'a str,
    /// The endpoint family the client called.
    pub route_kind: ProviderRouteKind,
    /// The model name the client asked for.
    pub requested_model: &'a str,
    /// The session id attributed to this request (plan 04 step 10), when
    /// one is known: the sticky-affinity input. `None` disables pinning for
    /// this request.
    pub session_id: Option<&'a str>,
}

/// The routing decision: the ordered candidate targets plus the ladder
/// policy that applies to them.
#[derive(Clone)]
pub struct RoutePlan {
    /// The route the client addressed: a provider name or a pool name.
    pub route: String,
    /// Candidate targets in failover order. A direct provider route has
    /// exactly one; a pool has one per member.
    pub candidates: Vec<ResolvedTarget>,
    /// The retry/failover ladder for this route: attempts per member, one
    /// deadline across all attempts, and the streaming hold budget.
    pub retry: RetryConfig,
    /// Session affinity policy for this route (pools only).
    pub affinity: AffinityConfig,
}

impl Debug for RoutePlan {
    fn fmt(&self, f: &mut std::fmt::Formatter<'_>) -> std::fmt::Result {
        f.debug_struct("RoutePlan")
            .field("route", &self.route)
            .field("candidates", &self.candidates.len())
            .field("retry", &self.retry)
            .field("affinity", &self.affinity)
            .finish()
    }
}

/// The routing decision for one candidate: which adapter config serves this
/// member.
#[derive(Clone)]
pub struct ResolvedTarget {
    /// The provider config's resolved adapter target (endpoint, protocol,
    /// auth style, static headers, model aliasing, `lossy`, and the inbound
    /// header forwarding allowlist).
    pub target: llm_proxy_core::ProviderAdapterTargetConfig,
}

impl Debug for ResolvedTarget {
    fn fmt(&self, f: &mut std::fmt::Formatter<'_>) -> std::fmt::Result {
        // The target carries the upstream credential; never include it.
        f.debug_struct("ResolvedTarget")
            .field("provider_name", &self.target.provider_name)
            .field("protocol", &self.target.protocol)
            .field("adapter_name", &self.target.adapter_name)
            .field("upstream_model", &self.target.upstream_model)
            .finish()
    }
}

/// The default [`Router`]: the loaded [`ProviderRegistry`], with catalog
/// enforcement for providers that opt in, pool expansion for pool routes,
/// and (when constructed with one) sticky-affinity reordering of pool
/// candidates.
#[derive(Debug)]
pub struct RegistryRouter {
    registry: Arc<ProviderRegistry>,
    catalogs: Arc<ModelCatalogService>,
    affinity: Option<Arc<AffinityTable>>,
}

impl RegistryRouter {
    /// Resolves one provider through the registry with catalog enforcement.
    async fn resolve_one(
        &self,
        query: &RouteQuery<'_>,
        provider: &str,
    ) -> Result<ResolvedTarget, EngineError> {
        let target = self
            .registry
            .resolve_provider_route(provider, query.route_kind, query.requested_model)
            .map_err(EngineError::from_route_error)?;
        if let Some(provider) = self.registry.get(provider)
            && provider
                .catalog
                .as_ref()
                .is_some_and(|catalog| catalog.enforce)
        {
            let allowed = self
                .catalogs
                .contains_model(provider, &target.upstream_model, &target.protocol)
                .await
                .map_err(|error| EngineError::Internal(error.to_string()))?;
            if !allowed {
                return Err(EngineError::ModelNotAllowed(target.upstream_model.clone()));
            }
        }
        Ok(ResolvedTarget { target })
    }

    /// Wrap a registry and the catalog service.
    #[must_use]
    pub fn new(registry: Arc<ProviderRegistry>, catalogs: Arc<ModelCatalogService>) -> Self {
        Self {
            registry,
            catalogs,
            affinity: None,
        }
    }

    /// Give the router the shared affinity table, so a session pinned to a
    /// pool member is tried first while that member is healthy.
    #[must_use]
    pub fn with_affinity(mut self, affinity: Arc<AffinityTable>) -> Self {
        self.affinity = Some(affinity);
        self
    }
}

#[async_trait]
impl Router for RegistryRouter {
    async fn resolve(&self, query: &RouteQuery<'_>) -> Result<RoutePlan, EngineError> {
        // Pool routes: resolve every member, apply the pool's ladder, and
        // reorder for sticky affinity.
        if let Some(pool) = self.registry.pool(query.provider) {
            // Resolve each member (a member that cannot serve the route kind
            // is a config-time fact, so it fails the request rather than
            // being silently skipped — the operator asked for it as fallback
            // capacity).
            let mut candidates = Vec::with_capacity(pool.members.len());
            for member in &pool.members {
                candidates.push(self.resolve_one(query, member).await?);
            }
            let mut plan = RoutePlan {
                route: pool.name.clone(),
                candidates,
                retry: pool.retry.clone(),
                affinity: pool.affinity.clone(),
            };
            if pool.affinity.sticky
                && let (Some(table), Some(session)) = (&self.affinity, query.session_id)
                && let Some(pinned) = table.pinned_provider(session)
            {
                plan.candidates
                    .sort_by_key(|candidate| u8::from(candidate.target.provider_name != pinned));
            }
            return Ok(plan);
        }

        // Direct provider route: exactly one candidate, the provider's own
        // opt-in ladder, and no failover beyond it. Without `[provider.retry]`
        // the ladder is exactly one attempt — the pre-plan behaviour.
        let resolved = self.resolve_one(query, query.provider).await?;
        let retry = self
            .registry
            .get(query.provider)
            .and_then(|p| p.retry.clone())
            .unwrap_or_else(single_attempt);
        Ok(RoutePlan {
            route: query.provider.to_owned(),
            candidates: vec![resolved],
            retry,
            affinity: AffinityConfig::default(),
        })
    }
}

/// One admission step: reserve budget up front, then settle or refund
/// (audit conflict 2's resolution). The default admits everything.
///
/// `reserve` is async (it may consult a backend budget store); `settle` is
/// synchronous fire-and-forget accounting, mirroring the contract of
/// [`EventBus::emit`](llm_proxy_storage::EventBus::emit): implementations
/// must not block the calling task.
#[async_trait]
pub trait Admission: Debug + Send + Sync {
    /// Reserve capacity (budget, tokens, concurrency) before egress. Returns
    /// an opaque ticket handed back at [`Admission::settle`].
    async fn reserve(&self, claim: &AdmissionClaim<'_>) -> Result<AdmissionTicket, EngineError> {
        let _ = claim;
        Ok(AdmissionTicket::default())
    }

    /// Settle or refund the reservation once the attempt outcome is known.
    /// Called exactly once per successful [`Admission::reserve`].
    fn settle(&self, ticket: &AdmissionTicket, outcome: &AdmissionOutcome<'_>) {
        let _ = (ticket, outcome);
    }
}

/// What is being admitted.
#[derive(Debug)]
pub struct AdmissionClaim<'a> {
    /// The caller identity (key id or `"anonymous"`).
    pub caller: &'a str,
    /// Provider the request routes to.
    pub provider: &'a str,
    /// Requested model.
    pub model: &'a str,
    /// SHA-256 of the raw client body (never the body itself).
    pub body_hash: &'a str,
}

/// An admission reservation; implementations carry what they need to settle.
#[derive(Debug, Default, Clone)]
pub struct AdmissionTicket {
    /// Reserved units, if the implementation accounts in tokens/credits.
    pub reserved: Option<u64>,
}

/// The outcome handed back at settlement.
#[derive(Debug)]
pub struct AdmissionOutcome<'a> {
    /// Whether the request completed.
    pub succeeded: bool,
    /// Final usage, when the attempt produced one.
    pub usage: Option<&'a llm_proxy_protocol::core::Usage>,
}

/// The default [`Admission`]: everything is admitted, nothing is accounted.
#[derive(Debug, Default, Clone, Copy)]
pub struct AllowAllAdmission;

#[async_trait]
impl Admission for AllowAllAdmission {}

/// Response cache lookup (slot 5) and store (slot 13). The default caches
/// nothing. Keys are tenant-safe by construction: caller, provider, route,
/// model and body digest.
#[async_trait]
pub trait Cache: Debug + Send + Sync {
    /// Look up a stored response for this key.
    async fn lookup(&self, key: &CacheKey<'_>) -> Result<Option<CacheEntry>, EngineError> {
        let _ = key;
        Ok(None)
    }

    /// Store a completed response under this key.
    async fn store(&self, key: &CacheKey<'_>, entry: &CacheEntry) {
        let _ = (key, entry);
    }
}

/// A cache key: identifies one normalized request, caller-scoped.
#[derive(Debug)]
pub struct CacheKey<'a> {
    /// The caller identity (key id or `"anonymous"`).
    pub caller: &'a str,
    /// Provider the request routed to.
    pub provider: &'a str,
    /// The endpoint family.
    pub route_kind: ProviderRouteKind,
    /// The model name sent upstream (after aliasing).
    pub model: &'a str,
    /// SHA-256 of the raw client body.
    pub body_hash: &'a str,
    /// Whether the client asked for a stream.
    pub streaming: bool,
}

/// A cached response.
#[derive(Debug, Clone)]
pub struct CacheEntry {
    /// The stored core response (a stream is replayed from its collected
    /// events).
    pub response: CoreResponse,
    /// The collected core events of a streamed response, in order.
    pub events: Vec<CoreEvent>,
}

/// The default [`Cache`]: nothing is stored or answered.
#[derive(Debug, Default, Clone, Copy)]
pub struct NoCache;

#[async_trait]
impl Cache for NoCache {}

/// A guardrail hook. Modes follow audit conflict 9: pre-call (before egress),
/// post-call (non-streaming response), and per-event (streaming), with the
/// verdict deciding rejection; buffering/redaction modes are a later plan.
#[async_trait]
pub trait Guard: Debug + Send + Sync {
    /// Inspect the normalized request before egress.
    async fn inspect_request(&self, request: &CoreRequest) -> Result<GuardDecision, EngineError> {
        let _ = request;
        Ok(GuardDecision::Allow)
    }

    /// Inspect a completed non-streaming response.
    async fn inspect_response(
        &self,
        response: &CoreResponse,
    ) -> Result<GuardDecision, EngineError> {
        let _ = response;
        Ok(GuardDecision::Allow)
    }

    /// Inspect each streamed core event as it is decoded.
    async fn inspect_event(&self, event: &CoreEvent) -> Result<GuardDecision, EngineError> {
        let _ = event;
        Ok(GuardDecision::Allow)
    }
}

/// What a guard decides.
#[derive(Debug, Clone)]
pub enum GuardDecision {
    /// Let the request/response/event through.
    Allow,
    /// Reject: the message is surfaced to the client as the rejection reason.
    Reject(String),
}

/// Supplies the upstream credential for an attempt (slot 9's credential
/// pick). The default is the static key from provider config, with
/// client-token passthrough when the provider opts in; providers configured
/// with more than one key rotate across the pool with failure feedback
/// (plan 04 step 5, backlog 31).
#[async_trait]
pub trait CredentialSource: Debug + Send + Sync {
    /// Pick the credential for one attempt.
    ///
    /// `query.keys` is the member's resolved key pool (`api_keys` plus the
    /// base `api_key`, or just the base key); `query.avoid` names the
    /// credential that just failed, so a rotating implementation can move
    /// on even statelessly. Returns the secret plus the id recorded on
    /// ledger rows (never the secret itself).
    async fn pick(&self, query: &CredentialQuery<'_>) -> Result<CredentialPick, EngineError> {
        if query.passthrough {
            return Ok(CredentialPick {
                secret: query.inbound.cloned().ok_or(EngineError::Unauthorized)?,
                credential_id: None,
            });
        }
        let secret = query.keys.first().cloned().ok_or(EngineError::Internal(
            "no upstream credential configured".to_owned(),
        ))?;
        Ok(CredentialPick {
            secret,
            credential_id: None,
        })
    }

    /// Feedback after the attempt ran (plan 04 step 5): which credential was
    /// used and how it ended. Default: ignore.
    fn feedback(
        &self,
        _provider: &str,
        _credential_id: Option<&str>,
        _outcome: CredentialFeedback,
    ) {
    }
}

/// What a credential pick hands back.
#[derive(Debug, Clone)]
pub struct CredentialPick {
    /// The secret to send upstream.
    pub secret: SecretString,
    /// The id recorded on usage rows identifying which pool key was used
    /// (for example `key-2`); `None` when the member has a single key or
    /// passthrough auth supplied it.
    pub credential_id: Option<String>,
}

/// What the attempt loop knows when picking a credential.
#[derive(Debug)]
pub struct CredentialQuery<'a> {
    /// The member provider the attempt targets.
    pub provider: &'a str,
    /// The member's resolved credential pool.
    pub keys: &'a [SecretString],
    /// Whether the member forwards the client's own token.
    pub passthrough: bool,
    /// The client's token when one arrived.
    pub inbound: Option<&'a SecretString>,
    /// The id of the credential that failed the previous attempt against
    /// this member, if that attempt used one.
    pub avoid: Option<&'a str>,
    /// Ids of this member's credentials still cooling down from an earlier
    /// rejection (the engine's [`CooldownStore`](crate::health::CooldownStore)
    /// view). A pick skips them while another key exists; they are the ids
    /// the source itself returned, so any naming scheme round-trips.
    pub cooling: &'a [String],
}

/// How an attempt that used a credential ended, for
/// [`CredentialSource::feedback`].
#[derive(Debug, Clone, Copy, PartialEq, Eq)]
pub enum CredentialFeedback {
    /// The attempt succeeded.
    Succeeded,
    /// The credential was rejected or throttled (401/403/429): a pool should
    /// let this key cool down.
    Rejected,
    /// The member failed transiently (5xx/timeout): the key is probably
    /// fine, but the member cools down.
    TransientFailure,
}

/// The default [`CredentialSource`]: the configured static key, or the
/// client's token on `passthrough_auth` providers (which requires one).
/// With a multi-key pool it rotates round-robin, avoiding the key that just
/// failed and the keys the engine's
/// [`CooldownStore`](crate::health::CooldownStore) reports as cooling
/// (`query.cooling`, fed by the attempt loop's feedback) while another key
/// exists.
#[derive(Debug)]
pub struct ConfigCredentialSource {
    last_pick: Mutex<HashMap<String, usize>>,
}

use std::sync::Mutex;

impl Default for ConfigCredentialSource {
    fn default() -> Self {
        Self {
            last_pick: Mutex::new(HashMap::new()),
        }
    }
}

impl ConfigCredentialSource {
    /// A fresh source with no rotation memory.
    #[must_use]
    pub fn new() -> Self {
        Self::default()
    }
}

#[async_trait]
impl CredentialSource for ConfigCredentialSource {
    async fn pick(&self, query: &CredentialQuery<'_>) -> Result<CredentialPick, EngineError> {
        if query.passthrough {
            return Ok(CredentialPick {
                secret: query.inbound.cloned().ok_or(EngineError::Unauthorized)?,
                credential_id: None,
            });
        }
        let Some(first) = query.keys.first() else {
            return Err(EngineError::Internal(
                "no upstream credential configured".to_owned(),
            ));
        };
        if query.keys.len() == 1 {
            // Single-key member: the base key, no id to record.
            return Ok(CredentialPick {
                secret: first.clone(),
                credential_id: None,
            });
        }
        // Multi-key pool (the base key plus extras): walk the rotation from
        // the key after the last pick. The key that just failed is skipped
        // first, cooling keys next; when every key is excluded the plain
        // rotation stands — cooldowns reorder, they never refuse service.
        let total = query.keys.len();
        let mut guard = self.last_pick.lock().unwrap_or_else(|e| e.into_inner());
        let last = guard.get(query.provider).copied().unwrap_or(total - 1);
        let start = (last + 1) % total;
        let avoid = query.avoid.and_then(parse_key_index);
        let cooling: Vec<usize> = query
            .cooling
            .iter()
            .filter_map(|id| parse_key_index(id))
            .collect();
        let rotation = (0..total).map(|step| (start + step) % total);
        let next = rotation
            .clone()
            .find(|index| avoid != Some(*index) && !cooling.contains(index))
            .or_else(|| rotation.clone().find(|index| avoid != Some(*index)))
            .unwrap_or(start);
        guard.insert(query.provider.to_owned(), next);
        let secret = query.keys.get(next).cloned().ok_or(EngineError::Internal(
            "credential pool index out of range".to_owned(),
        ))?;
        Ok(CredentialPick {
            secret,
            credential_id: Some(format!("key-{next}")),
        })
    }
}

/// Pool credential ids are `key-<index>`; parse the index back out.
fn parse_key_index(id: &str) -> Option<usize> {
    id.strip_prefix("key-")?.parse().ok()
}

/// Where usage rows go (slot 13). The default forwards to the
/// [`EventBus`](llm_proxy_storage::EventBus) the app configured (SQLite
/// ledger or [`NoopBus`](llm_proxy_storage::NoopBus)).
pub trait UsageSink: Debug + Send + Sync {
    /// Record one lifecycle event.
    fn record(&self, event: &llm_proxy_storage::ProxyEvent);
}

/// The default [`UsageSink`]: delegate to an event bus.
#[derive(Debug)]
pub struct EventBusSink {
    bus: Arc<dyn llm_proxy_storage::EventBus>,
}

impl EventBusSink {
    /// Wrap an event bus.
    #[must_use]
    pub fn new(bus: Arc<dyn llm_proxy_storage::EventBus>) -> Self {
        Self { bus }
    }

    /// The wrapped bus.
    #[must_use]
    pub fn bus(&self) -> &Arc<dyn llm_proxy_storage::EventBus> {
        &self.bus
    }
}

impl UsageSink for EventBusSink {
    fn record(&self, event: &llm_proxy_storage::ProxyEvent) {
        self.bus.emit(event);
    }
}

/// Supplies the configuration snapshot (audit conflict 11). TOML files are
/// one source; programmatic config is another, and a record-store backend
/// (key API, hot reload) is a later plan implementing this same trait.
pub trait ConfigSource: Debug + Send + Sync {
    /// The current configuration snapshot.
    fn load(&self) -> Result<Arc<AppConfig>, EngineError>;
}

/// A [`ConfigSource`] over one immutable [`AppConfig`] snapshot — what a
/// TOML file or a builder produces.
#[derive(Debug, Clone)]
pub struct StaticConfigSource {
    config: Arc<AppConfig>,
}

impl StaticConfigSource {
    /// Wrap a config snapshot.
    #[must_use]
    pub fn new(config: Arc<AppConfig>) -> Self {
        Self { config }
    }
}

impl ConfigSource for StaticConfigSource {
    fn load(&self) -> Result<Arc<AppConfig>, EngineError> {
        Ok(Arc::clone(&self.config))
    }
}

/// Inbound headers as the engine sees them: names lowercased, UTF-8 values
/// only. The server performs the conversion from its HTTP layer.
pub type InboundHeaders = HashMap<String, String>;
