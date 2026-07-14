//! Tool-call validation layer.
//!
//! Wraps every `Box<dyn Tool>` in a [`ValidatedTool`] that intercepts `invoke()`
//! to run tiered checks before forwarding to the inner tool:
//!
//! - **Layer 0 — Static checks** (no LLM cost): duplicate detection, write-before-read,
//!   rapid-retry loop detection. Runs for all risk levels.
//! - **Layer 1 — LLM pre-flight** (opt-in): a second, cheap model validates whether the
//!   tool call makes sense given the agent's stated `_reason` and recent history.
//!   Runs only for `Mutating` and `Destructive` tools.
//! - **Layer 2 — Direct human approval** (opt-in): tool calls at/above a configured
//!   risk threshold suspend and wait for a human approve/deny (see [`approval`]).

pub mod approval;

use std::borrow::Cow;
use std::sync::Arc;

use async_trait::async_trait;
use chrono::{DateTime, Utc};
use swiftide::chat_completion::{Tool, ToolCall, ToolOutput, ToolSpec, errors::ToolError};
use swiftide::traits::AgentContext;
use uuid::Uuid;

use crate::model::{ChatEvent, RunningTool, RunningToolValidation};
use approval::{ApprovalBroker, ApprovalOutcome, ApprovalPolicy, GuardRole, PendingApproval};

// ── Risk classification ──────────────────────────────────────────────

/// Risk level for a tool, controlling which validation tiers fire.
#[derive(Debug, Clone, Copy, PartialEq, Eq, PartialOrd, Ord)]
pub enum ToolRisk {
    /// Read-only, no side effects. Static checks only, no LLM validation.
    ReadOnly,
    /// Session-local bookkeeping (pin, name_session). No external visibility,
    /// no state machine transitions. Static checks only — not worth validating.
    SessionLocal,
    /// Externally visible or state-changing but bounded (config patches,
    /// set_phase). LLM validation, fail-open on validator error.
    Mutating,
    /// Hard to reverse (write_file, set_config, run_command).
    /// LLM validation, fail-closed on validator error.
    Destructive,
}

/// Convert a ToolRisk to its wire string representation.
pub fn risk_to_str(risk: ToolRisk) -> &'static str {
    match risk {
        ToolRisk::ReadOnly => "read_only",
        ToolRisk::SessionLocal => "session_local",
        ToolRisk::Mutating => "mutating",
        ToolRisk::Destructive => "destructive",
    }
}

#[cfg(feature = "api-mcp")]
impl From<plan_ai_api_mcp::Risk> for ToolRisk {
    fn from(r: plan_ai_api_mcp::Risk) -> Self {
        match r {
            plan_ai_api_mcp::Risk::ReadOnly => ToolRisk::ReadOnly,
            plan_ai_api_mcp::Risk::Mutating => ToolRisk::Mutating,
            plan_ai_api_mcp::Risk::Destructive => ToolRisk::Destructive,
        }
    }
}

// ── Configuration ────────────────────────────────────────────────────

/// Configuration for the validation layer.
#[derive(Clone)]
pub struct ValidationConfig {
    /// LLM backend for pre-flight validation. `None` = Layer 0 only.
    pub validator_llm: Option<Arc<dyn ValidatorLlm>>,
    /// Master switch. When false, `ValidatedTool` delegates directly.
    pub enabled: bool,
    /// Shared running-tools snapshot for broadcasting validation state.
    pub running_tools: Arc<std::sync::Mutex<Vec<RunningTool>>>,
    /// Event broadcaster for SSE updates.
    pub events_tx: tokio::sync::broadcast::Sender<ChatEvent>,
    /// Direct human approval (Layer 2). `None` = disabled.
    pub approval: Option<ApprovalHook>,
}

/// Everything Layer 2 needs to gate a call on a human decision.
#[derive(Clone)]
pub struct ApprovalHook {
    pub policy: ApprovalPolicy,
    pub broker: Arc<ApprovalBroker>,
    /// Store for persisting `approval_request` audit messages.
    pub store: crate::store::DynChatStore,
    pub session_id: Uuid,
}

// ── Validator LLM trait ──────────────────────────────────────────────

/// Trait abstracting the validator LLM call.
#[async_trait]
pub trait ValidatorLlm: Send + Sync {
    /// Validate a tool call. Returns the verdict with reasoning.
    async fn validate_tool_call(
        &self,
        ctx: &ValidationContext<'_>,
    ) -> anyhow::Result<ValidationVerdict>;
}

/// Context passed to the validator LLM.
pub struct ValidationContext<'a> {
    pub tool_name: &'a str,
    pub tool_description: &'a str,
    pub args: &'a str,
    pub reason: &'a str,
    pub risk: ToolRisk,
    pub history: &'a [ToolCallRecord],
    /// Last assistant message (truncated to 500 chars).
    pub last_assistant_message: &'a str,
    /// Current session phase (domain state string), if known.
    pub session_phase: &'a str,
}

/// Verdict from the validator LLM.
#[derive(Debug, Clone)]
pub enum ValidationVerdict {
    Approved { reasoning: String },
    Rejected { explanation: String },
}

// ── Tool call history ────────────────────────────────────────────────

/// A record of a single tool call, kept in session-scoped history.
#[derive(Debug, Clone)]
pub struct ToolCallRecord {
    pub tool_name: String,
    /// Full args JSON (not truncated).
    pub args: String,
    /// Full result for results <= MAX_RESULT_SIZE; capped with marker for larger.
    pub result: String,
    /// "ok" or "error"
    pub status: String,
    pub timestamp: DateTime<Utc>,
    /// Validation verdict, if LLM validation ran.
    pub validation: Option<ValidationResult>,
}

/// Stored validation result for a tool call.
#[derive(Debug, Clone, serde::Serialize)]
pub struct ValidationResult {
    pub approved: bool,
    pub reasoning: String,
    pub risk: &'static str,
}

/// Maximum result size stored verbatim in history. Larger results are truncated
/// with an explicit marker so the validator knows the content is incomplete.
const MAX_RESULT_SIZE: usize = 2048;

/// Maximum number of history entries to keep per session.
const MAX_HISTORY: usize = 20;

/// Shared, append-only history of tool calls within a session.
#[derive(Clone, Default)]
pub struct ToolCallHistory {
    inner: Arc<std::sync::Mutex<Vec<ToolCallRecord>>>,
}

impl ToolCallHistory {
    pub fn push(&self, record: ToolCallRecord) {
        let mut hist = self.inner.lock().unwrap();
        hist.push(record);
        let len = hist.len();
        if len > MAX_HISTORY {
            hist.drain(..len - MAX_HISTORY);
        }
    }

