//! `private-worker::tests::derived_dispatch_e2e` — ADR-0036 / ADR-0058 acceptance, distill side: the cross-tenant,
//!   slot-bounded, tenant-fair dispatcher behind `humaux-private-worker --distill-once` / `--distill-serve`.
//! Depends-on: crates=[async-trait, humaux-adapters, humaux-domain, humaux-testkit, postgres, serde_json, tokio,
//!   uuid]; services=[PostgreSQL(owner) r=[control.audit_events, ops.claim_derived_work_v2, ops.commit_seq_seq, ops.distill_calls, ops.distill_tenant_scheduler, ops.model_call_ledger,
//!   ops.provider_arbiters, ops.provider_slots, private.memory_affects, private.memory_records, private.processing_runs]
//!   w=[control.credentials, control.memberships, control.private_reasoning_domains, control.processor_models,
//!   control.provider_accounts, control.provider_endpoints, control.reasoning_credential_bindings,
//!   control.reasoning_profiles, control.reasoning_route_bindings, control.reasoning_route_candidates,
//!   control.reasoning_route_policies, control.tenants, control.users, ops.jobs, ops.outbox, ops.provider_slots,
//!   ops.reasoning_account_health_observations, ops.reasoning_provider_health_observations, private.events,
//!   private.evidence_objects], PostgreSQL(role_maintenance), PostgreSQL(role_private_worker) x=[ops.claim_derived_work_v2],
//!   HTTP(literal endpoint), HTTP(loopback), subprocess(humaux-private-worker), subprocess(kill)]; env=[CARGO_BIN_EXE_humaux-private-worker,
//!   HUMAUX_CARD15_TEST_SECRET, HUMAUX_LIVE_P2_KEY_ENV, HUMAUX_PRIVATE_WORKER_CANDIDATE_TTL_SECONDS,
//!   HUMAUX_PRIVATE_WORKER_CONSOLIDATION_UID, HUMAUX_PRIVATE_WORKER_CREDENTIALS,
//!   HUMAUX_PRIVATE_WORKER_DISTILL_BUDGET_MAX_CALLS,
//!   HUMAUX_PRIVATE_WORKER_DISTILL_BUDGET_WINDOW_SECS, HUMAUX_PRIVATE_WORKER_DISTILL_HARD_DEADLINE_SECS, HUMAUX_PRIVATE_WORKER_DISTILL_IN_FLIGHT,
//!   HUMAUX_PRIVATE_WORKER_DISTILL_LEASE_SECS, HUMAUX_PRIVATE_WORKER_DISTILL_MAX_ATTEMPTS,
//!   HUMAUX_PRIVATE_WORKER_DISTILL_NOT_READY_PARK_SECS, HUMAUX_PRIVATE_WORKER_DISTILL_POLL_INTERVAL_SECS,
//!   HUMAUX_PRIVATE_WORKER_DISTILL_SERVE_METRICS_ADDR, HUMAUX_PRIVATE_WORKER_DNS_PINS, HUMAUX_PRIVATE_WORKER_EGRESS_RECIPIENTS,
//!   HUMAUX_PRIVATE_WORKER_HEALTH_RENEW_SECS, HUMAUX_PRIVATE_WORKER_HTTP_TIMEOUT_SECS,
//!   HUMAUX_PRIVATE_WORKER_PERMIT_TTL_SECS, HUMAUX_PRIVATE_WORKER_REGIONS, HUMAUX_PRIVATE_WORKER_RPC_SOCKET_PATH,
//!   HUMAUX_PRIVATE_WORKER_SERVE_RPC_METRICS_ADDR, HUMAUX_TEST_PG_DSN, MINIMAX_API_KEY, PRIVATE_WORKER_PG_DSN,
//!   refused:HUMAUX_PRIVATE_WORKER_EGRESS_PROCESSOR_ID]; modules=[adapters::byok,
//!   adapters::contribution_reasoner, adapters::disclosure, adapters::distill_reasoner, adapters::jobs,
//!   adapters::maintenance_repo, adapters::membership_repo, adapters::postgres, adapters::provisioning,
//!   adapters::reasoning_route_admission, adapters::tests::support::throwaway_db, domain::evidence, humaux-testkit,
//!   private-worker::distill, private-worker::tests::support::dispatch_fence,
//!   private-worker::tests::support::double_spend, private-worker::tests::support::live_minimax,
//!   private-worker::tests::support::live_provider, private-worker::inference_rpc, private-worker::route_providers,
//!   adapters::byok::ssrf, testkit::fixture_purge, testkit::reaped]
//! Called-by: [cargo-test]
//! Invariants: [only this file's tenants are ever claimed (foreign scheduler rows are fenced FOR UPDATE); every
//!   scenario's faults are named in its doc (ADR-0058 records the red→green runs); a fixture deletes its jobs, slots
//!   and data rows in one printed batch and its tenant rows in a separate best-effort batch; the automatic re-drive
//!   tests run on their own throwaway database (ADR-0062 E8), never on the shared dev database]
//! Spec: Baseline §16.1.1; §10.1; §67.2; §11; §11.2.5; §79.2; ADR-0058; ADR-0059; ADR-0060; ADR-0062 D-P
//!
//! The Distill hop's own behaviour (route admission, §16.1.1 fingerprint, §10.1 ceiling, the
//! fenced write transaction) is `tests/distill_hop_e2e.rs`' subject. This file covers the layer
//! above it: one job = one Evidence (P1-4), the four provider slots and the tenant rotation
//! (P1-16, debts 1 and 2), counted attempts and honest DEAD, WAITING_KEY parking, the generation
//! fence under two dispatchers, the binary's resident loop, and the maintenance daemon's one
//! automatic re-drive of a schema-failed death (ADR-0062 D-P).

use humaux_adapters::byok::{
    OutputChannel, PrivateInferenceContext, ReasoningCapability, ReasoningProviderDescriptor,
    ReasoningProviderError, StructuredReasoningRequest, StructuredReasoningResponse, TokenUsage,
    UserReasoningProvider, VisionReasoningRequest, VisionReasoningResponse,
};
use humaux_adapters::contribution_reasoner::ContributionReasonerConfig;
use humaux_adapters::disclosure::DeletionCapability;
use humaux_adapters::jobs::{self, DistillLease};
use humaux_adapters::maintenance_repo;
use humaux_adapters::membership_repo::AdminAction;
use humaux_adapters::postgres::{MaintenanceDbPool, PrivateWorkerDbPool};
use humaux_adapters::provisioning::{
    self, ProvisioningError, RequeueReceipt, RequeueSkipReason, RequeueTarget, RequeuedJob,
    SkippedJob,
};
use humaux_adapters::reasoning_route_admission::{
    ProviderFor, ROUTE_HEALTH_DENIED, ROUTE_HEALTH_STALE, ReasoningAdmissionLocator,
};
use humaux_private_worker::distill::{self, DistillDispatchConfig, DistillDispatchReport};
use humaux_private_worker::route_providers::{
    self, CREDENTIAL_NOT_MAPPED, EGRESS_RECIPIENTS, REGIONS, RouteProviders,
};
use humaux_testkit::fixture_purge::purge_tenant_fixture_sql;
use humaux_testkit::reaped::{Reaped, SpawnReaped};
use humaux_testkit::{DbFixtureSkipReason, DbIntegrationFixture, run_db_fixture};
use postgres::{Client, NoTls};
use std::sync::atomic::{AtomicBool, AtomicU32, Ordering};
use std::sync::{Arc, Mutex};
use std::time::Duration;
use uuid::Uuid;

#[path = "support/dispatch_fence.rs"]
mod dispatch_fence;
#[path = "support/double_spend.rs"]
mod double_spend;
#[path = "support/live_minimax.rs"]
mod live_minimax;
#[path = "support/live_provider.rs"]
mod live_provider;
#[path = "../../../crates/adapters/tests/support/throwaway_db.rs"]
mod throwaway_db;

/// Every test drives the ONE global slot set and the cross-tenant claim, so tests never overlap.
static SERIAL_GUARD: Mutex<()> = Mutex::new(());

/// `HUMAUX_PRIVATE_WORKER_CREDENTIALS` for a spawned worker: every credential reference of
/// `tenants`' rehearsal-vendor profiles names `var`. They all declare [`ACCOUNT_REF`]'s vendor
/// account, so the worker's one-secret-one-account boot check accepts them (ADR-0060 D-J).
fn credentials_spec(admin: &mut Client, tenants: &[Uuid], var: &str) -> String {
    admin
        .query(
            "SELECT p.credential_ref FROM control.reasoning_profiles p \
               JOIN control.provider_accounts a ON a.provider_account_id = p.provider_account_id \
             WHERE p.tenant_id = ANY($1) AND a.processor_id = $2 ORDER BY 1",
            &[&tenants, &PROVIDER_ID],
        )
        .expect("mapped credential references")
        .into_iter()
        .map(|row| format!("{}={var}", row.get::<_, Uuid>(0)))
        .collect::<Vec<_>>()
        .join(",")
}

/// ADR-0060 D-J: the one vendor account behind every profile this file seeds for a vendor
/// (`external_account_ref_hash = sha256(ACCOUNT_REF)` per processor).
const ACCOUNT_REF: &str = "derived-dispatch-e2e-vendor-account";
/// The host the subprocess workers' recipient may dial: the literal endpoint and the rehearsal
/// host (ADR-0060 D-L).
fn subprocess_recipients() -> String {
    format!(
        "{EGRESS_PROCESSOR_ID}=192.88.99.1|{}",
        live_minimax::MINIMAX_HOST
    )
}

const REGION: &str = "cn-shanghai";
const SERVICE_TIER: &str = "standard";
const EGRESS_PROCESSOR_ID: Uuid = Uuid::from_u128(0x2001);
/// A DIFFERENT deployment's egress processor: a tenant whose admitted route points at it can
/// never be served by THIS worker (card 16's P0).
const FOREIGN_EGRESS_PROCESSOR_ID: Uuid = Uuid::from_u128(0x2002);
/// The static class `PrivateReasoningError::class` carries for that failure.
const FOREIGN_EGRESS_REASON: &str = "EGRESS_PROCESSOR_NOT_ALLOWED";
/// The NOT_READY class of a tenant with no admitted binding.
const NO_BINDING_REASON: &str = "no admitted PRIVATE_DISTILL_TEXT route binding";
/// Route-graph fixture values, mirrored from `tests/distill_hop_e2e.rs` so the two files share
/// one catalog row in the global append-only `control.processor_models`.
const PROVIDER_ID: &str = live_minimax::MINIMAX_PROVIDER;
const MODEL_ID: &str = live_minimax::MINIMAX_MODEL;
const ENDPOINT_REF: &str = live_minimax::MINIMAX_CHAT_URL;
const PURPOSE_DB: &str = "PRIVATE_DISTILL_TEXT";
/// The transport timeout the in-process tests size `ops.begin_call`'s window with.
const HTTP_SECS: f64 = 5.0;
/// ADR-0058 D-T: a §72.3 budget no test in this file reaches (the budget gate has its own test,
/// distill_dispatch_v2 T21).
const TEST_BUDGET: jobs::DistillCallBudget = jobs::DistillCallBudget {
    window_seconds: 60.0,
    max_calls: 10_000,
};
/// One §10.1-admissible distilled memory (`PrivateKnowledge` ≤ the `DirectUserInput` ceiling).
const ONE_MEMORY_REPLY: &str = r#"{"memories":[{"content":"Health endpoint before traffic.","memory_type":"Decision","class":"PrivateKnowledge","confidence":0.9}]}"#;

fn dsn_as_role(admin_dsn: &str, role: &str) -> String {
    // ADR-0059 D-D: a real login as `role`, its password from HUMAUX_ROLE_PASSWORD_<SUFFIX>.
    humaux_testkit::role_login_dsn(admin_dsn, role, |name| std::env::var(name).ok())
        .unwrap_or_else(|missing| panic!("missing object: {missing} (ADR-0059 D-D)"))
}

fn db_detail(error: &postgres::Error) -> String {
    match error.as_db_error() {
        Some(db) => format!("{}: {}", db.code().code(), db.message()),
        None => format!("{error}"),
    }
}

/// Never called: tenants with no admitted binding are settled NOT_READY before any provider
/// round trip. `unreachable!` is the assertion.
struct NeverCalledProvider(ReasoningProviderDescriptor);

#[async_trait::async_trait]
impl UserReasoningProvider for NeverCalledProvider {
    fn descriptor(&self) -> &ReasoningProviderDescriptor {
        &self.0
    }

    fn endpoint_ref(&self) -> &str {
        "https://example.invalid/v1/chat/completions"
    }

    fn model_revision(&self) -> Option<&str> {
        None
    }

    async fn complete_structured(
        &self,
        _context: &PrivateInferenceContext,
        _request: StructuredReasoningRequest,
    ) -> Result<StructuredReasoningResponse, ReasoningProviderError> {
        unreachable!("no admitted distill route: the job must settle before any provider call")
    }

    async fn analyze_vision(
        &self,
        _context: &PrivateInferenceContext,
        _request: VisionReasoningRequest,
    ) -> Result<VisionReasoningResponse, ReasoningProviderError> {
        unreachable!("distill never calls vision")
    }
}

fn never_called() -> Arc<NeverCalledProvider> {
    Arc::new(NeverCalledProvider(ReasoningProviderDescriptor {
        provider_id: "derived-dispatch-e2e".to_string(),
        model_id: "never-called".to_string(),
        model_revision: None,
        capabilities: vec![ReasoningCapability::StructuredOutput],
        custom_endpoint: Some("https://example.invalid/v1/chat/completions".to_string()),
        request_extras: Default::default(),
    }))
}

/// What a scripted call answers.
enum Reply {
    Json(String),
    RetryWait,
    WaitingKey,
}

type Script = dyn Fn(&str) -> (Duration, Reply) + Send + Sync;

/// The admitted tenants' provider: the script maps the request's user prompt (which carries the
/// Evidence payload, so a marker text selects a behaviour) to a delay and a reply. Counts calls
/// and the highest number of calls live at once.
struct StubProvider {
    descriptor: ReasoningProviderDescriptor,
    calls: AtomicU32,
    /// Calls sent on the tool channel (ADR-0058 D-M; ADR-0060 D-D: only a profile declaring
    /// TOOL_CALLS gets it).
    tool_calls: AtomicU32,
    finished: AtomicU32,
    live: AtomicU32,
    max_live: AtomicU32,
    script: Box<Script>,
}

impl StubProvider {
    fn new(script: impl Fn(&str) -> (Duration, Reply) + Send + Sync + 'static) -> Arc<Self> {
        Self::declaring(live_minimax::descriptor(), script)
    }

    /// A stub built as the route of `descriptor` would build it (ADR-0060 D-B): its endpoint is
    /// the descriptor's.
    fn declaring(
        descriptor: ReasoningProviderDescriptor,
        script: impl Fn(&str) -> (Duration, Reply) + Send + Sync + 'static,
    ) -> Arc<Self> {
        Arc::new(Self {
            descriptor,
            calls: AtomicU32::new(0),
            tool_calls: AtomicU32::new(0),
            finished: AtomicU32::new(0),
            live: AtomicU32::new(0),
            max_live: AtomicU32::new(0),
            script: Box::new(script),
        })
    }

    /// Answers every call with one admissible memory after `delay`.
    fn one_memory(delay: Duration) -> Arc<Self> {
        Self::new(move |_| (delay, Reply::Json(ONE_MEMORY_REPLY.to_string())))
    }

    fn calls(&self) -> u32 {
        self.calls.load(Ordering::SeqCst)
    }
}

struct LiveGuard<'a>(&'a AtomicU32);

impl Drop for LiveGuard<'_> {
    fn drop(&mut self) {
        self.0.fetch_sub(1, Ordering::SeqCst);
    }
}

#[async_trait::async_trait]
impl UserReasoningProvider for StubProvider {
    fn descriptor(&self) -> &ReasoningProviderDescriptor {
        &self.descriptor
    }

    fn endpoint_ref(&self) -> &str {
        self.descriptor
            .custom_endpoint
            .as_deref()
            .unwrap_or(ENDPOINT_REF)
    }

    fn model_revision(&self) -> Option<&str> {
        self.descriptor.model_revision.as_deref()
    }

    async fn complete_structured(
        &self,
        _context: &PrivateInferenceContext,
        request: StructuredReasoningRequest,
    ) -> Result<StructuredReasoningResponse, ReasoningProviderError> {
        self.calls.fetch_add(1, Ordering::SeqCst);
        if matches!(request.output, OutputChannel::Tool(_)) {
            self.tool_calls.fetch_add(1, Ordering::SeqCst);
        }
        let live = self.live.fetch_add(1, Ordering::SeqCst) + 1;
        self.max_live.fetch_max(live, Ordering::SeqCst);
        let _live = LiveGuard(&self.live);
        let (delay, reply) = (self.script)(&request.user_prompt);
        if !delay.is_zero() {
            tokio::time::sleep(delay).await;
        }
        self.finished.fetch_add(1, Ordering::SeqCst);
        match reply {
            Reply::Json(json) => Ok(StructuredReasoningResponse {
                json,
                usage: TokenUsage::default(),
                channel_fallback: false,
            }),
            Reply::RetryWait => Err(ReasoningProviderError::RetryWait { retry_after: None }),
            Reply::WaitingKey => Err(ReasoningProviderError::WaitingKey { fingerprint: None }),
        }
    }

    async fn analyze_vision(
        &self,
        _context: &PrivateInferenceContext,
        _request: VisionReasoningRequest,
    ) -> Result<VisionReasoningResponse, ReasoningProviderError> {
        unreachable!("distill never calls vision")
    }
}

/// ADR-0060 D-B: every admitted route goes to `provider`, unless its recipient is not this
/// deployment's — the deny-only check the private worker's route mapping holds (§11.2.5: it can
/// refuse a route, never select one). D-C still compares the stub with the route.
fn routes<P: UserReasoningProvider + 'static>(
    provider: &Arc<P>,
) -> impl Fn(&ReasoningAdmissionLocator) -> Result<Arc<dyn UserReasoningProvider>, &'static str>
+ Send
+ Sync
+ use<P> {
    let provider = Arc::clone(provider);
    move |route| {
        if route.egress_processor_id.0 == EGRESS_PROCESSOR_ID {
            Ok(Arc::clone(&provider) as Arc<dyn UserReasoningProvider>)
        } else {
            Err(FOREIGN_EGRESS_REASON)
        }
    }
}

fn reasoner_config() -> ContributionReasonerConfig {
    ContributionReasonerConfig {
        permit_ttl: Duration::from_secs(30),
        deletion_capability: DeletionCapability::Unknown,
        system_prompt: "s".to_string(),
        json_schema: "{}".to_string(),
        max_output_tokens: 64,
    }
}

/// ADR-0058 D-K shape with the smallest admissible hard deadline for `lease_seconds`.
fn dispatch_config(owner: &str, lease_seconds: f64) -> DistillDispatchConfig {
    DistillDispatchConfig {
        lease_owner: owner.to_string(),
        lease_seconds,
        in_flight: 4,
        hard_deadline_seconds: 2.0 * (HTTP_SECS + lease_seconds),
        http_timeout_seconds: HTTP_SECS,
        not_ready_park_seconds: 600.0,
        max_attempts: 5,
        budget: TEST_BUDGET,
        health_renew_seconds: HEALTH_RENEW_SECS,
        dns_pins_configured: false,
    }
}

/// Ruling E3: the renewal window every in-process dispatcher of this file uses. The seed's
/// 30-minute observations have more than half of it left, so traffic renews nothing unless a
/// test shortens them.
const HEALTH_RENEW_SECS: i64 = 1800;

struct SeededTenant {
    tenant_id: Uuid,
    reasoning_domain_id: Uuid,
    /// The tenant's `PRIVATE_DISTILL_TEXT` route policy, when it has one (a second domain binds it).
    route_policy_id: Option<Uuid>,
}

struct Handle {
    rt: tokio::runtime::Runtime,
    private: PrivateWorkerDbPool,
    admin: Client,
    /// Holds every pre-existing scheduler row FOR UPDATE (`dispatch_fence`).
    fence: Client,
    dsn: String,
    tenants: Vec<SeededTenant>,
    user_id: Uuid,
    /// ADR-0062 E8: the throwaway database a re-drive test runs on, dropped after every connection above.
    _throwaway: Option<throwaway_db::ThrowawayDb>,
}

impl Drop for Handle {
    /// Throwaway-tenant cleanup through the one fixture purge (`humaux_testkit::fixture_purge`, ADR-0063 "Dev
    /// integrity finding"; the replica-mode DELETE list it replaces skipped RI and the identity release triggers and
    /// left orphans on dev). The slots this file's jobs hold are released first: `ops.provider_slots` rows are global
    /// and carry no FK, so the purge never reaches them. A failure is printed (that fixture tenant stays, nothing is
    /// half-deleted); the shared user is not a tenant row and goes last with constraints enforced, best effort.
    fn drop(&mut self) {
        let _ = self.fence.batch_execute("ROLLBACK");
        let ids: Vec<Uuid> = self.tenants.iter().map(|t| t.tenant_id).collect();
        if let Err(e) = self.admin.execute(
            "UPDATE ops.provider_slots SET job_id = NULL, claim_generation = NULL, bound_until = NULL \
             WHERE job_id IN (SELECT job_id FROM ops.jobs WHERE tenant_id = ANY($1))",
            &[&ids],
        ) {
            eprintln!("derived_dispatch_e2e cleanup: slot release failed: {}", db_detail(&e));
        }
        for tenant in &ids {
            let purged = purge_tenant_fixture_sql(&tenant.to_string())
                .and_then(|sql| self.admin.batch_execute(&sql).map_err(|e| db_detail(&e)));
            if let Err(error) = purged {
                eprintln!("derived_dispatch_e2e cleanup ({tenant}): {error}");
            }
        }
        let _ = self.admin.execute(
            "DELETE FROM control.users WHERE user_id = $1",
            &[&self.user_id],
        );
    }
}

struct DispatchFixture;

impl DbIntegrationFixture for DispatchFixture {
    type Handle = Handle;

    fn isolate() -> Result<Self::Handle, DbFixtureSkipReason> {
        let dsn =
            std::env::var("HUMAUX_TEST_PG_DSN").map_err(|_| DbFixtureSkipReason::NoDatabaseUrl)?;
        Handle::open(dsn, None)
    }
}

/// ADR-0062 E8: the re-drive tests' fixture. The same four tenants on a throwaway database created and migrated for
/// the test, so no automatic re-drive ever touches the shared dev database.
struct RedriveFixture;

impl DbIntegrationFixture for RedriveFixture {
    type Handle = Handle;

    fn isolate() -> Result<Self::Handle, DbFixtureSkipReason> {
        let db = throwaway_db::create("c35_redrive")?;
        Handle::open(db.dsn(), Some(db))
    }
}

impl Handle {
    /// Seeds the four tenants on `dsn` (the owner DSN); `throwaway` is the database `dsn` points at, if the test
    /// owns one.
    fn open(
        dsn: String,
        throwaway: Option<throwaway_db::ThrowawayDb>,
    ) -> Result<Self, DbFixtureSkipReason> {
        // dep: PostgreSQL(owner) — admin connection for seeding, inspection and cleanup
        let mut admin = Client::connect(&dsn, NoTls)
            .map_err(|e| DbFixtureSkipReason::ConnectFailed(e.to_string()))?;
        let migrated: bool = admin
            .query_one(
                "SELECT to_regprocedure('ops.claim_derived_work_v2(text,double precision,double precision)') \
                 IS NOT NULL",
                &[],
            )
            .map_err(|e| DbFixtureSkipReason::IsolationSetupFailed(db_detail(&e)))?
            .get(0);
        if !migrated {
            return Err(DbFixtureSkipReason::IsolationSetupFailed(
                "ops.claim_derived_work_v2 does not exist — run `cargo xtask migrate` (0190) \
                 against HUMAUX_TEST_PG_DSN first"
                    .to_string(),
            ));
        }
        let fence = dispatch_fence::open(&mut admin, &dsn)
            .map_err(DbFixtureSkipReason::IsolationSetupFailed)?;

        let user_id: Uuid = admin
            .query_one(
                "INSERT INTO control.users (state) VALUES ('ACTIVE') RETURNING user_id",
                &[],
            )
            .map_err(|e| DbFixtureSkipReason::IsolationSetupFailed(db_detail(&e)))?
            .get(0);

        let rt = tokio::runtime::Runtime::new()
            .map_err(|e| DbFixtureSkipReason::IsolationSetupFailed(e.to_string()))?;
        let private = rt
            // dep: PostgreSQL(role_private_worker) — role-scoped pool call
            .block_on(PrivateWorkerDbPool::connect(&dsn_as_role(
                &dsn,
                "role_private_worker",
            )))
            .map_err(|e| DbFixtureSkipReason::IsolationSetupFailed(e.to_string()))?;
        let mut handle = Handle {
            rt,
            private,
            admin,
            fence,
            dsn,
            tenants: Vec::new(),
            user_id,
            _throwaway: throwaway,
        };
        // A and B are provisioned with an admitted PRIVATE_DISTILL_TEXT route; C deliberately is
        // not ("onboarded before its route was admitted"); D has a COMPLETE, admitted route bound
        // to another deployment's egress processor (card 16).
        for (label, binding_egress) in [
            (
                "private derived_dispatch_e2e tenant A",
                Some(EGRESS_PROCESSOR_ID),
            ),
            (
                "private derived_dispatch_e2e tenant B",
                Some(EGRESS_PROCESSOR_ID),
            ),
            ("private derived_dispatch_e2e tenant C (no route)", None),
            (
                "private derived_dispatch_e2e tenant D (foreign egress)",
                Some(FOREIGN_EGRESS_PROCESSOR_ID),
            ),
        ] {
            handle
                .add_tenant(label, binding_egress)
                .map_err(|e| DbFixtureSkipReason::IsolationSetupFailed(db_detail(&e)))?;
        }
        Ok(handle)
    }
}

impl Handle {
    /// Seeds one more tenant (pushed onto `tenants`, cleaned up with them); returns its index.
    fn add_tenant(
        &mut self,
        label: &str,
        binding_egress: Option<Uuid>,
    ) -> Result<usize, postgres::Error> {
        self.add_tenant_declaring(label, binding_egress, &live_minimax::REHEARSAL_CAPABILITIES)
    }

    /// [`Self::add_tenant`] whose Profile declares exactly `capabilities` (ADR-0060 D-C: the
    /// provider serving it must declare the same set).
    fn add_tenant_declaring(
        &mut self,
        label: &str,
        binding_egress: Option<Uuid>,
        capabilities: &[ReasoningCapability],
    ) -> Result<usize, postgres::Error> {
        let tenant = seed_tenant(
            &mut self.admin,
            label,
            self.user_id,
            binding_egress,
            ENDPOINT_REF,
            capabilities,
        )?;
        self.tenants.push(tenant);
        Ok(self.tenants.len() - 1)
    }

    /// One more tenant whose domain is bound to a Profile of `lane` (ADR-0060 D-B: the route picks
    /// the provider). Returns its index and the Profile's route ids.
    fn add_tenant_on(&mut self, label: &str, lane: &Lane) -> (usize, SeededRoute) {
        let tenant = seed_tenant(
            &mut self.admin,
            label,
            self.user_id,
            None,
            ENDPOINT_REF,
            &[],
        )
        .expect("tenant");
        let (policy, route) = seed_route_binding_on(
            &mut self.admin,
            tenant.tenant_id,
            self.user_id,
            tenant.reasoning_domain_id,
            label,
            lane,
        )
        .expect("route");
        self.tenants.push(SeededTenant {
            route_policy_id: Some(policy),
            ..tenant
        });
        (self.tenants.len() - 1, route)
    }

    /// A second reasoning domain of tenant `idx`, bound to the tenant's own route policy.
    fn add_domain(&mut self, idx: usize, label: &str) -> Uuid {
        let tenant_id = self.tenants[idx].tenant_id;
        let policy = self.tenants[idx]
            .route_policy_id
            .expect("a second domain needs the tenant's route policy");
        let domain: Uuid = self
            .admin
            .query_one(
                "INSERT INTO control.private_reasoning_domains (tenant_id, name, owner_user_id, status) \
                 VALUES ($1, $2, $3, 'ACTIVE') RETURNING reasoning_domain_id",
                &[&tenant_id, &label, &self.user_id],
            )
            .expect("second reasoning domain")
            .get(0);
        self.admin
            .execute(
                "INSERT INTO control.reasoning_route_bindings \
                   (tenant_id, reasoning_domain_id, purpose, route_policy_id, route_policy_version) \
                 VALUES ($1, $2, $3, $4, 1)",
                &[&tenant_id, &domain, &PURPOSE_DB, &policy],
            )
            .expect("second domain binding");
        domain
    }

    fn pass<P: UserReasoningProvider + 'static>(
        &self,
        provider: &Arc<P>,
        config: &DistillDispatchConfig,
    ) -> DistillDispatchReport {
        self.pass_routes(&routes(provider), config)
    }

    /// One `--distill-once` pass over any route→provider mapping (ADR-0060 D-B).
    fn pass_routes(
        &self,
        providers: &ProviderFor,
        config: &DistillDispatchConfig,
    ) -> DistillDispatchReport {
        self.rt
            .block_on(distill::dispatch_pass(
                &self.private,
                providers,
                reasoner_config(),
                config,
            ))
            .expect("dispatch pass")
    }

    fn tenant_ids(&self) -> Vec<Uuid> {
        self.tenants.iter().map(|t| t.tenant_id).collect()
    }

    /// (status, attempt, last_error_class, claim_generation, abandoned_claims)
    fn job(&mut self, job_id: Uuid) -> (String, i32, Option<String>, i32, i32) {
        let r = self
            .admin
            .query_one(
                "SELECT status, attempt, last_error_class, claim_generation, abandoned_claims \
                 FROM ops.jobs WHERE job_id = $1",
                &[&job_id],
            )
            .expect("job row");
        (r.get(0), r.get(1), r.get(2), r.get(3), r.get(4))
    }

    /// The job of one Evidence (0164's idempotency key).
    fn job_of(&mut self, evidence_id: Uuid) -> Uuid {
        self.admin
            .query_one(
                "SELECT job_id FROM ops.jobs WHERE idempotency_key = 'derived-work:DERIVED_DISTILL:' || $1::uuid::text",
                &[&evidence_id],
            )
            .expect("one job per Evidence")
            .get(0)
    }

    fn outbox_status(&mut self, evidence_id: Uuid) -> String {
        self.admin
            .query_one(
                "SELECT status FROM ops.outbox WHERE evidence_id = $1",
                &[&evidence_id],
            )
            .expect("outbox row")
            .get(0)
    }

    fn calls_of(&mut self, job_id: Uuid) -> i64 {
        self.admin
            .query_one(
                "SELECT count(*) FROM ops.distill_calls WHERE job_id = $1",
                &[&job_id],
            )
            .expect("distill_calls")
            .get(0)
    }

    fn sql(&mut self, sql: &str, id: Uuid) {
        self.admin.execute(sql, &[&id]).expect("admin statement");
    }

    /// Makes a backed-off or parked job claimable now.
    fn ready_now(&mut self, job_id: Uuid) {
        self.sql(
            "UPDATE ops.jobs SET next_retry_at = clock_timestamp() - interval '1 second' WHERE job_id = $1",
            job_id,
        );
    }

    /// ADR-0058 §2.1 I-SLOT over the whole table.
    fn assert_i_slot(&mut self) {
        assert_eq!(i_slot_violations(&mut self.admin), 0, "I-SLOT");
    }
}

