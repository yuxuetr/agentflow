//! Real LLM-backed [`HarnessSessionExecutor`] (P-H.5 slice 2).
//!
//! Replaces the [`StubHarnessExecutor`] for deployments that have an LLM
//! provider configured. Wires `agentflow-harness::HarnessRuntime` around
//! a `ReActAgent`, hooks tool execution through `wrap_registry` so the
//! shared `ServerApprovalProvider` can park decisions, and routes the
//! resulting `HarnessEvent` stream into the server's
//! [`HarnessEventBroker`] + Postgres event log.
//!
//! [`StubHarnessExecutor`]: crate::harness::StubHarnessExecutor

use std::path::PathBuf;
use std::sync::Arc;
use std::time::Duration;

use async_trait::async_trait;
use tokio::sync::OnceCell;
use tracing::{error, info, warn};

use agentflow_agent_spi::checkpoint::{
  AgentLoopCheckpoint, AgentLoopCheckpointer, LoopRuntimeKind,
};
use agentflow_agents::plan_execute::{PlanExecuteAgent, PlanExecuteConfig};
use agentflow_agents::react::{ReActAgent, ReActConfig};
use agentflow_agents::runtime::{AgentRuntime, AgentStopReason, RuntimeLimits};
use agentflow_harness::{
  ApprovalProvider, HarnessEvent, HarnessEventBody, HarnessEventSink, HarnessProfile,
  HarnessRunOptions, HarnessRuntime, HarnessRuntimeKind, HookConfig, SeqAllocator, SinkChain,
  StopReason, StoppedPayload, default_providers, wrap_registry,
};
use agentflow_llm::AgentFlow;
use agentflow_memory::{MemoryStore, SessionMemory, SqliteMemory};
use agentflow_tools::ToolRegistry;

use agentflow_db::{
  DbLoopCheckpointer, HarnessEventRepo, HarnessSessionRepo, HarnessSessionStatus,
  NewHarnessSessionEvent, Repositories,
};

use crate::events_stream::broker_finalize_grace;
use crate::harness::{
  HarnessEventBroker, HarnessSessionContext, HarnessSessionExecutor, StreamedHarnessEvent,
};
use crate::harness_approval::{PendingApprovalRegistry, ServerApprovalProvider};

/// HarnessEventSink that fans every envelope out to:
///
/// - the `harness_session_events` Postgres table (durable history,
///   serves SSE backfill and JSON history);
/// - the process-local [`HarnessEventBroker`] (live SSE push).
///
/// Failures persist as `tracing::warn!` and are otherwise non-fatal:
/// the agent run continues even if the event log is briefly unavailable,
/// since dropping a synthetic event is safer than aborting a real
/// session. Subscribers can reconnect with `?after_seq=` to refill from
/// the DB once writes recover.
pub struct ServerHarnessEventSink {
  repos: Repositories,
  broker: HarnessEventBroker,
}

impl ServerHarnessEventSink {
  pub fn new(repos: Repositories, broker: HarnessEventBroker) -> Self {
    Self { repos, broker }
  }
}

#[async_trait]
impl HarnessEventSink for ServerHarnessEventSink {
  fn name(&self) -> &str {
    "server"
  }

  async fn write(&self, event: &HarnessEvent) -> Result<(), agentflow_harness::HarnessError> {
    let Ok(session_uuid) = uuid::Uuid::parse_str(&event.session_id) else {
      // Non-UUID session id arrived (test runtime or external caller).
      // Drop with a warning; the contract guarantees server-managed
      // sessions always pass through `Uuid::new_v4()`.
      warn!(
        session_id = %event.session_id,
        seq = event.seq,
        "harness event sink: session id is not a UUID, skipping persistence"
      );
      return Ok(());
    };
    let kind = harness_event_kind(&event.body);
    let payload = serde_json::to_value(&event.body).unwrap_or(serde_json::Value::Null);

    let new_event = NewHarnessSessionEvent {
      session_id: session_uuid,
      seq: event.seq as i64,
      kind: kind.to_string(),
      payload,
    };
    match self.repos.harness_events.append(new_event).await {
      Ok(stored) => {
        self.broker.publish(StreamedHarnessEvent::from(stored));
        Ok(())
      }
      Err(err) => {
        warn!(
          session_id = %event.session_id,
          seq = event.seq,
          error = %err,
          "harness event sink: persist failed"
        );
        // Surface to the runtime as Ok so the agent keeps running. The
        // event is lost from the live stream; subscribers can pull
        // history once persistence recovers.
        Ok(())
      }
    }
  }
}