    pub fn recent(&self, n: usize) -> Vec<ToolCallRecord> {
        let hist = self.inner.lock().unwrap();
        hist.iter()
            .rev()
            .take(n)
            .cloned()
            .collect::<Vec<_>>()
            .into_iter()
            .rev()
            .collect()
    }
}

// ── Static checks (Layer 0) ─────────────────────────────────────────

/// Fast, no-LLM validation. Returns `Some(reason)` to reject, `None` to pass.
fn static_check(
    tool_name: &str,
    args: &str,
    risk: ToolRisk,
    history: &[ToolCallRecord],
) -> Option<String> {
    // Duplicate: same tool + identical args within last 3 calls
    let recent_dupes = history
        .iter()
        .rev()
        .take(3)
        .filter(|e| e.tool_name == tool_name && e.args == args)
        .count();
    if recent_dupes >= 1 {
        return Some(format!(
            "Identical call to `{tool_name}` with the same arguments was made recently. \
             Check if you already have the result."
        ));
    }

    // Write-before-read: destructive tool without any prior read/get/list
    if risk == ToolRisk::Destructive && !history.is_empty() {
        let has_prior_read = history.iter().any(|r| {
            r.tool_name.starts_with("read_")
                || r.tool_name.starts_with("get_")
                || r.tool_name.starts_with("list_")
                || r.tool_name.ends_with("_list")
                || r.tool_name.ends_with("_get")
                || r.tool_name == "fetch_logs"
                || r.tool_name == "fetch_cluster_logs"
                || r.tool_name == "check_node_online"
        });
        if !has_prior_read {
            return Some(format!(
                "Destructive tool `{tool_name}` called without any prior read/get operation. \
                 Read the current state first."
            ));
        }
    }

    // Rapid retry: same tool >3 times in last 10 calls (looping)
    let rapid_count = history
        .iter()
        .rev()
        .take(10)
        .filter(|e| e.tool_name == tool_name)
        .count();
    if rapid_count > 3 {
        return Some(format!(
            "Tool `{tool_name}` has been called {rapid_count} times in the last 10 calls. \
             This looks like a loop — try a different approach."
        ));
    }

    None
}

// ── Schema injection ─────────────────────────────────────────────────

/// Inject a `_reason` string property into an existing schemars Schema.
fn inject_reason_field(schema: &mut schemars::Schema) {
    let value = serde_json::to_value(&*schema).unwrap();
    let serde_json::Value::Object(mut obj) = value else {
        return;
    };

    // Add to properties
    if let Some(props_val) = obj.get_mut("properties") {
        if let Some(props) = props_val.as_object_mut() {
            props.insert(
                "_reason".to_string(),
                serde_json::json!({
                    "type": "string",
                    "description": "Brief explanation of WHY you are making this tool call and what you expect to learn or change."
                }),
            );
        }
    }

    // Add to required array
    if let Some(req_val) = obj.get_mut("required") {
        if let Some(req) = req_val.as_array_mut() {
            req.push(serde_json::json!("_reason"));
        }
    }

    *schema = serde_json::from_value(serde_json::Value::Object(obj)).unwrap();
}

/// Create a schema containing only the `_reason` field (for no-params tools).
fn reason_only_schema() -> schemars::Schema {
    serde_json::from_value(serde_json::json!({
        "type": "object",
        "properties": {
            "_reason": {
                "type": "string",
                "description": "Brief explanation of WHY you are making this tool call and what you expect to learn or change."
            }
        },
        "required": ["_reason"]
    }))
    .unwrap()
}

/// Extract `_reason` from JSON args, returning (reason, cleaned_args).
/// The cleaned args have `_reason` stripped so the inner tool doesn't see it.
fn extract_reason(args: Option<&str>) -> (String, Option<String>) {
    let Some(args_str) = args else {
        return (String::new(), None);
    };
    let Ok(mut obj) = serde_json::from_str::<serde_json::Value>(args_str) else {
        return (String::new(), Some(args_str.to_string()));
    };
    let reason = obj
        .as_object_mut()
        .and_then(|m| m.remove("_reason"))
        .and_then(|v| match v {
            serde_json::Value::String(s) => Some(s),
            _ => None,
        })
        .unwrap_or_default();
    let clean = serde_json::to_string(&obj).ok();
    (reason, clean)
}

/// Cap a result string to MAX_RESULT_SIZE with an explicit truncation marker.
fn cap_result(result: &str) -> String {
    if result.len() <= MAX_RESULT_SIZE {
        result.to_string()
    } else {
        let first_kb = &result[..1024.min(result.len())];
        format!(
            "[truncated: {} bytes total] {}... [remaining {} bytes omitted]",
            result.len(),
            first_kb,
            result.len() - 1024
        )
    }
}

// ── ValidatedTool wrapper ────────────────────────────────────────────

/// A tool wrapper that validates calls before forwarding to the inner tool.
#[derive(Clone)]
pub struct ValidatedTool {
    inner: Box<dyn Tool>,
    risk: ToolRisk,
    config: ValidationConfig,
    history: ToolCallHistory,
    /// Cached ToolSpec with `_reason` injected.
    spec: ToolSpec,
}

impl ValidatedTool {
    /// Wrap a single tool with validation.
    pub fn wrap(
        tool: Box<dyn Tool>,
        risk: ToolRisk,
        config: ValidationConfig,
        history: ToolCallHistory,
    ) -> Box<dyn Tool> {
        let mut spec = tool.tool_spec();
        if spec.parameters_schema.is_some() {
            inject_reason_field(spec.parameters_schema.as_mut().unwrap());
        } else {
            spec.parameters_schema = Some(reason_only_schema());
        }
        Box::new(Self {
            inner: tool,
            risk,
            config,
            history,
            spec,
        })
    }

    /// Wrap a batch of tools with validation.
    pub fn wrap_all(
        tools: Vec<(Box<dyn Tool>, ToolRisk)>,
        config: ValidationConfig,
        history: ToolCallHistory,
    ) -> Vec<Box<dyn Tool>> {
        tools
            .into_iter()
            .map(|(tool, risk)| Self::wrap(tool, risk, config.clone(), history.clone()))
            .collect()
    }
}

impl ValidatedTool {
    /// Update the validation state of a running tool and broadcast the snapshot.
    fn update_running_tool_validation(
        &self,
        tool_name: &str,
        validation: Option<RunningToolValidation>,
    ) {
        let snapshot = {
            let mut tools = self.config.running_tools.lock().unwrap();
            if let Some(t) = tools.iter_mut().find(|t| t.name == tool_name) {
                t.validation = validation;
            }
            tools.clone()
        };
        let _ = self
            .config
            .events_tx
            .send(ChatEvent::RunningTools { tools: snapshot });
    }