fn i_slot_violations(admin: &mut Client) -> i64 {
    admin
        .query_one(
            "SELECT count(*) FROM ops.jobs j \
             WHERE j.job_type = 'DERIVED_DISTILL' AND j.status = 'PROCESSING' \
               AND j.dispatch_state IS NOT NULL \
               AND (SELECT count(*) FROM ops.provider_slots s \
                    WHERE s.job_id = j.job_id AND s.claim_generation = j.claim_generation) <> 1",
            &[],
        )
        .expect("I-SLOT probe")
        .get(0)
}

/// `binding_egress`: `Some(id)` seeds an admitted `PRIVATE_DISTILL_TEXT` route whose endpoint
/// carries that egress processor; `None` seeds no route at all.
fn seed_tenant(
    admin: &mut Client,
    label: &str,
    user_id: Uuid,
    binding_egress: Option<Uuid>,
    endpoint_ref: &str,
    capabilities: &[ReasoningCapability],
) -> Result<SeededTenant, postgres::Error> {
    let tenant_id: Uuid = admin
        .query_one(
            "INSERT INTO control.tenants (name, state) VALUES ($1, 'ACTIVE') RETURNING tenant_id",
            &[&format!("e2e-fixture {label}")],
        )?
        .get(0);
    // `control.reasoning_route_policies_check_owner` refuses a policy whose owner has no ACTIVE
    // membership in the policy's own tenant (§6.3); the binding trigger additionally requires the
    // domain to name that same owner, and `distill::acting_user` installs it for the RLS reads.
    admin.execute(
        "INSERT INTO control.memberships (tenant_id, user_id, role, state) \
         VALUES ($1, $2, 'OWNER', 'ACTIVE')",
        &[&tenant_id, &user_id],
    )?;
    let reasoning_domain_id: Uuid = admin
        .query_one(
            "INSERT INTO control.private_reasoning_domains \
               (tenant_id, name, owner_user_id, status) \
             VALUES ($1, $2, $3, 'ACTIVE') RETURNING reasoning_domain_id",
            &[&tenant_id, &label, &user_id],
        )?
        .get(0);
    let route_policy_id = match binding_egress {
        Some(egress) => Some(
            seed_route_binding_on(
                admin,
                tenant_id,
                user_id,
                reasoning_domain_id,
                label,
                &Lane::rehearsal(egress, endpoint_ref, MODEL_ID, capabilities),
            )?
            .0,
        ),
        None => None,
    };
    Ok(SeededTenant {
        tenant_id,
        reasoning_domain_id,
        route_policy_id,
    })
}

/// One provider a Profile can name — ADR-0060 D-B: the admitted route, not the worker, picks the
/// provider, model, endpoint, recipient, capabilities and request extras of a call.
#[derive(Clone)]
struct Lane {
    provider_id: String,
    model_id: String,
    endpoint_ref: String,
    egress_processor_id: Uuid,
    region: String,
    capabilities: Vec<ReasoningCapability>,
    request_extras: serde_json::Value,
}

impl Lane {
    /// The rehearsal vendor at `endpoint_ref` / `model_id`, declaring `capabilities`, no extras.
    fn rehearsal(
        egress_processor_id: Uuid,
        endpoint_ref: &str,
        model_id: &str,
        capabilities: &[ReasoningCapability],
    ) -> Self {
        Self {
            provider_id: PROVIDER_ID.to_owned(),
            model_id: model_id.to_owned(),
            endpoint_ref: endpoint_ref.to_owned(),
            egress_processor_id,
            region: REGION.to_owned(),
            capabilities: capabilities.to_vec(),
            request_extras: serde_json::json!({}),
        }
    }

    /// A live provider's lane (ADR-0060 D-B / D-L): its recipient is `egress_processor_id` unless
    /// the provider fixes its own.
    fn live(profile: &live_provider::LiveProfile, egress_processor_id: Uuid) -> Self {
        Self {
            provider_id: profile.provider_id.clone(),
            model_id: profile.model_id.clone(),
            endpoint_ref: profile.chat_url.clone(),
            egress_processor_id: profile.egress_processor_id.unwrap_or(egress_processor_id),
            region: profile.region.clone(),
            capabilities: profile.capabilities.clone(),
            request_extras: serde_json::Value::Object(profile.request_extras.clone()),
        }
    }

    /// The descriptor an instance built from this lane's route carries (ADR-0060 D-C compares it).
    fn descriptor(&self) -> ReasoningProviderDescriptor {
        ReasoningProviderDescriptor {
            provider_id: self.provider_id.clone(),
            model_id: self.model_id.clone(),
            model_revision: Some(live_minimax::caps_revision_label(&self.capabilities)),
            capabilities: self.capabilities.clone(),
            custom_endpoint: Some(self.endpoint_ref.clone()),
            request_extras: self.request_extras.as_object().cloned().unwrap_or_default(),
        }
    }
}

/// The admitted `PRIVATE_DISTILL_TEXT` binding the dispatcher resolves per claimed job, mirrored
/// from `tests/distill_hop_e2e.rs::setup_db`. Returns the route policy (a second domain of the
/// tenant binds it too). `endpoint_ref` must equal the worker provider's endpoint for the route
/// to match (`provider_matches_admission`); so must `model_id`.
#[allow(clippy::too_many_arguments)] // one route graph's identity: tenant, owner, domain, lane
fn seed_route_binding(
    admin: &mut Client,
    tenant_id: Uuid,
    user_id: Uuid,
    reasoning_domain_id: Uuid,
    label: &str,
    egress_processor_id: Uuid,
    endpoint_ref: &str,
    model_id: &str,
    capabilities: &[ReasoningCapability],
) -> Result<Uuid, postgres::Error> {
    let lane = Lane::rehearsal(egress_processor_id, endpoint_ref, model_id, capabilities);
    seed_route_binding_on(admin, tenant_id, user_id, reasoning_domain_id, label, &lane)
        .map(|(policy, _)| policy)
}

/// [`seed_route_binding`] over any [`Lane`]: Profile + PINNED policy + one candidate + binding v1
/// + fresh health. Returns the policy and the Profile's route ids.
fn seed_route_binding_on(
    admin: &mut Client,
    tenant_id: Uuid,
    user_id: Uuid,
    reasoning_domain_id: Uuid,
    label: &str,
    lane: &Lane,
) -> Result<(Uuid, SeededRoute), postgres::Error> {
    let route = seed_reasoning_profile(admin, tenant_id, user_id, label, lane)?;
    let policy = seed_pinned_policy(admin, tenant_id, user_id, route.profile_id)?;
    admin.execute(
        "INSERT INTO control.reasoning_route_bindings \
           (tenant_id, reasoning_domain_id, purpose, route_policy_id, route_policy_version) \
         VALUES ($1, $2, $3, $4, 1)",
        &[&tenant_id, &reasoning_domain_id, &PURPOSE_DB, &policy],
    )?;
    Ok((policy, route))
}

/// A SERVING PINNED policy whose one candidate is `profile_id@1`. A PINNED policy needs exactly one
/// priority-0 candidate before it may leave DRAFT, and DRAFT -> SHADOW -> SERVING is the only order
/// the owner check accepts.
fn seed_pinned_policy(
    admin: &mut Client,
    tenant_id: Uuid,
    user_id: Uuid,
    profile_id: Uuid,
) -> Result<Uuid, postgres::Error> {
    let policy: Uuid = admin
        .query_one(
            "INSERT INTO control.reasoning_route_policies \
               (tenant_id, policy_owner_user_id, purpose) \
             VALUES ($1, $2, $3) RETURNING route_policy_id",
            &[&tenant_id, &user_id, &PURPOSE_DB],
        )?
        .get(0);
    admin.execute(
        "INSERT INTO control.reasoning_route_candidates \
           (tenant_id, route_policy_id, route_policy_version, profile_id, profile_version, \
            priority) \
         VALUES ($1, $2, 1, $3, 1, 0)",
        &[&tenant_id, &policy, &profile_id],
    )?;
    for state in ["SHADOW", "SERVING"] {
        admin.execute(
            "UPDATE control.reasoning_route_policies SET lifecycle_state = $2 \
             WHERE route_policy_id = $1 AND policy_version = 1",
            &[&policy, &state],
        )?;
    }
    Ok(policy)
}

/// ADR-0060 D-H shape, as the test owner: closes the domain's current binding and inserts its
/// successor version over a new PINNED policy naming the tenant's OWN `profile_id@1` (the 0128
/// candidate FK makes a cross-tenant profile impossible). Returns `(binding_id, new version)`.
fn switch_binding(
    admin: &mut Client,
    tenant_id: Uuid,
    user_id: Uuid,
    reasoning_domain_id: Uuid,
    profile_id: Uuid,
) -> (Uuid, i64) {
    let policy = seed_pinned_policy(admin, tenant_id, user_id, profile_id).expect("new policy");
    let mut txn = admin.transaction().expect("switch txn");
    let (binding_id, version): (Uuid, i64) = {
        let row = txn
            .query_one(
                "UPDATE control.reasoning_route_bindings SET effective_to = clock_timestamp() \
                 WHERE tenant_id = $1 AND reasoning_domain_id = $2 AND purpose = $3 \
                   AND effective_to IS NULL \
                 RETURNING binding_id, binding_version",
                &[&tenant_id, &reasoning_domain_id, &PURPOSE_DB],
            )
            .expect("close the current binding");
        (row.get(0), row.get(1))
    };
    txn.execute(
        "INSERT INTO control.reasoning_route_bindings \
           (binding_id, binding_version, tenant_id, reasoning_domain_id, purpose, route_policy_id, \
            route_policy_version, effective_from) \
         VALUES ($1, $2, $3, $4, $5, $6, 1, clock_timestamp())",
        &[
            &binding_id,
            &(version + 1),
            &tenant_id,
            &reasoning_domain_id,
            &PURPOSE_DB,
            &policy,
        ],
    )
    .expect("successor binding");
    txn.commit().expect("commit the switch");
    (binding_id, version + 1)
}

/// The two health observations of a Profile's exact identity, observed now, valid `valid_for`.
fn seed_health(
    admin: &mut Client,
    tenant_id: Uuid,
    lane: &Lane,
    route: &SeededRoute,
    valid_for: Duration,
) -> Result<(), postgres::Error> {
    let secs = valid_for.as_secs_f64();
    admin.execute(
        "INSERT INTO ops.reasoning_provider_health_observations \
           (tenant_id, processor_id, processor_model_id, provider_model_id, model_revision, \
            provider_endpoint_id, endpoint_ref, region, service_tier, source_kind, reason_code, \
            verdict, observed_at, valid_until) \
         VALUES ($1, $2, $3, $4, $9, $5, $6, $7, $8, 'TEST', NULL, 'HEALTHY', \
                 clock_timestamp() - interval '1 second', \
                 clock_timestamp() + make_interval(secs => $10))",
        &[
            &tenant_id,
            &lane.provider_id,
            &route.processor_model_id,
            &lane.model_id,
            &route.endpoint_id,
            &lane.endpoint_ref,
            &lane.region,
            &SERVICE_TIER,
            &route.model_revision,
            &secs,
        ],
    )?;
    admin.execute(
        "INSERT INTO ops.reasoning_account_health_observations \
           (tenant_id, provider_account_id, credential_ref, billing_account_id, \
            billing_instrument_id, source_kind, reason_code, account_verdict, \
            credential_verdict, billing_account_verdict, billing_instrument_verdict, \
            observed_at, valid_until) \
         VALUES ($1, $2, $3, NULL, NULL, 'TEST', NULL, 'HEALTHY', 'VALID', NULL, NULL, \
                 clock_timestamp() - interval '1 second', \
                 clock_timestamp() + make_interval(secs => $4))",
        &[
            &tenant_id,
            &route.provider_account_id,
            &route.credential_ref,
            &secs,
        ],
    )?;
    Ok(())
}

/// The route-graph tail `control.reasoning_route_candidates` needs, plus the ids the two health
/// observations key on.
#[derive(Clone)]
struct SeededRoute {
    profile_id: Uuid,
    processor_model_id: Uuid,
    model_revision: String,
    provider_account_id: Uuid,
    endpoint_id: Uuid,
    credential_ref: Uuid,
}

/// The tenant's [`ACCOUNT_REF`] account of `lane`'s vendor and its endpoint for `lane`, created on
/// first use and reused after.
fn vendor_account_and_endpoint(
    admin: &mut Client,
    tenant_id: Uuid,
    user_id: Uuid,
    lane: &Lane,
) -> Result<(Uuid, Uuid), postgres::Error> {
    // ADR-0060 D-J: one vendor = one account row per tenant (0128 UNIQUE), reused with its endpoint
    // by a second profile (M6 poison lane) as `register_reasoning_profile` (0208) does; an endpoint
    // whose region / tier / recipient differ selects no row, so `query_one` fails.
    let account: Uuid = admin
        .query_one(
            "WITH new AS (INSERT INTO control.provider_accounts \
               (tenant_id, owner_user_id, processor_id, external_account_ref_hash) \
             VALUES ($1, $2, $3, sha256(convert_to($4::text, 'UTF8'))) \
             ON CONFLICT (tenant_id, owner_user_id, processor_id, external_account_ref_hash) \
             DO NOTHING RETURNING provider_account_id) \
             SELECT provider_account_id FROM new UNION ALL \
             SELECT provider_account_id FROM control.provider_accounts \
             WHERE tenant_id = $1 AND owner_user_id = $2 AND processor_id = $3 \
               AND external_account_ref_hash = sha256(convert_to($4::text, 'UTF8'))",
            &[&tenant_id, &user_id, &lane.provider_id, &ACCOUNT_REF],
        )?
        .get(0);
    let endpoint: Uuid = admin
        .query_one(
            "WITH new AS (INSERT INTO control.provider_endpoints \
               (tenant_id, provider_account_id, region, service_tier, endpoint_ref, \
                egress_processor_id) \
             VALUES ($1, $2, $3, $4, $5, $6) \
             ON CONFLICT (tenant_id, provider_account_id, endpoint_ref) DO NOTHING \
             RETURNING endpoint_id) \
             SELECT endpoint_id FROM new UNION ALL \
             SELECT endpoint_id FROM control.provider_endpoints \
             WHERE tenant_id = $1 AND provider_account_id = $2 AND region = $3 \
               AND service_tier = $4 AND endpoint_ref = $5 AND egress_processor_id = $6",
            &[
                &tenant_id,
                &account,
                &lane.region,
                &SERVICE_TIER,
                &lane.endpoint_ref,
                &lane.egress_processor_id,
            ],
        )?
        .get(0);
    Ok((account, endpoint))
}

/// One Profile@1 of `lane` with its account (vendor account [`ACCOUNT_REF`]), credential, endpoint
/// and catalog row, plus fresh 30-minute health.
fn seed_reasoning_profile(
    admin: &mut Client,
    tenant_id: Uuid,
    user_id: Uuid,
    label: &str,
    lane: &Lane,
) -> Result<SeededRoute, postgres::Error> {
    let credential: Uuid = admin
        .query_one(
            "INSERT INTO control.credentials (tenant_id, purpose, openbao_ref) \
             VALUES ($1, 'USER_REASONING', $2) RETURNING credential_id",
            &[&tenant_id, &format!("openbao://derived-dispatch/{label}")],
        )?
        .get(0);
    // `control.processor_models` is global and append-only (0128 trigger): one catalog row per
    // (processor, model, revision) across every run of every test in this workspace.
    // ADR-0060 D-C / E5: the catalog row, the Profile and the stub declare one capability set; the
    // revision label keeps a wider set off the frozen NULL-revision row.
    let caps: Vec<&str> = lane.capabilities.iter().map(|c| c.as_str()).collect();
    let model_revision = live_minimax::caps_revision_label(&lane.capabilities);
    admin.execute(
        "INSERT INTO control.processor_models \
           (processor_id, provider_model_id, model_revision, capabilities, status, \
            catalog_observed_at) \
         VALUES ($1, $2, $3, $4, 'ACTIVE', clock_timestamp()) \
         ON CONFLICT DO NOTHING",
        &[&lane.provider_id, &lane.model_id, &model_revision, &caps],
    )?;
    let processor_model_id: Uuid = admin
        .query_one(
            "SELECT processor_model_id FROM control.processor_models \
             WHERE processor_id = $1 AND provider_model_id = $2 AND model_revision = $3 \
               AND status = 'ACTIVE'",
            &[&lane.provider_id, &lane.model_id, &model_revision],
        )?
        .get(0);
    let (account, endpoint) = vendor_account_and_endpoint(admin, tenant_id, user_id, lane)?;
    admin.execute(
        "INSERT INTO control.reasoning_credential_bindings \
           (credential_ref, tenant_id, owner_user_id, provider_account_id, processor_id) \
         VALUES ($1, $2, $3, $4, $5)",
        &[
            &credential,
            &tenant_id,
            &user_id,
            &account,
            &lane.provider_id,
        ],
    )?;
    let profile: Uuid = admin
        .query_one(
            "INSERT INTO control.reasoning_profiles \
               (tenant_id, owner_user_id, provider_account_id, endpoint_id, processor_model_id, \
                credential_ref, billing_account_id, default_billing_instrument_id, capabilities, \
                processing_region, request_extras) \
             VALUES ($1, $2, $3, $4, $5, $6, NULL, NULL, $8, $7, $9) RETURNING profile_id",
            &[
                &tenant_id,
                &user_id,
                &account,
                &endpoint,
                &processor_model_id,
                &credential,
                &lane.region,
                &caps,
                &lane.request_extras,
            ],
        )?
        .get(0);
    let route = SeededRoute {
        profile_id: profile,
        processor_model_id,
        model_revision,
        provider_account_id: account,
        endpoint_id: endpoint,
        credential_ref: credential,
    };
    seed_health(admin, tenant_id, lane, &route, Duration::from_secs(1800))?;
    Ok(route)
}

/// What `remember` writes for one accepted Evidence (§14): the Evidence row plus the
/// `EVIDENCE_ACCEPTED` outbox row. The outbox INSERT is what 0164's
/// `derived_distill_work_enqueue` trigger fires on — this file never writes an `ops.jobs` row.
/// `text` lands in the event payload, i.e. in the prompt the stub provider sees.
fn accept_evidence_in(handle: &mut Handle, tenant_id: Uuid, domain: Uuid, text: &str) -> Uuid {
    let mut txn = handle.admin.transaction().expect("begin remember txn");
    let evidence_id: Uuid = txn
        .query_one(
            "INSERT INTO private.evidence_objects \
               (tenant_id, evidence_kind, payload_sha256, data_class, origin_class, \
                visibility_class, reasoning_domain_id) \
             VALUES ($1, 'EVENT', sha256(convert_to(gen_random_uuid()::text, 'UTF8')), \
                     'INTERNAL', 'DirectUserInput', 'TENANT_SHARED', $2) \
             RETURNING evidence_id",
            &[&tenant_id, &domain],
        )
        .expect("insert evidence")
        .get(0);
    txn.execute(
        "INSERT INTO private.events (event_id, event_kind, payload) \
         VALUES ($1, 'USER_MESSAGE', jsonb_build_object('text', $2::text))",
        &[&evidence_id, &text],
    )
    .expect("insert event");
    let commit_seq: i64 = txn
        .query_one("SELECT nextval('ops.commit_seq_seq')", &[])
        .expect("commit seq")
        .get(0);
    txn.execute(
        "INSERT INTO ops.outbox (tenant_id, commit_seq, stream_seq, event_type, evidence_id) \
         VALUES ($1, $2, 1, 'EVIDENCE_ACCEPTED', $3)",
        &[&tenant_id, &commit_seq, &evidence_id],
    )
    .expect("insert outbox");
    txn.commit().expect("commit remember txn");
    evidence_id
}

/// One accepted Evidence in tenant `idx`'s first domain.
fn accept_evidence(handle: &mut Handle, idx: usize) -> Uuid {
    accept_evidence_marked(handle, idx, "")
}

fn accept_evidence_marked(handle: &mut Handle, idx: usize, text: &str) -> Uuid {
    let (tenant, domain) = (
        handle.tenants[idx].tenant_id,
        handle.tenants[idx].reasoning_domain_id,
    );
    accept_evidence_in(handle, tenant, domain, text)
}

fn jobs_of(handle: &mut Handle, idx: usize) -> Vec<(Uuid, String, serde_json::Value)> {
    let tenant_id = handle.tenants[idx].tenant_id;
    handle
        .admin
        .query(
            "SELECT job_id, status, payload FROM ops.jobs \
             WHERE tenant_id = $1 AND job_type = 'DERIVED_DISTILL' ORDER BY created_at",
            &[&tenant_id],
        )
        .expect("read jobs")
        .into_iter()
        .map(|r| (r.get(0), r.get(1), r.get(2)))
        .collect()
}

/// Distilled `private.memory_records` rows of one seeded tenant ("assert row counts, not logs").
fn memory_count(handle: &mut Handle, idx: usize) -> i64 {
    let tenant_id = handle.tenants[idx].tenant_id;
    handle
        .admin
        .query_one(
            "SELECT count(*) FROM private.memory_records WHERE tenant_id = $1",
            &[&tenant_id],
        )
        .expect("count memories")
        .get(0)
}

fn run(name: &str, body: impl FnOnce(Handle)) {
    let _guard = SERIAL_GUARD.lock().unwrap_or_else(|e| e.into_inner());
    run_db_fixture::<DispatchFixture, _>(name, body);
}

/// One pass discovers and COMPLETES work in two tenants with no tenant id in its inputs — proved
/// by the distilled row counts. A second pass writes nothing new: no double distill.
#[test]
fn dispatch_discovers_pending_evidence_in_two_tenants() {
    run(
        "dispatch_discovers_pending_evidence_in_two_tenants",
        |mut handle| {
            accept_evidence(&mut handle, 0);
            accept_evidence(&mut handle, 1);
            for tenant in 0..2 {
                let jobs = jobs_of(&mut handle, tenant);
                assert_eq!(jobs.len(), 1, "one job per accepted Evidence");
                assert_eq!(jobs[0].1, "PENDING");
                assert_eq!(
                    jobs[0].2["reasoning_domain_id"].as_str(),
                    Some(
                        handle.tenants[tenant]
                            .reasoning_domain_id
                            .to_string()
                            .as_str()
                    ),
                    "the trigger must carry the Evidence's own reasoning domain"
                );
            }
            let provider = StubProvider::one_memory(Duration::ZERO);
            let report = handle.pass(&provider, &dispatch_config("private-worker-one", 60.0));
            assert_eq!(
                report.claimed, 2,
                "one pass must find BOTH tenants: {report:?}"
            );
            assert_eq!(report.completed, 2, "{report:?}");
            assert_eq!(report.attempts, 2, "{report:?}");
            assert_eq!(report.memories, 2, "{report:?}");
            assert_eq!(provider.calls(), 2, "one provider call per Evidence");
            for tenant in 0..2 {
                assert_eq!(memory_count(&mut handle, tenant), 1);
                assert_eq!(jobs_of(&mut handle, tenant)[0].1, "DONE");
            }
            let again = handle.pass(&provider, &dispatch_config("private-worker-one", 60.0));
            assert_eq!(again.claimed, 0, "{again:?}");
            assert_eq!(provider.calls(), 2, "a second pass must not re-infer");
            handle.assert_i_slot();
        },
    );
}

/// E1 (debt 1d) — one hung provider call (3 s, then `RetryWait`) for ONE Evidence of tenant A
/// while tenant B has three rows; lease 1 s, four seats, a second claimer sweeping every 100 ms.
/// ⇒ every B row DONE before A's call ends, `lost_lease == 0`, `heartbeat_lost == 0`, the hung job
/// never seen EXECUTION_UNCERTAIN, then PENDING with attempt 1 and a backoff. Faults: (a) remove
/// the heartbeat future from the per-job select ⇒ the sweep turns the hung job UNCERTAIN (its
/// lease is gone; ADR-0058 D-G keeps the slot and accepts the same-generation settle, so nothing
/// else breaks); (b) seats forced to 1 ⇒ a B row waits behind the hang. Red on v1's serial pass
/// (card 30b evidence).
#[test]
#[allow(clippy::too_many_lines)]
// one scenario: seed, sweep-after-claim sampler, pass, ordered assertions
// ponytail: nesting past clippy.toml's 5 (§78.4 / G-M01-8, measured 39973585345); M01-6 refactors nothing
#[allow(clippy::excessive_nesting)]
fn one_hung_provider_call_does_not_cost_siblings_their_leases_or_stall_another_tenant() {
    run(
        "one_hung_provider_call_does_not_cost_siblings_their_leases_or_stall_another_tenant",
        |mut handle| {
            let hung = accept_evidence_marked(&mut handle, 0, "HANG");
            let b_rows: Vec<Uuid> = (0..3).map(|_| accept_evidence(&mut handle, 1)).collect();
            let provider = StubProvider::new(|prompt| {
                if prompt.contains("HANG") {
                    (Duration::from_secs(3), Reply::RetryWait)
                } else {
                    (Duration::ZERO, Reply::Json(ONE_MEMORY_REPLY.to_string()))
                }
            });
            let hung_job = handle.job_of(hung);
            // A second claimer sweeps every 100 ms while the pass runs (so an expired lease would
            // be acted on), and the sampler records the hung job's state: with its heartbeat the
            // job stays DISPATCH_INTENT for the whole hang; without it, T5 makes it UNCERTAIN.
            let stop = std::sync::Arc::new(AtomicBool::new(false));
            // Job ids (b_rows are evidence ids; the ordering probe below keys on those).
            let seeded: Vec<Uuid> = b_rows
                .iter()
                .map(|e| handle.job_of(*e))
                .chain([hung_job])
                .collect();
            let sampler = {
                let (stop, dsn) = (stop.clone(), handle.dsn.clone());
                std::thread::spawn(move || {
                    // dep: PostgreSQL(owner) — state sampler
                    let mut admin = Client::connect(&dsn, NoTls).expect("sampler connection");
                    // dep: PostgreSQL(role_private_worker) — the sweeping claimer
                    let mut sweeper =
                        Client::connect(&dsn_as_role(&dsn, "role_private_worker"), NoTls)
                            .expect("sweeper connection");
                    // Sweep only once the pass has claimed every seeded job: a fixed 300 ms delay raced the
                    // pass on a loaded host and the sweeper took a READY B row (card-39 chain, 2026-10-12).
                    // READY is the claim's own predicate (0206 `ops.claim_derived_work_v2`) over the four
                    // seeded jobs; nothing else of this tenant pair is claimable.
                    let claim_deadline = std::time::Instant::now() + Duration::from_secs(10);
                    loop {
                        let ready: i64 = admin
                            .query_one(
                                "SELECT count(*) FROM ops.jobs WHERE job_id = ANY($1) \
                                   AND ((status IN ('PENDING', 'RETRY_WAIT') AND next_retry_at <= clock_timestamp()) \
                                        OR (status = 'PROCESSING' AND lease_expires_at < clock_timestamp()))",
                                &[&seeded],
                            )
                            .expect("ready probe")
                            .get(0);
                        if ready == 0 {
                            break;
                        }
                        assert!(
                            std::time::Instant::now() < claim_deadline,
                            "{ready} seeded jobs still READY 10 s after the pass started"
                        );
                        std::thread::sleep(Duration::from_millis(20));
                    }
                    let mut uncertain = 0_u32;
                    // The claim is DB-wide (lane(a:shared_db)): a READY DERIVED_DISTILL job of another tenant
                    // (the rehearsal's inspection tenants, an interrupted run — card-39 chain #2, 2026-10-12: the
                    // untyped assert went red on exactly that, alone and without load) would be claimed by the
                    // sweep, hold a provider slot and delay B's rows behind the hang. So a sweep runs only while
                    // the shared queue holds no foreign READY job; a skipped sweep is counted and the scenario is
                    // inconclusive (§57.1 below) instead of red or quietly green.
                    let (mut sweeps, mut sweeps_skipped) = (0_u32, 0_u32);
                    while !stop.load(Ordering::SeqCst) {
                        let foreign: i64 = admin
                            .query_one(
                                "SELECT count(*) FROM ops.jobs WHERE job_type = 'DERIVED_DISTILL' \
                                   AND NOT (job_id = ANY($1)) \
                                   AND ((status IN ('PENDING', 'RETRY_WAIT') AND next_retry_at <= clock_timestamp()) \
                                        OR (status = 'PROCESSING' AND lease_expires_at < clock_timestamp()))",
                                &[&seeded],
                            )
                            .expect("foreign READY probe")
                            .get(0);
                        if foreign == 0 {
                            let swept = sweeper
                                .query("SELECT job_id FROM ops.claim_derived_work_v2('c32-e1-sweeper', 1, 12)", &[])
                                .expect("sweep claim");
                            let mine: Vec<Uuid> =
                                swept.iter().map(|r| r.get::<_, Uuid>(0)).collect();
                            assert!(
                                mine.is_empty(),
                                "nothing else of this scenario is READY: {mine:?}"
                            );
                            sweeps += 1;
                        } else {
                            if sweeps_skipped == 0 {
                                // Name the residue once (tenant, status, class): the operator tears it down.
                                let rows = admin
                                    .query(
                                        "SELECT t.name, j.status, coalesce(j.last_error_class, '-') FROM ops.jobs j \
                                           JOIN control.tenants t ON t.tenant_id = j.tenant_id \
                                         WHERE j.job_type = 'DERIVED_DISTILL' AND NOT (j.job_id = ANY($1)) \
                                           AND ((j.status IN ('PENDING', 'RETRY_WAIT') AND j.next_retry_at <= clock_timestamp()) \
                                                OR (j.status = 'PROCESSING' AND j.lease_expires_at < clock_timestamp())) \
                                         LIMIT 5",
                                        &[&seeded],
                                    )
                                    .expect("residue probe");
                                for r in rows {
                                    eprintln!(
                                        "E1 residue: tenant={} status={} class={}",
                                        r.get::<_, String>(0),
                                        r.get::<_, String>(1),
                                        r.get::<_, String>(2)
                                    );
                                }
                            }
                            sweeps_skipped += 1;
                        }
                        let state: Option<String> = admin
                            .query_one(
                                "SELECT dispatch_state FROM ops.jobs WHERE job_id = $1",
                                &[&hung_job],
                            )
                            .expect("sample")
                            .get(0);
                        uncertain += u32::from(state.as_deref() == Some("EXECUTION_UNCERTAIN"));
                        std::thread::sleep(Duration::from_millis(100));
                    }
                    (uncertain, sweeps, sweeps_skipped)
                })
            };
            let started = std::time::Instant::now();
            let report = handle.pass(&provider, &dispatch_config("c32-e1", 1.0));
            stop.store(true, Ordering::SeqCst);
            let (uncertain_samples, sweeps, sweeps_skipped) = sampler.join().expect("sampler");
            if sweeps_skipped > 0 {
                // §57.1: the measurement's missing object is an empty shared queue; the scenario needs the sweep to
                // act on an expired lease, so a run without one proves nothing and says so.
                println!(
                    "not_applicable: missing object = an empty shared DERIVED_DISTILL queue \
                     ({sweeps_skipped} sweep(s) skipped behind READY jobs of other tenants, {sweeps} done; \
                     tear the rehearsal's inspection tenants down: xtask e2e-seed --teardown <tenant>)"
                );
                return;
            }
            println!(
                "E1 report {report:?} wall {:?} uncertain_samples {uncertain_samples}",
                started.elapsed()
            );
            assert_eq!(
                uncertain_samples, 0,
                "the hung job's own heartbeat keeps its lease through the hang"
            );
            assert_eq!(report.lost_lease, 0, "{report:?}");
            assert_eq!(report.heartbeat_lost, 0, "{report:?}");
            assert_eq!(report.completed, 3, "{report:?}");
            assert_eq!(report.deferred, 1, "{report:?}");
            let hung_settled: bool = handle
                .admin
                .query_one(
                    "SELECT (SELECT max(o.processed_at) FROM ops.outbox o WHERE o.evidence_id = ANY($1)) \
                          < (SELECT l.called_at + make_interval(secs => l.latency_ms / 1000.0) \
                             FROM ops.distill_calls c JOIN ops.model_call_ledger l USING (model_call_id) \
                             WHERE c.job_id = $2)",
                    &[&b_rows, &hung_job],
                )
                .expect("ordering probe")
                .get(0);
            assert!(
                hung_settled,
                "every B row must be DONE before A's hung call ends"
            );
            for row in &b_rows {
                assert_eq!(handle.outbox_status(*row), "DONE");
            }
            let (status, attempt, class, ..) = handle.job(hung_job);
            assert_eq!(
                (status.as_str(), attempt, class.as_deref()),
                ("PENDING", 1, Some("RETRY_WAIT"))
            );
            let backed_off: bool = handle
                .admin
                .query_one(
                    "SELECT next_retry_at > clock_timestamp() FROM ops.jobs WHERE job_id = $1",
                    &[&hung_job],
                )
                .unwrap()
                .get(0);
            assert!(
                backed_off,
                "a failing job backs off and does not head the next pass"
            );
            handle.assert_i_slot();
        },
    );
}