fn harness_event_kind(body: &HarnessEventBody) -> &'static str {
  match body {
    HarnessEventBody::SessionStarted(_) => "session_started",
    HarnessEventBody::StepStarted(_) => "step_started",
    HarnessEventBody::ToolCallRequested(_) => "tool_call_requested",
    HarnessEventBody::ApprovalRequested(_) => "approval_requested",
    HarnessEventBody::ApprovalDecided(_) => "approval_decided",
    HarnessEventBody::ToolCallCompleted(_) => "tool_call_completed",
    HarnessEventBody::TokenDelta(_) => "token_delta",
    HarnessEventBody::InterruptRequested(_) => "interrupt_requested",
    HarnessEventBody::InterruptAnswered(_) => "interrupt_answered",
    HarnessEventBody::BackgroundTaskUpdated(_) => "background_task_updated",
    HarnessEventBody::MemorySummaryAdded(_) => "memory_summary_added",
    HarnessEventBody::Stopped(_) => "stopped",
  }
}

/// LLM-backed harness executor.
///
/// Each `execute` call assembles a fresh `ReActAgent` + `HarnessRuntime`
/// around the session's context (workspace_root, profile, runtime kind,
/// model). The executor calls [`AgentFlow::init`] lazily on first use so
/// the test suite doesn't pay for provider config when running the stub
/// path.
///
/// W0.1: every session gets a real, governed tool registry — read-only
/// file access scoped to `workspace_root` plus outbound HTTP (see
/// `build_default_tool_registry`) — wrapped through `wrap_registry` with
/// `ServerApprovalProvider` so the approval pipeline has something to
/// actually govern. Skill-backed tool loading (`skill_name` beyond this
/// default) and MCP/plugin capability come in via subsequent slices
/// (W4.1's tool distribution contract).
#[derive(Clone)]
pub struct LiveHarnessExecutor {
  approval_registry: PendingApprovalRegistry,
  approval_timeout: Duration,
  /// Q3.4.3: bounds concurrent harness sessions. Each session spawns
  /// a dedicated OS thread via `spawn_blocking`; uncapped that's a
  /// DoS vector (`/v1/harness/sessions` has no rate limit). The
  /// semaphore caps in-flight executions; callers wait for a permit
  /// before starting their session's blocking runtime. Default cap
  /// is set by `default_max_concurrent_sessions()` (32) and is
  /// overridable via `with_max_concurrent_sessions()`.
  concurrency_limit: Arc<tokio::sync::Semaphore>,
}

/// Q3.4.3: production-safe default cap on concurrent live harness
/// sessions. Each session burns an OS thread for the duration of its
/// run, so the cap is the upper bound on extra OS threads the live
/// executor will materialize. 32 is a balance between local-dev
/// ergonomics (rarely hit) and shared-infra survival.
pub fn default_max_concurrent_sessions() -> usize {
  32
}

impl LiveHarnessExecutor {
  pub fn new(approval_registry: PendingApprovalRegistry, approval_timeout: Duration) -> Self {
    Self {
      approval_registry,
      approval_timeout,
      concurrency_limit: Arc::new(tokio::sync::Semaphore::new(
        default_max_concurrent_sessions(),
      )),
    }
  }

  /// Q3.4.3: override the default concurrency cap. `0` is treated as
  /// "1" so the executor always permits forward progress.
  pub fn with_max_concurrent_sessions(mut self, max: usize) -> Self {
    let max = max.max(1);
    self.concurrency_limit = Arc::new(tokio::sync::Semaphore::new(max));
    self
  }
}

impl std::fmt::Debug for LiveHarnessExecutor {
  fn fmt(&self, f: &mut std::fmt::Formatter<'_>) -> std::fmt::Result {
    f.debug_struct("LiveHarnessExecutor")
      .field("approval_timeout", &self.approval_timeout)
      .finish()
  }
}

#[async_trait]
impl HarnessSessionExecutor for LiveHarnessExecutor {
  async fn execute(&self, ctx: HarnessSessionContext) {
    let Some(_permit_guard) = self.acquire_permit(&ctx).await else {
      return;
    };
    if let Err(err) = live_execute(self, &ctx).await {
      handle_live_failure(&ctx, &err).await;
    }
  }

  async fn resume_interrupt(&self, ctx: HarnessSessionContext, answer: String) {
    let Some(_permit_guard) = self.acquire_permit(&ctx).await else {
      return;
    };
    if let Err(err) = live_resume_interrupt(self, &ctx, answer).await {
      handle_live_failure(&ctx, &err).await;
    }
  }
}

impl LiveHarnessExecutor {
  /// Q3.4.3: acquire the per-process concurrency permit before spawning
  /// the OS thread that runs a session. Without this gate a flood of
  /// `POST /v1/harness/sessions` (or `.../interrupt/answer`) would spawn
  /// one OS thread per request — `spawn_blocking` doesn't bound thread
  /// count by itself. `None` means the semaphore is permanently closed
  /// (collector shutdown); the caller should bail out without running.
  async fn acquire_permit(
    &self,
    ctx: &HarnessSessionContext,
  ) -> Option<tokio::sync::OwnedSemaphorePermit> {
    match self.concurrency_limit.clone().acquire_owned().await {
      Ok(permit) => Some(permit),
      Err(_closed) => {
        warn!(session_id = %ctx.session_id, "harness concurrency semaphore closed; rejecting session");
        None
      }
    }
  }
}

