//! `agent_interrupt` / `agent_kill` (#904) — first-class stop verbs for
//! Synapse-spawned sub-agents.
//!
//! Until this module, the only way to stop a spawned agent was the
//! coarse-grained `session_end` teardown of the *caller's* whole session. These
//! two verbs target **one** agent by its own MCP session id (or `agent-spawn-*`
//! id) and stop it with source-of-truth readback in the response: the
//! actual OS process table is read back before and after, the registry/journal
//! state transition is recorded, and every channel reports its real outcome.
//!
//! # Channel ranking (research-grounded, #904)
//!
//! The issue asks for a *channel-ranked* graceful interrupt. Each channel
//! reports its true status; **no channel ever silently "succeeds"**:
//!
//! 1. `codex_app_server_turn_interrupt` — Codex `turn/interrupt` JSON-RPC
//!    (`{threadId,turnId}` → `{}`, turn ends `interrupted`). Wired for Codex
//!    agents spawned through the app-server runner, using the per-spawn
//!    `codex-control.json` artifact as the physical SoT for endpoint/thread/turn
//!    ids. Older plain-CLI Codex rows report `channel_not_wired`.
//! 2. `claude_stream_json_control` — there is **no supported stdin cancel frame**
//!    for `claude -p` today (anthropics/claude-code#51078 is an open feature
//!    request); the Agent SDK's `interruptTurn` only works when the SDK owns the
//!    persistent stream-json stdin pipe, which the daemon does not. **Not wired.**
//! 3. `mailbox_interrupt` — **wired.** A durable `interrupt` mailbox row (#908)
//!    delivered to the agent's steering inbox. Cooperative agents drain it
//!    between tool calls and bail (`steering_requests_shutdown` honors
//!    `kill|stop|cancel|interrupt|shutdown`). Delivery is proven by the
//!    persisted `CF_KV` row readback.
//! 4. `pty_esc` — the documented last-resort interrupt key requires owned-PTY
//!    capture (#902), which does not exist yet. **Not wired.**
//!
//! `agent_kill` reuses the authoritative per-session teardown machinery
//! (`session_lifecycle::teardown_session`): every spawned agent's *own* session
//! id owns both its process resource (the Windows job handle) and its
//! leases/claims/desktops, so a single teardown of that session does job-close →
//! force-kill of the process tree and releases all of the agent's resources.

use std::{
    collections::BTreeSet,
    fs,
    path::PathBuf,
    process::{Command, Output, Stdio},
    time::{Duration, Instant},
};

use schemars::JsonSchema;
use serde::{Deserialize, Serialize};
use serde_json::{Value, json};
use synapse_core::{AgentEndState, AgentEventKind, AgentEventRecord, error_codes};

use rmcp::{RoleServer, service::RequestContext};

use super::agent_events::{record_agent_event_durable, unix_time_ns_now};
use super::command_audit::CommandAuditInput;
use super::session_lifecycle::{SessionTeardownOptions, SessionTeardownReport};
use super::session_registry::{SpawnedAgentControlRead, unix_time_ms_now};
use super::{ErrorData, Json, Parameters, SynapseService, mcp_error, tool, tool_router};
use futures_util::future::join_all;

// ----------------------------------------------------------------------------
// Tunables
// ----------------------------------------------------------------------------

/// Default graceful window between the interrupt attempt and the force-kill.
const DEFAULT_KILL_GRACE_MS: u64 = 3_000;
/// Hard ceiling on the graceful window so a kill cannot block unbounded.
const MAX_KILL_GRACE_MS: u64 = 120_000;
/// Poll cadence while waiting for the process tree to exit during the grace
/// window.
const GRACE_POLL_INTERVAL_MS: u64 = 100;
/// TTL for the cooperative interrupt mailbox row — short, because a stale
/// interrupt request is noise once the agent is gone.
const INTERRUPT_MESSAGE_TTL_MS: u64 = 60_000;
/// Mailbox kind the cooperative shutdown contract recognizes.
const INTERRUPT_MAILBOX_KIND: &str = "interrupt";

const TOOL_AGENT_INTERRUPT: &str = "agent_interrupt";
const TOOL_AGENT_KILL: &str = "agent_kill";
const TOOL_FLEET_STOP: &str = "fleet_stop";
const TOOL_AGENT_STEER: &str = "agent_steer";

/// TTL for a cooperative steering instruction. Long enough that an agent busy
/// in a multi-minute turn still sees it when it next drains its inbox, short
/// enough that a stale instruction does not haunt a later turn.
const STEER_MESSAGE_TTL_MS: u64 = 600_000;
/// Hard ceiling on a single steering instruction. The mailbox row caps the
/// whole payload at 64 KiB; this bounds the human-authored text well under that
/// so the envelope (control fields, from, reason) always fits.
const MAX_STEER_INSTRUCTION_CHARS: usize = 16_000;
const CODEX_APP_SERVER_INTERRUPT_SCRIPT: &str = include_str!("codex_app_server_interrupt.ps1");
const CODEX_INTERRUPT_HELPER_TIMEOUT_MS: u64 = 8_000;

/// Destructive-action confirmation token for `fleet_stop`, matching the
/// action-diagnostic confirm pattern. A typo or empty value is refused.
const FLEET_STOP_CONFIRM: &str = "STOP-FLEET";

// ----------------------------------------------------------------------------
// Params
// ----------------------------------------------------------------------------

#[derive(Clone, Debug, Deserialize, JsonSchema)]
#[serde(deny_unknown_fields)]
pub struct AgentInterruptParams {
    /// The agent to interrupt: its own MCP session id, or its `agent-spawn-*`
    /// id. Resolves through the live session registry.
    pub session_id: String,
}

#[derive(Clone, Debug, Deserialize, JsonSchema)]
#[serde(deny_unknown_fields)]
pub struct AgentKillParams {
    /// The agent to kill: its own MCP session id, or its `agent-spawn-*` id.
    pub session_id: String,
    /// Graceful window (ms) to wait for the agent to stop on its own after the
    /// interrupt attempt, before force-terminating the process tree.
    #[serde(default = "default_kill_grace_ms")]
    #[schemars(default = "default_kill_grace_ms", range(min = 0, max = 120_000))]
    pub grace_ms: u64,
    /// When true (default) a graceful interrupt is attempted first; when false
    /// the process tree is force-terminated immediately.
    #[serde(default = "default_true")]
    #[schemars(default = "default_true")]
    pub interrupt_first: bool,
}

const fn default_kill_grace_ms() -> u64 {
    DEFAULT_KILL_GRACE_MS
}
const fn default_true() -> bool {
    true
}

#[derive(Clone, Debug, Deserialize, JsonSchema)]
#[serde(deny_unknown_fields)]
pub struct FleetStopParams {
    /// `kill` force-terminates every live agent's process tree; `interrupt`
    /// delivers a graceful interrupt to each.
    pub mode: String,
    /// Destructive-action confirmation token; must equal `STOP-FLEET`.
    pub confirm: String,
    /// Optional registry `agent_kind` filter (e.g. `["codex"]`). Empty = every
    /// live spawned agent.
    #[serde(default)]
    #[schemars(default)]
    pub agent_kinds: Vec<String>,
    /// Graceful window (ms) per agent for `mode=kill` before force-termination.
    #[serde(default = "default_kill_grace_ms")]
    #[schemars(default = "default_kill_grace_ms", range(min = 0, max = 120_000))]
    pub grace_ms: u64,
}

// ----------------------------------------------------------------------------
// Response types
// ----------------------------------------------------------------------------

/// A live readback of the agent's process tree from the OS process table — the
/// source of truth for "is it actually dead".
#[derive(Clone, Debug, Serialize, JsonSchema)]
#[serde(deny_unknown_fields)]
pub struct ProcessReadback {
    pub launcher_process_id: u32,
    /// Every pid the owned job/process tree currently maps to.
    pub process_tree_ids: Vec<u32>,
    /// The subset of `process_tree_ids` that are still alive right now.
    pub live_process_ids: Vec<u32>,
}

/// One ranked channel's real outcome. `status` is one of `delivered`,
/// `unavailable`, or `failed` — never a fabricated success.
#[derive(Clone, Debug, Serialize, JsonSchema)]
#[serde(deny_unknown_fields)]
pub struct ChannelAttempt {
    pub channel: String,
    pub rank: u32,
    pub status: String,
    pub reason: String,
    #[serde(skip_serializing_if = "Option::is_none")]
    pub message_id: Option<String>,
    #[serde(skip_serializing_if = "Option::is_none")]
    pub row_key: Option<String>,
}

/// Physical readback of a persisted journal row.
#[derive(Clone, Debug, Serialize, JsonSchema)]
#[serde(deny_unknown_fields)]
pub struct JournalReadback {
    pub kind: String,
    pub ts_ns: u64,
    pub seq: u32,
    pub value_len_bytes: u64,
}

#[derive(Clone, Debug, Serialize, JsonSchema)]
#[serde(deny_unknown_fields)]
pub struct AgentInterruptResponse {
    pub requested_id: String,
    pub session_id: String,
    #[serde(skip_serializing_if = "Option::is_none")]
    pub spawn_id: Option<String>,
    pub agent_kind: String,
    pub lifecycle: String,
    pub resolution_source: String,
    /// True when at least one channel actually delivered the interrupt.
    pub delivered: bool,
    #[serde(skip_serializing_if = "Option::is_none")]
    pub delivered_via: Option<String>,
    /// Every ranked channel and its true outcome.
    pub channels: Vec<ChannelAttempt>,
    /// The `interrupted` journal row written when a channel delivered.
    #[serde(skip_serializing_if = "Option::is_none")]
    pub journal_event: Option<JournalReadback>,
    /// The OS process table at interrupt time (an interrupt never kills, so it
    /// is read once for evidence).
    pub process: ProcessReadback,
}