/// E2 (debt 2) — 20 never-ready tenants × 10 jobs, all older than the ready tenant B's one job.
/// B is claimed within the first 21 claims of the pass and completes; the never-ready jobs spend
/// no attempt. Fault: global-FIFO job pick (T2 fault) ⇒ B is claim #201. Red on v1's global FIFO.
#[test]
fn twenty_never_ready_tenants_cannot_delay_the_ready_tenant() {
    run(
        "twenty_never_ready_tenants_cannot_delay_the_ready_tenant",
        |mut handle| {
            let mut never_ready = Vec::new();
            for n in 0..20 {
                let idx = handle
                    .add_tenant(
                        &format!("private derived_dispatch_e2e never-ready tenant {n}"),
                        None,
                    )
                    .expect("never-ready tenant");
                for _ in 0..10 {
                    accept_evidence(&mut handle, idx);
                }
                never_ready.push(handle.tenants[idx].tenant_id);
            }
            let b = accept_evidence(&mut handle, 1);
            let start_turn: i64 = handle
                .admin
                .query_one(
                    "SELECT next_turn FROM ops.provider_arbiters WHERE budget = 'PRIVATE_REASONING'",
                    &[],
                )
                .unwrap()
                .get(0);
            let provider = StubProvider::one_memory(Duration::ZERO);
            let started = std::time::Instant::now();
            let report = handle.pass(&provider, &dispatch_config("c32-e2", 60.0));
            let wall = started.elapsed();
            let b_turn: i64 = handle
                .admin
                .query_one(
                    "SELECT last_served_turn FROM ops.distill_tenant_scheduler WHERE tenant_id = $1",
                    &[&handle.tenants[1].tenant_id],
                )
                .unwrap()
                .get(0);
            println!(
                "E2 report {report:?} wall {wall:?} start_turn {start_turn} b_turn {b_turn} (claim #{})",
                b_turn - start_turn + 1
            );
            assert_eq!(
                handle.outbox_status(b),
                "DONE",
                "the ready tenant completes"
            );
            assert!(
                b_turn - start_turn <= 21,
                "B must be served within the first 21 claims, was claim #{}",
                b_turn - start_turn + 1
            );
            let spent: i64 = handle
                .admin
                .query_one(
                    "SELECT count(*) FROM ops.jobs WHERE tenant_id = ANY($1) AND (attempt > 0 OR status = 'DEAD')",
                    &[&never_ready],
                )
                .unwrap()
                .get(0);
            assert_eq!(
                spent, 0,
                "a never-ready job spends no attempt and never dies"
            );
            assert_eq!(provider.calls(), 1, "only B reaches the provider");
            handle.assert_i_slot();
        },
    );
}

/// E3 (P1-4) — one tenant, two reasoning domains: both Evidence are distilled, none FAILED. The
/// second domain's Evidence is committed first and the first domain's job is forced to be
/// claimed first. Fault: take the tenant's oldest open outbox row instead of the job's own
/// `evidence_id` ⇒ the first job reads the other domain's Evidence (DOMAIN_MISMATCH, not done).
#[test]
fn one_tenant_two_reasoning_domains_distills_both_and_fails_none() {
    run(
        "one_tenant_two_reasoning_domains_distills_both_and_fails_none",
        |mut handle| {
            let d2 = handle.add_domain(0, "private derived_dispatch_e2e tenant A domain 2");
            let tenant = handle.tenants[0].tenant_id;
            let d1 = handle.tenants[0].reasoning_domain_id;
            let e2 = accept_evidence_in(&mut handle, tenant, d2, "second domain");
            let e1 = accept_evidence_in(&mut handle, tenant, d1, "first domain");
            let j1 = handle.job_of(e1);
            handle.sql(
                "UPDATE ops.jobs SET created_at = created_at - interval '1 hour' WHERE job_id = $1",
                j1,
            );
            let provider = StubProvider::one_memory(Duration::ZERO);
            let mut config = dispatch_config("c32-e3", 60.0);
            config.in_flight = 1;
            let report = handle.pass(&provider, &config);
            println!("E3 report {report:?}");
            assert_eq!(report.completed, 2, "{report:?}");
            assert_eq!(report.failed, 0, "{report:?}");
            assert_eq!(report.not_ready, 0, "{report:?}");
            for evidence in [e1, e2] {
                assert_eq!(handle.outbox_status(evidence), "DONE");
                let job = handle.job_of(evidence);
                assert_eq!(handle.job(job).0, "DONE");
            }
            assert_eq!(memory_count(&mut handle, 0), 2);
            handle.assert_i_slot();
        },
    );
}

/// E4 (ADR-0058 D-D) — a job whose payload names another (bound) domain than its Evidence goes
/// back to PENDING as NOT_READY `DOMAIN_MISMATCH`; nothing is processed, nothing FAILED. Fault:
/// remove the `evidence_domain` comparison ⇒ the other domain's binding is used and the Evidence
/// is settled FAILED.
#[test]
fn a_job_whose_domain_does_not_match_its_evidence_returns_to_pending_never_failed() {
    run(
        "a_job_whose_domain_does_not_match_its_evidence_returns_to_pending_never_failed",
        |mut handle| {
            let d2 = handle.add_domain(0, "private derived_dispatch_e2e tenant A domain 2");
            let evidence = accept_evidence(&mut handle, 0);
            let job = handle.job_of(evidence);
            handle
                .admin
                .execute(
                    "UPDATE ops.jobs SET payload = jsonb_set(payload, '{reasoning_domain_id}', to_jsonb($2::uuid::text)) \
                     WHERE job_id = $1",
                    &[&job, &d2],
                )
                .expect("rewrite the payload domain");
            let provider = StubProvider::one_memory(Duration::ZERO);
            let report = handle.pass(&provider, &dispatch_config("c32-e4", 60.0));
            assert_eq!(report.not_ready, 1, "{report:?}");
            assert_eq!(handle.outbox_status(evidence), "PENDING");
            let (status, attempt, class, ..) = handle.job(job);
            assert_eq!(
                (status.as_str(), attempt, class.as_deref()),
                ("PENDING", 0, Some("DOMAIN_MISMATCH"))
            );
            let runs: i64 = handle
                .admin
                .query_one(
                    "SELECT count(*) FROM private.processing_runs WHERE evidence_id = $1",
                    &[&evidence],
                )
                .unwrap()
                .get(0);
            assert_eq!(runs, 0, "nothing was processed");
            assert_eq!(provider.calls(), 0);
            handle.assert_i_slot();
        },
    );
}

/// E5 (scope 4) — a provider that always answers `RetryWait` for one Evidence: the job backs
/// off, then is DEAD with class `RETRY_WAIT` after `max_attempts` (2) admitted calls — attempt ==
/// ledger rows == `distill_calls` rows — and its outbox row is FAILED; the tenant's other
/// Evidence (another domain) is DONE. Fault: drop the `attempt >= max_attempts ⇒ DEAD` branch.
#[test]
fn a_failing_provider_backs_off_and_dies_after_max_attempts_with_its_class() {
    run(
        "a_failing_provider_backs_off_and_dies_after_max_attempts_with_its_class",
        |mut handle| {
            let d2 = handle.add_domain(0, "private derived_dispatch_e2e tenant A domain 2");
            let tenant = handle.tenants[0].tenant_id;
            let poison = accept_evidence_marked(&mut handle, 0, "FAIL");
            let good = accept_evidence_in(&mut handle, tenant, d2, "fine");
            let provider = StubProvider::new(|prompt| {
                if prompt.contains("FAIL") {
                    (Duration::ZERO, Reply::RetryWait)
                } else {
                    (Duration::ZERO, Reply::Json(ONE_MEMORY_REPLY.to_string()))
                }
            });
            let mut config = dispatch_config("c32-e5", 60.0);
            config.max_attempts = 2;
            let first = handle.pass(&provider, &config);
            assert_eq!((first.deferred, first.completed), (1, 1), "{first:?}");
            let job = handle.job_of(poison);
            assert_eq!(handle.job(job).0, "PENDING", "backed off, not dead yet");
            handle.ready_now(job);
            let second = handle.pass(&provider, &config);
            assert_eq!(second.dead, 1, "{second:?}");
            let (status, attempt, class, ..) = handle.job(job);
            assert_eq!(
                (status.as_str(), attempt, class.as_deref()),
                ("DEAD", 2, Some("RETRY_WAIT"))
            );
            assert_eq!(handle.outbox_status(poison), "FAILED");
            assert_eq!(handle.outbox_status(good), "DONE");
            assert_eq!(handle.calls_of(job), 2);
            let failed_ledger: i64 = handle
                .admin
                .query_one(
                    "SELECT count(*) FROM ops.model_call_ledger WHERE tenant_id = $1 AND status = 'FAILED'",
                    &[&tenant],
                )
                .unwrap()
                .get(0);
            assert_eq!(
                failed_ledger, 2,
                "attempt == ledger rows == distill_calls rows"
            );
            let again = handle.pass(&provider, &config);
            assert_eq!(
                again.claimed, 0,
                "a DEAD job is never claimed again: {again:?}"
            );
            handle.assert_i_slot();
        },
    );
}

/// E6 (ADR-0058 D-H) — a tenant with no binding: NOT_READY spends no attempt and, once not ready
/// for the park age, parks as `WAITING_KEY` with its class. Fault: admit a provider request
/// (`ops.begin_call`) before the binding is resolved ⇒ the attempt is counted.
#[test]
fn not_ready_never_spends_an_attempt_and_parks_after_the_age() {
    run(
        "not_ready_never_spends_an_attempt_and_parks_after_the_age",
        |mut handle| {
            let evidence = accept_evidence(&mut handle, 2);
            let job = handle.job_of(evidence);
            let mut config = dispatch_config("c32-e6", 60.0);
            config.not_ready_park_seconds = 1.0;
            let provider = never_called();
            let first = handle.pass(&provider, &config);
            assert_eq!(first.not_ready, 1, "{first:?}");
            let (status, attempt, class, ..) = handle.job(job);
            assert_eq!(
                (status.as_str(), attempt, class.as_deref()),
                ("PENDING", 0, Some(NO_BINDING_REASON))
            );
            assert_eq!(handle.calls_of(job), 0);
            std::thread::sleep(Duration::from_millis(1200));
            handle.ready_now(job);
            let second = handle.pass(&provider, &config);
            assert_eq!(second.parked, 1, "{second:?}");
            let (status, attempt, class, ..) = handle.job(job);
            assert_eq!(
                (status.as_str(), attempt, class.as_deref()),
                ("WAITING_KEY", 0, Some(NO_BINDING_REASON)),
                "parked past the age, never DEAD, no attempt"
            );
            assert_eq!(handle.outbox_status(evidence), "PENDING");
            handle.assert_i_slot();
        },
    );
}

/// The production [`RouteProviders`] of an in-process dispatcher (ADR-0060 D-B): `mapped` refs
/// name one generated throwaway key, the rehearsal recipient may dial the rehearsal host, one
/// region. A route outside them parks with its class before any build, ledger row or call.
fn production_routes(mapped: &[Uuid]) -> Arc<RouteProviders> {
    let spec = mapped
        .iter()
        .map(|r| format!("{r}=HX33B_TEST_KEY"))
        .collect::<Vec<_>>()
        .join(",");
    let key = Uuid::new_v4().simple().to_string();
    let lookup = |name: &str| match name {
        route_providers::CREDENTIALS => Some(spec.clone()),
        "HX33B_TEST_KEY" => Some(key.clone()),
        EGRESS_RECIPIENTS => Some(format!(
            "{EGRESS_PROCESSOR_ID}={}",
            live_minimax::MINIMAX_HOST
        )),
        REGIONS => Some(REGION.to_owned()),
        _ => None,
    };
    Arc::new(RouteProviders::new(
        route_providers::parse_credential_map(lookup).expect("credential map"),
        route_providers::parse_recipients(lookup).expect("recipients"),
        route_providers::parse_regions(lookup).expect("regions"),
        live_minimax::live_dns_resolver(),
        Duration::from_secs_f64(HTTP_SECS),
    ))
}

/// The ledger rows of one tenant.
fn ledger_rows(handle: &mut Handle, tenant_id: Uuid) -> i64 {
    handle
        .admin
        .query_one(
            "SELECT count(*) FROM ops.model_call_ledger WHERE tenant_id = $1",
            &[&tenant_id],
        )
        .expect("ledger count")
        .get(0)
}

/// T17 (card 33 T25, ADR-0060 D-B step 1) — tenant A's route names a credential reference the
/// worker's map does not hold: `WAITING_KEY` / `CREDENTIAL_NOT_MAPPED` after the park age, attempt
/// 0, no ledger row, no `distill_calls` row, no provider instance built. Fault: remove the map
/// check from `RouteProviders::provider_for` ⇒ the instance is built and the key lookup fails
/// after the reservation ⇒ a ledger row exists.
#[test]
fn foreign_credential_ref_parks_waiting_key_without_ledger_row() {
    run(
        "foreign_credential_ref_parks_waiting_key_without_ledger_row",
        |mut handle| {
            let tenant_id = handle.tenants[0].tenant_id;
            let others: Vec<Uuid> = handle.tenant_ids()[1..].to_vec();
            let mapped: Vec<Uuid> = handle
                .admin
                .query(
                    "SELECT credential_ref FROM control.reasoning_profiles WHERE tenant_id = ANY($1)",
                    &[&others],
                )
                .expect("other tenants' credentials")
                .into_iter()
                .map(|r| r.get(0))
                .collect();
            let routes = production_routes(&mapped);
            let providers = {
                let routes = Arc::clone(&routes);
                move |l: &ReasoningAdmissionLocator| routes.provider_for(l)
            };
            let evidence = accept_evidence(&mut handle, 0);
            let job = handle.job_of(evidence);
            let mut config = dispatch_config("c33-t25", 60.0);
            config.not_ready_park_seconds = 1.0;
            let first = handle.pass_routes(&providers, &config);
            assert_eq!((first.not_ready, first.attempts), (1, 0), "{first:?}");
            let (status, attempt, class, ..) = handle.job(job);
            assert_eq!(
                (status.as_str(), attempt, class.as_deref()),
                ("PENDING", 0, Some(CREDENTIAL_NOT_MAPPED))
            );
            std::thread::sleep(Duration::from_millis(1200));
            handle.ready_now(job);
            let second = handle.pass_routes(&providers, &config);
            assert_eq!(second.parked, 1, "{second:?}");
            let (status, attempt, class, ..) = handle.job(job);
            assert_eq!(
                (status.as_str(), attempt, class.as_deref()),
                ("WAITING_KEY", 0, Some(CREDENTIAL_NOT_MAPPED)),
                "parked with the named class, never DEAD, no attempt"
            );
            assert_eq!(
                (
                    ledger_rows(&mut handle, tenant_id),
                    handle.calls_of(job),
                    routes.built()
                ),
                (0, 0, 0),
                "no ledger row, no distill call, no provider instance"
            );
            assert_eq!(handle.outbox_status(evidence), "PENDING", "not stranded");
            handle.assert_i_slot();
        },
    );
}

/// T35 (ADR-0060 D-J, review finding 9) — a node with an explicitly empty credential map boots:
/// the RPC state builds over it, and a bound domain's job parks `WAITING_KEY` /
/// `CREDENTIAL_NOT_MAPPED` with no ledger row. Fault: refuse an empty map at parse (the card-33
/// rule) ⇒ the map does not build.
#[test]
fn zero_profile_boot_parks_with_a_class() {
    run("zero_profile_boot_parks_with_a_class", |mut handle| {
        let routes = production_routes(&[]);
        let state = humaux_private_worker::inference_rpc::RpcState {
            expected_consolidation_uid: 0,
            calls: handle
                .rt
                // dep: PostgreSQL(role_private_worker) — the RPC state's own pool
                .block_on(PrivateWorkerDbPool::connect(&dsn_as_role(
                    &handle.dsn,
                    "role_private_worker",
                )))
                .expect("pool"),
            config: reasoner_config(),
            providers: {
                let routes = Arc::clone(&routes);
                Box::new(move |l: &ReasoningAdmissionLocator| routes.provider_for(l))
            },
            health_renew_seconds: HEALTH_RENEW_SECS,
        };
        let evidence = accept_evidence(&mut handle, 0);
        let job = handle.job_of(evidence);
        let mut config = dispatch_config("c33b-t35", 60.0);
        config.not_ready_park_seconds = 1.0;
        let first = handle.pass_routes(state.providers.as_ref(), &config);
        assert_eq!((first.not_ready, first.attempts), (1, 0), "{first:?}");
        std::thread::sleep(Duration::from_millis(1200));
        handle.ready_now(job);
        let second = handle.pass_routes(state.providers.as_ref(), &config);
        assert_eq!(second.parked, 1, "{second:?}");
        let (status, _, class, ..) = handle.job(job);
        assert_eq!(
            (status.as_str(), class.as_deref()),
            ("WAITING_KEY", Some(CREDENTIAL_NOT_MAPPED))
        );
        let tenant_id = handle.tenants[0].tenant_id;
        assert_eq!(
            (ledger_rows(&mut handle, tenant_id), routes.built()),
            (0, 0)
        );
    });
}

/// E7 (§11) — a provider that always answers 401: every round parks the job `WAITING_KEY` with
/// attempt 0 and the outbox row open, even with `max_attempts = 1`; the physical calls stay in
/// the ledger and in `ops.distill_calls`. Since ruling E3 each 401 also records the credential
/// INVALID, so the operator re-attests the account before each further round (the "key rotated,
/// still rejected" case). Fault: drop the WAITING_KEY revert in `ops.finish_derived_work_v2` ⇒
/// round 2 sees attempt 1 = max ⇒ DEAD.
#[test]
fn a_401_parks_waiting_key_and_never_dies() {
    run("a_401_parks_waiting_key_and_never_dies", |mut handle| {
        let evidence = accept_evidence(&mut handle, 0);
        let job = handle.job_of(evidence);
        let provider = StubProvider::new(|_| (Duration::ZERO, Reply::WaitingKey));
        let mut config = dispatch_config("c32-e7", 60.0);
        config.max_attempts = 1;
        config.not_ready_park_seconds = 1.0;
        let tenant_id = handle.tenants[0].tenant_id;
        for round in 1..=3 {
            if round > 1 {
                reattest_account(&mut handle.admin, tenant_id);
            }
            let report = handle.pass(&provider, &config);
            assert_eq!(report.parked, 1, "round {round}: {report:?}");
            let (status, attempt, class, ..) = handle.job(job);
            assert_eq!(
                (status.as_str(), attempt, class.as_deref()),
                ("WAITING_KEY", 0, Some("WAITING_KEY")),
                "round {round}"
            );
            assert_eq!(handle.outbox_status(evidence), "PENDING", "round {round}");
            handle.ready_now(job);
        }
        assert_eq!(handle.calls_of(job), 3);
        let failed: i64 = handle
            .admin
            .query_one(
                "SELECT count(*) FROM ops.model_call_ledger WHERE tenant_id = $1 AND status = 'FAILED'",
                &[&handle.tenants[0].tenant_id],
            )
            .unwrap()
            .get(0);
        assert_eq!(failed, 3, "every 401 call is ledgered");
        handle.assert_i_slot();
    });
}

/// An operator attestation of every profile account of `tenant_id` (HEALTHY / VALID, 30 minutes),
/// newer than any worker-observed verdict.
fn reattest_account(admin: &mut Client, tenant_id: Uuid) {
    admin
        .execute(
            "INSERT INTO ops.reasoning_account_health_observations \
               (tenant_id, provider_account_id, credential_ref, billing_account_id, \
                billing_instrument_id, source_kind, reason_code, account_verdict, \
                credential_verdict, billing_account_verdict, billing_instrument_verdict, \
                observed_at, valid_until) \
             SELECT tenant_id, provider_account_id, credential_ref, billing_account_id, \
                    default_billing_instrument_id, 'TEST', NULL, 'HEALTHY', 'VALID', NULL, NULL, \
                    clock_timestamp(), clock_timestamp() + interval '30 minutes' \
             FROM control.reasoning_profiles WHERE tenant_id = $1",
            &[&tenant_id],
        )
        .expect("re-attest the account");
}

/// E8 — two in-process dispatchers (different owners, separate pools) over one backlog: every
/// Evidence is called once and distilled once; the double-spend report is clean. Fault: drop
/// `SKIP LOCKED` + the restated eligibility on the job pick (recorded in ADR-0058: the arbiter
/// lock serializes claims, so this pair is defence in depth).
#[test]
fn two_dispatchers_over_one_backlog_call_each_evidence_once() {
    run(
        "two_dispatchers_over_one_backlog_call_each_evidence_once",
        |mut handle| {
            let mut evidence = Vec::new();
            for _ in 0..6 {
                evidence.push(accept_evidence(&mut handle, 0));
                evidence.push(accept_evidence(&mut handle, 1));
            }
            let second_pool = handle
                .rt
                // dep: PostgreSQL(role_private_worker) — role-scoped pool call
                .block_on(PrivateWorkerDbPool::connect(&dsn_as_role(
                    &handle.dsn,
                    "role_private_worker",
                )))
                .expect("second pool");
            let provider = StubProvider::one_memory(Duration::from_millis(50));
            let (config_one, config_two) = (
                dispatch_config("c32-e8-one", 30.0),
                dispatch_config("c32-e8-two", 30.0),
            );
            let providers = routes(&provider);
            let (one, two) = handle.rt.block_on(async {
                tokio::join!(
                    distill::dispatch_pass(
                        &handle.private,
                        &providers,
                        reasoner_config(),
                        &config_one,
                    ),
                    distill::dispatch_pass(
                        &second_pool,
                        &providers,
                        reasoner_config(),
                        &config_two
                    )
                )
            });
            let (one, two) = (one.expect("dispatcher one"), two.expect("dispatcher two"));
            println!("E8 one {one:?} two {two:?}");
            assert_eq!(one.completed + two.completed, 12);
            assert_eq!(one.lost_lease + two.lost_lease, 0);
            assert_eq!(provider.calls(), 12, "each Evidence is called once");
            let tenants = handle.tenant_ids();
            let report = double_spend::report(
                &mut handle.admin,
                &tenants,
                3,
                config_one.hard_deadline_seconds,
            );
            println!("E8 {}", report.line());
            assert_eq!((report.duplicates, report.overlaps), (0, 0));
            assert_eq!(report.unattributed_succeeded, 0);
            for row in &evidence {
                assert_eq!(handle.outbox_status(*row), "DONE");
            }
            assert_eq!(
                memory_count(&mut handle, 0) + memory_count(&mut handle, 1),
                12
            );
            assert!(
                provider.max_live.load(Ordering::SeqCst) <= 4,
                "never more than four calls in flight across both dispatchers"
            );
            handle.assert_i_slot();
        },
    );
}