    /// Remove a tool from the running snapshot (on rejection).
    fn remove_running_tool(&self, tool_name: &str) {
        let snapshot = {
            let mut tools = self.config.running_tools.lock().unwrap();
            tools.retain(|t| t.name != tool_name);
            tools.clone()
        };
        let _ = self
            .config
            .events_tx
            .send(ChatEvent::RunningTools { tools: snapshot });
    }

    /// Layer 2: gate the call on a human decision. Returns `Some(fail_output)`
    /// to block the call, `None` to proceed.
    async fn await_human_approval(
        &self,
        hook: &ApprovalHook,
        clean_args: &str,
        reason: &str,
        guard_result: Option<&ValidationResult>,
    ) -> Option<ToolOutput> {
        // Standing session grant?
        if hook.policy.allow_approve_all && hook.broker.approve_all() {
            return None;
        }
        // Guard decides: an explicit guard approval auto-approves.
        if hook.policy.guard_role == GuardRole::Decides
            && guard_result.map(|v| v.approved).unwrap_or(false)
        {
            return None;
        }

        let tool_name = self.inner.name().to_string();
        let info = PendingApproval {
            id: Uuid::new_v4(),
            session_id: hook.session_id,
            tool_name: tool_name.clone(),
            args: clean_args.to_string(),
            reason: reason.to_string(),
            risk: self.risk,
            guard_reasoning: guard_result.map(|v| v.reasoning.clone()),
            requested_at: Utc::now(),
        };

        // Persist an audit message so the request survives restarts/reloads.
        let meta = serde_json::json!({
            "approval_id": info.id,
            "tool_name": tool_name,
            "tool_args": clean_args,
            "reason": reason,
            "risk": risk_to_str(self.risk),
            "guard_reasoning": info.guard_reasoning,
        });
        let content = format!("Approval requested for `{tool_name}`");
        hook.store
            .append_message(hook.session_id, "approval_request", &content, Some(&meta))
            .await
            .ok();

        // Mark the running tool as awaiting approval.
        self.update_running_tool_validation(
            &tool_name,
            Some(RunningToolValidation {
                status: "awaiting_approval".to_string(),
                reasoning: info.guard_reasoning.clone(),
                risk: risk_to_str(self.risk).to_string(),
            }),
        );

        match hook.broker.request(info, &hook.policy).await {
            ApprovalOutcome::Approved => {
                self.update_running_tool_validation(
                    &tool_name,
                    Some(RunningToolValidation {
                        status: "approved".to_string(),
                        reasoning: Some("approved by human".to_string()),
                        risk: risk_to_str(self.risk).to_string(),
                    }),
                );
                None
            }
            ApprovalOutcome::Denied { reason } => {
                self.remove_running_tool(&tool_name);
                let msg = match reason {
                    Some(r) => format!("[Approval denied] {r}"),
                    None => "[Approval denied] The user denied this tool call.".to_string(),
                };
                self.history.push(ToolCallRecord {
                    tool_name,
                    args: clean_args.to_string(),
                    result: msg.clone(),
                    status: "rejected".to_string(),
                    timestamp: Utc::now(),
                    validation: Some(ValidationResult {
                        approved: false,
                        reasoning: msg.clone(),
                        risk: risk_to_str(self.risk),
                    }),
                });
                Some(ToolOutput::Fail(msg))
            }
            ApprovalOutcome::TimedOut => {
                self.remove_running_tool(&tool_name);
                let msg = "[Approval timed out] No human decision arrived in time. \
                           Do not retry this call — ask the user or continue with read-only work."
                    .to_string();
                self.history.push(ToolCallRecord {
                    tool_name,
                    args: clean_args.to_string(),
                    result: msg.clone(),
                    status: "rejected".to_string(),
                    timestamp: Utc::now(),
                    validation: None,
                });
                Some(ToolOutput::Fail(msg))
            }
        }
    }
}

#[async_trait]
impl Tool for ValidatedTool {
    fn name(&self) -> Cow<'_, str> {
        self.inner.name()
    }

    fn tool_spec(&self) -> ToolSpec {
        self.spec.clone()
    }

    async fn invoke(
        &self,
        agent_context: &dyn AgentContext,
        tool_call: &ToolCall,
    ) -> Result<ToolOutput, ToolError> {
        if !self.config.enabled {
            return self.inner.invoke(agent_context, tool_call).await;
        }

        // 1. Extract _reason, build clean args for inner tool
        let (reason, clean_args) = extract_reason(tool_call.args());
        // Own the args string for use throughout the method
        let clean_args_owned = clean_args.unwrap_or_else(|| "{}".to_string());

        // 2. Layer 0: static checks
        let history_snapshot = self.history.recent(10);
        if let Some(rejection) = static_check(
            &self.inner.name(),
            &clean_args_owned,
            self.risk,
            &history_snapshot,
        ) {
            return Ok(ToolOutput::Fail(format!(
                "[Validation rejected] {rejection}"
            )));
        }

        // 3. Layer 1: LLM pre-flight (Mutating/Destructive only)
        let risk_str = risk_to_str(self.risk);
        let mut validation_result: Option<ValidationResult> = None;
        if self.risk >= ToolRisk::Mutating {
            if let Some(validator) = &self.config.validator_llm {
                // Broadcast "validating" state
                self.update_running_tool_validation(
                    &self.inner.name(),
                    Some(RunningToolValidation {
                        status: "validating".to_string(),
                        reasoning: None,
                        risk: risk_str.to_string(),
                    }),
                );

                let reason_str = if reason.is_empty() {
                    "(no reason given)"
                } else {
                    &reason
                };
                let tool_spec = self.inner.tool_spec();
                let tool_name = self.inner.name();
                let ctx = ValidationContext {
                    tool_name: &tool_name,
                    tool_description: &tool_spec.description,
                    args: &clean_args_owned,
                    reason: reason_str,
                    risk: self.risk,
                    history: &history_snapshot,
                    last_assistant_message: "",
                    session_phase: "",
                };

                match validator.validate_tool_call(&ctx).await {
                    Ok(ValidationVerdict::Rejected { explanation }) => {
                        validation_result = Some(ValidationResult {
                            approved: false,
                            reasoning: explanation.clone(),
                            risk: risk_str,
                        });
                        // Remove from running tools (rejection means it won't execute)
                        self.remove_running_tool(&self.inner.name());
                        // Record rejected call in history
                        self.history.push(ToolCallRecord {
                            tool_name: self.inner.name().to_string(),
                            args: clean_args_owned,
                            result: format!("[rejected] {explanation}"),
                            status: "rejected".to_string(),
                            timestamp: Utc::now(),
                            validation: validation_result.clone(),
                        });
                        return Ok(ToolOutput::Fail(format!(
                            "[Validator rejected] {explanation}"
                        )));
                    }
                    Ok(ValidationVerdict::Approved { reasoning }) => {
                        validation_result = Some(ValidationResult {
                            approved: true,
                            reasoning: reasoning.clone(),
                            risk: risk_str,
                        });
                        // Broadcast "approved" state
                        self.update_running_tool_validation(
                            &self.inner.name(),
                            Some(RunningToolValidation {
                                status: "approved".to_string(),
                                reasoning: Some(reasoning),
                                risk: risk_str.to_string(),
                            }),
                        );
                    }
                    Err(e) => {
                        // Fail-open for Mutating, fail-closed for Destructive
                        if self.risk == ToolRisk::Destructive {
                            self.remove_running_tool(&self.inner.name());
                            return Ok(ToolOutput::Fail(format!(
                                "[Validator error, blocking destructive call] {e}"
                            )));
                        }
                        tracing::warn!(
                            tool = %self.inner.name(),
                            err = %e,
                            "validator LLM error, proceeding (fail-open for mutating)"
                        );
                    }
                }
            }
        }

        // 4. Layer 2: direct human approval (opt-in, threshold-gated)
        if let Some(hook) = self.config.approval.clone() {
            if self.risk >= hook.policy.gate_threshold {
                if let Some(fail) = self
                    .await_human_approval(
                        &hook,
                        &clean_args_owned,
                        if reason.is_empty() {
                            "(no reason given)"
                        } else {
                            &reason
                        },
                        validation_result.as_ref(),
                    )
                    .await
                {
                    return Ok(fail);
                }
            }
        }

        // 5. Forward to inner tool with _reason stripped
        let mut modified_call = tool_call.clone();
        modified_call.with_args(Some(clean_args_owned.clone()));
        let result = self.inner.invoke(agent_context, &modified_call).await;

        // 6. Record in history
        let (status, result_text) = match &result {
            Ok(out) => ("ok".to_string(), out.content().unwrap_or("").to_string()),
            Err(e) => ("error".to_string(), e.to_string()),
        };
        self.history.push(ToolCallRecord {
            tool_name: self.inner.name().to_string(),
            args: clean_args_owned,
            result: cap_result(&result_text),
            status,
            timestamp: Utc::now(),
            validation: validation_result,
        });

        result
    }
}