#[derive(Clone, Debug, Serialize, JsonSchema)]
#[serde(deny_unknown_fields)]
pub struct AgentKillResponse {
    pub requested_id: String,
    pub session_id: String,
    #[serde(skip_serializing_if = "Option::is_none")]
    pub spawn_id: Option<String>,
    pub agent_kind: String,
    pub resolution_source: String,
    /// True when the process tree was already gone before this call acted —
    /// makes double-kill idempotent (the second call reports `already_dead`).
    pub already_dead: bool,
    /// The graceful interrupt attempt, when `interrupt_first` was set.
    #[serde(skip_serializing_if = "Option::is_none")]
    pub interrupt: Option<AgentInterruptResponse>,
    pub grace_ms: u64,
    /// True when the agent exited on its own during the grace window, with no
    /// force-termination needed.
    pub natural_exit: bool,
    pub process_before: ProcessReadback,
    pub process_after: ProcessReadback,
    /// Live pids still standing after teardown. MUST be empty for `killed`.
    pub orphan_process_ids: Vec<u32>,
    /// True iff zero orphan processes remain (the OS process table is the SoT).
    pub killed: bool,
    /// Exact-PID fallback used when no live teardown job handle exists, such as
    /// after daemon restart handoff.
    #[serde(skip_serializing_if = "Option::is_none")]
    pub post_teardown_force_termination: Option<crate::m4::OwnedProcessTerminationReadback>,
    #[serde(skip_serializing_if = "Option::is_none")]
    pub completion_artifact_cleanup_status: Option<String>,
    #[serde(skip_serializing_if = "Option::is_none")]
    pub completion_artifact_cleanup_error: Option<String>,
    /// The `killed` journal row, written before teardown when a force-kill was
    /// actually required.
    #[serde(skip_serializing_if = "Option::is_none")]
    pub journal_killed_event: Option<JournalReadback>,
    /// Full per-resource teardown report (process job close/force, lease, claim,
    /// desktop, registry transitions) when teardown succeeded.
    #[serde(skip_serializing_if = "Option::is_none")]
    pub teardown: Option<SessionTeardownReport>,
    /// Set when teardown returned an error; the kill's success is still judged
    /// by `orphan_process_ids` (the OS process table), never by this alone.
    #[serde(skip_serializing_if = "Option::is_none")]
    pub teardown_error: Option<String>,
}

/// One agent's outcome in a `fleet_stop` sweep.
#[derive(Clone, Debug, Serialize, JsonSchema)]
#[serde(deny_unknown_fields)]
pub struct FleetStopAgentOutcome {
    pub session_id: String,
    #[serde(skip_serializing_if = "Option::is_none")]
    pub spawn_id: Option<String>,
    pub agent_kind: String,
    /// True when the agent was stopped as requested (killed with zero orphans,
    /// or interrupt delivered).
    pub ok: bool,
    /// Outcome detail: how it was stopped, or exactly why it could not be.
    pub reason: String,
    /// Live pids still standing for this agent (non-empty only on a failed kill).
    pub surviving_process_ids: Vec<u32>,
}

#[derive(Clone, Debug, Serialize, JsonSchema)]
#[serde(deny_unknown_fields)]
pub struct FleetStopResponse {
    pub mode: String,
    /// Live spawned agents that matched the filter at sweep time.
    pub matched: usize,
    pub succeeded: usize,
    pub failed: usize,
    /// True iff every matched agent was stopped (vacuously true for an empty
    /// fleet).
    pub all_stopped: bool,
    pub agents: Vec<FleetStopAgentOutcome>,
}

#[derive(Clone, Debug, Deserialize, JsonSchema)]
#[serde(deny_unknown_fields)]
pub struct AgentSteerParams {
    /// The agent to steer: its own MCP session id, or its `agent-spawn-*` id.
    pub session_id: String,
    /// The instruction to inject. Spliced into the agent's context at the next
    /// safe point by the cooperative steering-inbox contract. Non-empty,
    /// bounded to 16 000 chars.
    pub instruction: String,
    /// When true (default), the steering row requests a read receipt: when the
    /// agent drains and applies the instruction it writes a receipt to the
    /// caller's receipt box (readable via `agent_receipts`), turning delivery
    /// into provable consumption. The `agent_steer` response always proves
    /// *delivery* (the durable row) regardless of this flag.
    #[serde(default = "default_true")]
    #[schemars(default = "default_true")]
    pub request_receipt: bool,
}

#[derive(Clone, Debug, Serialize, JsonSchema)]
#[serde(deny_unknown_fields)]
pub struct AgentSteerResponse {
    pub requested_id: String,
    pub session_id: String,
    #[serde(skip_serializing_if = "Option::is_none")]
    pub spawn_id: Option<String>,
    pub agent_kind: String,
    pub lifecycle: String,
    pub resolution_source: String,
    /// True when at least one channel actually delivered the instruction.
    pub delivered: bool,
    #[serde(skip_serializing_if = "Option::is_none")]
    pub delivered_via: Option<String>,
    /// Character count of the instruction that was delivered (the SoT for "what
    /// was injected" is the persisted mailbox row referenced by `row_key`).
    pub instruction_chars: usize,
    /// Every ranked channel and its true outcome.
    pub channels: Vec<ChannelAttempt>,
    /// The `MessageSent` journal row written when a channel delivered.
    #[serde(skip_serializing_if = "Option::is_none")]
    pub journal_event: Option<JournalReadback>,
    /// Where a consumption receipt will appear once the agent applies the
    /// instruction, when `request_receipt` was set. Poll `agent_receipts` for
    /// proof of consumption (delivery is already proven by `delivered`).
    #[serde(skip_serializing_if = "Option::is_none")]
    pub receipt_box_session_id: Option<String>,
    /// The OS process table at steer time (steering never kills; read once for
    /// evidence the target is live).
    pub process: ProcessReadback,
}

// ----------------------------------------------------------------------------
// Resolved-target model
// ----------------------------------------------------------------------------

/// A spawned agent located in the live session registry.
#[derive(Clone, Debug)]
struct ResolvedAgent {
    /// The agent's own MCP session id (owns the process resource and leases).
    session_id: String,
    spawn_id: Option<String>,
    agent_kind: String,
    lifecycle: String,
    resolution_source: String,
    dead: bool,
    launcher_process_id: u32,
    agent_process_id: Option<u32>,
    log_dir: String,
    control: Option<SpawnedAgentControlRead>,
}

// ----------------------------------------------------------------------------
// Tools
// ----------------------------------------------------------------------------

#[tool_router(router = agent_control_tool_router, vis = "pub(super)")]
impl SynapseService {
    #[tool(
        description = "Gracefully interrupt one running spawned agent (#904/#958) by its MCP session id or agent-spawn-* id, via ranked clean channels. Codex app-server spawns use real turn/interrupt from codex-control.json; cooperative mailbox remains available; claude stream-json cancel and PTY ESC are reported unavailable unless their real channel exists. Reports each channel's real outcome plus a process-table readback; errors if no channel can deliver. Use agent_kill to force-terminate."
    )]
    pub async fn agent_interrupt(
        &self,
        params: Parameters<AgentInterruptParams>,
        request_context: RequestContext<RoleServer>,
    ) -> Result<Json<AgentInterruptResponse>, ErrorData> {
        tracing::info!(
            code = "MCP_TOOL_INVOCATION",
            kind = "agent_interrupt",
            "tool.invocation kind=agent_interrupt"
        );
        let caller = super::context::mcp_session_id_from_request_context(&request_context)?;
        self.agent_interrupt_impl(params.0, caller.as_deref())
            .map(Json)
    }

    #[tool(
        description = "Force-stop one spawned agent (#904): attempt a graceful interrupt, wait grace_ms, then terminate the recorded process tree (Windows job-close → force kill) by reusing per-session teardown, releasing the agent's leases/claims/desktops and journaling a durable killed event. Source-of-truth readback is in the response: the OS process table is read back before and after, and killed is true only when zero orphan processes remain. Double-kill is idempotent (reports already_dead); unknown/non-spawned sessions error."
    )]
    pub async fn agent_kill(
        &self,
        params: Parameters<AgentKillParams>,
        request_context: RequestContext<RoleServer>,
    ) -> Result<Json<AgentKillResponse>, ErrorData> {
        tracing::info!(
            code = "MCP_TOOL_INVOCATION",
            kind = "agent_kill",
            "tool.invocation kind=agent_kill"
        );
        let caller = super::context::mcp_session_id_from_request_context(&request_context)?;
        self.agent_kill_impl(params.0, caller.as_deref())
            .await
            .map(Json)
    }

    #[tool(
        description = "Fleet kill switch (#907): interrupt or kill EVERY live spawned agent (optionally filtered by agent_kind) in one call. Requires confirm=\"STOP-FLEET\" (destructive-action token). mode=kill force-terminates each agent's process tree and releases its leases/claims/desktops; mode=interrupt delivers a graceful interrupt to each. Returns a per-agent outcome table; any agent that could not be stopped is listed loudly with its reason and surviving pids (never summarized away). Empty fleet is an honest no-op. Writes a single fleet_stop command-audit pair."
    )]
    pub async fn fleet_stop(
        &self,
        params: Parameters<FleetStopParams>,
        request_context: RequestContext<RoleServer>,
    ) -> Result<Json<FleetStopResponse>, ErrorData> {
        tracing::info!(
            code = "MCP_TOOL_INVOCATION",
            kind = "fleet_stop",
            "tool.invocation kind=fleet_stop"
        );
        let caller = super::context::mcp_session_id_from_request_context(&request_context)?;
        self.fleet_stop_impl(params.0, caller.as_deref())
            .await
            .map(Json)
    }

    #[tool(
        description = "Inject an instruction into ONE running spawned agent (#905) by its MCP session id or agent-spawn-* id, via ranked clean channels. The cooperative steering-inbox (durable `steer` mailbox row, #908) is the wired channel: well-behaved agents drain it between tool calls and splice it into context. Codex app-server mid-turn inject and claude stream-json stdin inject are reported unavailable (the daemon owns neither input pipe; mid-turn claude stdin messages are also dropped from history per anthropics/claude-code#41230); PTY stdin needs owned-PTY capture (#902). Reports each channel's real outcome plus a process-table readback; the durable row is the delivery source of truth and a read receipt (default on) proves consumption via agent_receipts. Errors if no channel can deliver."
    )]
    pub async fn agent_steer(
        &self,
        params: Parameters<AgentSteerParams>,
        request_context: RequestContext<RoleServer>,
    ) -> Result<Json<AgentSteerResponse>, ErrorData> {
        tracing::info!(
            code = "MCP_TOOL_INVOCATION",
            kind = "agent_steer",
            "tool.invocation kind=agent_steer"
        );
        let caller = super::context::mcp_session_id_from_request_context(&request_context)?;
        self.agent_steer_impl(params.0, caller.as_deref()).map(Json)
    }
}