/// Shared failure path for [`LiveHarnessExecutor::execute`] and
/// [`LiveHarnessExecutor::resume_interrupt`]: mark the session `Failed`
/// and emit a terminal `stopped` event so SSE subscribers and event-log
/// consumers see the H0 contract's required close signal. Two failure
/// shapes need this:
///   1. the live call errored before `HarnessRuntime` could start (e.g.
///      LLM init / checkpoint load failed), so nothing but
///      `session_started` (or nothing at all) was ever written.
///   2. `HarnessRuntime` errored mid-way (inner agent failed) and does
///      not itself emit `stopped` on its error path.
///
/// Both leave the broker open and the event history missing a terminal
/// kind, which the closed kind set documented in `docs/HARNESS_MODE.md`
/// promises is always present.
async fn handle_live_failure(ctx: &HarnessSessionContext, err: &LiveExecutorError) {
  let err_msg = err.to_string();
  error!(session_id = %ctx.session_id, error = %err_msg, "live harness executor failed");
  let _ = ctx
    .repos
    .harness_sessions
    .update_status(
      ctx.session_id,
      HarnessSessionStatus::Failed,
      None,
      Some(&err_msg),
    )
    .await;
  emit_failure_stopped_event(ctx, &err_msg).await;
  ctx
    .broker
    .finalise_with_grace(ctx.session_id, broker_finalize_grace());
}

/// Persist + publish a synthetic `stopped` event with
/// `StopReason::Failed` for a session whose execution failed before the
/// runtime could emit its own terminal event. seq is computed from the
/// current `MAX(seq)` in the event log so the synthetic event always
/// lands after whatever the runtime did manage to write (typically a
/// solitary `session_started`).
async fn emit_failure_stopped_event(ctx: &HarnessSessionContext, err_msg: &str) {
  let next_seq = match ctx.repos.harness_events.max_seq(ctx.session_id).await {
    Ok(Some(max)) => (max as u64).saturating_add(1),
    Ok(None) => 0,
    Err(err) => {
      warn!(
        session_id = %ctx.session_id,
        error = %err,
        "harness failure-stopped emit: max_seq lookup failed, skipping",
      );
      return;
    }
  };
  let event = HarnessEvent {
    seq: next_seq,
    session_id: ctx.session_id.to_string(),
    ts: chrono::Utc::now(),
    body: HarnessEventBody::Stopped(StoppedPayload {
      reason: StopReason::Failed,
      final_answer: None,
      error: Some(err_msg.to_string()),
    }),
  };
  let sink = ServerHarnessEventSink::new(ctx.repos.clone(), ctx.broker.clone());
  if let Err(err) = sink.write(&event).await {
    warn!(
      session_id = %ctx.session_id,
      error = %err,
      "harness failure-stopped emit: sink write failed",
    );
  }
}

/// Lazy AgentFlow init guard so the LLM registry is loaded at most once
/// per process. Subsequent calls are no-ops and return immediately.
async fn ensure_llm_initialized() -> Result<(), LiveExecutorError> {
  static INIT: OnceCell<()> = OnceCell::const_new();
  INIT
    .get_or_try_init(|| async { AgentFlow::init().await.map_err(LiveExecutorError::from) })
    .await
    .map(|_| ())
}

/// Snapshot of the inputs the inner harness session needs. We move a
/// fresh owned copy onto the blocking thread so the spawned task is
/// `'static` and doesn't carry a borrow of [`HarnessSessionContext`].
#[derive(Clone)]
struct RunInputs {
  session_id: uuid::Uuid,
  user_input: String,
  workspace_root: String,
  profile: String,
  runtime_kind: String,
  model: String,
  skill_name: Option<String>,
  /// U1.3: see `HarnessSessionContext::cost_limit_usd`.
  cost_limit_usd: Option<f64>,
  /// W0.1: see `HarnessSessionContext::max_steps`.
  max_steps: Option<usize>,
  repos: Repositories,
  broker: HarnessEventBroker,
  initial_seq: u64,
}

fn clone_run_inputs(ctx: &HarnessSessionContext) -> RunInputs {
  RunInputs {
    session_id: ctx.session_id,
    user_input: ctx.user_input.clone(),
    workspace_root: ctx.workspace_root.clone(),
    profile: ctx.profile.clone(),
    runtime_kind: ctx.runtime_kind.clone(),
    model: ctx.model.clone(),
    skill_name: ctx.skill_name.clone(),
    cost_limit_usd: ctx.cost_limit_usd,
    max_steps: ctx.max_steps,
    repos: ctx.repos.clone(),
    broker: ctx.broker.clone(),
    initial_seq: ctx.initial_seq,
  }
}