// ── Swiftide-based validator LLM ──────────────────────────────────────

use swiftide::chat_completion::{
    ChatCompletion, ChatCompletionRequest, ChatCompletionResponse, ChatMessage,
};

/// Validator backed by a swiftide `ChatCompletion` provider (same as the main
/// agent LLM). Uses approve/reject tools instead of parsing free text.
#[derive(Clone)]
pub struct SwiftideValidatorLlm {
    llm: Arc<dyn ChatCompletion>,
}

impl SwiftideValidatorLlm {
    pub fn new(llm: Box<dyn ChatCompletion>) -> Self {
        Self {
            llm: Arc::from(llm),
        }
    }
}

/// Build the tool specs for approve/reject tools.
fn validator_tool_specs() -> Vec<ToolSpec> {
    let reasoning_schema: schemars::Schema = serde_json::from_value(serde_json::json!({
        "type": "object",
        "properties": {
            "reasoning": {
                "type": "string",
                "description": "Brief explanation of why this tool call is appropriate or inappropriate."
            }
        },
        "required": ["reasoning"]
    })).unwrap();

    vec![
        ToolSpec::builder()
            .name("approve")
            .description("Approve this tool call — it makes sense given the agent's intent and history.")
            .parameters_schema(reasoning_schema.clone())
            .build()
            .unwrap(),
        ToolSpec::builder()
            .name("reject")
            .description("Reject this tool call — it is wrong, redundant, dangerous, or doesn't match the stated reason.")
            .parameters_schema(reasoning_schema)
            .build()
            .unwrap(),
    ]
}

/// Extract the verdict from tool calls in the completion response.
fn extract_verdict(response: &ChatCompletionResponse) -> Option<ValidationVerdict> {
    let tool_calls = response.tool_calls.as_ref()?;
    for tc in tool_calls {
        let reasoning = tc
            .args()
            .and_then(|args| serde_json::from_str::<serde_json::Value>(args).ok())
            .and_then(|v| {
                v.get("reasoning")
                    .and_then(|r| r.as_str())
                    .map(String::from)
            })
            .unwrap_or_default();

        match tc.name() {
            "approve" => return Some(ValidationVerdict::Approved { reasoning }),
            "reject" => {
                return Some(ValidationVerdict::Rejected {
                    explanation: reasoning,
                });
            }
            _ => {}
        }
    }
    None
}

#[async_trait]
impl ValidatorLlm for SwiftideValidatorLlm {
    async fn validate_tool_call(
        &self,
        ctx: &ValidationContext<'_>,
    ) -> anyhow::Result<ValidationVerdict> {
        // Build history summary
        let mut history_text = String::new();
        for (i, entry) in ctx.history.iter().enumerate() {
            history_text.push_str(&format!(
                "  {}. {}({}) -> {} ({})\n",
                i + 1,
                entry.tool_name,
                truncate_for_prompt(&entry.args, 200),
                entry.status,
                truncate_for_prompt(&entry.result, 300),
            ));
        }
        if history_text.is_empty() {
            history_text = "  (no prior tool calls)\n".to_string();
        }

        let user_prompt = format!(
            r#"Tool: `{name}` ({risk})
Description: {desc}
Args: {args}
Agent's reason: "{reason}"
{phase_line}{assistant_line}
Recent tool history:
{history}
Does this tool call make sense given the agent's stated reason and history?
Use the `approve` or `reject` tool to record your verdict."#,
            name = ctx.tool_name,
            risk = risk_to_str(ctx.risk),
            desc = ctx.tool_description,
            args = ctx.args,
            reason = ctx.reason,
            phase_line = if ctx.session_phase.is_empty() {
                String::new()
            } else {
                format!("Session phase: {}\n", ctx.session_phase)
            },
            assistant_line = if ctx.last_assistant_message.is_empty() {
                String::new()
            } else {
                format!("Agent's last message: \"{}\"\n", ctx.last_assistant_message)
            },
            history = history_text,
        );

        let messages = vec![
            ChatMessage::new_system(
                "You are a tool-call validator for an operations agent. \
                 Evaluate whether the proposed tool call is appropriate given the agent's \
                 stated intent and recent actions. Use the `approve` tool if the call is \
                 reasonable, or the `reject` tool if it is wrong, redundant, or dangerous. \
                 Always provide brief reasoning.",
            ),
            ChatMessage::new_user(user_prompt),
        ];

        let tools = validator_tool_specs();
        let request = ChatCompletionRequest::builder()
            .messages(messages)
            .tool_specs(tools)
            .build()
            .map_err(|e| anyhow::anyhow!("failed to build validation request: {e}"))?;

        let response = self
            .llm
            .complete(&request)
            .await
            .map_err(|e| anyhow::anyhow!("validator completion failed: {e}"))?;

        // Try to extract verdict from tool calls
        if let Some(verdict) = extract_verdict(&response) {
            return Ok(verdict);
        }

        // Fallback: try parsing from message content (model didn't use tools)
        let text = response.message.as_deref().unwrap_or("").trim();
        if let Some(reasoning) = text.strip_prefix("APPROVED:") {
            Ok(ValidationVerdict::Approved {
                reasoning: reasoning.trim().to_string(),
            })
        } else if let Some(reasoning) = text.strip_prefix("REJECTED:") {
            Ok(ValidationVerdict::Rejected {
                explanation: reasoning.trim().to_string(),
            })
        } else {
            // Ambiguous → fail-open
            let debug_info = if text.is_empty() {
                "(no tool call and no text content in response)".to_string()
            } else {
                text.to_string()
            };
            tracing::warn!("ambiguous validator response: {debug_info}");
            Ok(ValidationVerdict::Approved {
                reasoning: format!("(ambiguous response, defaulting to approved) {debug_info}"),
            })
        }
    }
}