/// E13 (ADR-0058 D-E, card-32 review) — a DB error AFTER a counted call (here: the zero-candidate
/// re-ask's run-close transaction hits `lock_timeout` on a run row another transaction holds) is
/// settled by ONE fenced RETRY in a fresh transaction: the job is PENDING with its class, its slot
/// is free and nothing waits for `hard_deadline` or comes back as EXECUTION_UNCERTAIN. Fault: let
/// the error propagate with `?` from the call loop (no settle) → the job stays
/// PROCESSING/DISPATCH_INTENT holding its slot, reported `lost_lease`.
#[test]
fn a_db_error_after_a_counted_call_settles_one_fenced_retry() {
    run(
        "a_db_error_after_a_counted_call_settles_one_fenced_retry",
        |mut handle| {
            let tenant = handle.tenants[0].tenant_id;
            let evidence = accept_evidence(&mut handle, 0);
            let job = handle.job_of(evidence);
            let lock_holders: std::sync::Arc<Mutex<Vec<std::thread::JoinHandle<()>>>> =
                std::sync::Arc::default();
            let provider = {
                let (dsn, holders) = (handle.dsn.clone(), std::sync::Arc::clone(&lock_holders));
                StubProvider::new(move |_| {
                    let (locked_tx, locked_rx) = std::sync::mpsc::channel();
                    let dsn = dsn.clone();
                    holders.lock().unwrap().push(std::thread::spawn(move || {
                        // dep: PostgreSQL(owner) — holds the open processing run row past the
                        // worker's lock_timeout, as a slow concurrent writer would
                        let mut holder = Client::connect(&dsn, NoTls).expect("lock holder");
                        holder.batch_execute("BEGIN").unwrap();
                        holder
                            .query(
                                "SELECT 1 FROM private.processing_runs \
                                 WHERE tenant_id = $1 AND completed_at IS NULL FOR UPDATE",
                                &[&tenant],
                            )
                            .unwrap();
                        locked_tx.send(()).unwrap();
                        std::thread::sleep(Duration::from_secs(4));
                        holder.batch_execute("ROLLBACK").unwrap();
                    }));
                    locked_rx.recv().expect("run row locked");
                    (
                        Duration::ZERO,
                        Reply::Json(r#"{"memories":[]}"#.to_string()),
                    )
                })
            };
            let short_lock_pool = handle
                .rt
                // dep: PostgreSQL(role_private_worker) — role-scoped pool call
                .block_on(PrivateWorkerDbPool::connect(&format!(
                    "{}{}options=-c%20lock_timeout%3D1000",
                    dsn_as_role(&handle.dsn, "role_private_worker"),
                    if handle.dsn.contains('?') { '&' } else { '?' }
                )))
                .expect("lock_timeout pool");
            let config = dispatch_config("c32-e13", 30.0);
            let report = handle
                .rt
                .block_on(distill::dispatch_pass(
                    &short_lock_pool,
                    &routes(&provider),
                    reasoner_config(),
                    &config,
                ))
                .expect("dispatch pass");
            for holder in lock_holders.lock().unwrap().drain(..) {
                holder.join().expect("lock holder");
            }
            println!("E13 {report:?}");
            assert_eq!(provider.calls(), 1);
            assert_eq!(
                (report.deferred, report.lost_lease, report.unknown),
                (1, 0, 0),
                "{report:?}"
            );
            let (status, attempt, class, generation, _) = handle.job(job);
            assert_eq!(
                (status.as_str(), attempt, class.as_deref(), generation),
                ("PENDING", 1, Some("WORKER_DB_ERROR"), 1),
                "one fenced RETRY with the error's class, the call counted"
            );
            let slots: i64 = handle
                .admin
                .query_one(
                    "SELECT count(*) FROM ops.provider_slots WHERE job_id = $1",
                    &[&job],
                )
                .unwrap()
                .get(0);
            assert_eq!(slots, 0, "the slot is freed now, not at hard_deadline");
            assert_eq!(handle.calls_of(job), 1);
            assert_eq!(handle.outbox_status(evidence), "PENDING");
            handle.assert_i_slot();
        },
    );
}

/// E14 (ADR-0058 R3) — an error that escapes the job (here: taking the Evidence's outbox row hits
/// `lock_timeout` on a row another transaction holds, before anything could be settled) is counted
/// as `errors` with its class, never as a lost lease: the fence refused nothing. Fault: report an
/// escaped error as `LeaseLost` → `lost_lease = 1, errors = 0`.
#[test]
fn an_escaped_job_error_is_counted_as_an_error_not_a_lost_lease() {
    run(
        "an_escaped_job_error_is_counted_as_an_error_not_a_lost_lease",
        |mut handle| {
            let evidence = accept_evidence(&mut handle, 0);
            let job = handle.job_of(evidence);
            let (locked_tx, locked_rx) = std::sync::mpsc::channel();
            let holder = {
                let dsn = handle.dsn.clone();
                std::thread::spawn(move || {
                    // dep: PostgreSQL(owner) — holds the outbox row past the worker's lock_timeout
                    let mut holder = Client::connect(&dsn, NoTls).expect("lock holder");
                    holder.batch_execute("BEGIN").unwrap();
                    holder
                        .query(
                            "SELECT 1 FROM ops.outbox WHERE evidence_id = $1 FOR UPDATE",
                            &[&evidence],
                        )
                        .unwrap();
                    locked_tx.send(()).unwrap();
                    std::thread::sleep(Duration::from_secs(3));
                    holder.batch_execute("ROLLBACK").unwrap();
                })
            };
            locked_rx.recv().expect("outbox row locked");
            let short_lock_pool = handle
                .rt
                // dep: PostgreSQL(role_private_worker) — role-scoped pool call
                .block_on(PrivateWorkerDbPool::connect(&format!(
                    "{}{}options=-c%20lock_timeout%3D1000",
                    dsn_as_role(&handle.dsn, "role_private_worker"),
                    if handle.dsn.contains('?') { '&' } else { '?' }
                )))
                .expect("lock_timeout pool");
            let provider = StubProvider::one_memory(Duration::ZERO);
            let report = handle
                .rt
                .block_on(distill::dispatch_pass(
                    &short_lock_pool,
                    &routes(&provider),
                    reasoner_config(),
                    &dispatch_config("c32-e14", 30.0),
                ))
                .expect("dispatch pass");
            holder.join().expect("lock holder");
            println!("E14 {report:?}");
            assert_eq!(provider.calls(), 0, "nothing was sent");
            assert_eq!(
                (report.claimed, report.errors, report.lost_lease),
                (1, 1, 0),
                "{report:?}"
            );
            assert!(report.summary_line().contains(" errors=1 "), "{report:?}");
            let (status, attempt, _, _, _) = handle.job(job);
            assert_eq!(
                (status.as_str(), attempt),
                ("PROCESSING", 0),
                "unsettled: the claim reconciles through the T4 sweep"
            );
            handle.assert_i_slot();
        },
    );
}

/// ADR-0060 D-C / D-J / E3 / E7 — the binary refuses to start without each required route list
/// or the health renewal window, and refuses a removed process-level key that is still set (stale
/// configuration is never silently ignored). The keys are named by the boot error; the unreachable
/// DSN proves the refusal comes before any connection.
#[test]
fn the_worker_refuses_to_boot_without_its_route_lists() {
    for missing in [
        route_providers::CREDENTIALS,
        EGRESS_RECIPIENTS,
        REGIONS,
        "HUMAUX_PRIVATE_WORKER_HEALTH_RENEW_SECS",
    ] {
        let out = distill_serve_command("postgres://nobody@127.0.0.1:1/none", "")
            .env_remove(missing)
            .arg("--distill-once")
            .output()
            .expect("spawn humaux-private-worker");
        let stderr = String::from_utf8_lossy(&out.stderr);
        assert!(!out.status.success(), "{missing}: must not start");
        assert!(
            stderr.contains(&format!("missing required configuration: {missing}")),
            "{missing}: {stderr}"
        );
    }
    let out = distill_serve_command("postgres://nobody@127.0.0.1:1/none", "")
        .env(
            "HUMAUX_PRIVATE_WORKER_EGRESS_PROCESSOR_ID",
            EGRESS_PROCESSOR_ID.to_string(),
        )
        .arg("--distill-once")
        .output()
        .expect("spawn humaux-private-worker");
    assert!(
        String::from_utf8_lossy(&out.stderr).contains(
            "invalid configuration: HUMAUX_PRIVATE_WORKER_EGRESS_PROCESSOR_ID was removed by ADR-0060 D-C"
        ),
        "a removed singular recipient key is refused, never silently ignored"
    );
}

/// E9 (ADR-0058 D-F) — claims that crash before any request (lease expiry while `CLAIMED`) are
/// counted in `abandoned_claims`; at the cap the job is DEAD `PRE_DISPATCH_ABANDONED` with its
/// outbox row FAILED and no call. Fault: the worker ignores `abandoned_claims`.
#[test]
fn abandoned_pre_dispatch_claims_reach_dead_at_the_cap() {
    run(
        "abandoned_pre_dispatch_claims_reach_dead_at_the_cap",
        |mut handle| {
            let evidence = accept_evidence(&mut handle, 0);
            let job = handle.job_of(evidence);
            let expire = |handle: &mut Handle| {
                handle.sql(
                    "UPDATE ops.jobs SET lease_expires_at = clock_timestamp() - interval '1 second' WHERE job_id = $1",
                    job,
                )
            };
            for crash in 1..=2 {
                let claimed = handle
                    .rt
                    .block_on(jobs::claim_distill(
                        &handle.private,
                        "c32-e9-crash",
                        30.0,
                        300.0,
                    ))
                    .expect("raw claim")
                    .expect("the job is READY");
                assert_eq!(claimed.job_id, job);
                assert_eq!(claimed.abandoned_claims, crash - 1);
                expire(&mut handle);
            }
            let provider = never_called();
            let mut config = dispatch_config("c32-e9", 30.0);
            config.max_attempts = 2;
            let report = handle.pass(&provider, &config);
            assert_eq!(report.dead, 1, "{report:?}");
            let (status, attempt, class, _, abandoned) = handle.job(job);
            assert_eq!(
                (status.as_str(), attempt, class.as_deref(), abandoned),
                ("DEAD", 0, Some("PRE_DISPATCH_ABANDONED"), 2)
            );
            assert_eq!(handle.outbox_status(evidence), "FAILED");
            assert_eq!(handle.calls_of(job), 0);
            handle.assert_i_slot();
        },
    );
}

/// E11 (ADR-0058 D-J, review finding 2) — a call admitted at the latest admissible moment whose
/// answer arrives just inside the HTTP window, followed by a write leg slowed past the HTTP
/// cutoff (but not past `hard_deadline`), is kept in generation 1 and never resent, while a
/// second dispatcher — started once the pass holds the lease — sweeps every 100 ms. Fault: put the
/// deadline around the whole job future.
#[test]
#[allow(clippy::too_many_lines)]
// ponytail: nesting past clippy.toml's 5 (§78.4 / G-M01-8, measured 39973585345); M01-6 refactors nothing
#[allow(clippy::excessive_nesting)]
fn a_success_at_the_end_of_the_http_window_is_kept_not_resent() {
    run(
        "a_success_at_the_end_of_the_http_window_is_kept_not_resent",
        |mut handle| {
            const HTTP: f64 = 3.0;
            const LEASE: f64 = 2.0;
            let evidence = accept_evidence(&mut handle, 0);
            let job = handle.job_of(evidence);
            let config = DistillDispatchConfig {
                lease_owner: "c32-e11".into(),
                lease_seconds: LEASE,
                in_flight: 1,
                hard_deadline_seconds: 2.0 * (HTTP + LEASE),
                http_timeout_seconds: HTTP,
                not_ready_park_seconds: 600.0,
                max_attempts: 5,
                budget: TEST_BUDGET,
                health_renew_seconds: HEALTH_RENEW_SECS,
                dns_pins_configured: false,
            };
            let replied = std::sync::Arc::new(AtomicBool::new(false));
            let called = std::sync::Arc::new(AtomicBool::new(false));
            let provider = {
                let (replied, called) = (replied.clone(), called.clone());
                StubProvider::new(move |_| {
                    called.store(true, Ordering::SeqCst);
                    // Answered 0.35 s before the HTTP window closes.
                    // ponytail: the 0.35 s reply margin here and the gate's 0.4 s read-leg margin
                    // are wall-clock ceilings — a runner stalled longer than either misses the
                    // latest admissible moment (DISPATCH_REFUSED) or the window. Upgrade: an
                    // injectable clock for `begin_call`'s `min_remaining` and the local HTTP cutoff.
                    let delay = Duration::from_secs_f64(HTTP - 0.35);
                    let replied = replied.clone();
                    std::thread::spawn(move || {
                        std::thread::sleep(delay);
                        replied.store(true, Ordering::SeqCst);
                    });
                    (delay, Reply::Json(ONE_MEMORY_REPLY.to_string()))
                })
            };
            // The admin side: holds the Evidence row FOR UPDATE so the read leg's processing-run
            // INSERT (FK) waits until `hard_deadline - (http + lease) - 0.4 s` (begin_call then runs
            // at the latest admissible moment), then holds it again from the call until 1 s after
            // the answer, so the write leg's memory_evidence INSERT crosses the HTTP cutoff.
            let dsn = handle.dsn.clone();
            let (replied2, called2) = (replied.clone(), called.clone());
            // Invariant: the sweeper must not race the pass's first claim (ADR-0058 D-E — a claim is
            // whoever commits first on the arbiter row; a sweeper-owned claim is never worked, so
            // no call would come). It starts only after the gate has seen the pass's lease.
            let pass_claimed = std::sync::Arc::new(AtomicBool::new(false));
            let pass_claimed2 = pass_claimed.clone();
            let owner = config.lease_owner.clone();
            let gate = std::thread::spawn(move || {
                // dep: PostgreSQL(owner) — lock-holder connection steering the job's timing
                let mut admin = Client::connect(&dsn, NoTls).expect("gate connection");
                let mut tx = admin.transaction().expect("begin");
                tx.query_one(
                    "SELECT 1 FROM private.evidence_objects WHERE evidence_id = $1 FOR UPDATE",
                    &[&evidence],
                )
                .expect("lock evidence");
                // dep: PostgreSQL(owner) — probe connection
                let mut probe = Client::connect(&dsn, NoTls).expect("probe connection");
                // Every wait below is bounded: a timing miss (the call never admitted, so `called` never
                // flips) is a fast, named failure — unbounded, it hung CI run 38343204163 for 90 min.
                let give_up = std::time::Instant::now() + Duration::from_secs(60);
                let within = |what: &str| {
                    assert!(
                        std::time::Instant::now() < give_up,
                        "E11 gate: {what} not seen within 60 s — the call missed its window"
                    );
                };
                let wait: f64 = loop {
                    within("the job PROCESSING");
                    let row = probe
                        .query_one(
                            "SELECT COALESCE(status = 'PROCESSING' AND lease_owner = $3, false), \
                                    extract(epoch FROM hard_deadline - make_interval(secs => $2) - clock_timestamp())::float8 \
                             FROM ops.jobs WHERE job_id = $1",
                            &[&job, &(HTTP + LEASE + 0.4), &owner],
                        )
                        .expect("job probe");
                    if row.get::<_, bool>(0) {
                        pass_claimed2.store(true, Ordering::SeqCst);
                        break row.get::<_, Option<f64>>(1).unwrap_or(0.0);
                    }
                    std::thread::sleep(Duration::from_millis(10));
                };
                std::thread::sleep(Duration::from_secs_f64(wait.max(0.0)));
                tx.commit().expect("release the read leg");
                while !called2.load(Ordering::SeqCst) {
                    within("the provider call");
                    std::thread::sleep(Duration::from_millis(5));
                }
                let mut tx = admin.transaction().expect("begin");
                tx.query_one(
                    "SELECT 1 FROM private.evidence_objects WHERE evidence_id = $1 FOR UPDATE",
                    &[&evidence],
                )
                .expect("lock evidence again");
                while !replied2.load(Ordering::SeqCst) {
                    within("the provider reply");
                    std::thread::sleep(Duration::from_millis(5));
                }
                std::thread::sleep(Duration::from_secs_f64(LEASE / 2.0));
                tx.commit().expect("release the write leg");
            });
            let sweeper_pool = handle
                .rt
                // dep: PostgreSQL(role_private_worker) — role-scoped pool call
                .block_on(PrivateWorkerDbPool::connect(&dsn_as_role(
                    &handle.dsn,
                    "role_private_worker",
                )))
                .expect("sweeper pool");
            let stop = AtomicBool::new(false);
            let (report, stolen) = handle.rt.block_on(async {
                let pass = async {
                    // With the handshake this delay changes nothing; without it, the sweeper's
                    // first poll claims the job before the pass does, so the test goes red
                    // deterministically if the handshake is removed.
                    tokio::time::sleep(Duration::from_millis(300)).await;
                    let r = distill::dispatch_pass(
                        &handle.private,
                        &routes(&provider),
                        reasoner_config(),
                        &config,
                    )
                    .await;
                    stop.store(true, Ordering::SeqCst);
                    r
                };
                let sweeper = async {
                    let mut stolen = 0;
                    while !pass_claimed.load(Ordering::SeqCst) && !stop.load(Ordering::SeqCst) {
                        tokio::time::sleep(Duration::from_millis(10)).await;
                    }
                    while !stop.load(Ordering::SeqCst) {
                        if jobs::claim_distill(
                            &sweeper_pool,
                            "c32-e11-sweeper",
                            LEASE,
                            2.0 * (HTTP + LEASE),
                        )
                        .await
                        .expect("sweep claim")
                        .is_some()
                        {
                            stolen += 1;
                        }
                        tokio::time::sleep(Duration::from_millis(100)).await;
                    }
                    stolen
                };
                tokio::join!(pass, sweeper)
            });
            // Printed before the join: a gate timeout then still shows who took the claim.
            println!("E11 report {report:?} stolen {stolen}");
            gate.join().expect("gate thread");
            let report = report.expect("dispatch pass");
            let (status, attempt, _, generation, _) = handle.job(job);
            assert_eq!(
                (status.as_str(), generation, attempt),
                ("DONE", 1, 1),
                "kept in generation 1, never resent"
            );
            assert_eq!(stolen, 0);
            assert_eq!(handle.calls_of(job), 1);
            let succeeded: i64 = handle
                .admin
                .query_one(
                    "SELECT count(*) FROM ops.model_call_ledger WHERE tenant_id = $1 AND status = 'SUCCEEDED'",
                    &[&handle.tenants[0].tenant_id],
                )
                .unwrap()
                .get(0);
            assert_eq!(succeeded, 1);
            assert_eq!(report.unknown, 0, "{report:?}");
            handle.assert_i_slot();
        },
    );
}

/// E12 (ADR-0048 D-D, review finding 6) — a malformed reply whose re-ask cannot fit before
/// `hard_deadline` (the stub moves the deadline on its first call) fails closed once: one
/// `distill_calls` row, job DEAD `FAILED_OUTPUT_SCHEMA`, outbox FAILED, and a later pass sends
/// nothing. Fault: map a refused re-ask to NOT_READY (the original prompt would be sent again).
#[test]
fn a_malformed_reply_whose_reask_cannot_fit_fails_closed_once() {
    run(
        "a_malformed_reply_whose_reask_cannot_fit_fails_closed_once",
        |mut handle| {
            let evidence = accept_evidence(&mut handle, 0);
            let job = handle.job_of(evidence);
            let dsn = handle.dsn.clone();
            let provider = StubProvider::new(move |_| {
                let dsn = dsn.clone();
                std::thread::spawn(move || {
                    // dep: PostgreSQL(owner) — moves the claim's deadline under the running call
                    let mut admin = Client::connect(&dsn, NoTls).expect("deadline connection");
                    admin
                        .execute(
                            "UPDATE ops.jobs SET hard_deadline = clock_timestamp() + interval '2 seconds' \
                             WHERE job_id = $1",
                            &[&job],
                        )
                        .expect("move hard_deadline");
                })
                .join()
                .expect("deadline thread");
                (Duration::ZERO, Reply::Json("not json".to_string()))
            });
            let report = handle.pass(&provider, &dispatch_config("c32-e12", 30.0));
            println!("E12 report {report:?}");
            assert_eq!(report.dead, 1, "{report:?}");
            let (status, attempt, class, ..) = handle.job(job);
            assert_eq!(
                (status.as_str(), attempt, class.as_deref()),
                ("DEAD", 1, Some("FAILED_OUTPUT_SCHEMA"))
            );
            assert_eq!(handle.outbox_status(evidence), "FAILED");
            assert_eq!(handle.calls_of(job), 1);
            let again = handle.pass(&provider, &dispatch_config("c32-e12", 30.0));
            assert_eq!(
                (again.claimed, provider.calls()),
                (0, 1),
                "nothing is sent again"
            );
            handle.assert_i_slot();
        },
    );
}

/// E15 (ADR-0058 R8 a) — a reply whose memory text carries U+0000 (a live reply did, card-32
/// M3) is refused by the parser as `nul_character`: no write is attempted, one re-ask, then DEAD
/// `FAILED_OUTPUT_SCHEMA` with the outbox FAILED, and a later pass sends nothing
/// (`double_spend duplicates=0`). Fault: drop the parser's NUL refusal ⇒ PostgreSQL refuses the
/// write (`WORKER_DB_ERROR`), the job settles RETRY and the next pass calls again (duplicates > 0).
#[test]
fn a_reply_carrying_u0000_is_malformed_never_written_and_never_resent() {
    run(
        "a_reply_carrying_u0000_is_malformed_never_written_and_never_resent",
        |mut handle| {
            let evidence = accept_evidence(&mut handle, 0);
            let job = handle.job_of(evidence);
            let tenants = handle.tenant_ids();
            let provider = StubProvider::new(|_| {
                (
                    Duration::ZERO,
                    Reply::Json(
                        ONE_MEMORY_REPLY.replace("Health endpoint", "Health\\u0000endpoint"),
                    ),
                )
            });
            let config = dispatch_config("c32-r8a", 30.0);
            let first = handle.pass(&provider, &config);
            println!("R8a first {first:?}");
            handle.ready_now(job);
            let again = handle.pass(&provider, &config);
            println!("R8a again {again:?}");
            let report =
                double_spend::report(&mut handle.admin, &tenants, 3, config.hard_deadline_seconds);
            println!("R8a {}", report.line());
            assert_eq!(report.duplicates, 0, "{}", report.line());
            assert_eq!(
                (
                    first.dead,
                    first.malformed_retries,
                    first.attempts,
                    first.errors
                ),
                (1, 1, 2, 0),
                "{first:?}"
            );
            let (status, attempt, class, ..) = handle.job(job);
            assert_eq!(
                (status.as_str(), attempt, class.as_deref()),
                ("DEAD", 2, Some("FAILED_OUTPUT_SCHEMA"))
            );
            assert_eq!(handle.outbox_status(evidence), "FAILED");
            assert_eq!((handle.calls_of(job), provider.calls()), (2, 2));
            assert_eq!(memory_count(&mut handle, 0), 0, "nothing was written");
            handle.assert_i_slot();
        },
    );
}

/// A job that distilled NOTHING (tenant C has no admitted route) is settled NOT_READY with a
/// backoff — never DONE (its Evidence would be stranded: 0164's enqueue key is per evidence_id
/// with ON CONFLICT DO NOTHING), and its outbox row stays claimable. Fault: settle DONE.
#[test]
fn a_job_that_distilled_nothing_is_not_ready_instead_of_completed() {
    run(
        "a_job_that_distilled_nothing_is_not_ready_instead_of_completed",
        |mut handle| {
            let evidence = accept_evidence(&mut handle, 2);
            let provider = never_called();
            let mut config = dispatch_config("unprovisioned-worker", 60.0);
            config.max_attempts = 1;
            let report = handle.pass(&provider, &config);
            assert_eq!(
                (
                    report.claimed,
                    report.completed,
                    report.not_ready,
                    report.dead
                ),
                (1, 0, 1, 0),
                "{report:?}"
            );
            assert_eq!(memory_count(&mut handle, 2), 0);
            let job = handle.job_of(evidence);
            let (status, attempt, class, ..) = handle.job(job);
            assert_eq!(
                (status.as_str(), attempt, class.as_deref()),
                ("PENDING", 0, Some(NO_BINDING_REASON)),
                "released with its class, never DONE"
            );
            let backed_off: bool = handle
                .admin
                .query_one(
                    "SELECT next_retry_at > clock_timestamp() FROM ops.jobs WHERE job_id = $1",
                    &[&job],
                )
                .unwrap()
                .get(0);
            assert!(backed_off, "the release must back off");
            assert_eq!(handle.outbox_status(evidence), "PENDING", "not stranded");
            handle.assert_i_slot();
        },
    );
}

/// Card 16's P0: tenant D's route is fully admitted but bound to another deployment's egress;
/// it is NOT_READY with that class (never DEAD, no attempt), and the ready tenant claimed in the
/// same pass still completes.
#[test]
fn a_tenant_the_deployment_cannot_admit_is_named_and_does_not_starve_the_ready_one() {
    run(
        "a_tenant_the_deployment_cannot_admit_is_named_and_does_not_starve_the_ready_one",
        |mut handle| {
            accept_evidence(&mut handle, 0);
            let foreign = accept_evidence(&mut handle, 3);
            let provider = StubProvider::one_memory(Duration::ZERO);
            let mut config = dispatch_config("mixed-readiness-worker", 60.0);
            config.max_attempts = 1;
            for pass in 1..=2 {
                let report = handle.pass(&provider, &config);
                assert_eq!(report.not_ready, 1, "pass {pass}: {report:?}");
                assert_eq!(report.dead, 0, "pass {pass}: {report:?}");
                let job = handle.job_of(foreign);
                let (status, attempt, class, ..) = handle.job(job);
                assert_eq!(
                    (status.as_str(), attempt, class.as_deref()),
                    ("PENDING", 0, Some(FOREIGN_EGRESS_REASON)),
                    "pass {pass}: named, released, never DEAD"
                );
                handle.ready_now(job);
            }
            assert_eq!(
                memory_count(&mut handle, 0),
                1,
                "the ready tenant is not starved"
            );
            assert_eq!(jobs_of(&mut handle, 0)[0].1, "DONE");
            assert_eq!(
                provider.calls(),
                1,
                "only the admitted tenant reaches the provider"
            );
            handle.assert_i_slot();
        },
    );
}

/// Two racing claims take each job exactly once (ADR-0058 T1 under two owners).
#[test]
fn two_racing_claims_take_each_job_exactly_once() {
    run(
        "two_racing_claims_take_each_job_exactly_once",
        |mut handle| {
            accept_evidence(&mut handle, 0);
            accept_evidence(&mut handle, 1);
            let claim = |owner: &str| {
                handle
                    .rt
                    .block_on(jobs::claim_distill(&handle.private, owner, 60.0, 300.0))
                    .expect("claim")
            };
            let (first, second, third) =
                (claim("racer-one"), claim("racer-two"), claim("racer-three"));
            let (first, second) = (first.expect("first job"), second.expect("second job"));
            assert_ne!(first.job_id, second.job_id, "no job may be claimed twice");
            assert!(third.is_none(), "both live claims are held");
            for c in [&first, &second] {
                assert_eq!((c.attempt, c.claim_generation), (0, 1));
            }
            handle.assert_i_slot();
        },
    );
}

/// Recovery: a crashed claim's lease expires, the job is READY again (T4), the next claim takes
/// it in generation 2, and the stale generation settles nothing.
#[test]
fn expired_lease_is_reclaimed_and_the_stale_generation_settles_nothing() {
    run(
        "expired_lease_is_reclaimed_and_the_stale_generation_settles_nothing",
        |mut handle| {
            let evidence = accept_evidence(&mut handle, 0);
            let job = handle.job_of(evidence);
            let dead = handle
                .rt
                .block_on(jobs::claim_distill(
                    &handle.private,
                    "killed-worker",
                    30.0,
                    300.0,
                ))
                .expect("claim")
                .expect("job");
            handle.sql(
                "UPDATE ops.jobs SET lease_expires_at = clock_timestamp() - interval '1 second' WHERE job_id = $1",
                job,
            );
            let survivor = handle
                .rt
                .block_on(jobs::claim_distill(
                    &handle.private,
                    "survivor",
                    30.0,
                    300.0,
                ))
                .expect("claim")
                .expect("an expired CLAIMED job is READY again");
            assert_eq!(survivor.job_id, dead.job_id);
            assert_eq!(survivor.claim_generation, 2, "the generation moved");
            let stale = handle
                .rt
                .block_on(jobs::finish_distill(
                    &handle.private,
                    &DistillLease::of(&dead, "killed-worker"),
                    jobs::DistillFinish::Done,
                    None,
                    0.0,
                    60.0,
                ))
                .expect("stale finish");
            assert!(!stale, "a stale generation settles nothing");
            let settled = handle
                .rt
                .block_on(jobs::finish_distill(
                    &handle.private,
                    &DistillLease::of(&survivor, "survivor"),
                    jobs::DistillFinish::Done,
                    None,
                    0.0,
                    60.0,
                ))
                .expect("survivor finish");
            assert!(settled);
            assert_eq!(handle.job(job).0, "DONE");
            handle.assert_i_slot();
        },
    );
}

/// The owner arm 0164 added to `jobs_tenant_isolation` is reachable ONLY from inside the
/// SECURITY DEFINER doors: a `role_private_worker` session still sees exactly its own tenant.
#[test]
fn worker_session_still_sees_only_its_own_tenants_jobs() {
    run(
        "worker_session_still_sees_only_its_own_tenants_jobs",
        |mut handle| {
            accept_evidence(&mut handle, 0);
            accept_evidence(&mut handle, 1);
            let (a, b) = (handle.tenants[0].tenant_id, handle.tenants[1].tenant_id);
            let mut worker =
            // dep: PostgreSQL(role_private_worker) — role-scoped pool call
            Client::connect(&dsn_as_role(&handle.dsn, "role_private_worker"), NoTls)
                .expect("connect as role_private_worker");
            let mut txn = worker.transaction().expect("begin");
            txn.batch_execute(&format!("SET LOCAL humaux.tenant_id = '{a}'"))
                .expect("install tenant A context");
            let count = |txn: &mut postgres::Transaction<'_>, t: Uuid| -> i64 {
                txn.query_one(
                "SELECT count(*) FROM ops.jobs WHERE tenant_id = $1 AND job_type = 'DERIVED_DISTILL'",
                &[&t],
            )
            .expect("jobs")
            .get(0)
            };
            assert_eq!(count(&mut txn, a), 1);
            assert_eq!(
                count(&mut txn, b),
                0,
                "the owner arm must not widen a worker session"
            );
            txn.rollback().expect("rollback probe txn");
        },
    );
}

/// `--distill-once` with no input: nothing claimed, returns promptly rather than polling.
#[test]
fn dispatch_pass_with_no_pending_work_claims_nothing() {
    run(
        "dispatch_pass_with_no_pending_work_claims_nothing",
        |handle| {
            let started = std::time::Instant::now();
            let report = handle.pass(&never_called(), &dispatch_config("idle-worker", 60.0));
            assert_eq!(report.claimed, 0, "{report:?}");
            assert!(
                started.elapsed() < Duration::from_secs(10),
                "an empty pass returns promptly"
            );
        },
    );
}

/// Every free provider slot bound to a job id no `ops.jobs` row carries (the T9 orphan shape,
/// `bound_until` in the future so no sweep frees it); released on drop.
struct SlotsHeld {
    admin: Client,
    fake_jobs: Vec<Uuid>,
}

impl SlotsHeld {
    fn bind_all_free(dsn: &str) -> Self {
        // dep: PostgreSQL(owner) — binds and releases the held provider slots
        let mut admin = Client::connect(dsn, NoTls).expect("slot-holder connection");
        let fake_jobs = admin
            .query(
                "UPDATE ops.provider_slots SET job_id = gen_random_uuid(), claim_generation = 1, \
                   bound_until = clock_timestamp() + interval '5 minutes' \
                 WHERE job_id IS NULL RETURNING job_id",
                &[],
            )
            .expect("bind free slots")
            .iter()
            .map(|r| r.get(0))
            .collect();
        Self { admin, fake_jobs }
    }
}

impl Drop for SlotsHeld {
    fn drop(&mut self) {
        if let Err(e) = self.admin.execute(
            "UPDATE ops.provider_slots SET job_id = NULL, claim_generation = NULL, bound_until = NULL \
             WHERE job_id = ANY($1)",
            &[&self.fake_jobs],
        ) {
            eprintln!("derived_dispatch_e2e: releasing held slots failed: {e}");
        }
    }
}

/// ADR-0058 R5: `--distill-once` names why it stopped. With a free slot and nothing READY it is
/// `no_work`; with READY work left behind every bound slot it is `no_slot`, and the summary line
/// says so. Fault: `ops.distill_slots_all_bound()` answers false (the drain cannot tell the two
/// apart) → red, the blocked pass reports `no_work` while its job is still PENDING.
#[test]
fn a_drain_names_why_it_stopped() {
    run("a_drain_names_why_it_stopped", |mut handle| {
        let config = dispatch_config("c32-r5", 60.0);
        let idle = handle.pass(&never_called(), &config);
        assert_eq!(
            (idle.claimed, idle.stopped),
            (0, Some(distill::DrainStop::NoWork)),
            "{idle:?}"
        );
        assert!(
            idle.summary_line().ends_with(" stopped=no_work"),
            "{idle:?}"
        );

        let evidence = accept_evidence(&mut handle, 0);
        let blocked = {
            let held = SlotsHeld::bind_all_free(&handle.dsn);
            let report = handle.pass(&never_called(), &config);
            drop(held);
            report
        };
        assert_eq!(
            (blocked.claimed, blocked.stopped),
            (0, Some(distill::DrainStop::NoSlot)),
            "{blocked:?}"
        );
        assert!(
            blocked.summary_line().ends_with(" stopped=no_slot"),
            "{blocked:?}"
        );
        let job = handle.job_of(evidence);
        assert_eq!(
            handle.job(job).0,
            "PENDING",
            "the READY job was left behind"
        );
        handle.assert_i_slot();
    });
}

// ---------------------------------------------------------------------------
// Operator re-drive: `humaux-maintenance jobs requeue-dead` (ADR-0058 R4, migration 0197)
// ---------------------------------------------------------------------------

fn operator() -> AdminAction<'static> {
    AdminAction {
        actor: "c32-r4-test",
        reason: "card 32 R4 requeue-dead test",
        ticket: "T-32-R4",
        trace_id: "c32-r4-trace",
        step_up_auth_context: "test-mfa",
    }
}

impl Handle {
    /// The library call behind `jobs requeue-dead`, as the operator role (0197 grants EXECUTE to
    /// role_maintenance only).
    fn requeue(
        &self,
        tenant_id: Uuid,
        target: RequeueTarget<'_>,
    ) -> Result<RequeueReceipt, ProvisioningError> {
        let pool = self
            .rt
            // dep: PostgreSQL(role_maintenance) — the operator pool of `jobs requeue-dead`
            .block_on(MaintenanceDbPool::connect(&dsn_as_role(
                &self.dsn,
                "role_maintenance",
            )))
            .expect("maintenance pool");
        self.rt.block_on(provisioning::requeue_dead_distill(
            &pool,
            tenant_id,
            target,
            &operator(),
        ))
    }

    /// Settles `evidence_id`'s job DEAD the way a DEAD settle does (job DEAD with its class,
    /// outbox FAILED), without a provider round trip.
    fn kill(&mut self, evidence_id: Uuid) -> Uuid {
        let job = self.job_of(evidence_id);
        self.sql(
            "UPDATE ops.jobs SET status = 'DEAD', attempt = 3, last_error_class = 'RETRY_WAIT' \
             WHERE job_id = $1",
            job,
        );
        self.sql(
            "UPDATE ops.outbox SET status = 'FAILED', processed_at = now() WHERE evidence_id = $1",
            evidence_id,
        );
        job
    }
}

fn refusal(result: Result<RequeueReceipt, ProvisioningError>) -> String {
    match result {
        Err(ProvisioningError::Refused(reason)) => reason,
        other => panic!("expected a refusal, got {other:?}"),
    }
}

/// R4-a: a DEAD job and its FAILED outbox row re-armed together (PENDING, attempt 0, class kept)
/// are distilled by the next pass. Fault: the definer leaves the outbox row FAILED ⇒ red (the row
/// stays FAILED; the job's claim would find no open row and settle DONE with no memory).
#[test]
fn a_requeued_dead_job_is_distilled_by_the_next_pass() {
    run(
        "a_requeued_dead_job_is_distilled_by_the_next_pass",
        |mut handle| {
            let tenant = handle.tenants[0].tenant_id;
            let evidence = accept_evidence(&mut handle, 0);
            let failing = std::sync::Arc::new(AtomicBool::new(true));
            let script_failing = failing.clone();
            let provider = StubProvider::new(move |_| {
                if script_failing.load(Ordering::SeqCst) {
                    (Duration::ZERO, Reply::RetryWait)
                } else {
                    (Duration::ZERO, Reply::Json(ONE_MEMORY_REPLY.to_string()))
                }
            });
            let mut config = dispatch_config("c32-r4a", 60.0);
            config.max_attempts = 1;
            let first = handle.pass(&provider, &config);
            assert_eq!(first.dead, 1, "{first:?}");
            let job = handle.job_of(evidence);
            assert_eq!(handle.outbox_status(evidence), "FAILED");

            let receipt = handle
                .requeue(tenant, RequeueTarget::Job(job))
                .expect("requeue-dead");
            assert_eq!(
                receipt.requeued,
                vec![RequeuedJob {
                    job_id: job,
                    evidence_id: evidence,
                    last_error_class: Some("RETRY_WAIT".to_string()),
                    attempt_spent: 1,
                }]
            );
            let (status, attempt, class, ..) = handle.job(job);
            assert_eq!(
                (status.as_str(), attempt, class.as_deref()),
                ("PENDING", 0, Some("RETRY_WAIT")),
                "re-armed with a full budget, class kept"
            );
            assert_eq!(handle.outbox_status(evidence), "PENDING");

            failing.store(false, Ordering::SeqCst);
            let second = handle.pass(&provider, &config);
            assert_eq!(second.completed, 1, "{second:?}");
            assert_eq!(handle.job(job).0, "DONE");
            assert_eq!(handle.outbox_status(evidence), "DONE");
            assert_eq!(
                memory_count(&mut handle, 0),
                1,
                "the re-armed Evidence was distilled"
            );
            handle.assert_i_slot();
        },
    );
}

/// R4-b: a job that is not DEAD is refused and untouched. Fault: drop the definer's
/// `status <> 'DEAD'` refusal ⇒ the PENDING job is "re-armed" (red).
#[test]
fn requeue_dead_refuses_a_job_that_is_not_dead() {
    run(
        "requeue_dead_refuses_a_job_that_is_not_dead",
        |mut handle| {
            let tenant = handle.tenants[0].tenant_id;
            let evidence = accept_evidence(&mut handle, 0);
            let job = handle.job_of(evidence);
            let reason = refusal(handle.requeue(tenant, RequeueTarget::Job(job)));
            assert_eq!(reason, "job_not_dead");
            assert_eq!(handle.job(job).0, "PENDING");
            assert_eq!(handle.outbox_status(evidence), "PENDING");
        },
    );
}

/// R4-c: the door is tenant-scoped — another tenant's DEAD job is not found. Fault: drop the
/// definer's `j.tenant_id = p_tenant_id` job filter ⇒ the job is selected (and refused with
/// another reason, or re-armed) — red on the exact reason.
#[test]
fn requeue_dead_refuses_another_tenants_job() {
    run("requeue_dead_refuses_another_tenants_job", |mut handle| {
        let tenant_a = handle.tenants[0].tenant_id;
        let evidence_b = accept_evidence(&mut handle, 1);
        let job_b = handle.kill(evidence_b);
        let reason = refusal(handle.requeue(tenant_a, RequeueTarget::Job(job_b)));
        assert_eq!(reason, "job_not_found");
        assert_eq!(handle.job(job_b).0, "DEAD");
        assert_eq!(handle.outbox_status(evidence_b), "FAILED");
    });
}