impl SynapseService {
    pub(crate) async fn dashboard_agent_kill_request(
        &self,
        params: AgentKillParams,
    ) -> Result<AgentKillResponse, ErrorData> {
        tracing::info!(
            code = "DASHBOARD_AGENT_KILL_REQUESTED",
            kind = TOOL_AGENT_KILL,
            requested_id = %params.session_id,
            "dashboard.invocation kind=agent_kill"
        );
        self.agent_kill_impl(params, None).await
    }

    // ------------------------------------------------------------------
    // agent_interrupt
    // ------------------------------------------------------------------

    fn agent_interrupt_impl(
        &self,
        params: AgentInterruptParams,
        caller_session: Option<&str>,
    ) -> Result<AgentInterruptResponse, ErrorData> {
        let lookup = validate_lookup_id(&params.session_id, TOOL_AGENT_INTERRUPT)?;
        let target = self.resolve_spawned_agent(&lookup, TOOL_AGENT_INTERRUPT)?;
        if target.dead {
            return Err(mcp_error(
                error_codes::TOOL_PARAMS_INVALID,
                format!(
                    "AGENT_ALREADY_DEAD: agent {} (session {}) is closed; interrupt targets a live agent — use agent_kill to reclaim a dead agent's resources",
                    lookup, target.session_id
                ),
            ));
        }
        let process = process_readback_for_target(&target);

        let payload = json!({
            "reason": "operator_interrupt",
            "requested_id": lookup,
            "from": caller_session,
        });
        let before = json!({ "process": &process, "lifecycle": target.lifecycle });
        self.command_audit_intent(
            CommandAuditInput::mcp(
                TOOL_AGENT_INTERRUPT,
                "interrupt",
                caller_session.map(ToOwned::to_owned),
                Some(target.session_id.clone()),
                payload.clone(),
                before.clone(),
                Value::Null,
                "pending",
            )
            .with_target(json!({ "spawn_id": target.spawn_id, "agent_kind": target.agent_kind })),
        )?;

        let response = self.interrupt_core(&lookup, &target, caller_session)?;

        let after = json!({
            "delivered": response.delivered,
            "delivered_via": response.delivered_via,
            "channels": response.channels,
        });
        self.command_audit_final(
            CommandAuditInput::mcp(
                TOOL_AGENT_INTERRUPT,
                "interrupt",
                caller_session.map(ToOwned::to_owned),
                Some(target.session_id.clone()),
                payload,
                before,
                after,
                if response.delivered { "ok" } else { "error" },
            )
            .with_target(json!({ "spawn_id": target.spawn_id, "agent_kind": target.agent_kind })),
        )?;

        if !response.delivered {
            return Err(mcp_error(
                error_codes::TOOL_INTERNAL_ERROR,
                format!(
                    "AGENT_INTERRUPT_NO_CHANNEL: no clean channel could deliver an interrupt to agent {} (session {}); see the per-channel `channels` report for why each was unavailable. Use agent_kill to force-terminate.",
                    response.requested_id, response.session_id
                ),
            ));
        }
        Ok(response)
    }

    /// Builds an interrupt response (channels attempted + durable `interrupted`
    /// journal row on delivery) without auditing or erroring on non-delivery.
    /// Shared by `agent_interrupt` (which wraps it with audit + a no-channel
    /// error) and `agent_kill` (which calls it best-effort before force-kill).
    fn interrupt_core(
        &self,
        requested_id: &str,
        target: &ResolvedAgent,
        caller_session: Option<&str>,
    ) -> Result<AgentInterruptResponse, ErrorData> {
        let process = process_readback_for_target(target);
        let (channels, delivered_via, _send_row) =
            self.attempt_interrupt_channels(target, caller_session);
        let delivered = delivered_via.is_some();
        // Journal a durable `interrupted` event only when a channel actually
        // delivered — never claim an interruption that did not happen.
        let journal_event = if delivered {
            Some(self.journal_lifecycle_event(
                AgentEventKind::Interrupted,
                target,
                "agent_interrupt",
                None,
                json!({ "delivered_via": delivered_via, "process": &process }),
            )?)
        } else {
            None
        };
        Ok(AgentInterruptResponse {
            requested_id: requested_id.to_owned(),
            session_id: target.session_id.clone(),
            spawn_id: target.spawn_id.clone(),
            agent_kind: target.agent_kind.clone(),
            lifecycle: target.lifecycle.clone(),
            resolution_source: target.resolution_source.clone(),
            delivered,
            delivered_via,
            channels,
            journal_event,
            process,
        })
    }

    /// Attempts each ranked channel and returns `(attempts, delivered_via,
    /// send_row)`. Channels report true outcomes; unsupported legacy rows stay
    /// unavailable instead of being treated as delivered.
    fn attempt_interrupt_channels(
        &self,
        target: &ResolvedAgent,
        caller_session: Option<&str>,
    ) -> (Vec<ChannelAttempt>, Option<String>, Option<String>) {
        let mut attempts = Vec::new();
        let mut delivered_via = None;
        let mut send_row = None;

        let codex = self.deliver_codex_app_server_interrupt(target);
        record_first_delivered_channel(&mut delivered_via, &codex);
        attempts.push(codex);
        attempts.push(ChannelAttempt {
            channel: "claude_stream_json_control".to_owned(),
            rank: 2,
            status: "unavailable".to_owned(),
            reason: "channel_not_wired: no supported claude -p stdin cancel frame today \
                     (anthropics/claude-code#51078); the daemon does not own the stream-json pipe"
                .to_owned(),
            message_id: None,
            row_key: None,
        });

        // Rank 3: cooperative mailbox interrupt — the one wired channel.
        let mailbox = self.deliver_mailbox_interrupt(target, caller_session);
        if mailbox.status == "delivered" {
            record_first_delivered_channel(&mut delivered_via, &mailbox);
            send_row.clone_from(&mailbox.row_key);
        }
        attempts.push(mailbox);

        attempts.push(ChannelAttempt {
            channel: "pty_esc".to_owned(),
            rank: 4,
            status: "unavailable".to_owned(),
            reason: "channel_not_wired: PTY ESC (the documented interrupt key) needs owned-PTY \
                     capture (#902), which is not implemented yet"
                .to_owned(),
            message_id: None,
            row_key: None,
        });

        (attempts, delivered_via, send_row)
    }