fn truncate_for_prompt(s: &str, max: usize) -> &str {
    if s.len() <= max { s } else { &s[..max] }
}

// ── Builder helper ───────────────────────────────────────────────────

/// Resolve and build the validator LLM using swiftide's LLM infrastructure.
///
/// Uses the same `resolve_llm` as the main agent — all provider configs, client
/// setup, and token tracking are handled identically. Returns `None` if no
/// validator provider is configured.
pub async fn build_validator_llm(
    connector_config: &crate::connector::ConnectorConfig,
    token_ctx: Option<crate::connector::TokenEventContext>,
) -> Option<Arc<dyn ValidatorLlm>> {
    let provider = connector_config.validator_provider.as_deref()?;
    let model = connector_config.validator_model.as_deref()?;

    match crate::connector::resolve_llm(connector_config, Some(provider), Some(model), token_ctx)
        .await
    {
        Ok(handle) => {
            let llm: Box<dyn ChatCompletion> = match handle.provider {
                crate::connector::LlmProvider::Ollama(o) => Box::new(o),
                crate::connector::LlmProvider::Anthropic(a) => Box::new(a),
                crate::connector::LlmProvider::OpenRouter(o) => Box::new(o),
                crate::connector::LlmProvider::OpenAICompat(o) => Box::new(o),
            };
            tracing::info!(
                provider = %handle.resolved_provider,
                model = %handle.resolved_model,
                "validator LLM resolved"
            );
            Some(Arc::new(SwiftideValidatorLlm::new(llm)))
        }
        Err(e) => {
            tracing::warn!("failed to resolve validator LLM: {e:#}");
            None
        }
    }
}

// ── Tests ────────────────────────────────────────────────────────────

#[cfg(test)]
mod tests {
    use super::approval::{ApprovalDecision, TimeoutAction};
    use super::*;

    #[test]
    fn test_extract_reason_strips_field() {
        let args = r#"{"path": "/etc/config.toml", "_reason": "checking port setting"}"#;
        let (reason, clean) = extract_reason(Some(args));
        assert_eq!(reason, "checking port setting");
        let clean = clean.unwrap();
        assert!(!clean.contains("_reason"));
        assert!(clean.contains("path"));
    }

    #[test]
    fn test_extract_reason_missing() {
        let args = r#"{"path": "/etc/config.toml"}"#;
        let (reason, clean) = extract_reason(Some(args));
        assert_eq!(reason, "");
        // serde round-trip may normalize whitespace
        let clean = clean.unwrap();
        let parsed: serde_json::Value = serde_json::from_str(&clean).unwrap();
        assert_eq!(parsed, serde_json::json!({"path": "/etc/config.toml"}));
    }

    #[test]
    fn test_extract_reason_no_args() {
        let (reason, clean) = extract_reason(None);
        assert_eq!(reason, "");
        assert!(clean.is_none());
    }

    #[test]
    fn test_static_check_duplicate() {
        let history = vec![ToolCallRecord {
            tool_name: "read_file".to_string(),
            args: r#"{"path": "foo"}"#.to_string(),
            result: "ok".to_string(),
            status: "ok".to_string(),
            timestamp: Utc::now(),
            validation: None,
        }];
        let result = static_check(
            "read_file",
            r#"{"path": "foo"}"#,
            ToolRisk::ReadOnly,
            &history,
        );
        assert!(result.is_some());
        assert!(result.unwrap().contains("Identical call"));
    }

    #[test]
    fn test_static_check_no_duplicate_different_args() {
        let history = vec![ToolCallRecord {
            tool_name: "read_file".to_string(),
            args: r#"{"path": "foo"}"#.to_string(),
            result: "ok".to_string(),
            status: "ok".to_string(),
            timestamp: Utc::now(),
            validation: None,
        }];
        let result = static_check(
            "read_file",
            r#"{"path": "bar"}"#,
            ToolRisk::ReadOnly,
            &history,
        );
        assert!(result.is_none());
    }

    #[test]
    fn test_static_check_write_before_read() {
        // History has only a pin (session-local), no read
        let history = vec![ToolCallRecord {
            tool_name: "pin".to_string(),
            args: "{}".to_string(),
            result: "ok".to_string(),
            status: "ok".to_string(),
            timestamp: Utc::now(),
            validation: None,
        }];
        let result = static_check("write_file", "{}", ToolRisk::Destructive, &history);
        assert!(result.is_some());
        assert!(result.unwrap().contains("without any prior read"));
    }

    #[test]
    fn test_static_check_write_after_read_ok() {
        let history = vec![ToolCallRecord {
            tool_name: "read_file".to_string(),
            args: "{}".to_string(),
            result: "content".to_string(),
            status: "ok".to_string(),
            timestamp: Utc::now(),
            validation: None,
        }];
        let result = static_check("write_file", "{}", ToolRisk::Destructive, &history);
        assert!(result.is_none());
    }