/// R4-d: a DEAD job whose Evidence is gone (no outbox row left) is refused — re-armed it could
/// only die again. Fault: drop the definer's `v_outbox IS NULL` refusal ⇒ re-armed (red).
#[test]
fn requeue_dead_refuses_a_job_whose_evidence_is_gone() {
    run(
        "requeue_dead_refuses_a_job_whose_evidence_is_gone",
        |mut handle| {
            let tenant = handle.tenants[0].tenant_id;
            let evidence = accept_evidence(&mut handle, 0);
            let job = handle.kill(evidence);
            handle.sql("DELETE FROM ops.outbox WHERE evidence_id = $1", evidence);
            let reason = refusal(handle.requeue(tenant, RequeueTarget::Job(job)));
            assert_eq!(reason, "evidence_gone");
            assert_eq!(handle.job(job).0, "DEAD");
        },
    );
}

/// R4-e (ADR-0058 ruling 2026-10-02 20:30, migration 0200): class mode re-arms what it can and
/// REPORTS every matching DEAD job it skipped — Evidence gone, outbox already DONE — with the
/// reason, in the receipt and the audit row; a class whose every match is skipped answers
/// `nothing_requeued`, not `no_dead_job`. Fault: the definer's skip branch `CONTINUE`s without
/// `RETURN NEXT` (0198's body) ⇒ red.
#[test]
fn requeue_dead_by_class_reports_the_dead_jobs_it_skipped() {
    run(
        "requeue_dead_by_class_reports_the_dead_jobs_it_skipped",
        |mut handle| {
            let tenant = handle.tenants[0].tenant_id;
            let live = accept_evidence(&mut handle, 0);
            let gone = accept_evidence(&mut handle, 0);
            let settled = accept_evidence(&mut handle, 0);
            let (j_live, j_gone, j_settled) =
                (handle.kill(live), handle.kill(gone), handle.kill(settled));
            handle.sql("DELETE FROM ops.outbox WHERE evidence_id = $1", gone);
            handle.sql(
                "UPDATE ops.outbox SET status = 'DONE' WHERE evidence_id = $1",
                settled,
            );
            let skip = |job_id, evidence_id, reason| SkippedJob {
                job_id,
                evidence_id: Some(evidence_id),
                last_error_class: Some("RETRY_WAIT".to_string()),
                attempt_spent: 3,
                reason,
            };
            let expected_skips = vec![
                skip(j_gone, gone, RequeueSkipReason::EvidenceGone),
                skip(j_settled, settled, RequeueSkipReason::OutboxSettled),
            ];

            let receipt = handle
                .requeue(tenant, RequeueTarget::ErrorClass("RETRY_WAIT"))
                .expect("requeue-dead");
            println!("R4-e receipt {receipt:?}");
            assert_eq!(receipt.skipped, expected_skips);
            assert_eq!(
                (
                    receipt.outcome,
                    receipt.requeued.len(),
                    receipt.requeued[0].job_id
                ),
                ("requeued", 1, j_live)
            );
            let audited: serde_json::Value = handle
                .admin
                .query_one(
                    "SELECT metadata FROM control.audit_events WHERE audit_event_id = $1",
                    &[&receipt.audit_event_id],
                )
                .expect("audit row")
                .get(0);
            assert_eq!(
                audited["skipped"],
                serde_json::json!([
                    {"job_id": j_gone, "evidence_id": gone, "last_error_class": "RETRY_WAIT",
                     "attempt_spent": 3, "reason": "evidence_gone"},
                    {"job_id": j_settled, "evidence_id": settled, "last_error_class": "RETRY_WAIT",
                     "attempt_spent": 3, "reason": "outbox_settled"},
                ]),
                "{audited}"
            );
            assert_eq!(
                (handle.job(j_gone).0, handle.job(j_settled).0),
                ("DEAD".to_string(), "DEAD".to_string())
            );

            let only_skips = handle
                .requeue(tenant, RequeueTarget::ErrorClass("RETRY_WAIT"))
                .expect("every match skipped is a receipt, not a refusal");
            assert_eq!(
                (
                    only_skips.outcome,
                    only_skips.requeued.len(),
                    only_skips.skipped
                ),
                ("nothing_requeued", 0, expected_skips)
            );
            handle.sql(
                "UPDATE ops.jobs SET status = 'DONE' WHERE job_id = $1",
                j_live,
            );
        },
    );
}

// ---------------------------------------------------------------------------
// ADR-0062 D-P (card 35 S6): the daemon's automatic re-drive of a schema-failed death, on a throwaway database
// ---------------------------------------------------------------------------

/// The cool-down the re-drive tests pass to the door; each test sleeps past it before the call that must re-drive.
const REDRIVE_COOLDOWN: Duration = Duration::from_secs(1);

/// The §77 fields `humaux-maintenance --serve` writes under its own identity (`sweep once` passes the operator's).
fn daemon() -> AdminAction<'static> {
    AdminAction {
        actor: "system:humaux-maintenance --serve",
        reason: "ADR-0062 D-P",
        ticket: "ADR-0062 D-P",
        trace_id: "c35-redrive-trace",
        step_up_auth_context: "none: scheduled task (ADR-0062 D-P)",
    }
}

fn run_redrive(name: &str, body: impl FnOnce(Handle)) {
    let _guard = SERIAL_GUARD.lock().unwrap_or_else(|e| e.into_inner());
    run_db_fixture::<RedriveFixture, _>(name, body);
}

/// A provider whose first `refusals` replies are malformed JSON (a schema refusal) and every later one admissible.
fn refusing(refusals: u32) -> Arc<StubProvider> {
    let sent = AtomicU32::new(0);
    StubProvider::new(move |_| {
        let reply = if sent.fetch_add(1, Ordering::SeqCst) < refusals {
            "not json".to_string()
        } else {
            ONE_MEMORY_REPLY.to_string()
        };
        (Duration::ZERO, Reply::Json(reply))
    })
}

impl Handle {
    /// One daemon call of the `redrive` task for `tenant`: the library call behind it, as role_maintenance (0221
    /// grants EXECUTE to role_maintenance only).
    fn auto_redrive(&self, tenant_id: Uuid, cooldown: Duration) -> i64 {
        let pool = self
            .rt
            // dep: PostgreSQL(role_maintenance) — the daemon's pool on this test's throwaway database
            .block_on(MaintenanceDbPool::connect(&dsn_as_role(
                &self.dsn,
                "role_maintenance",
            )))
            .expect("maintenance pool");
        self.rt
            .block_on(maintenance_repo::auto_redrive_schema_failed(
                &pool,
                tenant_id,
                cooldown,
                10,
                &daemon(),
            ))
            .expect("auto re-drive")
    }

    /// (status, attempt, last_error_class, auto_redrives) of one job.
    fn redrive_state(&mut self, job_id: Uuid) -> (String, i32, Option<String>, i16) {
        let r = self
            .admin
            .query_one(
                "SELECT status, attempt, last_error_class, auto_redrives FROM ops.jobs WHERE job_id = $1",
                &[&job_id],
            )
            .expect("job row");
        (r.get(0), r.get(1), r.get(2), r.get(3))
    }

    /// The tenant's §77 rows of the daemon's re-drive.
    fn auto_redrive_audits(&mut self, tenant_id: Uuid) -> i64 {
        self.admin
            .query_one(
                "SELECT count(*) FROM control.audit_events \
                 WHERE tenant_id = $1 AND action = 'DISTILL_AUTO_REDRIVE'",
                &[&tenant_id],
            )
            .expect("audit rows")
            .get(0)
    }

    /// Distills tenant 0's pending work with `provider` and asserts every claimed job died of its schema after
    /// its one re-ask (attempt 2).
    fn die_of_schema(&mut self, provider: &Arc<StubProvider>, jobs: &[Uuid]) {
        let report = self.pass(provider, &dispatch_config("c35-redrive", 30.0));
        assert_eq!(
            usize::try_from(report.dead).ok(),
            Some(jobs.len()),
            "{report:?}"
        );
        for &job in jobs {
            assert_eq!(
                self.redrive_state(job),
                (
                    "DEAD".to_string(),
                    2,
                    Some("FAILED_OUTPUT_SCHEMA".to_string()),
                    0
                )
            );
        }
    }
}

/// T-P1 (ADR-0062 D-P; card 32 debt): calls 1-2 are refused, so the job dies DEAD `FAILED_OUTPUT_SCHEMA` at attempt
/// 2; after the cool-down one daemon call re-arms it, call 3 answers, and the Evidence is distilled with no operator,
/// under one `DISTILL_AUTO_REDRIVE` §77 row. Fault: the definer skips the `requeue_dead_distill` call ⇒ the job stays
/// DEAD ⇒ red.
#[test]
fn a_schema_failed_death_is_redriven_once_after_cooldown_and_distilled() {
    run_redrive(
        "a_schema_failed_death_is_redriven_once_after_cooldown_and_distilled",
        |mut handle| {
            let tenant = handle.tenants[0].tenant_id;
            let evidence = accept_evidence(&mut handle, 0);
            let job = handle.job_of(evidence);
            let provider = refusing(2);
            handle.die_of_schema(&provider, &[job]);
            std::thread::sleep(REDRIVE_COOLDOWN + Duration::from_millis(300));

            assert_eq!(handle.auto_redrive(tenant, REDRIVE_COOLDOWN), 1);
            assert_eq!(
                handle.redrive_state(job),
                (
                    "PENDING".to_string(),
                    0,
                    Some("FAILED_OUTPUT_SCHEMA".to_string()),
                    1
                ),
                "re-armed once, class kept"
            );
            let second = handle.pass(&provider, &dispatch_config("c35-redrive", 30.0));
            assert_eq!(second.completed, 1, "{second:?}");
            assert_eq!(handle.job(job).0, "DONE");
            assert_eq!(handle.outbox_status(evidence), "DONE");
            assert_eq!(
                memory_count(&mut handle, 0),
                1,
                "distilled without an operator"
            );
            assert_eq!(provider.calls(), 3);
            assert_eq!(handle.auto_redrive_audits(tenant), 1);
            handle.assert_i_slot();
        },
    );
}

/// T-P2 (ADR-0062 D-P): a provider that always refuses costs 2 + 2 calls: one re-drive, then DEAD for good; two
/// more daemon calls past the cool-down take nothing and write no §77 row. Fault: drop `auto_redrives = 0` from the
/// definer ⇒ the second call re-drives again ⇒ 6 calls ⇒ red.
#[test]
fn an_always_refusing_provider_is_redriven_once_and_never_loops() {
    run_redrive(
        "an_always_refusing_provider_is_redriven_once_and_never_loops",
        |mut handle| {
            let tenant = handle.tenants[0].tenant_id;
            let evidence = accept_evidence(&mut handle, 0);
            let job = handle.job_of(evidence);
            let provider = refusing(u32::MAX);
            handle.die_of_schema(&provider, &[job]);
            std::thread::sleep(REDRIVE_COOLDOWN + Duration::from_millis(300));
            assert_eq!(handle.auto_redrive(tenant, REDRIVE_COOLDOWN), 1);
            let second = handle.pass(&provider, &dispatch_config("c35-redrive", 30.0));
            assert_eq!(second.dead, 1, "{second:?}");

            std::thread::sleep(REDRIVE_COOLDOWN + Duration::from_millis(300));
            let later = [
                handle.auto_redrive(tenant, REDRIVE_COOLDOWN),
                handle.auto_redrive(tenant, REDRIVE_COOLDOWN),
            ];
            let third = handle.pass(&provider, &dispatch_config("c35-redrive", 30.0));
            println!(
                "T-P2 later={later:?} third={third:?} calls={}",
                provider.calls()
            );
            assert_eq!(later, [0, 0], "never re-driven twice");
            assert_eq!(third.claimed, 0, "{third:?}");
            assert_eq!(provider.calls(), 4, "2 + 2 counted calls, then nothing");
            assert_eq!(
                handle.redrive_state(job),
                (
                    "DEAD".to_string(),
                    2,
                    Some("FAILED_OUTPUT_SCHEMA".to_string()),
                    1
                )
            );
            assert_eq!(handle.outbox_status(evidence), "FAILED");
            assert_eq!(handle.auto_redrive_audits(tenant), 1);
            handle.assert_i_slot();
        },
    );
}

/// T-P3 (ADR-0062 D-P): the class predicate is exact. Three real schema deaths; two are re-classed by the owner as
/// `ATTEMPTS_EXHAUSTED` and `PROVIDER_PERMANENT`; past the cool-down only the third is re-driven. Fault: the class
/// predicate widened to `IS NOT NULL` ⇒ 3 re-armed ⇒ red.
#[test]
fn attempts_exhausted_and_provider_permanent_deaths_are_never_auto_redriven() {
    run_redrive(
        "attempts_exhausted_and_provider_permanent_deaths_are_never_auto_redriven",
        |mut handle| {
            let tenant = handle.tenants[0].tenant_id;
            let evidence: Vec<Uuid> = (0..3).map(|_| accept_evidence(&mut handle, 0)).collect();
            let jobs: Vec<Uuid> = evidence.iter().map(|&e| handle.job_of(e)).collect();
            handle.die_of_schema(&refusing(u32::MAX), &jobs);
            for (job, class) in jobs
                .iter()
                .zip(["ATTEMPTS_EXHAUSTED", "PROVIDER_PERMANENT"])
            {
                handle
                    .admin
                    .execute(
                        "UPDATE ops.jobs SET last_error_class = $2 WHERE job_id = $1",
                        &[job, &class],
                    )
                    .expect("re-class a death");
            }
            std::thread::sleep(REDRIVE_COOLDOWN + Duration::from_millis(300));

            assert_eq!(handle.auto_redrive(tenant, REDRIVE_COOLDOWN), 1);
            assert_eq!(
                handle.redrive_state(jobs[0]),
                (
                    "DEAD".to_string(),
                    2,
                    Some("ATTEMPTS_EXHAUSTED".to_string()),
                    0
                )
            );
            assert_eq!(
                handle.redrive_state(jobs[1]),
                (
                    "DEAD".to_string(),
                    2,
                    Some("PROVIDER_PERMANENT".to_string()),
                    0
                )
            );
            assert_eq!(
                handle.redrive_state(jobs[2]),
                (
                    "PENDING".to_string(),
                    0,
                    Some("FAILED_OUTPUT_SCHEMA".to_string()),
                    1
                )
            );
        },
    );
}

/// T-P4 (ADR-0062 D-P): a death whose last counted call lies inside the cool-down is left DEAD, unmarked, with no
/// §77 row. Fault: drop the cool-down predicate ⇒ re-driven at once ⇒ red.
#[test]
fn a_death_inside_the_cooldown_is_left_dead() {
    run_redrive("a_death_inside_the_cooldown_is_left_dead", |mut handle| {
        let tenant = handle.tenants[0].tenant_id;
        let evidence = accept_evidence(&mut handle, 0);
        let job = handle.job_of(evidence);
        handle.die_of_schema(&refusing(u32::MAX), &[job]);
        assert_eq!(handle.auto_redrive(tenant, Duration::from_secs(3600)), 0);
        assert_eq!(
            handle.redrive_state(job),
            (
                "DEAD".to_string(),
                2,
                Some("FAILED_OUTPUT_SCHEMA".to_string()),
                0
            )
        );
        assert_eq!(handle.auto_redrive_audits(tenant), 0);
    });
}

// ---------------------------------------------------------------------------
// ADR-0060 (card 33b): the route picks the provider; worker-observed health (ruling E3)
// ---------------------------------------------------------------------------

/// A second vendor for the stub tests: another processor, model, endpoint and capability set.
fn p2_lane() -> Lane {
    Lane {
        provider_id: "derived-dispatch-p2".to_owned(),
        model_id: "p2-model".to_owned(),
        endpoint_ref: "https://p2.derived-dispatch.example/v1/chat/completions".to_owned(),
        egress_processor_id: EGRESS_PROCESSOR_ID,
        region: REGION.to_owned(),
        capabilities: vec![
            ReasoningCapability::Text,
            ReasoningCapability::StructuredOutput,
        ],
        request_extras: serde_json::json!({}),
    }
}

/// The rehearsal lane every fixture tenant is seeded with.
fn rehearsal_lane() -> Lane {
    Lane::rehearsal(
        EGRESS_PROCESSOR_ID,
        ENDPOINT_REF,
        MODEL_ID,
        &live_minimax::REHEARSAL_CAPABILITIES,
    )
}

/// ADR-0060 D-B in the stub form: each admitted route goes to the stub of its processor; every
/// tenant asked for is recorded (T20: an unbound domain never reaches the seam).
fn by_provider(
    stubs: Vec<(String, Arc<StubProvider>)>,
    asked: Arc<Mutex<Vec<Uuid>>>,
) -> impl Fn(&ReasoningAdmissionLocator) -> Result<Arc<dyn UserReasoningProvider>, &'static str>
+ Send
+ Sync {
    move |route| {
        asked
            .lock()
            .unwrap_or_else(|e| e.into_inner())
            .push(route.tenant_id);
        stubs
            .iter()
            .find(|(processor, _)| *processor == route.processor_id)
            .map(|(_, stub)| Arc::clone(stub) as Arc<dyn UserReasoningProvider>)
            .ok_or("NO_STUB_FOR_PROVIDER")
    }
}

/// `(tenant, provider, model, binding_id, binding_version, profile_id, provider_account_id,
/// credential_ref, provider_endpoint_id, status)` of every ledger row of `tenants`, oldest first.
type LedgerRow = (
    Uuid,
    String,
    String,
    Uuid,
    i64,
    Uuid,
    Uuid,
    Uuid,
    Uuid,
    String,
);

fn ledger_of(admin: &mut Client, tenants: &[Uuid]) -> Vec<LedgerRow> {
    admin
        .query(
            "SELECT tenant_id, provider, model, binding_id, binding_version, profile_id, \
                    provider_account_id, credential_ref, provider_endpoint_id, status \
             FROM ops.model_call_ledger WHERE tenant_id = ANY($1) ORDER BY called_at, model_call_id",
            &[&tenants],
        )
        .expect("ledger rows")
        .into_iter()
        .map(|r| {
            (
                r.get(0),
                r.get(1),
                r.get(2),
                r.get(3),
                r.get(4),
                r.get(5),
                r.get(6),
                r.get(7),
                r.get(8),
                r.get(9),
            )
        })
        .collect()
}

/// T18 (ADR-0060 D-B, card fault 1 in the seam form) — two tenants on two providers in ONE
/// dispatch pass: each stub is called once, the tool channel only for the profile declaring
/// TOOL_CALLS, two ledger rows with distinct (provider, model), each equal to its tenant's route.
/// Fault: `DistillReasoner` keeps the first instance it got ⇒ B is refused
/// ROUTE_PROVIDER_MISMATCH and the ledger shows one provider.
#[test]
fn two_profiles_two_providers_one_dispatch() {
    run("two_profiles_two_providers_one_dispatch", |mut handle| {
        let (a_lane, b_lane) = (rehearsal_lane(), p2_lane());
        let (a, a_route) = handle.add_tenant_on("t18 tenant A (provider 1)", &a_lane);
        let (b, b_route) = handle.add_tenant_on("t18 tenant B (provider 2)", &b_lane);
        let reply = |_: &str| (Duration::ZERO, Reply::Json(ONE_MEMORY_REPLY.to_owned()));
        let (stub1, stub2) = (
            StubProvider::declaring(a_lane.descriptor(), reply),
            StubProvider::declaring(b_lane.descriptor(), reply),
        );
        let providers = by_provider(
            vec![
                (a_lane.provider_id.clone(), Arc::clone(&stub1)),
                (b_lane.provider_id.clone(), Arc::clone(&stub2)),
            ],
            Arc::default(),
        );
        let (ea, eb) = (
            accept_evidence(&mut handle, a),
            accept_evidence(&mut handle, b),
        );
        let report = handle.pass_routes(&providers, &dispatch_config("c33b-t18", 60.0));
        assert_eq!(report.completed, 2, "{report:?}");
        assert_eq!(
            (stub1.calls(), stub1.tool_calls.load(Ordering::SeqCst)),
            (1, 1),
            "A only, on the tool channel"
        );
        assert_eq!(
            (stub2.calls(), stub2.tool_calls.load(Ordering::SeqCst)),
            (1, 0),
            "B only, on the content channel"
        );
        for evidence in [ea, eb] {
            let job = handle.job_of(evidence);
            assert_eq!(handle.job(job).0, "DONE");
        }
        let tenants = [handle.tenants[a].tenant_id, handle.tenants[b].tenant_id];
        let rows = ledger_of(&mut handle.admin, &tenants);
        assert_eq!(rows.len(), 2, "{rows:?}");
        for (tenant, lane, route) in [
            (tenants[0], &a_lane, &a_route),
            (tenants[1], &b_lane, &b_route),
        ] {
            let row = rows
                .iter()
                .find(|r| r.0 == tenant)
                .expect("a row per tenant");
            assert_eq!(
                (
                    row.1.as_str(),
                    row.2.as_str(),
                    row.5,
                    row.6,
                    row.7,
                    row.8,
                    row.9.as_str()
                ),
                (
                    lane.provider_id.as_str(),
                    lane.model_id.as_str(),
                    route.profile_id,
                    route.provider_account_id,
                    route.credential_ref,
                    route.endpoint_id,
                    "SUCCEEDED"
                )
            );
        }
        assert_ne!((&rows[0].1, &rows[0].2), (&rows[1].1, &rows[1].2));
    });
}

/// T19 (ADR-0060 D-H shape, review findings 1/7) — tenant B's binding is switched from its
/// provider-2 Profile to B's OWN provider-1 Profile `PB1` between two jobs on one dispatcher, no
/// restart: job 1 → stub 2 with binding v1, job 2 → stub 1 with binding v2, `PB1@1`, B's provider-1
/// account and credential. No column of row 2 names a tenant-A route id; row 1 is unchanged.
/// Fault: the worker remembers the domain's first binding version ⇒ job 2 admits the closed v1 ⇒
/// NOT_READY.
#[test]
fn binding_switch_takes_effect_on_next_job_without_restart() {
    run(
        "binding_switch_takes_effect_on_next_job_without_restart",
        |mut handle| {
            let (a_lane, b_lane) = (rehearsal_lane(), p2_lane());
            let (a, a_route) = handle.add_tenant_on("t19 tenant A", &a_lane);
            let (b, b_route) = handle.add_tenant_on("t19 tenant B", &b_lane);
            let (tenant_b, domain_b, user) = (
                handle.tenants[b].tenant_id,
                handle.tenants[b].reasoning_domain_id,
                handle.user_id,
            );
            let pb1 = seed_reasoning_profile(&mut handle.admin, tenant_b, user, "t19 PB1", &a_lane)
                .expect("B's own provider-1 profile");
            let reply = |_: &str| (Duration::ZERO, Reply::Json(ONE_MEMORY_REPLY.to_owned()));
            let (stub1, stub2) = (
                StubProvider::declaring(a_lane.descriptor(), reply),
                StubProvider::declaring(b_lane.descriptor(), reply),
            );
            let providers = by_provider(
                vec![
                    (a_lane.provider_id.clone(), Arc::clone(&stub1)),
                    (b_lane.provider_id.clone(), Arc::clone(&stub2)),
                ],
                Arc::default(),
            );
            let config = dispatch_config("c33b-t19", 60.0);
            accept_evidence(&mut handle, b);
            let first = handle.pass_routes(&providers, &config);
            assert_eq!((first.completed, stub2.calls(), stub1.calls()), (1, 1, 0));
            let row1 = ledger_of(&mut handle.admin, &[tenant_b]);
            assert_eq!(row1.len(), 1);
            assert_eq!(
                (row1[0].4, row1[0].5, row1[0].7),
                (1, b_route.profile_id, b_route.credential_ref)
            );
            let (binding_id, version) =
                switch_binding(&mut handle.admin, tenant_b, user, domain_b, pb1.profile_id);
            assert_eq!((binding_id, version), (row1[0].3, 2), "a successor version");
            accept_evidence(&mut handle, b);
            let second = handle.pass_routes(&providers, &config);
            assert_eq!(
                (second.completed, stub1.calls(), stub2.calls()),
                (1, 1, 1),
                "{second:?}"
            );
            let rows = ledger_of(&mut handle.admin, &[tenant_b]);
            assert_eq!(rows.len(), 2);
            assert_eq!(rows[0], row1[0], "row 1 unchanged");
            let row2 = &rows[1];
            assert_eq!(
                (
                    row2.0,
                    row2.1.as_str(),
                    row2.2.as_str(),
                    row2.3,
                    row2.4,
                    row2.5,
                    row2.6,
                    row2.7,
                    row2.9.as_str()
                ),
                (
                    tenant_b,
                    a_lane.provider_id.as_str(),
                    a_lane.model_id.as_str(),
                    binding_id,
                    2,
                    pb1.profile_id,
                    pb1.provider_account_id,
                    pb1.credential_ref,
                    "SUCCEEDED"
                )
            );
            let a_ids = [
                handle.tenants[a].tenant_id,
                a_route.profile_id,
                a_route.provider_account_id,
                a_route.credential_ref,
                a_route.endpoint_id,
            ];
            for id in [row2.0, row2.3, row2.5, row2.6, row2.7, row2.8] {
                assert!(!a_ids.contains(&id), "row 2 names a tenant-A route id {id}");
            }
        },
    );
}

/// T20 (ADR-0060 D-G) — a domain with no binding parks `WAITING_KEY` / no-binding after the park
/// age, never reaches the provider seam and writes no ledger row, while tenant A is served. Fault:
/// settle the no-binding class as DEAD ⇒ C is DEAD with its outbox FAILED.
#[test]
fn unbound_domain_parks_waiting_key_others_unaffected() {
    run(
        "unbound_domain_parks_waiting_key_others_unaffected",
        |mut handle| {
            let asked = Arc::new(Mutex::new(Vec::new()));
            let stub = StubProvider::one_memory(Duration::ZERO);
            let providers = by_provider(
                vec![(PROVIDER_ID.to_owned(), Arc::clone(&stub))],
                Arc::clone(&asked),
            );
            let (ea, ec) = (
                accept_evidence(&mut handle, 0),
                accept_evidence(&mut handle, 2),
            );
            let (job_a, job_c) = (handle.job_of(ea), handle.job_of(ec));
            let mut config = dispatch_config("c33b-t20", 60.0);
            config.not_ready_park_seconds = 1.0;
            let first = handle.pass_routes(&providers, &config);
            assert_eq!((first.completed, first.not_ready), (1, 1), "{first:?}");
            assert_eq!(handle.job(job_a).0, "DONE");
            std::thread::sleep(Duration::from_millis(1200));
            handle.ready_now(job_c);
            let second = handle.pass_routes(&providers, &config);
            assert_eq!(second.parked, 1, "{second:?}");
            let (status, attempt, class, ..) = handle.job(job_c);
            assert_eq!(
                (status.as_str(), attempt, class.as_deref()),
                ("WAITING_KEY", 0, Some(NO_BINDING_REASON))
            );
            assert_eq!(handle.outbox_status(ec), "PENDING");
            let tenant_c = handle.tenants[2].tenant_id;
            assert_eq!(ledger_rows(&mut handle, tenant_c), 0);
            assert!(
                !asked
                    .lock()
                    .unwrap_or_else(|e| e.into_inner())
                    .contains(&tenant_c),
                "the seam is never asked for an unbound domain"
            );
        },
    );
}

/// T21 (ADR-0060 D-G, security argument (c)) — after job 1 the Profile is disabled: job 2 is
/// NOT_READY "reasoning route not admitted", no new call, no new ledger row. Fault: the reasoner
/// caches the admitted locator per Binding@version and skips the resolver ⇒ job 2 is served.
#[test]
fn disabled_profile_stops_being_used() {
    run("disabled_profile_stops_being_used", |mut handle| {
        let stub = StubProvider::one_memory(Duration::ZERO);
        let config = dispatch_config("c33b-t21", 60.0);
        accept_evidence(&mut handle, 0);
        let first = handle.pass(&stub, &config);
        assert_eq!((first.completed, stub.calls()), (1, 1), "{first:?}");
        let tenant_id = handle.tenants[0].tenant_id;
        handle.sql(
            "UPDATE control.reasoning_profiles SET enabled = false WHERE tenant_id = $1",
            tenant_id,
        );
        let evidence = accept_evidence(&mut handle, 0);
        let second = handle.pass(&stub, &config);
        assert_eq!((second.not_ready, stub.calls()), (1, 1), "{second:?}");
        let job = handle.job_of(evidence);
        assert_eq!(
            handle.job(job).2.as_deref(),
            Some("reasoning route not admitted")
        );
        assert_eq!(ledger_rows(&mut handle, tenant_id), 1, "no new ledger row");
    });
}