    fn deliver_codex_app_server_interrupt(&self, target: &ResolvedAgent) -> ChannelAttempt {
        if target.agent_kind != "codex" {
            return ChannelAttempt {
                channel: "codex_app_server_turn_interrupt".to_owned(),
                rank: 1,
                status: "unavailable".to_owned(),
                reason: format!(
                    "channel_not_applicable: target agent_kind={} is not codex",
                    target.agent_kind
                ),
                message_id: None,
                row_key: None,
            };
        }
        let Some(control) = target.control.as_ref() else {
            return ChannelAttempt {
                channel: "codex_app_server_turn_interrupt".to_owned(),
                rank: 1,
                status: "unavailable".to_owned(),
                reason: "channel_not_wired: this codex session has no codex-control.json metadata; it was likely spawned by the legacy plain-CLI path before #958".to_owned(),
                message_id: None,
                row_key: None,
            };
        };
        if control.protocol != "codex_app_server_ws" {
            return ChannelAttempt {
                channel: "codex_app_server_turn_interrupt".to_owned(),
                rank: 1,
                status: "unavailable".to_owned(),
                reason: format!(
                    "channel_not_wired: unsupported control protocol {}",
                    control.protocol
                ),
                message_id: None,
                row_key: Some(control.control_path.clone()),
            };
        }
        let Some(thread_id) = control
            .thread_id
            .as_deref()
            .filter(|value| !value.is_empty())
        else {
            return ChannelAttempt {
                channel: "codex_app_server_turn_interrupt".to_owned(),
                rank: 1,
                status: "unavailable".to_owned(),
                reason: "channel_not_ready: codex-control.json has no thread_id".to_owned(),
                message_id: None,
                row_key: Some(control.control_path.clone()),
            };
        };
        let Some(turn_id) = control.turn_id.as_deref().filter(|value| !value.is_empty()) else {
            return ChannelAttempt {
                channel: "codex_app_server_turn_interrupt".to_owned(),
                rank: 1,
                status: "unavailable".to_owned(),
                reason: "channel_not_ready: codex-control.json has no turn_id".to_owned(),
                message_id: None,
                row_key: Some(control.control_path.clone()),
            };
        };
        if matches!(
            control.turn_status.as_str(),
            "completed" | "interrupted" | "failed"
        ) {
            return ChannelAttempt {
                channel: "codex_app_server_turn_interrupt".to_owned(),
                rank: 1,
                status: "unavailable".to_owned(),
                reason: format!(
                    "turn_not_interruptible: codex-control.json reports turn_status={}",
                    control.turn_status
                ),
                message_id: Some(turn_id.to_owned()),
                row_key: Some(control.control_path.clone()),
            };
        }
        if crate::m4::owned_live_process_ids(&[control.app_server_process_id]).is_empty() {
            return ChannelAttempt {
                channel: "codex_app_server_turn_interrupt".to_owned(),
                rank: 1,
                status: "unavailable".to_owned(),
                reason: format!(
                    "app_server_not_live: codex app-server pid {} is not live",
                    control.app_server_process_id
                ),
                message_id: Some(turn_id.to_owned()),
                row_key: Some(control.control_path.clone()),
            };
        }

        let script_path = PathBuf::from(&target.log_dir).join("codex-app-server-interrupt.ps1");
        if let Err(error) = fs::write(&script_path, CODEX_APP_SERVER_INTERRUPT_SCRIPT) {
            return ChannelAttempt {
                channel: "codex_app_server_turn_interrupt".to_owned(),
                rank: 1,
                status: "failed".to_owned(),
                reason: format!(
                    "interrupt_helper_write_failed: {} ({error})",
                    script_path.display()
                ),
                message_id: Some(turn_id.to_owned()),
                row_key: Some(control.control_path.clone()),
            };
        }

        match run_codex_interrupt_helper(&script_path, control, thread_id, turn_id) {
            Ok(output) if output.status.success() => {
                let stdout = String::from_utf8_lossy(&output.stdout);
                ChannelAttempt {
                    channel: "codex_app_server_turn_interrupt".to_owned(),
                    rank: 1,
                    status: "delivered".to_owned(),
                    reason: format!(
                        "turn_interrupt_delivered: endpoint={} thread_id={} turn_id={} control_path={} stdout={}",
                        control.endpoint,
                        thread_id,
                        turn_id,
                        control.control_path,
                        compact_for_channel_reason(stdout.trim())
                    ),
                    message_id: Some(turn_id.to_owned()),
                    row_key: Some(control.control_path.clone()),
                }
            }
            Ok(output) => {
                let stdout = String::from_utf8_lossy(&output.stdout);
                let stderr = String::from_utf8_lossy(&output.stderr);
                ChannelAttempt {
                    channel: "codex_app_server_turn_interrupt".to_owned(),
                    rank: 1,
                    status: "failed".to_owned(),
                    reason: format!(
                        "turn_interrupt_failed: exit={:?} stdout={} stderr={}",
                        output.status.code(),
                        compact_for_channel_reason(stdout.trim()),
                        compact_for_channel_reason(stderr.trim())
                    ),
                    message_id: Some(turn_id.to_owned()),
                    row_key: Some(control.control_path.clone()),
                }
            }
            Err(error) => ChannelAttempt {
                channel: "codex_app_server_turn_interrupt".to_owned(),
                rank: 1,
                status: "failed".to_owned(),
                reason: error,
                message_id: Some(turn_id.to_owned()),
                row_key: Some(control.control_path.clone()),
            },
        }
    }

    /// Delivers a durable `interrupt` mailbox row to the target's steering
    /// inbox, proving delivery by the persisted `CF_KV` row readback.
    fn deliver_mailbox_interrupt(
        &self,
        target: &ResolvedAgent,
        caller_session: Option<&str>,
    ) -> ChannelAttempt {
        let Some(caller) = caller_session else {
            return ChannelAttempt {
                channel: "mailbox_interrupt".to_owned(),
                rank: 3,
                status: "unavailable".to_owned(),
                reason: "needs the caller's MCP session id (run the daemon in HTTP mode so each \
                         agent has its own Mcp-Session-Id)"
                    .to_owned(),
                message_id: None,
                row_key: None,
            };
        };
        let send = self.agent_send_impl(
            super::agent_mailbox::AgentSendParams {
                to_session: target.session_id.clone(),
                kind: INTERRUPT_MAILBOX_KIND.to_owned(),
                payload: json!({
                    "control": "interrupt",
                    "from": caller,
                    "reason": "operator_interrupt",
                    "instructions": "stop the current turn at the next safe point",
                }),
                artifact_handle: None,
                ttl_ms: INTERRUPT_MESSAGE_TTL_MS,
                request_receipt: false,
            },
            caller,
        );
        match send {
            Ok(response) => ChannelAttempt {
                channel: "mailbox_interrupt".to_owned(),
                rank: 3,
                status: "delivered".to_owned(),
                reason: format!(
                    "durable {} row persisted to CF_KV (queue_depth_after={}); cooperative agents \
                     drain it between tool calls and bail",
                    INTERRUPT_MAILBOX_KIND, response.queue_depth_after
                ),
                message_id: Some(response.message_id),
                row_key: Some(response.row_key),
            },
            Err(error) => ChannelAttempt {
                channel: "mailbox_interrupt".to_owned(),
                rank: 3,
                status: "failed".to_owned(),
                reason: format!("mailbox delivery failed: {}", error.message),
                message_id: None,
                row_key: None,
            },
        }
    }

    // ------------------------------------------------------------------
    // agent_steer (#905)
    // ------------------------------------------------------------------

    fn agent_steer_impl(
        &self,
        params: AgentSteerParams,
        caller_session: Option<&str>,
    ) -> Result<AgentSteerResponse, ErrorData> {
        let lookup = validate_lookup_id(&params.session_id, TOOL_AGENT_STEER)?;
        let instruction = params.instruction.trim();
        if instruction.is_empty() {
            return Err(mcp_error(
                error_codes::TOOL_PARAMS_INVALID,
                "AGENT_STEER_EMPTY: instruction must be a non-empty string of guidance to inject",
            ));
        }
        let instruction_chars = instruction.chars().count();
        if instruction_chars > MAX_STEER_INSTRUCTION_CHARS {
            return Err(mcp_error(
                error_codes::TOOL_PARAMS_INVALID,
                format!(
                    "AGENT_STEER_TOO_LONG: instruction is {instruction_chars} chars; the cooperative steering channel caps a single instruction at {MAX_STEER_INSTRUCTION_CHARS}"
                ),
            ));
        }
        let target = self.resolve_spawned_agent(&lookup, TOOL_AGENT_STEER)?;
        if target.dead {
            return Err(mcp_error(
                error_codes::TOOL_PARAMS_INVALID,
                format!(
                    "AGENT_ALREADY_DEAD: agent {} (session {}) is closed; steering targets a live agent",
                    lookup, target.session_id
                ),
            ));
        }
        let process = process_readback_for_target(&target);

        let payload = json!({
            "requested_id": lookup,
            "instruction_chars": instruction_chars,
            "request_receipt": params.request_receipt,
            "from": caller_session,
        });
        let before = json!({ "process": &process, "lifecycle": target.lifecycle });
        self.command_audit_intent(
            CommandAuditInput::mcp(
                TOOL_AGENT_STEER,
                "steer",
                caller_session.map(ToOwned::to_owned),
                Some(target.session_id.clone()),
                payload.clone(),
                before.clone(),
                Value::Null,
                "pending",
            )
            .with_target(json!({ "spawn_id": target.spawn_id, "agent_kind": target.agent_kind })),
        )?;

        let response =
            self.steer_core(&lookup, &target, instruction, params.request_receipt, caller_session)?;

        let after = json!({
            "delivered": response.delivered,
            "delivered_via": response.delivered_via,
            "channels": response.channels,
        });
        self.command_audit_final(
            CommandAuditInput::mcp(
                TOOL_AGENT_STEER,
                "steer",
                caller_session.map(ToOwned::to_owned),
                Some(target.session_id.clone()),
                payload,
                before,
                after,
                if response.delivered { "ok" } else { "error" },
            )
            .with_target(json!({ "spawn_id": target.spawn_id, "agent_kind": target.agent_kind })),
        )?;

        if !response.delivered {
            return Err(mcp_error(
                error_codes::TOOL_INTERNAL_ERROR,
                format!(
                    "AGENT_STEER_NO_CHANNEL: no clean channel could inject an instruction into agent {} (session {}); see the per-channel `channels` report for why each was unavailable.",
                    response.requested_id, response.session_id
                ),
            ));
        }
        Ok(response)
    }