/// W0.1: default step cap when the request doesn't specify one — matches
/// `RuntimeLimits::react_defaults()`.
const DEFAULT_MAX_STEPS: usize = 15;

/// W0.1: hard server-side ceiling regardless of what the request asks
/// for, so a careless or malicious caller can't run an unbounded loop.
const MAX_STEPS_CEILING: usize = 50;

fn resolve_max_steps(requested: Option<usize>) -> usize {
  requested
    .unwrap_or(DEFAULT_MAX_STEPS)
    .min(MAX_STEPS_CEILING)
}

/// W0.1: build the tool registry a harness session governs. Real tools —
/// not an always-empty `ToolRegistry::new()` — are what makes the
/// hook/approval pipeline meaningful: without them `wrap_registry` has
/// nothing to wrap and the session can never produce an
/// `approval_requested` event, no matter how the profile is configured.
///
/// Skill-backed tool loading (`inputs.skill_name`) is not wired yet — the
/// full form (tool distribution contract, W4.1) is tracked separately.
/// Until then every session, skill-named or not, gets this same safe
/// default: read-only file access scoped to the workspace root, plus
/// outbound HTTP.
fn build_default_tool_registry(workspace_root: &str) -> Result<ToolRegistry, LiveExecutorError> {
  agentflow_tools::default_governed_registry(std::path::Path::new(workspace_root)).map_err(|err| {
    LiveExecutorError::Harness(agentflow_harness::HarnessError::Other(format!(
      "failed to build default tool registry: {err}"
    )))
  })
}

/// Runs `HarnessRuntime::run` on a dedicated current-thread Tokio
/// runtime hosted inside `tokio::task::spawn_blocking`.
///
/// **Why:** `HarnessRuntime::run` holds `&self` across `.await` points
/// (it calls `self.collect_context(...).await` and friends). For its
/// future to be `Send`, `HarnessRuntime: Sync` would have to hold — but
/// the inner `Box<dyn AgentRuntime>` is `Send`-only because
/// `AgentRuntime: Send`. The smoke test in `agentflow-harness` works
/// around this by being a `current_thread` tokio test (no `Send`
/// requirement on the test future). Server-side we want the same
/// relaxed-Send execution environment without forcing the rest of the
/// server onto a current-thread runtime, so we offload onto
/// `spawn_blocking` and start an isolated current-thread runtime
/// there. The cost is one OS thread per concurrent harness session,
/// which is acceptable for now and is removed once `HarnessRuntime` is
/// updated to thread `&mut self` (or `Sync` is added to
/// `AgentRuntime`).
/// Build the harness agent's conversation memory.
///
/// When `AGENTFLOW_HARNESS_MEMORY_DB` is set to a non-empty path, use a
/// persistent SQLite store (keyed by session_id, WAL + busy_timeout via
/// the shared sqlite pool) so a `:resume` reads the prior turns back
/// across process restarts — long-lived server sessions. Otherwise the
/// in-process default (unchanged behaviour). Opt-in because a shared
/// SQLite file is a single-node assumption; multi-node deployments should
/// front it with their own backend.
async fn build_harness_memory() -> Result<Box<dyn MemoryStore>, LiveExecutorError> {
  match std::env::var("AGENTFLOW_HARNESS_MEMORY_DB")
    .ok()
    .filter(|p| !p.trim().is_empty())
  {
    Some(path) => open_persistent_harness_memory(path.trim()).await,
    None => Ok(Box::new(SessionMemory::default_window()) as Box<dyn MemoryStore>),
  }
}

/// Open a persistent SQLite conversation store at `path`, creating the
/// parent directory if needed. Keyed by session_id, so a resumed session
/// reads the prior turns back.
async fn open_persistent_harness_memory(
  path: &str,
) -> Result<Box<dyn MemoryStore>, LiveExecutorError> {
  let path = std::path::PathBuf::from(path);
  if let Some(parent) = path.parent().filter(|p| !p.as_os_str().is_empty()) {
    std::fs::create_dir_all(parent).map_err(|e| {
      LiveExecutorError::Harness(agentflow_harness::HarnessError::Other(format!(
        "could not create harness memory dir {}: {e}",
        parent.display()
      )))
    })?;
  }
  let store = SqliteMemory::open(&path).await.map_err(|e| {
    LiveExecutorError::Harness(agentflow_harness::HarnessError::Other(format!(
      "failed to open harness memory db {}: {e}",
      path.display()
    )))
  })?;
  Ok(Box::new(store))
}