/// T34 (ADR-0060 D-F, review finding 6) — tenant B's provider hangs past the HTTP timeout and
/// answers RETRY, A's answers at once; four seats over A's 500 and B's 50 READY jobs. Sampled every
/// 100 ms for 3 × the timeout: B never holds more than 2 of the 4 slots and A completes at least
/// 20 jobs; B's jobs wait RETRY (not WAITING_KEY, the D-G correction). Fault: the claim orders by
/// least-recently-served only (the 0199 body) ⇒ B takes all four slots.
#[test]
#[allow(clippy::too_many_lines)]
// one sampled scenario: seed, serve with a sampler, assert
// ponytail: nesting past clippy.toml's 5 (§78.4 / G-M01-8, measured 39973585345); M01-6 refactors nothing
#[allow(clippy::excessive_nesting)]
fn slow_provider_tenant_cannot_take_all_slots() {
    run(
        "slow_provider_tenant_cannot_take_all_slots",
        |mut handle| {
            const TIMEOUT_SECS: f64 = 2.0;
            let (a_lane, b_lane) = (rehearsal_lane(), p2_lane());
            let (a, _) = handle.add_tenant_on("t34 tenant A (fast)", &a_lane);
            let (b, _) = handle.add_tenant_on("t34 tenant B (hanging)", &b_lane);
            let fast = StubProvider::declaring(a_lane.descriptor(), |_| {
                (Duration::ZERO, Reply::Json(ONE_MEMORY_REPLY.to_owned()))
            });
            let slow = StubProvider::declaring(b_lane.descriptor(), |_| {
                (
                    Duration::from_secs_f64(TIMEOUT_SECS + 0.2),
                    Reply::RetryWait,
                )
            });
            let providers = by_provider(
                vec![
                    (a_lane.provider_id.clone(), Arc::clone(&fast)),
                    (b_lane.provider_id.clone(), Arc::clone(&slow)),
                ],
                Arc::default(),
            );
            for _ in 0..500 {
                accept_evidence(&mut handle, a);
            }
            for _ in 0..50 {
                accept_evidence(&mut handle, b);
            }
            let (tenant_a, tenant_b) = (handle.tenants[a].tenant_id, handle.tenants[b].tenant_id);
            let config = DistillDispatchConfig {
                http_timeout_seconds: TIMEOUT_SECS,
                hard_deadline_seconds: 2.0 * (TIMEOUT_SECS + 2.0),
                ..dispatch_config("c33b-t34", 2.0)
            };
            let stop = AtomicBool::new(false);
            let dsn = handle.dsn.clone();
            let (max_b, samples) = std::thread::scope(|scope| {
                let stop = &stop;
                let sampler = scope.spawn(move || {
                    // dep: PostgreSQL(owner) — sampler connection
                    let mut admin = Client::connect(&dsn, NoTls).expect("sampler");
                    let started = std::time::Instant::now();
                    let (mut max_b, mut samples) = (0_i64, 0_u32);
                    while started.elapsed() < Duration::from_secs_f64(3.0 * TIMEOUT_SECS) {
                        // ADR-0060 D-F is a contention invariant: B's share is bounded only while A
                        // still has claimable DISTILL work. Claimable = the claim's own READY predicate
                        // (0206 `ops.claim_derived_work_v2`: PENDING/RETRY_WAIT due now, or a PROCESSING
                        // job whose lease expired), copied verbatim (review fix 9, C39-F8-1); a PROCESSING
                        // job with a live lease already holds its slot, so once A's last job is in flight
                        // B may take the other three (card-39 chain, 2026-10-08: max_slots_b=3 with
                        // done_a=500 under a PENDING+PROCESSING guard). Once A's 500 distill jobs are drained (a
                        // warm host does it inside this window: card 34b chain, done_a=500 max_b=4)
                        // B is the only tenant with READY jobs and may hold every slot — so both
                        // counters fold a sample in only while A has a READY
                        // DERIVED_DISTILL job. The job_type predicate matters: 0164's trigger
                        // enqueues one DERIVED_CONSOLIDATE job per accepted Evidence that nothing in
                        // this test claims, so an untyped count never drops to 0 and the drained
                        // window would be folded in (card 35 final verification: max_slots_b=4 with
                        // done_a=500 while 500 consolidate jobs sat PENDING).
                        let row = admin
                            .query_one(
                                "SELECT (SELECT count(*) FROM ops.provider_slots s \
                                   JOIN ops.jobs j ON j.job_id = s.job_id WHERE j.tenant_id = $1), \
                                        (SELECT count(*) FROM ops.jobs \
                                   WHERE tenant_id = $2 AND job_type = 'DERIVED_DISTILL' \
                                     AND ((status IN ('PENDING', 'RETRY_WAIT') AND next_retry_at <= clock_timestamp()) \
                                          OR (status = 'PROCESSING' AND lease_expires_at < clock_timestamp())))",
                                &[&tenant_b, &tenant_a],
                            )
                            .expect("slots held by B / A's open jobs");
                        let (held, a_open): (i64, i64) = (row.get(0), row.get(1));
                        if a_open > 0 {
                            max_b = max_b.max(held);
                            samples += 1;
                        }
                        std::thread::sleep(Duration::from_millis(100));
                    }
                    stop.store(true, Ordering::SeqCst);
                    (max_b, samples)
                });
                handle
                    .rt
                    .block_on(distill::dispatch_serve(
                        &handle.private,
                        &providers,
                        reasoner_config(),
                        &config,
                        Duration::from_millis(100),
                        stop,
                    ))
                    .expect("dispatcher");
                sampler.join().expect("sampler")
            });
            let done_a: i64 = handle
                .admin
                .query_one(
                    "SELECT count(*) FROM ops.jobs WHERE tenant_id = $1 AND status = 'DONE'",
                    &[&tenant_a],
                )
                .expect("A done")
                .get(0);
            let (retry_b, parked_b): (i64, i64) = {
                let r = handle
                    .admin
                    .query_one(
                        "SELECT count(*) FILTER (WHERE last_error_class = 'RETRY_WAIT'), \
                            count(*) FILTER (WHERE status = 'WAITING_KEY') \
                     FROM ops.jobs WHERE tenant_id = $1",
                        &[&tenant_b],
                    )
                    .expect("B jobs");
                (r.get(0), r.get(1))
            };
            eprintln!(
                "c33b-t34 samples={samples} max_slots_b={max_b} done_a={done_a} retry_b={retry_b} slow_calls={}",
                slow.calls()
            );
            assert!(samples >= 20, "{samples} samples");
            assert!(max_b <= 2, "B held {max_b} of 4 slots");
            assert!(done_a >= 20, "A completed {done_a}");
            assert!(
                retry_b >= 1 && parked_b == 0,
                "retry={retry_b} parked={parked_b}"
            );
            retire_open_jobs(&mut handle.admin, &[tenant_a, tenant_b]);
        },
    );
}

/// Worker-observed health rows (ruling E3) of one tenant: `(provider rows, account rows, account
/// rows with credential verdict INVALID)`.
fn worker_observed(admin: &mut Client, tenant_id: Uuid) -> (i64, i64, i64) {
    let r = admin
        .query_one(
            "SELECT (SELECT count(*) FROM ops.reasoning_provider_health_observations \
                      WHERE tenant_id = $1 AND source_kind = 'WORKER_OBSERVED'), \
                    (SELECT count(*) FROM ops.reasoning_account_health_observations \
                      WHERE tenant_id = $1 AND source_kind = 'WORKER_OBSERVED'), \
                    (SELECT count(*) FROM ops.reasoning_account_health_observations \
                      WHERE tenant_id = $1 AND source_kind = 'WORKER_OBSERVED' \
                        AND credential_verdict = 'INVALID')",
            &[&tenant_id],
        )
        .expect("worker-observed health");
    (r.get(0), r.get(1), r.get(2))
}

/// E3 (ruling E3 (b), test 1) — the route's latest attestation expires in 4 s: a SUCCEEDED call
/// renews it (one HEALTHY provider row and one HEALTHY account row, valid for
/// HEALTH_RENEW_SECS), so a job after the old `valid_until` is admitted and served. Fault: no
/// renewal after a success ⇒ job 2 is NOT_READY ROUTE_HEALTH_STALE.
#[test]
fn a_success_near_expiry_renews_route_health() {
    run("a_success_near_expiry_renews_route_health", |mut handle| {
        let lane = rehearsal_lane();
        let (x, route) = handle.add_tenant_on("e3 renew", &lane);
        let tenant_id = handle.tenants[x].tenant_id;
        seed_health(
            &mut handle.admin,
            tenant_id,
            &lane,
            &route,
            Duration::from_secs(4),
        )
        .expect("short attestation");
        let stub = StubProvider::one_memory(Duration::ZERO);
        let config = dispatch_config("c33b-e3-renew", 60.0);
        accept_evidence(&mut handle, x);
        let first = handle.pass(&stub, &config);
        assert_eq!(first.completed, 1, "{first:?}");
        std::thread::sleep(Duration::from_millis(4500));
        let evidence = accept_evidence(&mut handle, x);
        let second = handle.pass(&stub, &config);
        let job = handle.job_of(evidence);
        assert_eq!(
            (second.completed, handle.job(job).2),
            (1, None),
            "admitted on the renewed health: {second:?}"
        );
        assert_eq!(worker_observed(&mut handle.admin, tenant_id), (1, 1, 0));
    });
}

/// E3 (ruling E3 (b), test 2) — a provider 401 appends one account row with the credential
/// verdict INVALID, so the next admission is refused ROUTE_HEALTH_DENIED although the attestation
/// is still valid, with no further call. Fault: no negative row on a 401 ⇒ job 2 is admitted and
/// the provider is called again.
#[test]
fn a_401_records_invalid_credential_and_denies_the_next_admission() {
    run(
        "a_401_records_invalid_credential_and_denies_the_next_admission",
        |mut handle| {
            let (y, _) = handle.add_tenant_on("e3 401", &rehearsal_lane());
            let tenant_id = handle.tenants[y].tenant_id;
            let stub = StubProvider::new(|_| (Duration::ZERO, Reply::WaitingKey));
            let config = dispatch_config("c33b-e3-401", 60.0);
            accept_evidence(&mut handle, y);
            let first = handle.pass(&stub, &config);
            assert_eq!((first.parked, stub.calls()), (1, 1), "{first:?}");
            let evidence = accept_evidence(&mut handle, y);
            let second = handle.pass(&stub, &config);
            let job = handle.job_of(evidence);
            assert_eq!(
                (second.not_ready, stub.calls(), handle.job(job).2.as_deref()),
                (1, 1, Some(ROUTE_HEALTH_DENIED)),
                "{second:?}"
            );
            assert_eq!(worker_observed(&mut handle.admin, tenant_id), (0, 1, 1));
        },
    );
}

/// E3 (ruling E3 (b), test 3) — renewal is rate-limited: with the seed's 30-minute attestation
/// and HEALTH_RENEW_SECS = 1800, more than half the window is left, so two SUCCEEDED calls append
/// nothing. Fault: drop the remaining-validity clause from
/// `control.observe_reasoning_route_health` (0206) ⇒ every success appends two rows.
#[test]
fn renewal_is_rate_limited() {
    run("renewal_is_rate_limited", |mut handle| {
        let (z, _) = handle.add_tenant_on("e3 rate limit", &rehearsal_lane());
        let tenant_id = handle.tenants[z].tenant_id;
        let stub = StubProvider::one_memory(Duration::ZERO);
        let config = dispatch_config("c33b-e3-rate", 60.0);
        for _ in 0..2 {
            accept_evidence(&mut handle, z);
            assert_eq!(handle.pass(&stub, &config).completed, 1);
        }
        assert_eq!(stub.calls(), 2);
        assert_eq!(worker_observed(&mut handle.admin, tenant_id), (0, 0, 0));
    });
}

/// Ruling E3 (c) — a route whose latest attestation ran out is NOT_READY with its own class
/// ROUTE_HEALTH_STALE (not the generic refusal, not the no-binding class), and nothing is called.
/// Fault: fold the health refusal into the generic "reasoning route not admitted".
#[test]
fn stale_health_parks_with_its_own_class() {
    run("stale_health_parks_with_its_own_class", |mut handle| {
        let lane = rehearsal_lane();
        let (w, route) = handle.add_tenant_on("e3 stale", &lane);
        let tenant_id = handle.tenants[w].tenant_id;
        seed_health(
            &mut handle.admin,
            tenant_id,
            &lane,
            &route,
            Duration::from_secs(1),
        )
        .expect("short attestation");
        std::thread::sleep(Duration::from_millis(1500));
        let stub = StubProvider::one_memory(Duration::ZERO);
        let evidence = accept_evidence(&mut handle, w);
        let report = handle.pass(&stub, &dispatch_config("c33b-e3-stale", 60.0));
        let job = handle.job_of(evidence);
        assert_eq!(
            (report.not_ready, stub.calls(), handle.job(job).2.as_deref()),
            (1, 0, Some(ROUTE_HEALTH_STALE))
        );
    });
}

/// The production instance of a live route, recording which output channel each call used (T24
/// asserts the tool channel is used only for a profile declaring TOOL_CALLS).
struct ChannelLog {
    inner: Arc<dyn UserReasoningProvider>,
    tenant_id: Uuid,
    log: Arc<Mutex<Vec<(Uuid, &'static str)>>>,
}

#[async_trait::async_trait]
impl UserReasoningProvider for ChannelLog {
    fn descriptor(&self) -> &ReasoningProviderDescriptor {
        self.inner.descriptor()
    }

    fn endpoint_ref(&self) -> &str {
        self.inner.endpoint_ref()
    }

    fn model_revision(&self) -> Option<&str> {
        self.inner.model_revision()
    }

    async fn complete_structured(
        &self,
        context: &PrivateInferenceContext,
        request: StructuredReasoningRequest,
    ) -> Result<StructuredReasoningResponse, ReasoningProviderError> {
        self.log
            .lock()
            .unwrap_or_else(|e| e.into_inner())
            .push((self.tenant_id, channel_name(&request.output)));
        self.inner.complete_structured(context, request).await
    }

    async fn analyze_vision(
        &self,
        _context: &PrivateInferenceContext,
        _request: VisionReasoningRequest,
    ) -> Result<VisionReasoningResponse, ReasoningProviderError> {
        unreachable!("distill never calls vision")
    }
}

fn channel_name(output: &OutputChannel) -> &'static str {
    match output {
        OutputChannel::Content => "content",
        OutputChannel::JsonObject => "json_object",
        OutputChannel::Tool(_) => "tool",
    }
}

/// T24 (ADR-0060 D-B, card fault 1 in the production form; the card's acceptance gate) — ONE
/// production [`RouteProviders`] (credential map composed from the two key variable NAMES, one
/// resolver from both pin specs, both recipients and regions, the D-J boot check passed) serves
/// tenant A on the first live provider and tenant B on the second (`HUMAUX_LIVE_P2_*`): each
/// distils one real Evidence, both rows SUCCEEDED with distinct (provider, model), each call on the
/// channel its own profile's capabilities select. Then B's binding is switched to B's OWN
/// first-provider Profile `PB1` and a second B Evidence runs on the SAME instance, no restart: one
/// new cache entry, a row naming binding v2, `PB1@1`, B's first-provider account and credential.
/// Prints one `c33b-live` line per ledger row and a summary (never a key, never an endpoint).
/// Fault: `provider_for` returns the first-built instance for every route ⇒ B is refused
/// ROUTE_PROVIDER_MISMATCH and never DONE; the ledger shows one provider.
#[test]
#[ignore = "lane(a:shared_db) live two-provider gate (card 33b T24): run with --include-ignored, HUMAUX_REQUIRE_MINIMAX=1 and HUMAUX_REQUIRE_SECOND_PROVIDER=1"]
#[allow(clippy::too_many_lines)]
// ponytail: nesting past clippy.toml's 5 (§78.4 / G-M01-8, measured 39973585345); M01-6 refactors nothing
#[allow(clippy::excessive_nesting)]
fn distill_two_provider_live() {
    let Some(mm_key) = live_minimax::load_minimax_key() else {
        humaux_testkit::skip_or_fail(
            "distill_two_provider_live",
            "missing object: MINIMAX_API_KEY (env and /Volumes/data/viral-skill-eval/.env both empty)",
            humaux_testkit::ExternalDep::MiniMax,
        );
        return;
    };
    let Some(p2) = live_provider::LiveProfile::second_provider() else {
        return;
    };
    let p2_key = p2.key().unwrap_or_else(|| {
        panic!(
            "missing object: {} (the variable HUMAUX_LIVE_P2_KEY_ENV names is unset or empty)",
            p2.key_env
        )
    });
    run("distill_two_provider_live", |mut handle| {
        // SAFETY: set while SERIAL_GUARD is held (see `distill_fairness_live`).
        unsafe {
            std::env::set_var("HUMAUX_PRIVATE_WORKER_CANDIDATE_TTL_SECONDS", "604800");
        }
        let mm = live_minimax::minimax_profile(REGION);
        let a_lane = Lane::live(&mm, EGRESS_PROCESSOR_ID);
        let b_lane = Lane::live(&p2, Uuid::new_v4());
        let (a, a_route) = handle.add_tenant_on("c33b live tenant A (provider 1)", &a_lane);
        let (b, b_route) = handle.add_tenant_on("c33b live tenant B (provider 2)", &b_lane);
        let (tenant_a, tenant_b, domain_b, user) = (
            handle.tenants[a].tenant_id,
            handle.tenants[b].tenant_id,
            handle.tenants[b].reasoning_domain_id,
            handle.user_id,
        );
        let pb1 = seed_reasoning_profile(
            &mut handle.admin,
            tenant_b,
            user,
            "c33b live tenant B PB1",
            &a_lane,
        )
        .expect("B's own first-provider profile");

        // The deployment: three map entries (two refs share the first key, one vendor account),
        // both recipients with their hosts, both regions, one resolver from both pin specs.
        let spec = format!(
            "{}=MINIMAX_API_KEY,{}={},{}=MINIMAX_API_KEY",
            a_route.credential_ref, b_route.credential_ref, p2.key_env, pb1.credential_ref
        );
        let recipients = format!(
            "{}={},{}={}",
            a_lane.egress_processor_id,
            mm.hosts.join("|"),
            b_lane.egress_processor_id,
            p2.hosts.join("|")
        );
        let regions: Vec<&str> = if mm.region == p2.region {
            vec![mm.region.as_str()]
        } else {
            vec![mm.region.as_str(), p2.region.as_str()]
        };
        let regions = regions.join(",");
        let lookup = |name: &str| match name {
            route_providers::CREDENTIALS => Some(spec.clone()),
            "MINIMAX_API_KEY" => Some(mm_key.clone()),
            EGRESS_RECIPIENTS => Some(recipients.clone()),
            REGIONS => Some(regions.clone()),
            other if other == p2.key_env => Some(p2_key.clone()),
            _ => None,
        };
        let credentials = route_providers::parse_credential_map(lookup).expect("credential map");
        for line in handle
            .rt
            .block_on(route_providers::verify_credential_accounts(
                &handle.private,
                &credentials,
            ))
            .expect("ADR-0060 D-J boot check")
        {
            println!("c33b-live boot {line}");
        }
        let pins = [mm.dns_pins.as_str(), p2.dns_pins.as_str()]
            .into_iter()
            .filter(|p| !p.is_empty())
            .collect::<Vec<_>>()
            .join(",");
        let routes = Arc::new(RouteProviders::new(
            credentials,
            route_providers::parse_recipients(lookup).expect("recipients"),
            route_providers::parse_regions(lookup).expect("regions"),
            Arc::new(
                humaux_adapters::byok::ssrf::PinnedDnsResolver::parse(&pins)
                    .expect("both pin specs parse"),
            ),
            Duration::from_secs(LIVE_HTTP_SECS),
        ));
        let log = Arc::new(Mutex::new(Vec::new()));
        let providers = {
            let (routes, log) = (Arc::clone(&routes), Arc::clone(&log));
            move |l: &ReasoningAdmissionLocator| {
                routes.provider_for(l).map(|inner| {
                    Arc::new(ChannelLog {
                        inner,
                        tenant_id: l.tenant_id,
                        log: Arc::clone(&log),
                    }) as Arc<dyn UserReasoningProvider>
                })
            }
        };
        let config = live_config("c33b-live", 30.0, 4);
        // ADR-0058 D-F: a live transient settles RETRY; the job is made due and claimed again
        // within its own attempt budget (as distill_hop_e2e D1 does).
        let drain = |handle: &mut Handle, evidence: &[Uuid]| {
            for pass in 1..=3 {
                let report = handle.pass_routes(&providers, &config);
                println!("c33b-live pass={pass} {}", report.summary_line());
                let jobs: Vec<Uuid> = evidence.iter().map(|e| handle.job_of(*e)).collect();
                let mut open = false;
                for job in jobs {
                    let (status, ..) = handle.job(job);
                    if status != "DONE" {
                        open = true;
                        handle.ready_now(job);
                    }
                }
                if !open {
                    return true;
                }
            }
            false
        };
        let first = [
            accept_evidence_marked(&mut handle, a, &live_note("c33b-a", 0)),
            accept_evidence_marked(&mut handle, b, &live_note("c33b-b", 0)),
        ];
        let first_done = drain(&mut handle, &first);
        let built_before = routes.built();
        let (binding_b, version) =
            switch_binding(&mut handle.admin, tenant_b, user, domain_b, pb1.profile_id);
        let second = [accept_evidence_marked(
            &mut handle,
            b,
            &live_note("c33b-b", 1),
        )];
        let second_done = drain(&mut handle, &second);
        let built_after = routes.built();
        if built_after == built_before + 1 {
            println!(
                "c33b-live route built tenant=B profile={}@1 provider={} model={} endpoint_id={} capabilities={}",
                pb1.profile_id,
                a_lane.provider_id,
                a_lane.model_id,
                pb1.endpoint_id,
                a_lane
                    .capabilities
                    .iter()
                    .map(|c| c.as_str())
                    .collect::<Vec<_>>()
                    .join(",")
            );
        }
        let rows = handle
            .admin
            .query(
                "SELECT tenant_id, binding_id, binding_version, profile_id, profile_version, \
                        provider_account_id, credential_ref, provider, model, provider_endpoint_id, \
                        status, coalesce(input_tokens::text, '-'), coalesce(output_tokens::text, '-'), \
                        coalesce(latency_ms::text, '-') \
                 FROM ops.model_call_ledger WHERE tenant_id = ANY($1) \
                 ORDER BY called_at, model_call_id",
                &[&vec![tenant_a, tenant_b]],
            )
            .expect("ledger rows");
        let channels = log.lock().unwrap_or_else(|e| e.into_inner()).clone();
        let mut seen: std::collections::HashMap<Uuid, usize> = std::collections::HashMap::new();
        let mut succeeded = std::collections::BTreeSet::new();
        for row in &rows {
            let tenant: Uuid = row.get(0);
            let nth = seen.entry(tenant).or_default();
            let channel = channels
                .iter()
                .filter(|(t, _)| *t == tenant)
                .nth(*nth)
                .map_or("-", |(_, c)| *c);
            *nth += 1;
            let (profile, account, credential): (Uuid, Uuid, Uuid) =
                (row.get(3), row.get(5), row.get(6));
            let status: String = row.get(10);
            println!(
                "c33b-live tenant={} binding={}@{} profile={}@{} account={} credential_ref={} provider={} model={} endpoint_id={} channel={channel} status={status} input_tokens={} output_tokens={} latency_ms={}",
                if tenant == tenant_a { "A" } else { "B" },
                row.get::<_, Uuid>(1),
                row.get::<_, i64>(2),
                profile,
                row.get::<_, i64>(4),
                account,
                credential,
                row.get::<_, String>(7),
                row.get::<_, String>(8),
                row.get::<_, Uuid>(9),
                row.get::<_, String>(11),
                row.get::<_, String>(12),
                row.get::<_, String>(13),
            );
            // Security argument (a): every row's route belongs to its own tenant.
            let own = if tenant == tenant_a {
                vec![(
                    a_route.profile_id,
                    a_route.provider_account_id,
                    a_route.credential_ref,
                )]
            } else {
                vec![
                    (
                        b_route.profile_id,
                        b_route.provider_account_id,
                        b_route.credential_ref,
                    ),
                    (pb1.profile_id, pb1.provider_account_id, pb1.credential_ref),
                ]
            };
            assert!(
                own.contains(&(profile, account, credential)),
                "a row names a route that is not its tenant's own"
            );
            if status == "SUCCEEDED" {
                succeeded.insert((row.get::<_, String>(7), row.get::<_, String>(8)));
            }
        }
        let expected_channel = |lane: &Lane| {
            channel_name(&humaux_adapters::distill_reasoner::distill_output_channel(
                &lane.descriptor(),
            ))
        };
        for (tenant, lane) in [(tenant_a, &a_lane), (tenant_b, &b_lane)] {
            let first_channel = channels.iter().find(|(t, _)| *t == tenant).map(|(_, c)| *c);
            assert_eq!(
                first_channel,
                Some(expected_channel(lane)),
                "the channel follows the tenant's own profile"
            );
        }
        let last_b = rows
            .iter()
            .rev()
            .find(|r| r.get::<_, Uuid>(0) == tenant_b)
            .expect("a row of B");
        let swap_effective = second_done
            && built_after == built_before + 1
            && last_b.get::<_, Uuid>(1) == binding_b
            && last_b.get::<_, i64>(2) == version
            && last_b.get::<_, Uuid>(3) == pb1.profile_id
            && last_b.get::<_, Uuid>(6) == pb1.credential_ref
            && last_b.get::<_, String>(10) == "SUCCEEDED";
        let (memories_a, memories_b) = (memory_count(&mut handle, a), memory_count(&mut handle, b));
        println!(
            "c33b-live providers_distinct={} swap_effective={swap_effective} rows={} memories_a={memories_a} memories_b={memories_b}",
            succeeded.len(),
            rows.len()
        );
        retire_open_jobs(&mut handle.admin, &[tenant_a, tenant_b]);
        assert!(first_done, "both first jobs DONE");
        assert_eq!(
            succeeded.len(),
            2,
            "two distinct (provider, model): {succeeded:?}"
        );
        assert!(
            swap_effective,
            "the switch took effect on the next job, no restart"
        );
    });
}

// ---------------------------------------------------------------------------
// The BINARY: graceful shutdown (card 15 / ADR-0037) and two resident workers (E10)
// ---------------------------------------------------------------------------

/// macOS XProtect assesses a freshly linked binary on its first exec; pay it once.
fn warm_binary() {
    // dep: subprocess(humaux-private-worker) — spawns the private-worker binary under test
    let _ = std::process::Command::new(env!("CARGO_BIN_EXE_humaux-private-worker"))
        .arg("--warm-up-not-a-mode")
        .output();
}

/// A non-forbidden IP LITERAL endpoint (`ssrf::validate_custom_endpoint` accepts it without a DNS
/// round trip; F25: no loopback stub is reachable from the subprocess).
const LITERAL_CHAT_URL: &str = "https://192.88.99.1/v1/chat/completions";
/// The literal endpoint's socket address (same host as [`LITERAL_CHAT_URL`]), for the black-hole probe.
const LITERAL_CHAT_ADDR: &str = "192.88.99.1:443";

/// True when the literal endpoint gives no byte back within 2 s — the only way a call can still be
/// open while a worker is stopped (F25 forbids a loopback stub). Two shapes count: the TCP connect
/// itself times out, or it succeeds (a TUN proxy on the dev host accepts every connect and then
/// relays nothing) and the first read times out. CI finding (PR #1, 2026-10-08): on some hosts
/// 192.88.99.1 answers a connection error at once, every attempt then dies TRANSPORT inside the
/// sample window and E10 is inconclusive by its own assert; §57.1 makes that a named missing object,
/// not a red.
fn literal_endpoint_black_holes() -> bool {
    use std::io::{ErrorKind, Read, Write};
    let addr = LITERAL_CHAT_ADDR.parse().expect("literal socket address");
    // dep: HTTP(literal endpoint) — the black-hole probe of the literal chat address, never a loopback stub
    let mut stream = match std::net::TcpStream::connect_timeout(&addr, Duration::from_secs(2)) {
        Ok(stream) => stream,
        Err(e) => return e.kind() == ErrorKind::TimedOut,
    };
    stream
        .set_read_timeout(Some(Duration::from_secs(2)))
        .expect("read timeout");
    let _ = stream.write_all(b"\r\n");
    matches!(
        stream.read(&mut [0_u8; 1]),
        Err(e) if matches!(e.kind(), ErrorKind::TimedOut | ErrorKind::WouldBlock)
    )
}

/// The `--distill-serve` environment: every required key of `bootstrap()`. ADR-0060 D-C: no
/// provider, model, endpoint or capability — each route names its own; the recipient list lets
/// the literal endpoint and the rehearsal host be dialled. `credentials` is the
/// `HUMAUX_PRIVATE_WORKER_CREDENTIALS` value ([`credentials_spec`]); its references name a
/// generated throwaway key the literal endpoint never receives.
fn distill_serve_command(dsn: &str, credentials: &str) -> std::process::Command {
    // dep: subprocess(humaux-private-worker) — spawns the private-worker binary under test
    let mut cmd = std::process::Command::new(env!("CARGO_BIN_EXE_humaux-private-worker"));
    cmd.env("PRIVATE_WORKER_PG_DSN", dsn)
        .env("HUMAUX_PRIVATE_WORKER_HTTP_TIMEOUT_SECS", "5")
        .env(route_providers::CREDENTIALS, credentials)
        .env(
            "HUMAUX_CARD15_TEST_SECRET",
            Uuid::new_v4().simple().to_string(),
        )
        .env(EGRESS_RECIPIENTS, subprocess_recipients())
        .env(REGIONS, REGION)
        .env(
            "HUMAUX_PRIVATE_WORKER_HEALTH_RENEW_SECS",
            HEALTH_RENEW_SECS.to_string(),
        )
        .env("HUMAUX_PRIVATE_WORKER_PERMIT_TTL_SECS", "30")
        .env("HUMAUX_PRIVATE_WORKER_DISTILL_LEASE_SECS", "120")
        .env("HUMAUX_PRIVATE_WORKER_DISTILL_IN_FLIGHT", "4")
        .env("HUMAUX_PRIVATE_WORKER_DISTILL_HARD_DEADLINE_SECS", "250")
        .env("HUMAUX_PRIVATE_WORKER_DISTILL_NOT_READY_PARK_SECS", "600")
        .env("HUMAUX_PRIVATE_WORKER_DISTILL_MAX_ATTEMPTS", "5")
        .env("HUMAUX_PRIVATE_WORKER_DISTILL_POLL_INTERVAL_SECS", "1")
        .env("HUMAUX_PRIVATE_WORKER_DISTILL_BUDGET_WINDOW_SECS", "60")
        .env("HUMAUX_PRIVATE_WORKER_DISTILL_BUDGET_MAX_CALLS", "10000")
        // ADR-0061 D-B: each resident mode's own ops listener, a fresh free loopback port per spawn (two
        // resident workers run at once in E10).
        .env(
            "HUMAUX_PRIVATE_WORKER_SERVE_RPC_METRICS_ADDR",
            free_ops_addr(),
        )
        .env(
            "HUMAUX_PRIVATE_WORKER_DISTILL_SERVE_METRICS_ADDR",
            free_ops_addr(),
        );
    cmd
}

/// The status line of one `GET /metrics`, `None` when the port refuses.
fn ops_metrics_status(addr: std::net::SocketAddr) -> Option<String> {
    use std::io::{Read as _, Write as _};
    // dep: HTTP(loopback) — the child's ops listener
    let mut s = std::net::TcpStream::connect_timeout(&addr, Duration::from_secs(1)).ok()?;
    s.set_read_timeout(Some(Duration::from_secs(5))).ok()?;
    write!(s, "GET /metrics HTTP/1.1\r\nHost: {addr}\r\n\r\n").ok()?;
    let mut raw = String::new();
    s.read_to_string(&mut raw).ok()?;
    raw.lines().next().map(str::to_owned)
}

/// A loopback address that was bound and released, for one spawn's ops listener.
fn free_ops_addr() -> String {
    std::net::TcpListener::bind("127.0.0.1:0")
        .and_then(|l| l.local_addr())
        .expect("reserve a loopback port")
        .to_string()
}

fn wait_exit(
    child: &mut std::process::Child,
    within: Duration,
    what: &str,
) -> std::process::ExitStatus {
    let deadline = std::time::Instant::now() + within;
    loop {
        match child.try_wait().expect("poll the worker") {
            Some(status) => return status,
            None if std::time::Instant::now() >= deadline => {
                panic!("{what} did not exit within {within:?}");
            }
            None => std::thread::sleep(Duration::from_millis(100)),
        }
    }
}

fn signal(pid: u32, sig: &str) {
    // dep: subprocess(kill) — spawns external process
    let status = std::process::Command::new("kill")
        .arg(format!("-{sig}"))
        .arg(pid.to_string())
        .status()
        .expect("send a signal");
    assert!(status.success(), "kill -{sig} {pid} failed");
}

/// ADR-0037 D3: SIGTERM to `--distill-serve` mid-serve — every seat finishes the job it holds and
/// the process exits zero; no job is left `PROCESSING` with a live lease, no outbox row leased.
/// 注错: make a seat stop mid-job on shutdown (drop its work future) ⇒ a claimed job is left
/// `PROCESSING` with a live lease.
#[test]
fn sigterm_mid_serve_drains_and_leaves_no_job_processing_with_a_live_lease() {
    distill_serve_drains_on(
        "TERM",
        "sigterm_mid_serve_drains_and_leaves_no_job_processing_with_a_live_lease",
    );
}

/// The Ctrl-C twin: SIGINT is latched before the first claim (`Shutdown::install`).
#[test]
fn sigint_mid_serve_drains_and_leaves_no_job_processing_with_a_live_lease() {
    distill_serve_drains_on(
        "INT",
        "sigint_mid_serve_drains_and_leaves_no_job_processing_with_a_live_lease",
    );
}