    /// Builds a steer response (channels attempted + durable `MessageSent`
    /// journal row on delivery) without auditing or erroring on non-delivery.
    fn steer_core(
        &self,
        requested_id: &str,
        target: &ResolvedAgent,
        instruction: &str,
        request_receipt: bool,
        caller_session: Option<&str>,
    ) -> Result<AgentSteerResponse, ErrorData> {
        let process = process_readback_for_target(target);
        let (channels, delivered_via) =
            self.attempt_steer_channels(target, instruction, request_receipt, caller_session);
        let delivered = delivered_via.is_some();
        let instruction_chars = instruction.chars().count();
        // Journal a durable `MessageSent` event only when a channel actually
        // delivered — never claim an injection that did not happen. `MessageSent`
        // is the #897 minimum-set kind for an orchestrator-to-agent message; the
        // steer reason_code distinguishes it from peer mailbox traffic.
        let journal_event = if delivered {
            Some(self.journal_lifecycle_event(
                AgentEventKind::MessageSent,
                target,
                "agent_steer",
                None,
                json!({
                    "delivered_via": delivered_via,
                    "instruction_chars": instruction_chars,
                    "instruction_preview": compact_for_channel_reason(instruction),
                    "process": &process,
                }),
            )?)
        } else {
            None
        };
        let receipt_box_session_id = if delivered && request_receipt {
            caller_session.map(ToOwned::to_owned)
        } else {
            None
        };
        Ok(AgentSteerResponse {
            requested_id: requested_id.to_owned(),
            session_id: target.session_id.clone(),
            spawn_id: target.spawn_id.clone(),
            agent_kind: target.agent_kind.clone(),
            lifecycle: target.lifecycle.clone(),
            resolution_source: target.resolution_source.clone(),
            delivered,
            delivered_via,
            instruction_chars,
            channels,
            journal_event,
            receipt_box_session_id,
            process,
        })
    }

    /// Attempts each ranked steering channel and returns `(attempts,
    /// delivered_via)`. Channels report true outcomes; unwired channels stay
    /// unavailable with a precise reason instead of being faked.
    fn attempt_steer_channels(
        &self,
        target: &ResolvedAgent,
        instruction: &str,
        request_receipt: bool,
        caller_session: Option<&str>,
    ) -> (Vec<ChannelAttempt>, Option<String>) {
        let mut attempts = Vec::new();
        let mut delivered_via = None;

        attempts.push(ChannelAttempt {
            channel: "codex_app_server_inject".to_owned(),
            rank: 1,
            status: "unavailable".to_owned(),
            reason: "channel_not_wired: the codex app-server protocol exposes turn/interrupt \
                     (cancel) but no mid-turn user-input inject RPC; a new turn would race the \
                     running one"
                .to_owned(),
            message_id: None,
            row_key: None,
        });
        attempts.push(ChannelAttempt {
            channel: "claude_stream_json_input".to_owned(),
            rank: 2,
            status: "unavailable".to_owned(),
            reason: "channel_not_wired: the daemon does not own the claude -p stream-json stdin \
                     pipe; even where owned, mid-turn stdin messages are processed in-memory only \
                     and dropped from session history (anthropics/claude-code#41230)"
                .to_owned(),
            message_id: None,
            row_key: None,
        });

        // Rank 3: cooperative steering mailbox — the one wired channel.
        let mailbox = self.deliver_mailbox_steer(target, instruction, request_receipt, caller_session);
        if mailbox.status == "delivered" {
            record_first_delivered_channel(&mut delivered_via, &mailbox);
        }
        attempts.push(mailbox);

        attempts.push(ChannelAttempt {
            channel: "pty_stdin".to_owned(),
            rank: 4,
            status: "unavailable".to_owned(),
            reason: "channel_not_wired: writing an instruction to the agent's terminal stdin needs \
                     owned-PTY capture (#902), which is not implemented yet"
                .to_owned(),
            message_id: None,
            row_key: None,
        });

        (attempts, delivered_via)
    }

    /// Delivers a durable `steer` mailbox row to the target's steering inbox,
    /// proving delivery by the persisted `CF_KV` row readback. The cooperative
    /// steering contract (`STEER_KIND`) is the same channel `agent_send` uses;
    /// the receipt (when requested) proves the agent actually applied it.
    fn deliver_mailbox_steer(
        &self,
        target: &ResolvedAgent,
        instruction: &str,
        request_receipt: bool,
        caller_session: Option<&str>,
    ) -> ChannelAttempt {
        let Some(caller) = caller_session else {
            return ChannelAttempt {
                channel: "mailbox_steer".to_owned(),
                rank: 3,
                status: "unavailable".to_owned(),
                reason: "needs the caller's MCP session id (run the daemon in HTTP mode so each \
                         agent has its own Mcp-Session-Id)"
                    .to_owned(),
                message_id: None,
                row_key: None,
            };
        };
        let send = self.agent_send_impl(
            super::agent_mailbox::AgentSendParams {
                to_session: target.session_id.clone(),
                kind: super::agent_mailbox::STEER_KIND.to_owned(),
                payload: json!({
                    "control": "steer",
                    "from": caller,
                    "reason": "operator_steer",
                    "instruction": instruction,
                }),
                artifact_handle: None,
                ttl_ms: STEER_MESSAGE_TTL_MS,
                request_receipt,
            },
            caller,
        );
        match send {
            Ok(response) => ChannelAttempt {
                channel: "mailbox_steer".to_owned(),
                rank: 3,
                status: "delivered".to_owned(),
                reason: format!(
                    "durable {} row persisted to CF_KV (queue_depth_after={}); cooperative agents \
                     drain it between tool calls and splice it into context{}",
                    super::agent_mailbox::STEER_KIND,
                    response.queue_depth_after,
                    if request_receipt {
                        " (read receipt requested — poll agent_receipts for consumption proof)"
                    } else {
                        ""
                    }
                ),
                message_id: Some(response.message_id),
                row_key: Some(response.row_key),
            },
            Err(error) => ChannelAttempt {
                channel: "mailbox_steer".to_owned(),
                rank: 3,
                status: "failed".to_owned(),
                reason: format!("mailbox delivery failed: {}", error.message),
                message_id: None,
                row_key: None,
            },
        }
    }

    // ------------------------------------------------------------------
    // agent_kill
    // ------------------------------------------------------------------

    async fn agent_kill_impl(
        &self,
        params: AgentKillParams,
        caller_session: Option<&str>,
    ) -> Result<AgentKillResponse, ErrorData> {
        let lookup = validate_lookup_id(&params.session_id, TOOL_AGENT_KILL)?;
        if params.grace_ms > MAX_KILL_GRACE_MS {
            return Err(mcp_error(
                error_codes::TOOL_PARAMS_INVALID,
                format!(
                    "AGENT_KILL_GRACE_INVALID: grace_ms must be 0..={MAX_KILL_GRACE_MS}, got {}",
                    params.grace_ms
                ),
            ));
        }
        let target = self.resolve_spawned_agent(&lookup, TOOL_AGENT_KILL)?;
        let process_before = process_readback_for_target(&target);
        let already_dead = process_before.live_process_ids.is_empty();

        let payload = json!({
            "requested_id": lookup,
            "grace_ms": params.grace_ms,
            "interrupt_first": params.interrupt_first,
            "from": caller_session,
        });
        let before = json!({ "process": &process_before, "lifecycle": target.lifecycle });
        self.command_audit_intent(
            CommandAuditInput::mcp(
                TOOL_AGENT_KILL,
                "kill",
                caller_session.map(ToOwned::to_owned),
                Some(target.session_id.clone()),
                payload.clone(),
                before.clone(),
                Value::Null,
                "pending",
            )
            .with_target(json!({ "spawn_id": target.spawn_id, "agent_kind": target.agent_kind })),
        )?;

        // Graceful first: attempt the interrupt (best-effort — its failure must
        // never block the force-kill), then wait the grace window for the tree
        // to exit on its own. Skipped entirely when already dead.
        let interrupt = if params.interrupt_first && !already_dead {
            self.interrupt_core(&target.session_id.clone(), &target, caller_session)
                .ok()
        } else {
            None
        };
        let natural_exit = if !already_dead && params.grace_ms > 0 {
            let (remaining, _waited) =
                wait_for_tree_exit_async(&process_before.process_tree_ids, params.grace_ms).await;
            remaining.is_empty()
        } else {
            false
        };

        // Was a force-kill actually required? (the tree is still alive)
        let live_after_grace = crate::m4::owned_live_process_ids(&process_before.process_tree_ids);
        let force_needed = !live_after_grace.is_empty();

        // Journal the durable `killed` event BEFORE teardown when a force-kill
        // is required, so the terminal transition is recorded as killed (not a
        // generic exit). The reducer treats a dead agent as dead, so teardown's
        // later `exited` row is absorbed without a spurious transition.
        let journal_killed_event = if force_needed {
            Some(self.journal_lifecycle_event(
                AgentEventKind::Killed,
                &target,
                "agent_kill",
                Some(AgentEndState::Error),
                json!({
                    "process_before": &process_before,
                    "live_before_force": live_after_grace,
                    "grace_ms": params.grace_ms,
                    "interrupt_first": params.interrupt_first,
                }),
            )?)
        } else {
            None
        };

        // Reuse the authoritative per-session teardown: job-close → force kill
        // of the process tree, plus lease/claim/desktop release and registry
        // close. Keyed by the agent's OWN session id, which owns all of it.
        let lifecycle = self.session_lifecycle_state()?;
        let (teardown, teardown_error) = match lifecycle
            .teardown_session_with_options(
                &target.session_id,
                "agent_kill",
                SessionTeardownOptions::explicit_kill(),
            )
            .await
        {
            Ok(report) => (Some(report), None),
            Err(error) => (None, Some(error.message.to_string())),
        };

        // Source of truth for "is it dead": re-read the OS process table.
        let mut process_after = process_readback_for_target(&target);
        let mut orphan_process_ids =
            merged_live_process_ids(&process_before.process_tree_ids, &process_after);
        let post_teardown_force_termination = if !orphan_process_ids.is_empty() {
            Some(crate::m4::terminate_owned_process_ids(&orphan_process_ids))
        } else {
            None
        };
        if post_teardown_force_termination.is_some() {
            process_after = process_readback_for_target(&target);
            orphan_process_ids =
                merged_live_process_ids(&process_before.process_tree_ids, &process_after);
        }
        let killed = orphan_process_ids.is_empty();
        let (completion_artifact_cleanup_status, completion_artifact_cleanup_error) =
            if killed && post_teardown_force_termination.is_some() {
                match write_agent_kill_restart_completion_artifact(
                    &target,
                    &process_before,
                    &orphan_process_ids,
                    post_teardown_force_termination.as_ref(),
                ) {
                    Ok(status) => (Some(status), None),
                    Err(error) => (None, Some(error)),
                }
            } else {
                (None, None)
            };

        let response = AgentKillResponse {
            requested_id: lookup,
            session_id: target.session_id.clone(),
            spawn_id: target.spawn_id.clone(),
            agent_kind: target.agent_kind.clone(),
            resolution_source: target.resolution_source.clone(),
            already_dead,
            interrupt,
            grace_ms: params.grace_ms,
            natural_exit,
            process_before,
            process_after,
            orphan_process_ids,
            killed,
            post_teardown_force_termination,
            completion_artifact_cleanup_status,
            completion_artifact_cleanup_error,
            journal_killed_event,
            teardown,
            teardown_error,
        };

        let after = json!({
            "killed": response.killed,
            "already_dead": response.already_dead,
            "natural_exit": response.natural_exit,
            "orphan_process_ids": response.orphan_process_ids,
            "process_after": response.process_after,
            "resolution_source": response.resolution_source,
            "teardown_error": response.teardown_error,
            "post_teardown_force_termination": response.post_teardown_force_termination,
            "completion_artifact_cleanup_status": response.completion_artifact_cleanup_status,
            "completion_artifact_cleanup_error": response.completion_artifact_cleanup_error,
        });
        self.command_audit_final(
            CommandAuditInput::mcp(
                TOOL_AGENT_KILL,
                "kill",
                caller_session.map(ToOwned::to_owned),
                Some(target.session_id.clone()),
                payload,
                before,
                after,
                if response.killed { "ok" } else { "error" },
            )
            .with_target(json!({ "spawn_id": target.spawn_id, "agent_kind": target.agent_kind })),
        )?;

        if !response.killed {
            return Err(mcp_error(
                error_codes::TOOL_INTERNAL_ERROR,
                format!(
                    "AGENT_KILL_ORPHANS: agent {} (session {}) still has live processes after teardown: {:?}{}. The kill is reported as failed; these pids survived.",
                    response.requested_id,
                    response.session_id,
                    response.orphan_process_ids,
                    response
                        .teardown_error
                        .as_ref()
                        .map(|error| format!(" (teardown error: {error})"))
                        .unwrap_or_default(),
                ),
            ));
        }
        Ok(response)
    }