    #[test]
    fn test_static_check_rapid_retry() {
        let history: Vec<ToolCallRecord> = (0..4)
            .map(|i| ToolCallRecord {
                tool_name: "staff_ping".to_string(),
                args: format!(r#"{{"msg": "attempt_{i}"}}"#),
                result: "ok".to_string(),
                status: "ok".to_string(),
                timestamp: Utc::now(),
                validation: None,
            })
            .collect();
        let result = static_check(
            "staff_ping",
            r#"{"msg": "attempt_5"}"#,
            ToolRisk::Mutating,
            &history,
        );
        assert!(result.is_some());
        assert!(result.unwrap().contains("loop"));
    }

    #[test]
    fn test_cap_result_small() {
        let small = "hello world";
        assert_eq!(cap_result(small), small);
    }

    #[test]
    fn test_cap_result_large() {
        let large = "x".repeat(5000);
        let capped = cap_result(&large);
        assert!(capped.contains("[truncated: 5000 bytes total]"));
        assert!(capped.len() < large.len());
    }

    #[test]
    fn test_inject_reason_field() {
        use schemars::JsonSchema;

        #[derive(serde::Deserialize, JsonSchema)]
        #[allow(dead_code)]
        struct TestParams {
            path: String,
        }

        let schema = schemars::schema_for!(TestParams);
        let mut schema: schemars::Schema =
            serde_json::from_value(serde_json::to_value(&schema).unwrap()).unwrap();

        inject_reason_field(&mut schema);

        let val = serde_json::to_value(&schema).unwrap();
        let props = val.get("properties").unwrap();
        assert!(props.get("_reason").is_some());
        assert!(props.get("path").is_some());

        let required = val.get("required").unwrap().as_array().unwrap();
        assert!(required.contains(&serde_json::json!("_reason")));
        assert!(required.contains(&serde_json::json!("path")));
    }

    #[test]
    fn test_history_bounds() {
        let hist = ToolCallHistory::default();
        for i in 0..30 {
            hist.push(ToolCallRecord {
                tool_name: format!("tool_{i}"),
                args: "{}".to_string(),
                result: "ok".to_string(),
                status: "ok".to_string(),
                timestamp: Utc::now(),
                validation: None,
            });
        }
        let recent = hist.recent(100);
        assert_eq!(recent.len(), MAX_HISTORY);
        assert_eq!(recent.first().unwrap().tool_name, "tool_10");
        assert_eq!(recent.last().unwrap().tool_name, "tool_29");
    }

    // ── Integration tests with mock tool + mock validator ────────────

    /// A minimal mock tool for testing ValidatedTool wrapping.
    #[derive(Clone)]
    struct MockTool {
        name: &'static str,
        invoked: Arc<std::sync::atomic::AtomicBool>,
    }

    impl MockTool {
        fn new(name: &'static str) -> (Box<dyn Tool>, Arc<std::sync::atomic::AtomicBool>) {
            let invoked = Arc::new(std::sync::atomic::AtomicBool::new(false));
            (
                Box::new(Self {
                    name,
                    invoked: invoked.clone(),
                }),
                invoked,
            )
        }
    }

    #[async_trait]
    impl Tool for MockTool {
        fn name(&self) -> Cow<'_, str> {
            Cow::Borrowed(self.name)
        }
        fn tool_spec(&self) -> ToolSpec {
            ToolSpec::builder()
                .name(self.name)
                .description("mock tool")
                .build()
                .unwrap()
        }
        async fn invoke(
            &self,
            _ctx: &dyn AgentContext,
            _call: &ToolCall,
        ) -> Result<ToolOutput, ToolError> {
            self.invoked
                .store(true, std::sync::atomic::Ordering::SeqCst);
            Ok(ToolOutput::Text("mock result".to_string()))
        }
    }

    /// A mock validator that always returns a fixed verdict.
    #[derive(Clone)]
    struct MockValidator {
        verdict: ValidationVerdict,
    }

    #[async_trait]
    impl ValidatorLlm for MockValidator {
        async fn validate_tool_call(
            &self,
            _ctx: &ValidationContext<'_>,
        ) -> anyhow::Result<ValidationVerdict> {
            Ok(self.verdict.clone())
        }
    }

    /// A mock validator that always returns an error.
    #[derive(Clone)]
    struct ErrorValidator;

    #[async_trait]
    impl ValidatorLlm for ErrorValidator {
        async fn validate_tool_call(
            &self,
            _ctx: &ValidationContext<'_>,
        ) -> anyhow::Result<ValidationVerdict> {
            anyhow::bail!("validator unavailable")
        }
    }

    fn test_config(validator: Option<Arc<dyn ValidatorLlm>>) -> ValidationConfig {
        let (events_tx, _) = tokio::sync::broadcast::channel(16);
        ValidationConfig {
            validator_llm: validator,
            enabled: true,
            running_tools: Arc::new(std::sync::Mutex::new(Vec::new())),
            events_tx,
            approval: None,
        }
    }

    fn make_tool_call(args: &str) -> ToolCall {
        ToolCall::builder()
            .id("test-1")
            .name("mock_tool")
            .args(args.to_string())
            .build()
            .unwrap()
    }

    fn seed_read(history: &ToolCallHistory) {
        history.push(ToolCallRecord {
            tool_name: "read_file".to_string(),
            args: "{}".to_string(),
            result: "ok".to_string(),
            status: "ok".to_string(),
            timestamp: Utc::now(),
            validation: None,
        });
    }