async fn run_harness_blocking(
  executor: LiveHarnessExecutor,
  inputs: RunInputs,
) -> Result<agentflow_harness::HarnessRunResult, LiveExecutorError> {
  let join = tokio::task::spawn_blocking(move || -> Result<_, LiveExecutorError> {
    let rt = tokio::runtime::Builder::new_current_thread()
      .enable_all()
      .build()
      .map_err(|err| {
        LiveExecutorError::Harness(agentflow_harness::HarnessError::Other(format!(
          "failed to build inner runtime: {err}"
        )))
      })?;
    rt.block_on(run_harness_inner(executor, inputs))
  });
  match join.await {
    Ok(result) => result,
    Err(err) => Err(LiveExecutorError::Harness(
      agentflow_harness::HarnessError::Other(format!("harness task panicked: {err}")),
    )),
  }
}

async fn run_harness_inner(
  executor: LiveHarnessExecutor,
  inputs: RunInputs,
) -> Result<agentflow_harness::HarnessRunResult, LiveExecutorError> {
  let session_id_string = inputs.session_id.to_string();
  let profile = parse_profile(&inputs.profile);
  let runtime_kind = parse_runtime_kind(&inputs.runtime_kind);

  let server_sink: Arc<dyn HarnessEventSink> = Arc::new(ServerHarnessEventSink::new(
    inputs.repos.clone(),
    inputs.broker.clone(),
  ));
  let sinks = SinkChain::new().push(server_sink.clone());

  // Q1.7.1 + P-A3.4: one shared `SeqAllocator` for both the hook layer and the
  // runtime. Pre-Q1.7.1 they each owned an independent counter and mixed events
  // would collide on the JSON-Lines sink's `(session_id, seq)` PK. P-A3.4 adds
  // the emit lock to the shared unit so the hook layer's concurrent tool /
  // approval events and the runtime's live bridge events also reach the sink in
  // seq order, not just carry monotonic seq numbers.
  let seq_allocator = SeqAllocator::with_initial(inputs.initial_seq);

  let approval_provider: Arc<dyn ApprovalProvider> = Arc::new(ServerApprovalProvider::new(
    executor.approval_registry.clone(),
    executor.approval_timeout,
  ));

  let hook_config = HookConfig::new(session_id_string.clone(), approval_provider, sinks.clone())
    .with_profile(profile)
    .with_seq_allocator(seq_allocator.clone())
    .with_approval_timeout(executor.approval_timeout);

  let tools = build_default_tool_registry(&inputs.workspace_root)?;
  let registry = wrap_registry(tools, hook_config);

  let react_config = ReActConfig::new(&inputs.model);
  // Conversation memory: persistent (keyed by session_id) when the
  // operator configures it, so `:resume` continues prior turns across
  // restarts; otherwise the in-process default (back-compat).
  let memory = build_harness_memory().await?;
  let agent = ReActAgent::new(react_config, memory, Arc::new(registry));

  // V2.3: attach the Postgres-backed checkpointer unconditionally — same
  // "on by default" posture the CLI's `harness run` already established.
  // A session has to be continuously checkpointed for `resume_interrupt`
  // to ever have something to load, once the loop pauses on `ask_user`.
  let checkpointer: Arc<dyn AgentLoopCheckpointer> = Arc::new(DbLoopCheckpointer::new(
    inputs.repos.harness_sessions.pool.clone(),
  ));

  let mut runtime = HarnessRuntime::new(Box::new(agent))
    .with_event_sink(server_sink.clone())
    .with_context_providers(default_providers())
    .with_seq_allocator(seq_allocator.clone());

  let options = HarnessRunOptions::new(
    inputs.user_input,
    PathBuf::from(&inputs.workspace_root),
    inputs.model,
  )
  .with_profile(profile)
  .with_runtime_kind(runtime_kind)
  .with_session_id(session_id_string)
  .with_loop_checkpointer(checkpointer)
  .with_limits(RuntimeLimits {
    max_steps: Some(resolve_max_steps(inputs.max_steps)),
    cost_limit_usd: inputs.cost_limit_usd,
    ..Default::default()
  });
  let options = match inputs.skill_name.as_ref() {
    Some(name) => options.with_skill_name(name.clone()),
    None => options,
  };

  let result = runtime.run(options).await?;
  Ok(result)
}