    // ------------------------------------------------------------------
    // fleet_stop
    // ------------------------------------------------------------------

    async fn fleet_stop_impl(
        &self,
        params: FleetStopParams,
        caller_session: Option<&str>,
    ) -> Result<FleetStopResponse, ErrorData> {
        let mode = params.mode.trim().to_ascii_lowercase();
        if mode != "kill" && mode != "interrupt" {
            return Err(mcp_error(
                error_codes::TOOL_PARAMS_INVALID,
                format!(
                    "FLEET_STOP_MODE_INVALID: mode must be \"kill\" or \"interrupt\", got {:?}",
                    params.mode
                ),
            ));
        }
        if params.confirm != FLEET_STOP_CONFIRM {
            return Err(mcp_error(
                error_codes::TOOL_PARAMS_INVALID,
                format!(
                    "FLEET_STOP_CONFIRM_REQUIRED: fleet_stop is destructive and requires confirm=\"{FLEET_STOP_CONFIRM}\""
                ),
            ));
        }
        if params.grace_ms > MAX_KILL_GRACE_MS {
            return Err(mcp_error(
                error_codes::TOOL_PARAMS_INVALID,
                format!(
                    "FLEET_STOP_GRACE_INVALID: grace_ms must be 0..={MAX_KILL_GRACE_MS}, got {}",
                    params.grace_ms
                ),
            ));
        }

        // Snapshot the matched live agents, then drop the registry lock BEFORE
        // stopping any (the stop path re-locks the registry to resolve).
        let matched_sessions = self.live_spawned_agent_sessions(&params.agent_kinds)?;

        let payload = json!({
            "mode": mode,
            "agent_kinds": params.agent_kinds,
            "grace_ms": params.grace_ms,
            "from": caller_session,
        });
        let before =
            json!({ "matched_sessions": matched_sessions, "matched": matched_sessions.len() });
        let verb = if mode == "kill" {
            "fleet_kill"
        } else {
            "fleet_interrupt"
        };
        self.command_audit_intent(CommandAuditInput::mcp(
            TOOL_FLEET_STOP,
            verb,
            caller_session.map(ToOwned::to_owned),
            None,
            payload.clone(),
            before.clone(),
            Value::Null,
            "pending",
        ))?;

        let agents: Vec<FleetStopAgentOutcome> =
            join_all(matched_sessions.iter().map(|session_id| {
                self.fleet_stop_one(&mode, session_id, params.grace_ms, caller_session)
            }))
            .await;

        let succeeded = agents.iter().filter(|outcome| outcome.ok).count();
        let failed = agents.len() - succeeded;
        let response = FleetStopResponse {
            mode: mode.clone(),
            matched: agents.len(),
            succeeded,
            failed,
            all_stopped: failed == 0,
            agents,
        };

        let after = json!({
            "matched": response.matched,
            "succeeded": response.succeeded,
            "failed": response.failed,
            "all_stopped": response.all_stopped,
            "agents": response.agents,
        });
        self.command_audit_final(CommandAuditInput::mcp(
            TOOL_FLEET_STOP,
            verb,
            caller_session.map(ToOwned::to_owned),
            None,
            payload,
            before,
            after,
            if response.all_stopped { "ok" } else { "error" },
        ))?;

        Ok(response)
    }

    /// Stops one agent for a fleet sweep, mapping any error to a loud per-agent
    /// outcome rather than aborting the whole sweep.
    async fn fleet_stop_one(
        &self,
        mode: &str,
        session_id: &str,
        grace_ms: u64,
        caller_session: Option<&str>,
    ) -> FleetStopAgentOutcome {
        if mode == "kill" {
            match self
                .agent_kill_impl(
                    AgentKillParams {
                        session_id: session_id.to_owned(),
                        grace_ms,
                        interrupt_first: true,
                    },
                    caller_session,
                )
                .await
            {
                Ok(kill) => FleetStopAgentOutcome {
                    session_id: kill.session_id,
                    spawn_id: kill.spawn_id,
                    agent_kind: kill.agent_kind,
                    ok: kill.killed,
                    reason: if kill.already_dead {
                        "already_dead".to_owned()
                    } else if kill.natural_exit {
                        "exited_during_grace".to_owned()
                    } else {
                        "force_killed".to_owned()
                    },
                    surviving_process_ids: kill.orphan_process_ids,
                },
                Err(error) => FleetStopAgentOutcome {
                    session_id: session_id.to_owned(),
                    spawn_id: None,
                    agent_kind: "unknown".to_owned(),
                    ok: false,
                    reason: error.message.to_string(),
                    surviving_process_ids: Vec::new(),
                },
            }
        } else {
            match self.agent_interrupt_impl(
                AgentInterruptParams {
                    session_id: session_id.to_owned(),
                },
                caller_session,
            ) {
                Ok(interrupt) => FleetStopAgentOutcome {
                    session_id: interrupt.session_id,
                    spawn_id: interrupt.spawn_id,
                    agent_kind: interrupt.agent_kind,
                    ok: interrupt.delivered,
                    reason: interrupt
                        .delivered_via
                        .unwrap_or_else(|| "no_channel_delivered".to_owned()),
                    surviving_process_ids: Vec::new(),
                },
                Err(error) => FleetStopAgentOutcome {
                    session_id: session_id.to_owned(),
                    spawn_id: None,
                    agent_kind: "unknown".to_owned(),
                    ok: false,
                    reason: error.message.to_string(),
                    surviving_process_ids: Vec::new(),
                },
            }
        }
    }

    /// Snapshots the session ids of every live spawned agent (optionally
    /// filtered by registry `agent_kind`). The registry lock is released before
    /// the caller stops anyone.
    fn live_spawned_agent_sessions(
        &self,
        agent_kinds: &[String],
    ) -> Result<Vec<String>, ErrorData> {
        let now = unix_time_ms_now();
        let registry = self.session_registry.lock().map_err(|_error| {
            mcp_error(
                error_codes::TOOL_INTERNAL_ERROR,
                "session registry lock poisoned while enumerating the live fleet",
            )
        })?;
        let mut sessions = BTreeSet::new();
        for read in registry.reads(now) {
            if read.spawned_agent.is_none() || read.lifecycle == "closed" {
                continue;
            }
            if !agent_kinds.is_empty() && !agent_kinds.iter().any(|kind| kind == &read.agent_kind) {
                continue;
            }
            sessions.insert(read.session_id.clone());
        }
        drop(registry);
        for read in super::agent_state::reads(now) {
            if read.spawn_id.is_none()
                || read.state == super::agent_state::AgentLifecycleState::Dead
            {
                continue;
            }
            let Some(session_id) = read.session_id else {
                continue;
            };
            let agent_kind = read.agent_kind.unwrap_or_else(|| "unknown".to_owned());
            if !agent_kinds.is_empty() && !agent_kinds.iter().any(|kind| kind == &agent_kind) {
                continue;
            }
            sessions.insert(session_id);
        }
        Ok(sessions.into_iter().collect())
    }