fn distill_serve_drains_on(sig: &str, test_name: &'static str) {
    run(test_name, |mut handle| {
        warm_binary();
        // Tenant C: no admitted route — its jobs are claimed and settled NOT_READY without an
        // inference call, which keeps this test hermetic.
        for _ in 0..3 {
            accept_evidence(&mut handle, 2);
        }
        let tenant_id = handle.tenants[2].tenant_id;
        let dsn = dsn_as_role(&handle.dsn, "role_private_worker");
        let tenants = handle.tenant_ids();
        let credentials =
            credentials_spec(&mut handle.admin, &tenants, "HUMAUX_CARD15_TEST_SECRET");
        let mut child = distill_serve_command(&dsn, &credentials)
            .arg("--distill-serve")
            .spawn_reaped("spawn humaux-private-worker --distill-serve");
        let deadline = std::time::Instant::now() + Duration::from_secs(90);
        loop {
            let touched: i64 = handle
                .admin
                .query_one(
                    "SELECT count(*) FROM ops.jobs \
                     WHERE tenant_id = $1 AND (not_ready_since IS NOT NULL OR status <> 'PENDING')",
                    &[&tenant_id],
                )
                .expect("read job progress")
                .get(0);
            if touched > 0 {
                break;
            }
            if std::time::Instant::now() >= deadline {
                panic!("the distill loop never claimed a job — this test would assert nothing");
            }
            std::thread::sleep(Duration::from_millis(100));
        }
        signal(child.id(), sig);
        let status = wait_exit(&mut child, Duration::from_secs(90), "the distill worker");
        assert!(
            status.success(),
            "SIG{sig} must drain to exit zero, got {status:?}"
        );
        let stuck: i64 = handle
            .admin
            .query_one(
                "SELECT count(*) FROM ops.jobs WHERE tenant_id = $1 AND status = 'PROCESSING' \
                   AND lease_expires_at > clock_timestamp()",
                &[&tenant_id],
            )
            .expect("read leases")
            .get(0);
        assert_eq!(
            stuck, 0,
            "a drained worker left a job PROCESSING with a live lease"
        );
        let leased: i64 = handle
            .admin
            .query_one(
                "SELECT count(*) FROM ops.outbox WHERE tenant_id = $1 AND lease_expires_at > clock_timestamp()",
                &[&tenant_id],
            )
            .expect("read outbox leases")
            .get(0);
        assert_eq!(
            leased, 0,
            "a drained worker left a live ops.outbox lease behind"
        );
        handle.assert_i_slot();
    });
}

/// ADR-0037 D3, the RPC-listener half: `--serve-rpc` holds no lease, its drain is "stop
/// accepting and return zero". 注错: drop the `shutdown.recv()` arm from `serve_rpc`'s `select!`.
/// ADR-0061 D-B: its ops listener answers while it serves and is closed after the exit.
#[test]
fn sigterm_to_the_inference_rpc_listener_exits_zero() {
    run(
        "sigterm_to_the_inference_rpc_listener_exits_zero",
        |mut handle| {
            warm_binary();
            let tenants = handle.tenant_ids();
            let credentials =
                credentials_spec(&mut handle.admin, &tenants, "HUMAUX_CARD15_TEST_SECRET");
            // Short `/tmp` path: macOS's temp dir plus a uuid overruns `sockaddr_un.sun_path`.
            // ADR-0066 D-M: the socket lives in a 0700 directory of this uid (a shared `/tmp` refuses the bind).
            struct RmDir(String);
            impl Drop for RmDir {
                fn drop(&mut self) {
                    let _ = std::fs::remove_dir_all(&self.0);
                }
            }
            let sock_dir = RmDir(format!("/tmp/hp15-rpc-{}", Uuid::now_v7().simple()));
            std::fs::create_dir(&sock_dir.0).expect("create the socket dir");
            std::fs::set_permissions(
                &sock_dir.0,
                std::os::unix::fs::PermissionsExt::from_mode(0o700),
            )
            .expect("chmod the socket dir");
            let socket_path = format!("{}/rpc.sock", sock_dir.0);
            let dsn = dsn_as_role(&handle.dsn, "role_private_worker");
            let ops = free_ops_addr();
            let mut child = distill_serve_command(&dsn, &credentials)
                .arg("--serve-rpc")
                .env("HUMAUX_PRIVATE_WORKER_SERVE_RPC_METRICS_ADDR", &ops)
                .env("HUMAUX_PRIVATE_WORKER_RPC_SOCKET_PATH", &socket_path)
                // ADR-0066 D-K: a uid nobody here runs as — the listener is never dialled, and its own uid
                // would refuse boot without the dev-only opt-in.
                .env(
                    "HUMAUX_PRIVATE_WORKER_CONSOLIDATION_UID",
                    own_uid().wrapping_add(1).to_string(),
                )
                .spawn_reaped("spawn humaux-private-worker --serve-rpc");
            let deadline = std::time::Instant::now() + Duration::from_secs(60);
            while !std::path::Path::new(&socket_path).exists() {
                if std::time::Instant::now() >= deadline {
                    panic!("the RPC listener never bound {socket_path}");
                }
                std::thread::sleep(Duration::from_millis(100));
            }
            let ops: std::net::SocketAddr = ops.parse().expect("ops address");
            assert!(
                ops_metrics_status(ops).is_some_and(|line| line.contains(" 200 ")),
                "--serve-rpc's ops listener does not answer /metrics on {ops}"
            );
            signal(child.id(), "TERM");
            let status = wait_exit(&mut child, Duration::from_secs(60), "the RPC listener");
            let _ = std::fs::remove_file(&socket_path);
            assert!(
                status.success(),
                "a drained RPC listener must exit zero, got {status:?}"
            );
            assert!(
                ops_metrics_status(ops).is_none(),
                "the ops port {ops} still accepts after exit"
            );
        },
    );
}

/// This process's uid, read from a file it just created (no `libc` for one call).
fn own_uid() -> u32 {
    use std::os::unix::fs::MetadataExt;
    let marker = std::env::temp_dir().join(format!("hp15-uid-{}", Uuid::now_v7().simple()));
    std::fs::write(&marker, b"").expect("write the uid marker file");
    let uid = std::fs::metadata(&marker)
        .expect("stat the uid marker file")
        .uid();
    let _ = std::fs::remove_file(&marker);
    uid
}

/// E10 (review finding 5, MiniMax-free M3) — two resident `--distill-serve` subprocesses over one
/// backlog whose provider endpoint never answers in time (the literal endpoint; HTTP 3 s, lease
/// 1 s, hard deadline 8 s, max 3 attempts). Once worker 1 holds a dispatched job it is stopped
/// (SIGSTOP) for 4 s: its leases expire while its calls are open. Sampled every 100 ms: bound
/// slots ≤ 4 and I-SLOT; at least one EXECUTION_UNCERTAIN is observed (else inconclusive); the
/// double-spend report has no overlap and no unattributed SUCCEEDED row; every job ends DEAD with
/// its outbox FAILED. Fault: T5 branch → READY (lease expiry frees the slot) ⇒ worker 2
/// re-dispatches a job while worker 1's stopped call is open ⇒ overlap.
#[test]
#[allow(clippy::too_many_lines)]
fn two_resident_workers_never_overlap_calls_for_one_evidence() {
    run(
        "two_resident_workers_never_overlap_calls_for_one_evidence",
        |mut handle| {
            if !literal_endpoint_black_holes() {
                println!(
                    "not_applicable: missing object = a black-holing literal endpoint \
                     ({LITERAL_CHAT_ADDR} answers or refuses within 2 s on this host; E10 needs an \
                     open call while worker 1 is stopped)"
                );
                return;
            }
            warm_binary();
            let mut evidence = Vec::new();
            for n in 0..4 {
                let tenant = seed_tenant(
                    &mut handle.admin,
                    &format!("private derived_dispatch_e2e e10 tenant {n}"),
                    handle.user_id,
                    Some(EGRESS_PROCESSOR_ID),
                    LITERAL_CHAT_URL,
                    &live_minimax::REHEARSAL_CAPABILITIES,
                )
                .expect("e10 tenant");
                handle.tenants.push(tenant);
                let idx = handle.tenants.len() - 1;
                for _ in 0..3 {
                    evidence.push(accept_evidence(&mut handle, idx));
                }
            }
            let dsn = dsn_as_role(&handle.dsn, "role_private_worker");
            let tenants = handle.tenant_ids();
            let credentials =
                credentials_spec(&mut handle.admin, &tenants, "HUMAUX_CARD15_TEST_SECRET");
            let spawn = || {
                distill_serve_command(&dsn, &credentials)
                    .env("HUMAUX_PRIVATE_WORKER_HTTP_TIMEOUT_SECS", "3")
                    .env("HUMAUX_PRIVATE_WORKER_DISTILL_LEASE_SECS", "1")
                    .env(
                        "HUMAUX_PRIVATE_WORKER_DISTILL_HARD_DEADLINE_SECS",
                        E10_HARD_DEADLINE_SECS.to_string(),
                    )
                    .env("HUMAUX_PRIVATE_WORKER_DISTILL_MAX_ATTEMPTS", "3")
                    .arg("--distill-serve")
                    .spawn_reaped("spawn a resident worker")
            };
            let mut one = spawn();
            let tenants = handle.tenant_ids();
            let started = std::time::Instant::now();
            // Worker 1's owner: the first dispatched job's lease owner (worker 2 is not up yet).
            let owner_one: String = loop {
                let row = handle
                    .admin
                    .query_opt(
                        "SELECT lease_owner FROM ops.jobs WHERE tenant_id = ANY($1) \
                           AND dispatch_state = 'DISPATCH_INTENT' LIMIT 1",
                        &[&tenants],
                    )
                    .expect("probe");
                if let Some(row) = row {
                    break row.get(0);
                }
                assert!(
                    started.elapsed() < Duration::from_secs(60),
                    "worker 1 never dispatched"
                );
                std::thread::sleep(Duration::from_millis(20));
            };
            let mut two = spawn();
            signal(one.id(), "STOP");
            let stopped_at = std::time::Instant::now();
            let mut resumed = false;
            let (mut max_bound, mut uncertain_seen, mut samples) = (0_i64, false, 0_u32);
            let done = loop {
                if !resumed && stopped_at.elapsed() >= Duration::from_secs(4) {
                    signal(one.id(), "CONT");
                    resumed = true;
                }
                let bound: i64 = handle
                    .admin
                    .query_one(
                        "SELECT count(*) FROM ops.provider_slots WHERE job_id IS NOT NULL",
                        &[],
                    )
                    .unwrap()
                    .get(0);
                max_bound = max_bound.max(bound);
                assert!(bound <= 4, "bound slots {bound} > 4");
                assert_eq!(
                    i_slot_violations(&mut handle.admin),
                    0,
                    "I-SLOT broke in a sample"
                );
                let row = handle
                    .admin
                    .query_one(
                        "SELECT count(*) FILTER (WHERE dispatch_state = 'EXECUTION_UNCERTAIN'), \
                                count(*) FILTER (WHERE status IN ('DEAD', 'DONE')) \
                         FROM ops.jobs WHERE tenant_id = ANY($1)",
                        &[&tenants],
                    )
                    .unwrap();
                uncertain_seen |= row.get::<_, i64>(0) > 0;
                samples += 1;
                if resumed && row.get::<_, i64>(1) == evidence.len() as i64 {
                    break true;
                }
                if started.elapsed() > Duration::from_secs(240) {
                    break false;
                }
                std::thread::sleep(Duration::from_millis(100));
            };
            if !resumed {
                signal(one.id(), "CONT");
            }
            for child in [&mut one, &mut two] {
                signal(child.id(), "TERM");
                let status = wait_exit(child, Duration::from_secs(60), "a resident worker");
                assert!(status.success(), "{status:?}");
            }
            let report =
                double_spend::report(&mut handle.admin, &tenants, 3, E10_HARD_DEADLINE_SECS);
            let classes: Vec<(String, Option<String>, i64)> = handle
                .admin
                .query(
                    "SELECT status, last_error_class, count(*) FROM ops.jobs WHERE tenant_id = ANY($1) GROUP BY 1, 2 ORDER BY 1, 2",
                    &[&tenants],
                )
                .unwrap()
                .into_iter()
                .map(|r| (r.get(0), r.get(1), r.get(2)))
                .collect();
            println!(
                "E10 owner_one={owner_one} samples={samples} max_bound={max_bound} uncertain_seen={uncertain_seen} wall={:?} jobs={classes:?} {}",
                started.elapsed(),
                report.line()
            );
            assert!(done, "every job must settle within 240 s: {classes:?}");
            assert_eq!(report.overlaps, 0, "{}", report.line());
            assert_eq!(report.unattributed_succeeded, 0, "{}", report.line());
            assert!(
                uncertain_seen,
                "inconclusive: no EXECUTION_UNCERTAIN observed while worker 1 was stopped"
            );
            assert!(max_bound <= 4);
            for row in &evidence {
                assert_eq!(
                    handle.outbox_status(*row),
                    "FAILED",
                    "DEAD flips its outbox row"
                );
            }
            let not_dead: i64 = handle
                .admin
                .query_one(
                    "SELECT count(*) FROM ops.jobs WHERE tenant_id = ANY($1) AND status <> 'DEAD'",
                    &[&tenants],
                )
                .unwrap()
                .get(0);
            assert_eq!(not_dead, 0, "{classes:?}");
            handle.assert_i_slot();
        },
    );
}

// ---------------------------------------------------------------------------
// ADR-0058 §7: the card's live acceptance gate (MiniMax), M1..M8.
// ---------------------------------------------------------------------------

/// The live transport timeout; `live_config` sizes `ops.begin_call`'s window from it (D-K).
const LIVE_HTTP_SECS: u64 = 60;
/// Card gate: B's single row completes within this while A has 200 queued (card 32 acceptance).
const FAIRNESS_BOUND_SECS: f64 = 60.0;
/// A model id MiniMax does not serve: every call to it is a real provider refusal (M6).
const POISON_MODEL_ID: &str = "c32-no-such-model";
/// ADR-0048 per-claim budget: first call + malformed re-ask + empty retry (M3's per-gen bound).
const PER_GEN_CALL_BUDGET: i64 = 3;
/// E10's `HUMAUX_PRIVATE_WORKER_DISTILL_HARD_DEADLINE_SECS` (also the double-spend window, R6).
const E10_HARD_DEADLINE_SECS: f64 = 8.0;

/// ADR-0058 D-K shape for the live provider: `hard_deadline = 2 × (http + lease)`.
fn live_config(owner: &str, lease_seconds: f64, in_flight: u32) -> DistillDispatchConfig {
    let http = LIVE_HTTP_SECS as f64;
    DistillDispatchConfig {
        lease_owner: owner.to_string(),
        lease_seconds,
        in_flight,
        hard_deadline_seconds: 2.0 * (http + lease_seconds),
        http_timeout_seconds: http,
        not_ready_park_seconds: 600.0,
        max_attempts: 5,
        budget: TEST_BUDGET,
        health_renew_seconds: HEALTH_RENEW_SECS,
        dns_pins_configured: false,
    }
}

/// One distinct, uuid-free factual note per index (gitleaks' generic-key rule flags a uuid inside
/// a distilled memory, card 27 run 2026-09-29 #3).
fn live_note(set: &str, n: usize) -> String {
    const NOUNS: [&str; 10] = [
        "billing",
        "search",
        "ledger",
        "inventory",
        "payroll",
        "gateway",
        "audit",
        "catalog",
        "shipping",
        "pricing",
    ];
    const DAYS: [&str; 5] = ["Monday", "Tuesday", "Wednesday", "Thursday", "Friday"];
    format!(
        "Card32 {set} note {n}: the {} service of team {} listens on port {} and ships every {}.",
        NOUNS[n % NOUNS.len()],
        n / NOUNS.len() + 1,
        7000 + n,
        DAYS[n % DAYS.len()]
    )
}

/// Outbox rows of `tenants` still open (`PENDING` / `PROCESSING`).
fn open_outbox(admin: &mut Client, tenants: &[Uuid]) -> i64 {
    admin
        .query_one(
            "SELECT count(*) FROM ops.outbox WHERE tenant_id = ANY($1) \
               AND event_type = 'EVIDENCE_ACCEPTED' AND status IN ('PENDING', 'PROCESSING')",
            &[&tenants],
        )
        .expect("open outbox")
        .get(0)
}

/// `(DONE, FAILED)` outbox rows of `tenants`.
fn outbox_done_failed(admin: &mut Client, tenants: &[Uuid]) -> (i64, i64) {
    let row = admin
        .query_one(
            "SELECT count(*) FILTER (WHERE status = 'DONE'), count(*) FILTER (WHERE status = 'FAILED') \
             FROM ops.outbox WHERE tenant_id = ANY($1) AND event_type = 'EVIDENCE_ACCEPTED'",
            &[&tenants],
        )
        .expect("outbox totals");
    (row.get(0), row.get(1))
}

/// Bound slots right now (M4 a).
fn bound_slots(admin: &mut Client) -> i64 {
    admin
        .query_one(
            "SELECT count(*) FROM ops.provider_slots WHERE job_id IS NOT NULL",
            &[],
        )
        .expect("bound slots")
        .get(0)
}

/// M4 (b): the most `distill_calls`-attributed ledger intervals `[called_at, called_at +
/// latency_ms]` of `tenants` open at one instant. Rows with no latency (RESERVED: killed or
/// unknown calls) are excluded and counted separately by the caller's double-spend line.
fn max_ledger_overlap(admin: &mut Client, tenants: &[Uuid]) -> i64 {
    admin
        .query_one(
            "WITH iv AS (SELECT l.called_at AS s, \
                    l.called_at + make_interval(secs => l.latency_ms / 1000.0) AS e \
                  FROM ops.distill_calls c JOIN ops.model_call_ledger l USING (model_call_id) \
                  WHERE c.tenant_id = ANY($1) AND l.latency_ms IS NOT NULL) \
             SELECT coalesce(max((SELECT count(*) FROM iv b WHERE b.s <= a.s AND b.e > a.s)), 0) \
             FROM iv a",
            &[&tenants],
        )
        .expect("ledger overlap")
        .get(0)
}

/// Evidence/s of one tenant set: n / (last outbox settle − first admitted call).
fn evidence_rate(admin: &mut Client, tenants: &[Uuid]) -> (i64, f64) {
    let row = admin
        .query_one(
            "SELECT (SELECT count(*) FROM ops.outbox WHERE tenant_id = ANY($1) AND status = 'DONE'), \
                    extract(epoch FROM (SELECT max(processed_at) FROM ops.outbox WHERE tenant_id = ANY($1)) \
                      - (SELECT min(begun_at) FROM ops.distill_calls WHERE tenant_id = ANY($1)))::float8",
            &[&tenants],
        )
        .expect("rate");
    let (done, secs): (i64, f64) = (row.get(0), row.get(1));
    (done, done as f64 / secs)
}

/// What [`serve_until`] observed while the dispatcher(s) ran.
struct Served {
    report: DistillDispatchReport,
    met: bool,
    wall: Duration,
    max_bound: i64,
    i_slot_breaks: u32,
    samples: u32,
}

/// One in-process `dispatch_serve` until `done` holds on an owner connection or `limit` passes;
/// a sampler records the bound-slot maximum and I-SLOT on every 100 ms tick (M4 a). One
/// dispatcher only: a process serves one provider (card 33b), so two dispatchers with different
/// providers over one queue race for each other's jobs (M6, `distill_poison_live`).
fn serve_until<P: UserReasoningProvider + 'static>(
    handle: &Handle,
    provider: &Arc<P>,
    config: &DistillDispatchConfig,
    limit: Duration,
    done: impl Fn(&mut Client) -> bool + Send,
) -> Served {
    let stop = AtomicBool::new(false);
    let poll = Duration::from_millis(500);
    let started = std::time::Instant::now();
    let (dsn, stop_flag) = (handle.dsn.clone(), &stop);
    std::thread::scope(|scope| {
        let sampler = scope.spawn(move || {
            // dep: PostgreSQL(owner) — sampler connection
            let mut admin = Client::connect(&dsn, NoTls).expect("sampler connection");
            let (mut max_bound, mut breaks, mut samples) = (0_i64, 0_u32, 0_u32);
            let met = loop {
                max_bound = max_bound.max(bound_slots(&mut admin));
                breaks += u32::from(i_slot_violations(&mut admin) != 0);
                samples += 1;
                if done(&mut admin) {
                    break true;
                }
                if started.elapsed() > limit {
                    break false;
                }
                std::thread::sleep(Duration::from_millis(100));
            };
            stop_flag.store(true, Ordering::SeqCst);
            (met, max_bound, breaks, samples)
        });
        let report = handle.rt.block_on(distill::dispatch_serve(
            &handle.private,
            &routes(provider),
            reasoner_config(),
            config,
            poll,
            &stop,
        ));
        let (met, max_bound, i_slot_breaks, samples) = sampler.join().expect("sampler");
        Served {
            report: report.expect("dispatcher"),
            met,
            wall: started.elapsed(),
            max_bound,
            i_slot_breaks,
            samples,
        }
    })
}

/// A resident `--distill-serve` subprocess on the live MiniMax lane (the same keys the rehearsal
/// sets; the key reaches the child's environment only). `credentials` maps the live tenants'
/// references to `MINIMAX_API_KEY` ([`credentials_spec`]).
fn live_serve_command(dsn: &str, key: &str, credentials: &str) -> std::process::Command {
    let mut cmd = distill_serve_command(dsn, credentials);
    cmd.env("HUMAUX_PRIVATE_WORKER_DNS_PINS", live_minimax::dns_pins())
        .env("MINIMAX_API_KEY", key)
        .env("HUMAUX_PRIVATE_WORKER_CANDIDATE_TTL_SECONDS", "604800")
        .env(
            "HUMAUX_PRIVATE_WORKER_HTTP_TIMEOUT_SECS",
            LIVE_HTTP_SECS.to_string(),
        )
        .env("HUMAUX_PRIVATE_WORKER_DISTILL_LEASE_SECS", "30")
        .env(
            "HUMAUX_PRIVATE_WORKER_DISTILL_HARD_DEADLINE_SECS",
            (2 * (LIVE_HTTP_SECS + 30)).to_string(),
        );
    cmd
}

/// Leftover open jobs of a measurement that stopped early are parked DEAD so the next
/// measurement's dispatcher never serves them (the fixture deletes them at drop).
fn retire_open_jobs(admin: &mut Client, tenants: &[Uuid]) -> u64 {
    admin
        .execute(
            "UPDATE ops.jobs SET status = 'DEAD', last_error_class = 'C32_LIVE_GATE_STOPPED', \
               next_retry_at = NULL, lease_owner = NULL, lease_expires_at = NULL \
             WHERE tenant_id = ANY($1) AND job_type = 'DERIVED_DISTILL' \
               AND status IN ('PENDING', 'RETRY_WAIT', 'WAITING_KEY')",
            &[&tenants],
        )
        .expect("retire leftover jobs")
}

/// ADR-0058 §7 M6 — a poison Evidence (its domain bound to a model MiniMax does not serve) dies
/// after `max_attempts` real provider refusals while the tenant's good domain is served. Phased so
/// no two dispatchers ever compete for one job (a process serves one provider until card 33b):
/// phase A runs only the poison-lane dispatcher until the poison job is DEAD — the good jobs it
/// claims are released NOT_READY and keep attempt 0; phase B makes the good jobs due and runs only
/// the good-lane dispatcher — every good job DONE at attempt 1, the DEAD job never claimed again.
#[test]
#[ignore = "lane(a:shared_db) live MiniMax acceptance gate (card 32 distill_poison_live): run with --include-ignored and HUMAUX_REQUIRE_MINIMAX=1"]
#[allow(clippy::too_many_lines)]
fn distill_poison_live() {
    let Some(key) = live_minimax::load_minimax_key() else {
        humaux_testkit::skip_or_fail(
            "distill_poison_live",
            "missing object: MINIMAX_API_KEY (env and /Volumes/data/viral-skill-eval/.env both empty)",
            humaux_testkit::ExternalDep::MiniMax,
        );
        return;
    };
    run("distill_poison_live", |mut handle| {
        // SAFETY: set while SERIAL_GUARD is held (see `distill_fairness_live`).
        unsafe {
            std::env::set_var("HUMAUX_PRIVATE_WORKER_CANDIDATE_TTL_SECONDS", "604800");
        }
        let http = Duration::from_secs(LIVE_HTTP_SECS);
        let m6 = handle
            .add_tenant(
                "private derived_dispatch_e2e live m6 poison",
                Some(EGRESS_PROCESSOR_ID),
            )
            .expect("live tenant");
        let m6_tenant = handle.tenants[m6].tenant_id;
        let poison_domain: Uuid = handle
            .admin
            .query_one(
                "INSERT INTO control.private_reasoning_domains (tenant_id, name, owner_user_id, status) \
                 VALUES ($1, 'private derived_dispatch_e2e live m6 poison domain', $2, 'ACTIVE') \
                 RETURNING reasoning_domain_id",
                &[&m6_tenant, &handle.user_id],
            )
            .expect("poison domain")
            .get(0);
        // The poison domain's own lane names a model MiniMax does not serve: every admitted call
        // is a real provider refusal.
        seed_route_binding(
            &mut handle.admin,
            m6_tenant,
            handle.user_id,
            poison_domain,
            "private derived_dispatch_e2e live m6 poison lane",
            EGRESS_PROCESSOR_ID,
            ENDPOINT_REF,
            POISON_MODEL_ID,
            &live_minimax::REHEARSAL_CAPABILITIES,
        )
        .expect("poison lane");
        let good_rows: Vec<Uuid> = (0..2)
            .map(|n| accept_evidence_marked(&mut handle, m6, &live_note("m6good", n)))
            .collect();
        let good_jobs: Vec<Uuid> = good_rows.iter().map(|r| handle.job_of(*r)).collect();
        let poison_row = accept_evidence_in(
            &mut handle,
            m6_tenant,
            poison_domain,
            &live_note("m6poison", 0),
        );
        let poison_job = handle.job_of(poison_row);
        let mut poison_config = live_config("c32-m6-poison-lane", 5.0, 3);
        poison_config.max_attempts = 3;
        let mut good_config = live_config("c32-m6-good-lane", 5.0, 3);
        good_config.max_attempts = 3;

        // Phase A bound: every attempt's HTTP window + one lease of claim/settle work, plus the
        // backoffs between attempts, plus one more lease of poll slack.
        let backoffs: f64 = (1..poison_config.max_attempts)
            .map(|a| jobs::retry_backoff_seconds(poison_config.lease_seconds, a))
            .sum();
        let phase_a_bound = backoffs
            + f64::from(poison_config.max_attempts)
                * (poison_config.http_timeout_seconds + poison_config.lease_seconds)
            + poison_config.lease_seconds;
        let poison_provider = Arc::new(live_minimax::live_provider(
            key.clone(),
            POISON_MODEL_ID,
            http,
        ));
        let phase_a = serve_until(
            &handle,
            &poison_provider,
            &poison_config,
            Duration::from_secs_f64(phase_a_bound),
            |admin| {
                admin
                    .query_one(
                        "SELECT status FROM ops.jobs WHERE job_id = $1",
                        &[&poison_job],
                    )
                    .expect("poison status")
                    .get::<_, String>(0)
                    == "DEAD"
            },
        );
        let good_attempts: Vec<i32> = good_jobs.iter().map(|j| handle.job(*j).1).collect();
        let (_, _, _, poison_gen, _) = handle.job(poison_job);

        // Phase B bound: the good jobs are due now; one claim's full call budget per job (all in
        // flight at once) + one lease of poll slack.
        for job in &good_jobs {
            handle.ready_now(*job);
        }
        let phase_b_bound = PER_GEN_CALL_BUDGET as f64 * good_config.http_timeout_seconds
            + good_config.lease_seconds;
        let live = Arc::new(live_minimax::live_provider(key.clone(), MODEL_ID, http));
        let phase_b = serve_until(
            &handle,
            &live,
            &good_config,
            Duration::from_secs_f64(phase_b_bound),
            |admin| open_outbox(admin, &[m6_tenant]) == 0,
        );

        let (status, attempt, class, gen_after, _) = handle.job(poison_job);
        let row = handle
            .admin
            .query_one(
                "SELECT count(*), count(*) FILTER (WHERE l.status = 'FAILED') \
                 FROM ops.model_call_ledger l JOIN ops.distill_calls c USING (model_call_id) \
                 WHERE c.job_id = $1",
                &[&poison_job],
            )
            .expect("poison ledger");
        let (poison_ledger, poison_refused): (i64, i64) = (row.get(0), row.get(1));
        let poison_calls = handle.calls_of(poison_job);
        let good_final: Vec<(String, i32)> = good_jobs
            .iter()
            .map(|j| {
                let (s, a, ..) = handle.job(*j);
                (s, a)
            })
            .collect();
        let good_done = good_rows
            .iter()
            .filter(|r| handle.outbox_status(**r) == "DONE")
            .count();
        println!(
            "M6 poison status={status} attempt={attempt} class={class:?} calls={poison_calls} ledger_rows={poison_ledger} ledger_failed={poison_refused} outbox={} good_done={good_done}/{} good_attempts_after_poison_phase={good_attempts:?} good_final={good_final:?} poison_gen_after_a={poison_gen} poison_gen_after_b={gen_after} wall_s={:.1} phase_a_s={:.1}/{phase_a_bound:.0} phase_b_s={:.1}/{phase_b_bound:.0} good_lane={} poison_lane={}",
            handle.outbox_status(poison_row),
            good_rows.len(),
            (phase_a.wall + phase_b.wall).as_secs_f64(),
            phase_a.wall.as_secs_f64(),
            phase_b.wall.as_secs_f64(),
            phase_b.report.summary_line(),
            phase_a.report.summary_line(),
        );
        assert!(phase_a.met, "M6 phase A: the poison job never reached DEAD");
        assert_eq!(
            (status.as_str(), attempt),
            ("DEAD", poison_config.max_attempts)
        );
        assert_eq!(class.as_deref(), Some("PROVIDER_PERMANENT"));
        let max_calls = i64::from(poison_config.max_attempts);
        assert_eq!(
            (poison_calls, poison_ledger, poison_refused),
            (max_calls, max_calls, max_calls),
            "one FAILED ledger row per real call"
        );
        assert_eq!(handle.outbox_status(poison_row), "FAILED");
        assert!(
            good_attempts.iter().all(|a| *a == 0),
            "a poison lane never spends another job's budget"
        );
        assert!(phase_b.met, "M6 phase B: the good jobs did not settle");
        // Every good job is DONE, and every attempt phase B spent is its DONE call, a provider RETRY
        // deferral (capacity is the provider's, never the scheduler's: §57.1; card-39 lane 2026-10-12:
        // one good job DONE at attempt 2 after one deferral) or an ADR-0048 re-ask (empty / malformed
        // reply: each is another `begin_call`, review fix 9 C39-F8-2). Exact accounting, no slack: phase A
        // left every good attempt at 0 (asserted above), so attempts = jobs + deferrals + re-asks.
        let good_attempts_total: u32 = good_final
            .iter()
            .map(|(_, a)| u32::try_from(*a).expect("attempt"))
            .sum();
        let explained = u32::try_from(good_rows.len()).expect("good rows")
            + phase_b.report.deferred
            + phase_b.report.empty_retries
            + phase_b.report.malformed_retries;
        assert!(
            good_final.iter().all(|(s, _)| s == "DONE")
                && good_attempts_total == phase_b.report.attempts
                && phase_b.report.attempts == explained,
            "every good job DONE at attempt 1 + its deferrals and re-asks: good_final={good_final:?} \
             phase_b attempts={} deferred={} empty_retries={} malformed_retries={}",
            phase_b.report.attempts,
            phase_b.report.deferred,
            phase_b.report.empty_retries,
            phase_b.report.malformed_retries
        );
        assert_eq!(good_done, good_rows.len());
        assert_eq!(
            gen_after, poison_gen,
            "the DEAD poison job was claimed again"
        );
        assert_eq!(phase_a.i_slot_breaks + phase_b.i_slot_breaks, 0, "I-SLOT");
        handle.assert_i_slot();
    });
}