/// V2.3: like [`run_harness_blocking`] but resumes a session paused on
/// [`AgentStopReason::AwaitingInput`] with the user's `answer`, instead of
/// starting a fresh run.
async fn run_harness_resume_blocking(
  executor: LiveHarnessExecutor,
  inputs: RunInputs,
  checkpoint: AgentLoopCheckpoint,
  answer: String,
) -> Result<agentflow_harness::HarnessRunResult, LiveExecutorError> {
  let join = tokio::task::spawn_blocking(move || -> Result<_, LiveExecutorError> {
    let rt = tokio::runtime::Builder::new_current_thread()
      .enable_all()
      .build()
      .map_err(|err| {
        LiveExecutorError::Harness(agentflow_harness::HarnessError::Other(format!(
          "failed to build inner runtime: {err}"
        )))
      })?;
    rt.block_on(run_harness_resume_inner(
      executor, inputs, checkpoint, answer,
    ))
  });
  match join.await {
    Ok(result) => result,
    Err(err) => Err(LiveExecutorError::Harness(
      agentflow_harness::HarnessError::Other(format!("harness task panicked: {err}")),
    )),
  }
}

/// V2.3: rebuild the inner agent matching `checkpoint.runtime_kind` (the
/// checkpoint is self-describing — it is not derived from `inputs.runtime_kind`,
/// since a checkpoint always records the runtime that actually produced it)
/// and dispatch through [`HarnessRuntime::resume_from_interrupt`].
async fn run_harness_resume_inner(
  executor: LiveHarnessExecutor,
  inputs: RunInputs,
  checkpoint: AgentLoopCheckpoint,
  answer: String,
) -> Result<agentflow_harness::HarnessRunResult, LiveExecutorError> {
  let session_id_string = inputs.session_id.to_string();
  let profile = parse_profile(&inputs.profile);

  let server_sink: Arc<dyn HarnessEventSink> = Arc::new(ServerHarnessEventSink::new(
    inputs.repos.clone(),
    inputs.broker.clone(),
  ));
  let sinks = SinkChain::new().push(server_sink.clone());
  let seq_allocator = SeqAllocator::with_initial(inputs.initial_seq);

  let approval_provider: Arc<dyn ApprovalProvider> = Arc::new(ServerApprovalProvider::new(
    executor.approval_registry.clone(),
    executor.approval_timeout,
  ));

  let hook_config = HookConfig::new(session_id_string.clone(), approval_provider, sinks.clone())
    .with_profile(profile)
    .with_seq_allocator(seq_allocator.clone())
    .with_approval_timeout(executor.approval_timeout);

  let tools = build_default_tool_registry(&inputs.workspace_root)?;
  let registry = Arc::new(wrap_registry(tools, hook_config));
  let memory = build_harness_memory().await?;

  let checkpointer: Arc<dyn AgentLoopCheckpointer> = Arc::new(DbLoopCheckpointer::new(
    inputs.repos.harness_sessions.pool.clone(),
  ));

  let inner_agent: Box<dyn AgentRuntime> = match checkpoint.runtime_kind {
    LoopRuntimeKind::React => {
      let react_config = ReActConfig::new(&inputs.model);
      Box::new(ReActAgent::new(react_config, memory, registry))
    }
    LoopRuntimeKind::PlanExecute => {
      let plan_config = PlanExecuteConfig::new(&inputs.model);
      Box::new(PlanExecuteAgent::new(plan_config, memory, registry))
    }
  };

  let mut runtime = HarnessRuntime::new(inner_agent)
    .with_event_sink(server_sink.clone())
    .with_seq_allocator(seq_allocator.clone());

  let options = HarnessRunOptions::new(
    inputs.user_input,
    PathBuf::from(&inputs.workspace_root),
    inputs.model,
  )
  .with_loop_checkpointer(checkpointer)
  .with_limits(RuntimeLimits {
    max_steps: Some(resolve_max_steps(inputs.max_steps)),
    cost_limit_usd: inputs.cost_limit_usd,
    ..Default::default()
  });

  let result = runtime
    .resume_from_interrupt(options, checkpoint, answer)
    .await?;
  Ok(result)
}

async fn live_execute(
  executor: &LiveHarnessExecutor,
  ctx: &HarnessSessionContext,
) -> Result<(), LiveExecutorError> {
  ensure_llm_initialized().await?;
  let result = run_harness_blocking(executor.clone(), clone_run_inputs(ctx)).await?;
  finish_live_result(ctx, &result).await
}

/// V2.3: resume a session paused on `awaiting_input` with the user's
/// `answer`. Loads the loop checkpoint the pause saved, rebuilds the
/// matching agent (`checkpoint.runtime_kind`), and dispatches through
/// `HarnessRuntime::resume_from_interrupt`.
async fn live_resume_interrupt(
  executor: &LiveHarnessExecutor,
  ctx: &HarnessSessionContext,
  answer: String,
) -> Result<(), LiveExecutorError> {
  ensure_llm_initialized().await?;
  let checkpointer = DbLoopCheckpointer::new(ctx.repos.harness_sessions.pool.clone());
  let checkpoint = checkpointer
    .load(&ctx.session_id.to_string())
    .await?
    .ok_or_else(|| {
      LiveExecutorError::Harness(agentflow_harness::HarnessError::Other(format!(
        "no loop checkpoint found for session {}",
        ctx.session_id
      )))
    })?;
  let result =
    run_harness_resume_blocking(executor.clone(), clone_run_inputs(ctx), checkpoint, answer)
      .await?;
  finish_live_result(ctx, &result).await
}