    // ------------------------------------------------------------------
    // Shared helpers
    // ------------------------------------------------------------------

    /// Locates a spawned agent in the live session registry by its own session
    /// id or its `agent-spawn-*` id. Errors structurally for unknown ids and
    /// for known sessions that are not Synapse-spawned (no owned process tree).
    fn resolve_spawned_agent(&self, lookup: &str, tool: &str) -> Result<ResolvedAgent, ErrorData> {
        let now = unix_time_ms_now();
        let registry = self.session_registry.lock().map_err(|_error| {
            mcp_error(
                error_codes::TOOL_INTERNAL_ERROR,
                "session registry lock poisoned while resolving agent target",
            )
        })?;
        let mut session_match = None;
        let mut non_spawned_session_hit = false;
        for read in registry.reads(now) {
            let Some(spawned) = read.spawned_agent.as_ref() else {
                if read.session_id == lookup {
                    non_spawned_session_hit = true;
                }
                continue;
            };
            if read.session_id == lookup || spawned.spawn_id == lookup {
                session_match = Some(ResolvedAgent {
                    session_id: read.session_id.clone(),
                    spawn_id: Some(spawned.spawn_id.clone()),
                    agent_kind: read.agent_kind.clone(),
                    lifecycle: read.lifecycle.clone(),
                    resolution_source: "session_registry".to_owned(),
                    dead: read.lifecycle == "closed",
                    launcher_process_id: spawned.launcher_process_id,
                    agent_process_id: spawned.agent_process_id,
                    log_dir: spawned.log_dir.clone(),
                    control: spawned.control.clone(),
                });
                break;
            }
        }
        drop(registry);

        if let Some(resolved) = session_match {
            return Ok(resolved);
        }
        if let Some(state_read) = super::agent_state::read_for_session(lookup, now) {
            if let Some(resolved) =
                resolved_agent_from_durable_state_read(lookup, tool, state_read)?
            {
                return Ok(resolved);
            }
        }
        if non_spawned_session_hit {
            return Err(mcp_error(
                error_codes::TOOL_PARAMS_INVALID,
                format!(
                    "AGENT_NOT_SPAWNED: session {lookup} exists but is not a Synapse-spawned agent; {tool} owns no process tree for it"
                ),
            ));
        }
        Err(mcp_error(
            error_codes::TOOL_PARAMS_INVALID,
            format!(
                "AGENT_NOT_FOUND: no live spawned agent resolves to '{lookup}' (try its MCP session id or agent-spawn-* id from act_spawn_agent / agent_query)"
            ),
        ))
    }

    /// Writes a durable lifecycle journal row (`Interrupted` / `Killed`) for an
    /// agent and returns its physical readback. Mirrors the attribution that
    /// `session_lifecycle` uses for its `Exited` rows.
    fn journal_lifecycle_event(
        &self,
        kind: AgentEventKind,
        target: &ResolvedAgent,
        reason_code: &str,
        end_state: Option<AgentEndState>,
        payload: Value,
    ) -> Result<JournalReadback, ErrorData> {
        let db = self.agent_control_db()?;
        let mut record = AgentEventRecord::new(unix_time_ns_now(), kind);
        record.session_id = Some(target.session_id.clone());
        record.spawn_id.clone_from(&target.spawn_id);
        record.reason_code = Some(reason_code.to_owned());
        record.end_state = end_state;
        record.attributes.conversation_id = Some(target.session_id.clone());
        if target.agent_kind != "unknown" {
            record.attributes.agent_name = Some(target.agent_kind.clone());
        }
        record.payload = payload;
        let readback = record_agent_event_durable(&db, &record)
            .map_err(|error| mcp_error(error.code(), error.to_string()))?;
        Ok(JournalReadback {
            kind: format!("{kind:?}"),
            ts_ns: readback.ts_ns,
            seq: readback.seq,
            value_len_bytes: readback.value_len_bytes as u64,
        })
    }

    /// Opens the shared M3 storage handle (same path `agent_query` uses).
    fn agent_control_db(&self) -> Result<std::sync::Arc<synapse_storage::Db>, ErrorData> {
        let state = self.m3_state_handle();
        let mut guard = state.lock().map_err(|_error| {
            mcp_error(
                error_codes::TOOL_INTERNAL_ERROR,
                "M3 service state lock poisoned while opening agent control storage",
            )
        })?;
        guard
            .ensure_storage()
            .map_err(|error| mcp_error(error.code(), error.to_string()))
    }
}

fn process_readback_for_target(target: &ResolvedAgent) -> ProcessReadback {
    if target.launcher_process_id == 0 {
        return ProcessReadback {
            launcher_process_id: 0,
            process_tree_ids: Vec::new(),
            live_process_ids: Vec::new(),
        };
    }
    let mut process_tree_ids = crate::m4::owned_process_tree_ids(target.launcher_process_id);
    if let Some(agent_pid) = target.agent_process_id {
        process_tree_ids.extend(crate::m4::owned_process_tree_ids(agent_pid));
    }
    process_tree_ids.sort_unstable();
    process_tree_ids.dedup();
    let live_process_ids = crate::m4::owned_live_process_ids(&process_tree_ids);
    ProcessReadback {
        launcher_process_id: target.launcher_process_id,
        process_tree_ids,
        live_process_ids,
    }
}

fn merged_live_process_ids(before_ids: &[u32], after: &ProcessReadback) -> Vec<u32> {
    let mut ids = before_ids.to_vec();
    ids.extend(after.process_tree_ids.iter().copied());
    ids.sort_unstable();
    ids.dedup();
    crate::m4::owned_live_process_ids(&ids)
}

fn resolved_agent_from_durable_state_read(
    lookup: &str,
    tool: &str,
    read: super::agent_state::AgentStateRead,
) -> Result<Option<ResolvedAgent>, ErrorData> {
    let Some(spawn_id) = read.spawn_id.clone() else {
        return Ok(None);
    };
    let session_matches = read.session_id.as_deref() == Some(lookup);
    let spawn_matches = spawn_id == lookup || read.anchor == lookup;
    if !session_matches && !spawn_matches {
        return Ok(None);
    }
    let terminal_dead = read.state == super::agent_state::AgentLifecycleState::Dead;
    let session_id = match read.session_id.clone() {
        Some(session_id) => session_id,
        None if terminal_dead => spawn_id.clone(),
        None => {
            return Err(mcp_error(
                error_codes::TOOL_PARAMS_INVALID,
                format!(
                    "AGENT_NOT_READY: {tool} resolved spawn {spawn_id} from durable agent state but no MCP session id is linked yet"
                ),
            ));
        }
    };
    let launcher_process_id = match read.launcher_process_id {
        Some(launcher_process_id) => launcher_process_id,
        None if terminal_dead => 0,
        None => {
            return Err(mcp_error(
                error_codes::TOOL_PARAMS_INVALID,
                format!(
                    "AGENT_PROCESS_UNAVAILABLE: {tool} resolved spawn {spawn_id} from durable agent state but no launcher process id is recorded"
                ),
            ));
        }
    };
    if session_id == spawn_id && terminal_dead {
        tracing::info!(
            code = "AGENT_KILL_ALREADY_DEAD_UNLINKED",
            spawn_id,
            tool,
            "durable terminal spawn has no session registration; resolving as already dead"
        );
    }
    let log_dir = read.log_dir.clone().unwrap_or_else(|| {
        super::m4_tools::agent_spawn_root_dir()
            .ok()
            .map(|root| root.join(&spawn_id).display().to_string())
            .unwrap_or_default()
    });
    Ok(Some(ResolvedAgent {
        session_id,
        spawn_id: Some(spawn_id),
        agent_kind: read.agent_kind.unwrap_or_else(|| "unknown".to_owned()),
        lifecycle: format!("agent_state:{}", read.state.as_str()),
        resolution_source: "durable_agent_state".to_owned(),
        dead: read.state == super::agent_state::AgentLifecycleState::Dead,
        launcher_process_id,
        agent_process_id: read.agent_process_id,
        log_dir,
        control: None,
    }))
}