/// ADR-0058 §7 — the card's live acceptance gate on MiniMax (`HUMAUX_REQUIRE_MINIMAX=1`). Prints
/// one `M<n>` line per measurement and asserts the card's bounds: M1 Evidence/s at 1 vs 4
/// in-flight (n = 50 each); M2 tenant B's single row DONE within 60 s while A has 200 queued; M3
/// two resident subprocess workers over a 100-Evidence backlog — no duplicate, overlap, budget
/// overrun or unattributed SUCCEEDED call, one memory set per Evidence; M4 bound slots ≤ 4 in
/// every sample and ≤ 4 overlapping ledger intervals; M5 kill -9 mid-call → EXECUTION_UNCERTAIN
/// with the slot kept, then the classed T6 reconcile after `hard_deadline`, never a resend before
/// it; M7 inferred affect rows (origin DISTILL, confidence ≤ 5000); M8 one tenant with two
/// domains, FAILED = 0. Faults are carried by T2/T3/E1/E2/E3/E10/d5b; this test is the
/// measurement. M6 moved to [`distill_poison_live`]: here it ran a poison-lane and a good-lane
/// dispatcher concurrently over one queue, each can only release the other's jobs NOT_READY, so
/// who claims the poison job after a backoff is a race (main-line run: `M6 poison status=PENDING
/// attempt=2 ... good_lane: claimed=34 completed=2 not_ready=32`).
#[test]
#[ignore = "lane(a:shared_db) live MiniMax acceptance gate (card 32 distill_fairness_live): run with --include-ignored and HUMAUX_REQUIRE_MINIMAX=1"]
#[allow(clippy::too_many_lines)]
fn distill_fairness_live() {
    let Some(key) = live_minimax::load_minimax_key() else {
        humaux_testkit::skip_or_fail(
            "distill_fairness_live",
            "missing object: MINIMAX_API_KEY (env and /Volumes/data/viral-skill-eval/.env both empty)",
            humaux_testkit::ExternalDep::MiniMax,
        );
        return;
    };
    run("distill_fairness_live", |mut handle| {
        // ADR-0026 candidate TTL for the in-process dispatcher's rejection path (§78.1, no
        // literal in the worker).
        // SAFETY: set while SERIAL_GUARD is held; no other test thread of this binary reads the
        // environment until it acquires the guard.
        unsafe {
            std::env::set_var("HUMAUX_PRIVATE_WORKER_CANDIDATE_TTL_SECONDS", "604800");
        }
        warm_binary();
        let http = Duration::from_secs(LIVE_HTTP_SECS);
        let live = Arc::new(live_minimax::live_provider(key.clone(), MODEL_ID, http));
        let new_tenant = |handle: &mut Handle, label: &str| {
            handle
                .add_tenant(
                    &format!("private derived_dispatch_e2e live {label}"),
                    Some(EGRESS_PROCESSOR_ID),
                )
                .expect("live tenant")
        };

        // ---- M1: Evidence/s, 1 vs 4 in-flight, n = 50 each ----
        let mut rates = Vec::new();
        for in_flight in [1_u32, 4] {
            let idx = new_tenant(&mut handle, &format!("m1 in_flight {in_flight}"));
            for n in 0..50 {
                accept_evidence_marked(&mut handle, idx, &live_note("m1", n));
            }
            let tenants = vec![handle.tenants[idx].tenant_id];
            let served = serve_until(
                &handle,
                &live,
                &live_config(&format!("c32-m1-{in_flight}"), 30.0, in_flight),
                Duration::from_secs(900),
                |admin| open_outbox(admin, &tenants) == 0,
            );
            let (done, rate) = evidence_rate(&mut handle.admin, &tenants);
            let failed = outbox_done_failed(&mut handle.admin, &tenants).1;
            println!(
                "M1 in_flight={in_flight} n=50 done={done} failed={failed} evidence_per_s={rate:.3} wall_s={:.1} max_bound={} report={}",
                served.wall.as_secs_f64(),
                served.max_bound,
                served.report.summary_line()
            );
            // Provider capacity is the measurement's missing object, never a red (§57.1): when the
            // backlog did not drain AND the provider deferred calls (RETRY_WAIT backoffs of 30–240 s eat
            // the budget), M1–M8 cannot be measured on this account today. A stalled backlog with no
            // deferral is still the scheduler's fault and stays red. Card-39 lane, 2026-10-08:
            // in_flight=1 drained 48/50 in 900 s with 26 of 74 attempts deferred (card 38: 50/50 in 541 s).
            // The two safety bounds hold whatever the provider's capacity (PR #2 review): a concurrency or
            // I-SLOT violation seen in this round is a red before the capacity skip can apply.
            assert!(served.max_bound <= i64::from(in_flight));
            assert_eq!(served.i_slot_breaks, 0, "I-SLOT");
            if !served.met && served.report.deferred > 0 {
                println!(
                    "not_applicable: missing object = provider capacity at in_flight={in_flight} \
                     ({} of {} attempts deferred by RETRY_WAIT, {done} of 50 drained within the budget)",
                    served.report.deferred, served.report.attempts
                );
                return;
            }
            assert!(served.met, "M1 in_flight={in_flight}: backlog not drained");
            rates.push(rate);
        }
        println!("M1 ratio in_flight4/in_flight1={:.2}", rates[1] / rates[0]);

        // ---- M2 + M4 (sampled): B's single row while A has 200 queued ----
        let a = new_tenant(&mut handle, "m2 tenant A");
        let b = new_tenant(&mut handle, "m2 tenant B");
        for n in 0..200 {
            accept_evidence_marked(&mut handle, a, &live_note("m2a", n));
        }
        let b_row = accept_evidence_marked(&mut handle, b, &live_note("m2b", 0));
        let (a_id, b_id) = (handle.tenants[a].tenant_id, handle.tenants[b].tenant_id);
        let a_depth_at_b = std::sync::Mutex::new(None::<i64>);
        let served = serve_until(
            &handle,
            &live,
            &live_config("c32-m2", 30.0, 4),
            Duration::from_secs(300),
            |admin| {
                let done = open_outbox(admin, &[b_id]) == 0;
                if done {
                    *a_depth_at_b.lock().expect("depth") = Some(open_outbox(admin, &[a_id]));
                }
                done
            },
        );
        let b_latency: f64 = handle
            .admin
            .query_one(
                "SELECT extract(epoch FROM processed_at - created_at)::float8 FROM ops.outbox WHERE evidence_id = $1",
                &[&b_row],
            )
            .expect("B latency")
            .get(0);
        let b_status = handle.outbox_status(b_row);
        let overlap = max_ledger_overlap(&mut handle.admin, &[a_id, b_id]);
        println!(
            "M2 tenantB_single_row_latency_s={b_latency:.1} bound_s={FAIRNESS_BOUND_SECS} b_status={b_status} a_queue_at_b_done={:?} wall_s={:.1}",
            a_depth_at_b.lock().expect("depth"),
            served.wall.as_secs_f64()
        );
        println!(
            "M4 m2 samples={} max_bound_slots={} i_slot_breaks={} max_ledger_overlap={overlap}",
            served.samples, served.max_bound, served.i_slot_breaks
        );
        assert!(served.met, "M2: B's row never completed");
        assert_eq!(b_status, "DONE");
        assert!(
            b_latency <= FAIRNESS_BOUND_SECS,
            "M2: B waited {b_latency:.1}s behind A's queue"
        );
        assert!(served.max_bound <= 4 && overlap <= 4);
        assert_eq!(served.i_slot_breaks, 0, "I-SLOT");
        retire_open_jobs(&mut handle.admin, &[a_id]);

        // ---- M3 + M4: two resident subprocess workers over one 100-Evidence backlog ----
        let m3: Vec<usize> = (0..2)
            .map(|t| new_tenant(&mut handle, &format!("m3 tenant {t}")))
            .collect();
        let mut m3_evidence = Vec::new();
        for (t, idx) in m3.iter().enumerate() {
            for n in 0..50 {
                m3_evidence.push(accept_evidence_marked(
                    &mut handle,
                    *idx,
                    &live_note(&format!("m3t{t}"), n),
                ));
            }
        }
        let m3_tenants: Vec<Uuid> = m3.iter().map(|i| handle.tenants[*i].tenant_id).collect();
        let worker_dsn = dsn_as_role(&handle.dsn, "role_private_worker");
        let live_tenants = handle.tenant_ids();
        let live_map = credentials_spec(&mut handle.admin, &live_tenants, "MINIMAX_API_KEY");
        let mut workers: Vec<Reaped> = (0..2)
            .map(|_| {
                live_serve_command(&worker_dsn, &key, &live_map)
                    .arg("--distill-serve")
                    .spawn_reaped("spawn a live resident worker")
            })
            .collect();
        let started = std::time::Instant::now();
        let (mut max_bound, mut breaks, mut samples) = (0_i64, 0_u32, 0_u32);
        let drained = loop {
            max_bound = max_bound.max(bound_slots(&mut handle.admin));
            breaks += u32::from(i_slot_violations(&mut handle.admin) != 0);
            samples += 1;
            if open_outbox(&mut handle.admin, &m3_tenants) == 0 {
                break true;
            }
            if started.elapsed() > Duration::from_secs(900) {
                break false;
            }
            std::thread::sleep(Duration::from_millis(100));
        };
        for child in &mut workers {
            signal(child.id(), "TERM");
            let status = wait_exit(child, Duration::from_secs(150), "a live resident worker");
            assert!(status.success(), "{status:?}");
        }
        let report = double_spend::report(
            &mut handle.admin,
            &m3_tenants,
            PER_GEN_CALL_BUDGET,
            (2 * (LIVE_HTTP_SECS + 30)) as f64,
        );
        let histogram: Vec<(i64, i64)> = handle
            .admin
            .query(
                "SELECT calls, count(*) FROM (SELECT j.job_id, count(c.model_call_id) AS calls \
                   FROM ops.jobs j LEFT JOIN ops.distill_calls c USING (job_id) \
                   WHERE j.tenant_id = ANY($1) AND j.job_type = 'DERIVED_DISTILL' GROUP BY 1) g \
                 GROUP BY 1 ORDER BY 1",
                &[&m3_tenants],
            )
            .expect("call histogram")
            .into_iter()
            .map(|r| (r.get(0), r.get(1)))
            .collect();
        let twice_processed: i64 = handle
            .admin
            .query_one(
                "SELECT count(*) FROM (SELECT evidence_id FROM private.processing_runs \
                   WHERE tenant_id = ANY($1) AND completed_at IS NOT NULL GROUP BY 1 HAVING count(*) > 1) g",
                &[&m3_tenants],
            )
            .expect("memory sets")
            .get(0);
        let (done, failed) = outbox_done_failed(&mut handle.admin, &m3_tenants);
        let overlap = max_ledger_overlap(&mut handle.admin, &m3_tenants);
        println!(
            "M3 workers=2 n={} done={done} failed={failed} wall_s={:.1} calls_per_evidence={histogram:?} evidence_with_two_memory_sets={twice_processed} {}",
            m3_evidence.len(),
            started.elapsed().as_secs_f64(),
            report.line()
        );
        println!(
            "M4 m3 samples={samples} max_bound_slots={max_bound} i_slot_breaks={breaks} max_ledger_overlap={overlap}"
        );
        assert!(drained, "M3: the backlog did not drain within 900 s");
        assert_eq!(
            (
                report.duplicates,
                report.overlaps,
                report.per_gen_over_budget,
                report.unattributed_succeeded
            ),
            (0, 0, 0, 0),
            "{}",
            report.line()
        );
        assert_eq!(twice_processed, 0, "one memory set per Evidence");
        assert_eq!(done + failed, m3_evidence.len() as i64);
        assert!(max_bound <= 4 && overlap <= 4, "M4: in-flight above 4");
        assert_eq!(breaks, 0, "I-SLOT");

        // ---- M5: kill -9 mid-call ----
        let m5 = new_tenant(&mut handle, "m5 kill9");
        let m5_row = accept_evidence_marked(&mut handle, m5, &live_note("m5", 0));
        let m5_job = handle.job_of(m5_row);
        let m5_env = |cmd: &mut std::process::Command| {
            cmd.env("HUMAUX_PRIVATE_WORKER_HTTP_TIMEOUT_SECS", "20")
                .env("HUMAUX_PRIVATE_WORKER_DISTILL_LEASE_SECS", "5")
                .env("HUMAUX_PRIVATE_WORKER_DISTILL_HARD_DEADLINE_SECS", "50")
                .arg("--distill-serve");
        };
        let live_tenants = handle.tenant_ids();
        let live_map = credentials_spec(&mut handle.admin, &live_tenants, "MINIMAX_API_KEY");
        let mut cmd = live_serve_command(&worker_dsn, &key, &live_map);
        m5_env(&mut cmd);
        let mut victim = cmd.spawn_reaped("spawn the kill -9 victim");
        let started = std::time::Instant::now();
        let (uncertain_call, gen_one): (Uuid, i32) = loop {
            let row = handle
                .admin
                .query_opt(
                    "SELECT dispatch_model_call_id, claim_generation FROM ops.jobs \
                     WHERE job_id = $1 AND dispatch_state = 'DISPATCH_INTENT'",
                    &[&m5_job],
                )
                .expect("probe");
            if let Some(row) = row {
                break (row.get(0), row.get(1));
            }
            assert!(
                started.elapsed() < Duration::from_secs(120),
                "M5: the victim never dispatched"
            );
            std::thread::sleep(Duration::from_millis(20));
        };
        signal(victim.id(), "KILL");
        let _ = victim.wait();
        let killed_at = std::time::Instant::now();
        let mut cmd = live_serve_command(&worker_dsn, &key, &live_map);
        m5_env(&mut cmd);
        let mut survivor = cmd.spawn_reaped("spawn the surviving worker");
        let (mut uncertain_with_slot, mut t6) = (false, None::<(Duration, f64, i32)>);
        let m5_done = loop {
            let row = handle
                .admin
                .query_one(
                    "SELECT j.status, j.dispatch_state, j.last_error_class, j.attempt, \
                            extract(epoch FROM clock_timestamp())::float8, \
                            EXISTS (SELECT 1 FROM ops.provider_slots s \
                                    WHERE s.job_id = j.job_id AND s.claim_generation = $2) \
                     FROM ops.jobs j WHERE j.job_id = $1",
                    &[&m5_job, &gen_one],
                )
                .expect("M5 sample");
            let (status, state, class, attempt, now, slot): (
                String,
                Option<String>,
                Option<String>,
                i32,
                f64,
                bool,
            ) = (
                row.get(0),
                row.get(1),
                row.get(2),
                row.get(3),
                row.get(4),
                row.get(5),
            );
            uncertain_with_slot |= state.as_deref() == Some("EXECUTION_UNCERTAIN") && slot;
            if t6.is_none()
                && status != "PROCESSING"
                && class.as_deref() == Some("EXECUTION_UNCERTAIN")
            {
                t6 = Some((killed_at.elapsed(), now, attempt));
            }
            if status == "DONE" || status == "DEAD" {
                break status;
            }
            assert!(
                killed_at.elapsed() < Duration::from_secs(240),
                "M5: the job never settled after the kill ({status} {state:?} {class:?})"
            );
            std::thread::sleep(Duration::from_millis(200));
        };
        signal(survivor.id(), "TERM");
        let status = wait_exit(
            &mut survivor,
            Duration::from_secs(90),
            "the surviving worker",
        );
        assert!(status.success(), "{status:?}");
        let ledger_status: String = handle
            .admin
            .query_one(
                "SELECT status FROM ops.model_call_ledger WHERE model_call_id = $1",
                &[&uncertain_call],
            )
            .expect("uncertain ledger row")
            .get(0);
        let resend_after_t6: Option<bool> = t6.map(|(_, t6_db, _)| {
            handle
                .admin
                .query_one(
                    "SELECT bool_and(extract(epoch FROM begun_at)::float8 > $2) FROM ops.distill_calls \
                     WHERE job_id = $1 AND claim_generation > $3",
                    &[&m5_job, &t6_db, &gen_one],
                )
                .expect("resend order")
                .get::<_, Option<bool>>(0)
                .unwrap_or(false)
        });
        println!(
            "M5 uncertain_with_slot_kept={uncertain_with_slot} reconcile_delay_s={:?} attempt_at_t6={:?} uncertain_ledger_status={ledger_status} resend_after_t6={resend_after_t6:?} final={m5_done} calls={}",
            t6.map(|(d, _, _)| d.as_secs_f64()),
            t6.map(|(_, _, a)| a),
            handle.calls_of(m5_job)
        );
        assert!(uncertain_with_slot, "M5: T5 must keep the slot");
        let (_, _, attempt_at_t6) = t6.expect("M5: T6 reconcile never observed");
        assert_eq!(attempt_at_t6, 1, "the uncertain call stays counted");
        assert_eq!(
            ledger_status, "RESERVED",
            "the killed call's outcome is unknown"
        );
        assert_eq!(resend_after_t6, Some(true), "no resend before T6");
        assert_eq!(m5_done, "DONE");

        // ---- M7: inferred affect rows ----
        let m7 = new_tenant(&mut handle, "m7 affect");
        let feelings = [
            "I am thrilled: the migration finished two days early and the whole team celebrated together.",
            "Honestly I feel anxious about tomorrow's launch; the load tests kept failing all week.",
            "I was furious when the vendor cancelled our contract without any warning yesterday.",
            "I feel deeply grateful to Maria for staying late to fix the billing outage with me.",
            "Losing the Hamburg customer left me sad and exhausted after months of work on that account.",
        ];
        for text in feelings {
            accept_evidence_marked(&mut handle, m7, text);
        }
        let m7_tenant = handle.tenants[m7].tenant_id;
        let served = serve_until(
            &handle,
            &live,
            &live_config("c32-m7", 30.0, 4),
            Duration::from_secs(300),
            |admin| open_outbox(admin, &[m7_tenant]) == 0,
        );
        let row = handle
            .admin
            .query_one(
                "SELECT count(*) FILTER (WHERE origin = 'DISTILL'), \
                        count(*) FILTER (WHERE origin = 'DISTILL' AND confidence_bp > 5000), \
                        count(DISTINCT memory_id) FILTER (WHERE origin = 'DISTILL') \
                 FROM private.memory_affects WHERE tenant_id = $1",
                &[&m7_tenant],
            )
            .expect("affect rows");
        let (inferred, over_ceiling, memories): (i64, i64, i64) =
            (row.get(0), row.get(1), row.get(2));
        println!(
            "M7 evidence=5 inferred_affect_rows={inferred} memories_with_inferred_affect={memories} over_ceiling={over_ceiling} report={}",
            served.report.summary_line()
        );
        assert!(served.met, "M7: the affect Evidence did not settle");
        assert!(
            inferred > 0,
            "M7: no inferred affect row from 5 emotional Evidence"
        );
        assert_eq!(over_ceiling, 0, "inferred confidence ≤ 5000");

        // ---- M8: one tenant, two reasoning domains ----
        let m8 = new_tenant(&mut handle, "m8 two domains");
        let m8_tenant = handle.tenants[m8].tenant_id;
        let second = handle.add_domain(m8, "private derived_dispatch_e2e live m8 domain 2");
        let first = handle.tenants[m8].reasoning_domain_id;
        for n in 0..3 {
            accept_evidence_in(&mut handle, m8_tenant, second, &live_note("m8d2", n));
            accept_evidence_in(&mut handle, m8_tenant, first, &live_note("m8d1", n));
        }
        let served = serve_until(
            &handle,
            &live,
            &live_config("c32-m8", 30.0, 4),
            Duration::from_secs(300),
            |admin| open_outbox(admin, &[m8_tenant]) == 0,
        );
        let per_domain: Vec<(Uuid, String, i64)> = handle
            .admin
            .query(
                "SELECT e.reasoning_domain_id, o.status, count(*) FROM ops.outbox o \
                   JOIN private.evidence_objects e USING (evidence_id) \
                 WHERE o.tenant_id = $1 GROUP BY 1, 2 ORDER BY 1, 2",
                &[&m8_tenant],
            )
            .expect("per-domain outbox")
            .into_iter()
            .map(|r| (r.get(0), r.get(1), r.get(2)))
            .collect();
        let (done, failed) = outbox_done_failed(&mut handle.admin, &[m8_tenant]);
        println!(
            "M8 domains=2 evidence=6 done={done} failed={failed} per_domain={per_domain:?} report={}",
            served.report.summary_line()
        );
        assert!(served.met, "M8: the two-domain tenant did not settle");
        assert_eq!((done, failed), (6, 0), "all Evidence distilled, FAILED = 0");
        handle.assert_i_slot();
    });
}

// ---------------------------------------------------------------------------
// ADR-0058 R10: the live channel A/B probe (a measurement, not an acceptance bound).
// ---------------------------------------------------------------------------

/// The A/B probe's Evidence count per channel (R10: n >= 100, the SAME texts on both channels).
const AB_N: usize = 100;

/// `AB_N` distinct realistic notes of the kinds the rehearsal and soak write: facts, preferences,
/// decisions, dated items, identifiers and emotional content. No `"` or `\`, so each text appears
/// verbatim in the request's user prompt (the recorder keys calls by it); no uuid.
fn ab_notes() -> Vec<String> {
    const TEMPLATES: [&str; 20] = [
        "We decided to move the {a} service to the new cluster before the end of {b}; the old nodes get drained one by one.",
        "I prefer short code reviews for {a} changes, ideally under {b} hundred lines, and I always want the tests in the same pull request.",
        "Fact: the {a} database is backed up every night at {b} am and the snapshots are kept for thirty days.",
        "Honestly I was really frustrated today, the {a} deploy failed three times and nobody answered on call until {b} pm.",
        "Meeting note from {b}: the team agreed that {a} owns the incident runbook from now on.",
        "Ticket OPS-{b}4 tracks the {a} latency regression; p95 went from 180 ms to 420 ms after release v2.{b}.0.",
        "Reminder for myself: renew the TLS certificate of the {a} gateway before {b} October, it expires at midnight UTC.",
        "I am relieved, the {a} migration finally finished without data loss after two weekends of work.",
        "The {a} team prefers Rust for new backend services because of memory safety, and Go only for small tools.",
        "Decision: from {b} onwards every {a} change needs a feature flag and a rollback plan written in the ticket.",
        "Customer feedback says the {a} page is confusing; {b} of the last ten support calls were about it.",
        "My manager asked me to take over the {a} roadmap next quarter and I feel nervous but also excited about it.",
        "The {a} API rate limit is {b}0 requests per second per tenant; anything above returns HTTP 429.",
        "We rejected the proposal to rewrite {a} in a new framework because the team has no time before {b}.",
        "Note: PR #{b}12 fixes the timezone bug in {a} where reports used local time instead of UTC.",
        "I like to start the day with the {a} dashboard and keep meetings after {b} am whenever possible.",
        "Postmortem summary: the {a} outage on {b} March lasted 47 minutes and was caused by an expired credential.",
        "The {a} contract with the vendor renews every year in {b}; legal needs sixty days notice to cancel.",
        "I am worried about the {a} on-call load, I was paged {b} times this week and slept badly.",
        "Architecture choice: {a} events go through the outbox table first, never straight to the queue, decided on {b} June.",
    ];
    const SERVICES: [&str; 5] = ["billing", "search", "payroll", "shipping", "catalog"];
    const SECONDS: [&str; 5] = ["3", "5", "7", "8", "9"];
    let mut notes = Vec::with_capacity(AB_N);
    for n in 0..AB_N {
        let template = TEMPLATES[n % TEMPLATES.len()];
        let variant = n / TEMPLATES.len();
        notes.push(
            template
                .replace("{a}", SERVICES[variant % SERVICES.len()])
                .replace("{b}", SECONDS[(variant + n) % SECONDS.len()]),
        );
    }
    notes
}

/// One provider call the [`RecordingProvider`] saw: which note it carried, how long it took and
/// what came back (`Ok((json, channel_fallback))` or the error's static class).
struct RecordedCall {
    note: Option<usize>,
    latency: Duration,
    outcome: Result<(String, bool), &'static str>,
}

/// Delegates every call to the live provider and records it (ADR-0058 R10: the probe measures the
/// first reply per Evidence, which the worker's counters fold away).
struct RecordingProvider<P> {
    inner: P,
    notes: Vec<String>,
    calls: Mutex<Vec<RecordedCall>>,
}

#[async_trait::async_trait]
impl<P: UserReasoningProvider> UserReasoningProvider for RecordingProvider<P> {
    fn descriptor(&self) -> &ReasoningProviderDescriptor {
        self.inner.descriptor()
    }

    fn endpoint_ref(&self) -> &str {
        self.inner.endpoint_ref()
    }

    fn model_revision(&self) -> Option<&str> {
        self.inner.model_revision()
    }

    async fn complete_structured(
        &self,
        context: &PrivateInferenceContext,
        request: StructuredReasoningRequest,
    ) -> Result<StructuredReasoningResponse, ReasoningProviderError> {
        let note = self
            .notes
            .iter()
            .position(|text| request.user_prompt.contains(text.as_str()));
        let started = std::time::Instant::now();
        let answer = self.inner.complete_structured(context, request).await;
        let outcome = match &answer {
            Ok(response) => Ok((response.json.clone(), response.channel_fallback)),
            Err(error) => Err(error.class()),
        };
        self.calls.lock().expect("calls").push(RecordedCall {
            note,
            latency: started.elapsed(),
            outcome,
        });
        answer
    }

    async fn analyze_vision(
        &self,
        _context: &PrivateInferenceContext,
        _request: VisionReasoningRequest,
    ) -> Result<VisionReasoningResponse, ReasoningProviderError> {
        unreachable!("distill never calls vision")
    }
}

/// Nearest-rank percentile of `sorted` in ms (`-` when empty).
fn percentile_ms(sorted: &[Duration], pct: usize) -> String {
    if sorted.is_empty() {
        return "-".to_owned();
    }
    let rank = (pct * sorted.len()).div_ceil(100).max(1) - 1;
    sorted[rank.min(sorted.len() - 1)].as_millis().to_string()
}

/// ADR-0058 R10 — the live A/B probe of the Distill output channel. The SAME [`AB_N`] Evidence
/// texts go once through the tool channel (with R9's `content` fallback) and once through the
/// content channel, same model, `in_flight` 4, each channel in its own tenant. One `AB` line per
/// channel: Evidence DONE / DEAD, first replies the ADR-0048 parser (or the tool-call shape) refused
/// and by which class, R9 fallbacks, dropped affects, provider calls and per-call latency p50/p95.
/// Asserts only that both runs finished: the comparison is a measurement, and R10's rule (tool
/// channel only if its DEAD count and first-reply malformed rate are not higher) is applied to the
/// rehearsal profile by hand and recorded in ADR-0058 D-M.
#[test]
#[ignore = "lane(a:shared_db) live MiniMax measurement (card 32 R10 distill_channel_ab_live): run with --include-ignored and HUMAUX_REQUIRE_MINIMAX=1"]
#[allow(clippy::too_many_lines)]
fn distill_channel_ab_live() {
    let Some(key) = live_minimax::load_minimax_key() else {
        humaux_testkit::skip_or_fail(
            "distill_channel_ab_live",
            "missing object: MINIMAX_API_KEY (env and /Volumes/data/viral-skill-eval/.env both empty)",
            humaux_testkit::ExternalDep::MiniMax,
        );
        return;
    };
    run("distill_channel_ab_live", |mut handle| {
        // SAFETY: set while SERIAL_GUARD is held (see `distill_fairness_live`).
        unsafe {
            std::env::set_var("HUMAUX_PRIVATE_WORKER_CANDIDATE_TTL_SECONDS", "604800");
        }
        let http = Duration::from_secs(LIVE_HTTP_SECS);
        let notes = ab_notes();
        let distinct: std::collections::BTreeSet<&String> = notes.iter().collect();
        assert_eq!(distinct.len(), AB_N, "the probe's texts are distinct");
        let offer_affects = humaux_adapters::distill_reasoner::offers_affects(
            humaux_domain::evidence::EvidenceOriginClass::DirectUserInput,
        );
        let mut finished = Vec::new();
        for (channel, capabilities) in [
            ("tool", &live_minimax::REHEARSAL_CAPABILITIES[..]),
            (
                "content",
                &[
                    ReasoningCapability::Text,
                    ReasoningCapability::StructuredOutput,
                ][..],
            ),
        ] {
            let idx = handle
                .add_tenant_declaring(
                    &format!("private derived_dispatch_e2e live ab {channel}"),
                    Some(EGRESS_PROCESSOR_ID),
                    capabilities,
                )
                .expect("live tenant");
            for text in &notes {
                accept_evidence_marked(&mut handle, idx, text);
            }
            let tenants = vec![handle.tenants[idx].tenant_id];
            let provider = Arc::new(RecordingProvider {
                inner: live_minimax::live_provider_declaring(
                    key.clone(),
                    MODEL_ID,
                    http,
                    capabilities,
                ),
                notes: notes.clone(),
                calls: Mutex::new(Vec::new()),
            });
            let served = serve_until(
                &handle,
                &provider,
                &live_config(&format!("c32-ab-{channel}"), 30.0, 4),
                Duration::from_secs(1800),
                |admin| open_outbox(admin, &tenants) == 0,
            );
            let (done, _) = outbox_done_failed(&mut handle.admin, &tenants);
            let dead: i64 = handle
                .admin
                .query_one(
                    "SELECT count(*) FROM ops.jobs WHERE tenant_id = ANY($1) \
                       AND job_type = 'DERIVED_DISTILL' AND status = 'DEAD'",
                    &[&tenants],
                )
                .expect("dead jobs")
                .get(0);
            let calls = std::mem::take(&mut *provider.calls.lock().expect("calls"));
            let mut first: Vec<Option<&RecordedCall>> = vec![None; AB_N];
            for call in &calls {
                if let Some(n) = call.note
                    && first[n].is_none()
                {
                    first[n] = Some(call);
                }
            }
            let mut by_class = std::collections::BTreeMap::<&str, u32>::new();
            for call in first.iter().flatten() {
                let class = match &call.outcome {
                    Err(class) if *class == ReasoningProviderError::FAILED_OUTPUT_SCHEMA_CLASS => {
                        Some("tool_call_shape")
                    }
                    Err(_) => None,
                    Ok((json, _)) => {
                        humaux_adapters::distill_reasoner::parse_distill_output_detailed(
                            json.as_bytes(),
                            offer_affects,
                        )
                        .err()
                        .map(humaux_adapters::distill_reasoner::DistillParseError::as_str)
                    }
                };
                if let Some(class) = class {
                    *by_class.entry(class).or_default() += 1;
                }
            }
            let mut latencies: Vec<Duration> = calls.iter().map(|c| c.latency).collect();
            latencies.sort();
            let classes = if by_class.is_empty() {
                "-".to_owned()
            } else {
                by_class
                    .iter()
                    .map(|(class, k)| format!("{class}:{k}"))
                    .collect::<Vec<_>>()
                    .join(",")
            };
            println!(
                "AB channel={channel} n={AB_N} done={done} dead={dead} first_reply_malformed={} by_class={classes} channel_fallback={} affects_dropped={} calls={} latency_p50_ms={} latency_p95_ms={}",
                by_class.values().sum::<u32>(),
                served.report.channel_fallback,
                served.report.affects_dropped,
                calls.len(),
                percentile_ms(&latencies, 50),
                percentile_ms(&latencies, 95),
            );
            println!(
                "AB channel={channel} unmatched_calls={} wall_s={:.1} report={}",
                calls.iter().filter(|c| c.note.is_none()).count(),
                served.wall.as_secs_f64(),
                served.report.summary_line()
            );
            if !served.met {
                retire_open_jobs(&mut handle.admin, &tenants);
            }
            finished.push((channel, served.met));
        }
        assert!(
            finished.iter().all(|(_, met)| *met),
            "both channels must finish their backlog: {finished:?}"
        );
    });
}