/// Persist the outcome of a fresh run or an interrupt resume, shared by
/// [`live_execute`] and [`live_resume_interrupt`].
///
/// `AgentStopReason::AwaitingInput` is a non-terminal pause, not a
/// terminal status transition like every other variant — it records the
/// question onto the session row's `pending_question*` columns via
/// `set_pending_question` instead of `update_status`, and returns early
/// without finalising the broker channel (the session isn't done; a
/// later `POST .../interrupt/answer` reuses the same channel).
async fn finish_live_result(
  ctx: &HarnessSessionContext,
  result: &agentflow_harness::HarnessRunResult,
) -> Result<(), LiveExecutorError> {
  if let AgentStopReason::AwaitingInput { question } = &result.stop_reason {
    let step_index = result
      .inner
      .steps
      .last()
      .map(|step| step.index as i64)
      .unwrap_or(0);
    ctx
      .repos
      .harness_sessions
      .set_pending_question(ctx.session_id, question, step_index)
      .await?;
    info!(session_id = %ctx.session_id, "live harness executor paused awaiting input");
    return Ok(());
  }

  // Map the inner agent's stop reason back to the session row's
  // terminal state. The closed `AgentStopReason` enum keeps the match
  // exhaustive at compile time, so new variants surface as errors here
  // rather than silently turning into `Failed`.
  let (status, final_answer, error) = match &result.stop_reason {
    AgentStopReason::FinalAnswer | AgentStopReason::StopCondition { .. } => {
      (HarnessSessionStatus::Completed, result.answer.clone(), None)
    }
    AgentStopReason::MaxSteps { max_steps } => (
      HarnessSessionStatus::Failed,
      result.answer.clone(),
      Some(format!("max_steps_reached:{max_steps}")),
    ),
    AgentStopReason::MaxToolCalls { max_tool_calls } => (
      HarnessSessionStatus::Failed,
      result.answer.clone(),
      Some(format!("max_tool_calls_reached:{max_tool_calls}")),
    ),
    AgentStopReason::Timeout { timeout_ms } => (
      HarnessSessionStatus::Failed,
      result.answer.clone(),
      Some(format!("timeout:{timeout_ms}ms")),
    ),
    AgentStopReason::Cancelled { message } => (
      HarnessSessionStatus::Cancelled,
      None,
      Some(format!("cancelled:{message}")),
    ),
    AgentStopReason::TokenBudgetExceeded { used, budget } => (
      HarnessSessionStatus::Failed,
      result.answer.clone(),
      Some(format!("token_budget_exceeded:{used}/{budget}")),
    ),
    AgentStopReason::CostLimitExceeded {
      used_usd,
      budget_usd,
    } => (
      HarnessSessionStatus::Failed,
      result.answer.clone(),
      Some(format!(
        "cost_limit_exceeded:${used_usd:.4}/${budget_usd:.4}"
      )),
    ),
    AgentStopReason::LoopDetected { tool, repeats } => (
      HarnessSessionStatus::Failed,
      result.answer.clone(),
      Some(format!("loop_detected:{tool}x{repeats}")),
    ),
    AgentStopReason::Error { message } => (
      HarnessSessionStatus::Failed,
      None,
      Some(format!("agent_error:{message}")),
    ),
    // Handled by the early return above.
    AgentStopReason::AwaitingInput { .. } => unreachable!("AwaitingInput handled above"),
    // W0.5: DenyAndStop's terminal state.
    AgentStopReason::ApprovalDenied { message } => (
      HarnessSessionStatus::Failed,
      None,
      Some(format!("approval_denied:{message}")),
    ),
  };
  ctx
    .repos
    .harness_sessions
    .update_status(
      ctx.session_id,
      status,
      final_answer.as_deref(),
      error.as_deref(),
    )
    .await?;

  ctx
    .broker
    .finalise_with_grace(ctx.session_id, broker_finalize_grace());
  info!(session_id = %ctx.session_id, "live harness executor finished");
  Ok(())
}

fn parse_profile(value: &str) -> HarnessProfile {
  match value {
    "dev" => HarnessProfile::Dev,
    "production" => HarnessProfile::Production,
    _ => HarnessProfile::Local,
  }
}

fn parse_runtime_kind(value: &str) -> HarnessRuntimeKind {
  match value {
    "plan_execute" => HarnessRuntimeKind::PlanExecute,
    _ => HarnessRuntimeKind::React,
  }
}