fn write_agent_kill_restart_completion_artifact(
    target: &ResolvedAgent,
    process_before: &ProcessReadback,
    remaining_process_ids_after: &[u32],
    termination: Option<&crate::m4::OwnedProcessTerminationReadback>,
) -> Result<String, String> {
    let Some(spawn_id) = target.spawn_id.as_deref() else {
        return Ok("not_spawned_agent".to_owned());
    };
    let log_dir = if target.log_dir.trim().is_empty() {
        super::m4_tools::agent_spawn_root_dir()
            .map_err(|error| {
                format!(
                    "failed to resolve agent spawn root for restart artifact: {}",
                    error.message
                )
            })?
            .join(spawn_id)
    } else {
        PathBuf::from(&target.log_dir)
    };
    fs::create_dir_all(&log_dir).map_err(|error| {
        format!(
            "failed to create restart artifact log dir {}: {error}",
            log_dir.display()
        )
    })?;
    let stdout_path = log_dir.join("stdout.jsonl");
    let stderr_path = log_dir.join("stderr.log");
    let final_message_path = log_dir.join("final-message.txt");
    let completion_status_path = log_dir.join("completion-status.json");
    let completion_status_before_cleanup = spawn_completion_status_value(&completion_status_path);
    let completion_status_before_cleanup_status = completion_status_before_cleanup
        .as_ref()
        .and_then(|value| value.get("status"))
        .and_then(Value::as_str)
        .map(ToOwned::to_owned);
    let overwrite_wrapper_fallback = completion_status_before_cleanup
        .as_ref()
        .is_some_and(|value| restart_kill_can_overwrite_wrapper_fallback_status(value));
    if completion_status_before_cleanup_status
        .as_deref()
        .is_some_and(|status| status != "running")
        && !overwrite_wrapper_fallback
    {
        return Ok("already_terminal".to_owned());
    }
    let final_message_len_before = spawn_file_len(&final_message_path);
    let stdout_len = spawn_file_len(&stdout_path);
    let stderr_len = spawn_file_len(&stderr_path);
    let (stdout_line_count, last_stdout_event_type) = spawn_stdout_summary(&stdout_path);
    let status = "agent_kill_forced_after_daemon_restart";
    let error_message =
        "spawned agent was force-killed after daemon restart without a live process job handle";
    let details = json!({
        "reason": "agent_kill_restart_fallback_without_process_job",
        "session_id": target.session_id,
        "spawn_id": spawn_id,
        "agent_kind": target.agent_kind,
        "resolution_source": target.resolution_source,
        "launcher_process_id": target.launcher_process_id,
        "agent_process_id": target.agent_process_id,
        "process_before": process_before,
        "remaining_process_ids_after": remaining_process_ids_after,
        "post_teardown_force_termination": termination,
        "completion_status_before_cleanup": completion_status_before_cleanup,
    });
    let write_final_message = final_message_len_before == 0 || overwrite_wrapper_fallback;
    if write_final_message {
        let final_message = json!({
            "schema_version": 1,
            "spawn_id": spawn_id,
            "cli": target.agent_kind,
            "status": status,
            "exit_code": null,
            "error_message": error_message,
            "message": "Synapse agent_kill wrote this terminal artifact after reclaiming a daemon-restart-handoff spawn without a live process job handle.",
            "stdout_path": stdout_path.display().to_string(),
            "stderr_path": stderr_path.display().to_string(),
            "completion_status_path": completion_status_path.display().to_string(),
            "details": details,
        });
        let bytes = serde_json::to_vec_pretty(&final_message)
            .map_err(|error| format!("failed to encode restart final-message artifact: {error}"))?;
        fs::write(&final_message_path, bytes).map_err(|error| {
            format!(
                "failed to write restart final-message artifact {}: {error}",
                final_message_path.display()
            )
        })?;
    }
    let final_message_len_after = spawn_file_len(&final_message_path);
    let completion_status = json!({
        "schema_version": 1,
        "spawn_id": spawn_id,
        "cli": target.agent_kind,
        "status": status,
        "exit_code": null,
        "error_message": error_message,
        "wrapper_started_at_unix_ms": null,
        "completed_at_unix_ms": unix_time_ms_now(),
        "elapsed_ms": null,
        "requested_hold_open_ms": null,
        "hold_open_elapsed_ms_met": false,
        "final_message_path": final_message_path.display().to_string(),
        "final_message_bytes": final_message_len_after,
        "final_message_present": final_message_len_after > 0,
        "final_message_source": if write_final_message {
            "agent_kill_restart_artifact_json"
        } else {
            "preexisting_final_message_without_terminal_status"
        },
        "recovered_final_message_written": false,
        "fallback_final_message_written": write_final_message,
        "stdout_path": stdout_path.display().to_string(),
        "stdout_line_count": stdout_line_count,
        "last_stdout_event_type": last_stdout_event_type,
        "stdout_bytes": stdout_len,
        "stderr_path": stderr_path.display().to_string(),
        "stderr_bytes": stderr_len,
        "daemon_terminal_artifact": true,
        "agent_kill_restart_artifact": true,
        "completion_status_source": "agent_kill_restart_artifact_json",
        "completion_status_before_cleanup": completion_status_before_cleanup,
        "log_dir": log_dir.display().to_string(),
        "details": details,
    });
    let bytes = serde_json::to_vec_pretty(&completion_status)
        .map_err(|error| format!("failed to encode restart completion-status artifact: {error}"))?;
    fs::write(&completion_status_path, bytes).map_err(|error| {
        format!(
            "failed to write restart completion-status artifact {}: {error}",
            completion_status_path.display()
        )
    })?;
    Ok(status.to_owned())
}

fn spawn_completion_status_value(path: &PathBuf) -> Option<Value> {
    let bytes = fs::read(path).ok()?;
    serde_json::from_slice::<Value>(&bytes).ok()
}

fn restart_kill_can_overwrite_wrapper_fallback_status(value: &Value) -> bool {
    let Some(status) = value.get("status").and_then(Value::as_str) else {
        return false;
    };
    if !matches!(
        status,
        "failed" | "missing_final_response" | "wrapper_error"
    ) {
        return false;
    }
    let final_message_source = value
        .get("final_message_source")
        .and_then(Value::as_str)
        .unwrap_or_default();
    let fallback_final_message_written = value
        .get("fallback_final_message_written")
        .and_then(Value::as_bool)
        .unwrap_or(false);
    final_message_source == "wrapper_fallback_json" || fallback_final_message_written
}

fn spawn_file_len(path: &PathBuf) -> u64 {
    fs::metadata(path).map_or(0, |metadata| metadata.len())
}

fn spawn_stdout_summary(path: &PathBuf) -> (u64, Option<String>) {
    let Ok(stdout) = fs::read(path) else {
        return (0, None);
    };
    let stdout = String::from_utf8_lossy(&stdout);
    let mut line_count = 0;
    let mut last_event_type = None;
    for line in stdout.lines() {
        if line.trim().is_empty() {
            continue;
        }
        line_count += 1;
        if let Ok(value) = serde_json::from_str::<Value>(line) {
            if let Some(event_type) = value.get("type").and_then(Value::as_str) {
                last_event_type = Some(event_type.to_owned());
            } else if let Some(event_type) = value
                .get("item")
                .and_then(|item| item.get("type"))
                .and_then(Value::as_str)
            {
                last_event_type = Some(event_type.to_owned());
            }
        }
    }
    (line_count, last_event_type)
}

fn run_codex_interrupt_helper(
    script_path: &PathBuf,
    control: &SpawnedAgentControlRead,
    thread_id: &str,
    turn_id: &str,
) -> Result<Output, String> {
    let mut child = Command::new("powershell.exe")
        .args([
            "-NoLogo",
            "-NoProfile",
            "-NonInteractive",
            "-ExecutionPolicy",
            "Bypass",
            "-File",
        ])
        .arg(script_path)
        .args([
            "-Endpoint",
            control.endpoint.as_str(),
            "-ThreadId",
            thread_id,
            "-TurnId",
            turn_id,
            "-ControlPath",
            control.control_path.as_str(),
            "-EventsPath",
            control.events_path.as_str(),
        ])
        .stdin(Stdio::null())
        .stdout(Stdio::piped())
        .stderr(Stdio::piped())
        .spawn()
        .map_err(|error| format!("interrupt_helper_spawn_failed: {error}"))?;

    let started = Instant::now();
    loop {
        match child.try_wait() {
            Ok(Some(_status)) => {
                return child
                    .wait_with_output()
                    .map_err(|error| format!("interrupt_helper_output_failed: {error}"));
            }
            Ok(None)
                if started.elapsed() < Duration::from_millis(CODEX_INTERRUPT_HELPER_TIMEOUT_MS) =>
            {
                std::thread::sleep(Duration::from_millis(50));
            }
            Ok(None) => {
                let pid = child.id();
                let _ = child.kill();
                let _ = child.wait();
                return Err(format!(
                    "interrupt_helper_timeout: helper pid {pid} exceeded {CODEX_INTERRUPT_HELPER_TIMEOUT_MS}ms"
                ));
            }
            Err(error) => {
                let pid = child.id();
                let _ = child.kill();
                let _ = child.wait();
                return Err(format!(
                    "interrupt_helper_wait_failed: helper pid {pid}: {error}"
                ));
            }
        }
    }
}

fn compact_for_channel_reason(value: &str) -> String {
    const LIMIT: usize = 512;
    let compact = value.split_whitespace().collect::<Vec<_>>().join(" ");
    if compact.len() <= LIMIT {
        compact
    } else {
        format!("{}...", &compact[..LIMIT])
    }
}

fn record_first_delivered_channel(delivered_via: &mut Option<String>, attempt: &ChannelAttempt) {
    if delivered_via.is_none() && attempt.status == "delivered" {
        *delivered_via = Some(attempt.channel.clone());
    }
}

/// Polls the owned process tree for exit up to `grace_ms`, yielding to the async
/// runtime between polls so the daemon stays responsive during the grace window.
async fn wait_for_tree_exit_async(process_ids: &[u32], grace_ms: u64) -> (Vec<u32>, u64) {
    let deadline = Duration::from_millis(grace_ms);
    let started = tokio::time::Instant::now();
    loop {
        let remaining = crate::m4::owned_live_process_ids(process_ids);
        if remaining.is_empty() {
            return (
                remaining,
                u64::try_from(started.elapsed().as_millis()).unwrap_or(u64::MAX),
            );
        }
        if started.elapsed() >= deadline {
            return (
                remaining,
                u64::try_from(started.elapsed().as_millis()).unwrap_or(u64::MAX),
            );
        }
        tokio::time::sleep(Duration::from_millis(GRACE_POLL_INTERVAL_MS)).await;
    }
}

fn validate_lookup_id(session_id: &str, tool: &str) -> Result<String, ErrorData> {
    let trimmed = session_id.trim();
    if trimmed.is_empty() {
        return Err(mcp_error(
            error_codes::TOOL_PARAMS_INVALID,
            format!("{tool}: session_id must be a non-empty MCP session id or agent-spawn-* id"),
        ));
    }
    Ok(trimmed.to_owned())
}

#[cfg(test)]
mod tests;