    #[tokio::test]
    async fn test_validated_tool_forwards_on_approval() {
        let (mock_tool, invoked) = MockTool::new("mock_tool");
        let validator = Arc::new(MockValidator {
            verdict: ValidationVerdict::Approved {
                reasoning: "looks good".to_string(),
            },
        });
        let config = test_config(Some(validator));
        let history = ToolCallHistory::default();
        seed_read(&history);

        let wrapped = ValidatedTool::wrap(mock_tool, ToolRisk::Mutating, config, history.clone());
        // Use () as AgentContext — swiftide provides a convenience impl
        let ctx: &dyn AgentContext = &();
        let call = make_tool_call(r#"{"_reason": "testing approval"}"#);

        let result = wrapped.invoke(ctx, &call).await.unwrap();
        assert!(result.as_text().is_some());
        assert_eq!(result.as_text().unwrap(), "mock result");
        assert!(invoked.load(std::sync::atomic::Ordering::SeqCst));

        // Check history recorded the call with validation
        let recent = history.recent(1);
        let last = recent.first().unwrap();
        assert_eq!(last.tool_name, "mock_tool");
        assert!(last.validation.is_some());
        assert!(last.validation.as_ref().unwrap().approved);
    }

    #[tokio::test]
    async fn test_validated_tool_blocks_on_rejection() {
        let (mock_tool, invoked) = MockTool::new("mock_tool");
        let validator = Arc::new(MockValidator {
            verdict: ValidationVerdict::Rejected {
                explanation: "bad idea".to_string(),
            },
        });
        let config = test_config(Some(validator));
        let history = ToolCallHistory::default();
        seed_read(&history);

        let wrapped = ValidatedTool::wrap(mock_tool, ToolRisk::Mutating, config, history);
        let ctx: &dyn AgentContext = &();
        let call = make_tool_call(r#"{"_reason": "testing rejection"}"#);

        let result = wrapped.invoke(ctx, &call).await.unwrap();
        assert!(result.as_fail().is_some());
        assert!(result.as_fail().unwrap().contains("bad idea"));
        assert!(!invoked.load(std::sync::atomic::Ordering::SeqCst));
    }

    #[tokio::test]
    async fn test_fail_closed_destructive() {
        let (mock_tool, invoked) = MockTool::new("mock_tool");
        let validator: Arc<dyn ValidatorLlm> = Arc::new(ErrorValidator);
        let config = test_config(Some(validator));
        let history = ToolCallHistory::default();
        seed_read(&history);

        let wrapped = ValidatedTool::wrap(mock_tool, ToolRisk::Destructive, config, history);
        let ctx: &dyn AgentContext = &();
        let call = make_tool_call(r#"{"_reason": "testing fail-closed"}"#);

        let result = wrapped.invoke(ctx, &call).await.unwrap();
        assert!(result.as_fail().is_some());
        assert!(result.as_fail().unwrap().contains("Validator error"));
        assert!(!invoked.load(std::sync::atomic::Ordering::SeqCst));
    }

    #[tokio::test]
    async fn test_fail_open_mutating() {
        let (mock_tool, invoked) = MockTool::new("mock_tool");
        let validator: Arc<dyn ValidatorLlm> = Arc::new(ErrorValidator);
        let config = test_config(Some(validator));
        let history = ToolCallHistory::default();
        seed_read(&history);

        let wrapped = ValidatedTool::wrap(mock_tool, ToolRisk::Mutating, config, history);
        let ctx: &dyn AgentContext = &();
        let call = make_tool_call(r#"{"_reason": "testing fail-open"}"#);

        let result = wrapped.invoke(ctx, &call).await.unwrap();
        assert!(result.as_text().is_some());
        assert_eq!(result.as_text().unwrap(), "mock result");
        assert!(invoked.load(std::sync::atomic::Ordering::SeqCst));
    }

    // ── Approval-layer integration tests ─────────────────────────────

    /// In-memory ChatStore stub recording appended messages.
    struct StubStore {
        messages: std::sync::Mutex<Vec<(String, String)>>,
    }

    impl StubStore {
        fn new() -> Arc<Self> {
            Arc::new(Self {
                messages: std::sync::Mutex::new(Vec::new()),
            })
        }
    }

    #[async_trait]
    impl crate::store::ChatStore for StubStore {
        async fn create_session(&self, _new: crate::store::NewSession<'_>) -> anyhow::Result<Uuid> {
            Ok(Uuid::new_v4())
        }
        async fn set_label(&self, _s: Uuid, _l: &str) -> anyhow::Result<()> {
            Ok(())
        }
        async fn transition_state(
            &self,
            _s: Uuid,
            _n: &str,
            _t: bool,
            _d: &serde_json::Value,
        ) -> anyhow::Result<()> {
            Ok(())
        }
        async fn fail_session(
            &self,
            _s: Uuid,
            _e: &str,
            _d: &serde_json::Value,
        ) -> anyhow::Result<()> {
            Ok(())
        }
        async fn get_session(
            &self,
            _s: Uuid,
        ) -> anyhow::Result<Option<crate::model::ChatSession>> {
            Ok(None)
        }
        async fn list_sessions(
            &self,
            _c: Uuid,
        ) -> anyhow::Result<Vec<crate::model::ChatSession>> {
            Ok(Vec::new())
        }
        async fn find_resumable(
            &self,
            _n: &[&str],
            _e: &[&str],
        ) -> anyhow::Result<Vec<crate::model::ChatSession>> {
            Ok(Vec::new())
        }
        async fn update_provider_model(
            &self,
            _s: Uuid,
            _p: &str,
            _m: &str,
        ) -> anyhow::Result<()> {
            Ok(())
        }
        async fn has_running_session(&self, _s: &str, _i: &[&str]) -> anyhow::Result<bool> {
            Ok(false)
        }
        async fn append_message(
            &self,
            _s: Uuid,
            role: &str,
            content: &str,
            _m: Option<&serde_json::Value>,
        ) -> anyhow::Result<()> {
            self.messages
                .lock()
                .unwrap()
                .push((role.to_string(), content.to_string()));
            Ok(())
        }
        async fn get_messages(&self, _s: Uuid) -> anyhow::Result<Vec<crate::model::ChatMessage>> {
            Ok(Vec::new())
        }
        async fn get_messages_after(
            &self,
            _s: Uuid,
            _a: DateTime<Utc>,
        ) -> anyhow::Result<Vec<crate::model::ChatMessage>> {
            Ok(Vec::new())
        }
        async fn append_token_event(
            &self,
            _s: Uuid,
            _p: &str,
            _m: &str,
            _i: u32,
            _o: u32,
        ) -> anyhow::Result<u64> {
            Ok(0)
        }
        async fn get_token_usage(&self, _s: Uuid) -> anyhow::Result<u64> {
            Ok(0)
        }
        async fn set_token_budget(&self, _s: Uuid, _b: u64) -> anyhow::Result<()> {
            Ok(())
        }
        async fn get_token_budget(&self, _s: Uuid) -> anyhow::Result<u64> {
            Ok(0)
        }
    }

    fn approval_config(
        broker: Arc<ApprovalBroker>,
        store: Arc<StubStore>,
        policy: ApprovalPolicy,
    ) -> ValidationConfig {
        let (events_tx, _) = tokio::sync::broadcast::channel(64);
        ValidationConfig {
            validator_llm: None,
            enabled: true,
            running_tools: Arc::new(std::sync::Mutex::new(Vec::new())),
            events_tx,
            approval: Some(ApprovalHook {
                policy,
                broker,
                store,
                session_id: Uuid::new_v4(),
            }),
        }
    }

    fn test_broker() -> Arc<ApprovalBroker> {
        let (tx, _rx) = tokio::sync::broadcast::channel(64);
        Arc::new(ApprovalBroker::new(
            Uuid::new_v4(),
            tx,
            Arc::new(tokio::sync::Notify::new()),
        ))
    }

    #[tokio::test]
    async fn approval_gates_mutating_call_until_approved() {
        let (mock_tool, invoked) = MockTool::new("mock_tool");
        let broker = test_broker();
        let store = StubStore::new();
        let config = approval_config(broker.clone(), store.clone(), ApprovalPolicy::default());
        let history = ToolCallHistory::default();
        seed_read(&history);

        let wrapped = ValidatedTool::wrap(mock_tool, ToolRisk::Mutating, config, history);
        let ctx: &dyn AgentContext = &();
        let call = make_tool_call(r#"{"_reason": "needs approval"}"#);

        let broker2 = broker.clone();
        let approver = tokio::spawn(async move {
            for _ in 0..200 {
                let pending = broker2.pending();
                if let Some(p) = pending.first() {
                    broker2
                        .resolve(p.id, ApprovalDecision::Approve, Some("tester"))
                        .unwrap();
                    return;
                }
                tokio::time::sleep(std::time::Duration::from_millis(5)).await;
            }
            panic!("no pending approval appeared");
        });

        let result = wrapped.invoke(ctx, &call).await.unwrap();
        approver.await.unwrap();
        assert_eq!(result.as_text().unwrap(), "mock result");
        assert!(invoked.load(std::sync::atomic::Ordering::SeqCst));
        // Audit message persisted
        let msgs = store.messages.lock().unwrap();
        assert!(msgs.iter().any(|(role, _)| role == "approval_request"));
    }

    #[tokio::test]
    async fn approval_denial_returns_fail_to_agent() {
        let (mock_tool, invoked) = MockTool::new("mock_tool");
        let broker = test_broker();
        let store = StubStore::new();
        let config = approval_config(broker.clone(), store, ApprovalPolicy::default());
        let history = ToolCallHistory::default();
        seed_read(&history);

        let wrapped = ValidatedTool::wrap(mock_tool, ToolRisk::Destructive, config, history);
        let ctx: &dyn AgentContext = &();
        let call = make_tool_call(r#"{"_reason": "should be denied"}"#);

        let broker2 = broker.clone();
        tokio::spawn(async move {
            loop {
                if let Some(p) = broker2.pending().first() {
                    broker2
                        .resolve(
                            p.id,
                            ApprovalDecision::Deny {
                                reason: Some("too risky".into()),
                            },
                            None,
                        )
                        .unwrap();
                    return;
                }
                tokio::time::sleep(std::time::Duration::from_millis(5)).await;
            }
        });

        let result = wrapped.invoke(ctx, &call).await.unwrap();
        assert!(result.as_fail().unwrap().contains("too risky"));
        assert!(!invoked.load(std::sync::atomic::Ordering::SeqCst));
    }

    #[tokio::test]
    async fn approve_all_skips_subsequent_prompts() {
        let broker = test_broker();
        let store = StubStore::new();
        broker.set_approve_all(true);
        let (mock_tool, invoked) = MockTool::new("mock_tool");
        let config = approval_config(broker, store, ApprovalPolicy::default());
        let history = ToolCallHistory::default();
        seed_read(&history);

        let wrapped = ValidatedTool::wrap(mock_tool, ToolRisk::Mutating, config, history);
        let ctx: &dyn AgentContext = &();
        let call = make_tool_call(r#"{"_reason": "standing grant"}"#);

        // No approver task needed — approve_all short-circuits.
        let result = wrapped.invoke(ctx, &call).await.unwrap();
        assert_eq!(result.as_text().unwrap(), "mock result");
        assert!(invoked.load(std::sync::atomic::Ordering::SeqCst));
    }

    #[tokio::test]
    async fn readonly_below_threshold_skips_approval() {
        let broker = test_broker();
        let store = StubStore::new();
        let (mock_tool, invoked) = MockTool::new("mock_tool");
        let config = approval_config(broker.clone(), store, ApprovalPolicy::default());
        let history = ToolCallHistory::default();

        let wrapped = ValidatedTool::wrap(mock_tool, ToolRisk::ReadOnly, config, history);
        let ctx: &dyn AgentContext = &();
        let call = make_tool_call(r#"{"_reason": "read only"}"#);

        let result = wrapped.invoke(ctx, &call).await.unwrap();
        assert_eq!(result.as_text().unwrap(), "mock result");
        assert!(invoked.load(std::sync::atomic::Ordering::SeqCst));
        assert!(broker.pending().is_empty());
    }

    #[tokio::test]
    async fn approval_timeout_denies() {
        let (mock_tool, invoked) = MockTool::new("mock_tool");
        let broker = test_broker();
        let store = StubStore::new();
        let policy = ApprovalPolicy {
            timeout: std::time::Duration::from_millis(30),
            on_timeout: TimeoutAction::Deny,
            ..Default::default()
        };
        let config = approval_config(broker, store, policy);
        let history = ToolCallHistory::default();
        seed_read(&history);

        let wrapped = ValidatedTool::wrap(mock_tool, ToolRisk::Mutating, config, history);
        let ctx: &dyn AgentContext = &();
        let call = make_tool_call(r#"{"_reason": "will time out"}"#);

        let result = wrapped.invoke(ctx, &call).await.unwrap();
        assert!(result.as_fail().unwrap().contains("timed out"));
        assert!(!invoked.load(std::sync::atomic::Ordering::SeqCst));
    }

    #[tokio::test]
    async fn guard_decides_auto_approves_guard_approved_calls() {
        let (mock_tool, invoked) = MockTool::new("mock_tool");
        let broker = test_broker();
        let store = StubStore::new();
        let validator = Arc::new(MockValidator {
            verdict: ValidationVerdict::Approved {
                reasoning: "guard says fine".to_string(),
            },
        });
        let policy = ApprovalPolicy {
            guard_role: GuardRole::Decides,
            // Short timeout: if the gate wrongly engages, the test fails fast.
            timeout: std::time::Duration::from_millis(50),
            ..Default::default()
        };
        let (events_tx, _) = tokio::sync::broadcast::channel(64);
        let config = ValidationConfig {
            validator_llm: Some(validator),
            enabled: true,
            running_tools: Arc::new(std::sync::Mutex::new(Vec::new())),
            events_tx,
            approval: Some(ApprovalHook {
                policy,
                broker,
                store,
                session_id: Uuid::new_v4(),
            }),
        };
        let history = ToolCallHistory::default();
        seed_read(&history);

        let wrapped = ValidatedTool::wrap(mock_tool, ToolRisk::Mutating, config, history);
        let ctx: &dyn AgentContext = &();
        let call = make_tool_call(r#"{"_reason": "guard decides"}"#);

        let result = wrapped.invoke(ctx, &call).await.unwrap();
        assert_eq!(result.as_text().unwrap(), "mock result");
        assert!(invoked.load(std::sync::atomic::Ordering::SeqCst));
    }
}