#[derive(Debug, thiserror::Error)]
enum LiveExecutorError {
  #[error(transparent)]
  Llm(#[from] agentflow_llm::LLMError),
  #[error(transparent)]
  Harness(#[from] agentflow_harness::HarnessError),
  #[error(transparent)]
  Db(#[from] agentflow_db::DbError),
  #[error(transparent)]
  Checkpoint(#[from] agentflow_agent_spi::checkpoint::AgentLoopCheckpointError),
}

#[cfg(test)]
mod tests {
  use super::*;

  /// Resume contract: a persistent harness store at a path keeps a
  /// session's turns across re-opens (keyed by session_id), so a `:resume`
  /// against the same DB reads the prior conversation back. Tested via
  /// the path helper (no env) to stay race-free.
  #[tokio::test]
  async fn persistent_harness_memory_survives_reopen() {
    let tmp = tempfile::tempdir().unwrap();
    let db = tmp.path().join("harness-memory.sqlite");
    let path = db.to_string_lossy().into_owned();

    let first = open_persistent_harness_memory(&path).await.unwrap();
    first
      .add_message(agentflow_memory::Message::user(
        "sess-srv",
        "remember the deploy key",
      ))
      .await
      .unwrap();
    drop(first);

    let second = open_persistent_harness_memory(&path).await.unwrap();
    let history = second.get_all("sess-srv").await.unwrap();
    assert!(
      history
        .iter()
        .any(|m| m.content.contains("remember the deploy key")),
      "resume must restore the prior conversation from the persistent store"
    );
  }

  use agentflow_harness::{
    HarnessEvent, HarnessEventBody, SessionStartedPayload, StopReason, StoppedPayload,
  };
  use chrono::Utc;

  #[test]
  fn parse_profile_falls_back_to_local() {
    assert!(matches!(parse_profile("dev"), HarnessProfile::Dev));
    assert!(matches!(
      parse_profile("production"),
      HarnessProfile::Production
    ));
    assert!(matches!(parse_profile("local"), HarnessProfile::Local));
    assert!(matches!(parse_profile(""), HarnessProfile::Local));
    assert!(matches!(parse_profile("wat"), HarnessProfile::Local));
  }

  #[test]
  fn parse_runtime_kind_defaults_to_react() {
    assert!(matches!(
      parse_runtime_kind("react"),
      HarnessRuntimeKind::React
    ));
    assert!(matches!(
      parse_runtime_kind("plan_execute"),
      HarnessRuntimeKind::PlanExecute
    ));
    assert!(matches!(
      parse_runtime_kind("unknown"),
      HarnessRuntimeKind::React
    ));
  }

  #[test]
  fn harness_event_kind_covers_every_variant() {
    // Sanity check: each variant's kind() matches the canonical wire
    // name. The closed enum guarantees this exhaustively at compile
    // time; the assertions guard against future renames.
    let started = HarnessEvent {
      seq: 0,
      session_id: "s".into(),
      ts: chrono::Utc::now(),
      body: HarnessEventBody::SessionStarted(SessionStartedPayload {
        workspace_root: "/".into(),
        runtime: HarnessRuntimeKind::React,
        profile: HarnessProfile::Local,
        model: "m".into(),
        skills: Vec::new(),
        context_item_count: 0,
        context_token_estimate: 0,
      }),
    };
    let stopped = HarnessEvent {
      seq: 1,
      session_id: "s".into(),
      ts: Utc::now(),
      body: HarnessEventBody::Stopped(StoppedPayload {
        reason: StopReason::Completed,
        final_answer: None,
        error: None,
      }),
    };
    assert_eq!(harness_event_kind(&started.body), "session_started");
    assert_eq!(harness_event_kind(&stopped.body), "stopped");
  }

  #[test]
  fn resolve_max_steps_defaults_and_clamps() {
    assert_eq!(resolve_max_steps(None), DEFAULT_MAX_STEPS);
    assert_eq!(resolve_max_steps(Some(5)), 5);
    assert_eq!(resolve_max_steps(Some(10_000)), MAX_STEPS_CEILING);
  }

  /// W0.1: the default (no-`--skill`) registry must actually contain
  /// governed tools — this is the regression test for the bug where
  /// every harness session (server or CLI) started from an always-empty
  /// `ToolRegistry::new()`, leaving the approval/hook pipeline nothing
  /// to ever govern.
  #[test]
  fn build_default_tool_registry_contains_file_and_http() {
    let tmp = tempfile::tempdir().unwrap();
    let registry = build_default_tool_registry(&tmp.path().display().to_string()).unwrap();
    let names: Vec<String> = registry
      .list()
      .iter()
      .map(|tool| tool.name().to_string())
      .collect();
    assert!(names.contains(&"file".to_string()), "names: {names:?}");
    assert!(names.contains(&"http".to_string()), "names: {names:?}");
  }
}
