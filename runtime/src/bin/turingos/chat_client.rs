//! TRACE_MATRIX FC2-N16: SiliconFlow HTTP client (Phase 6.3 real-LLM wire)
//!
//! Thin async client for the SiliconFlow OpenAI-compatible Chat Completions
//! API at https://api.siliconflow.cn/v1/chat/completions. Used by
//! `turingos spec` (Meta AI / reasoning) and `turingos generate`
//! (Blackbox AI / fast codegen).
//!
//! Architecture posture: SiliconFlow is one provider — the wire surface is
//! intentionally written so that swapping in another OpenAI-compatible
//! provider later requires changing only the endpoint constant and the
//! model_id strings, not the message-shape code.
//!
//! Phase 6.3 scope: chat completions (non-streaming). Streaming and tool-use
//! deferred to a future atom.

use std::time::Duration;

use serde::{Deserialize, Serialize};

/// TRACE_MATRIX FC2-N16: SiliconFlow default API endpoint (mainland China region).
pub(crate) const SILICONFLOW_ENDPOINT: &str = "https://api.siliconflow.cn/v1/chat/completions";

/// TRACE_MATRIX FC2-N16: Default reasoning model (Meta AI role).
/// Research note: DeepSeek-V3.2 — ¥2/M in, ¥3/M out, 160K ctx, Chinese-first.
pub(crate) const DEFAULT_META_MODEL: &str = "deepseek-ai/DeepSeek-V3.2";

/// TRACE_MATRIX FC2-N16: Default fast / codegen model (Blackbox AI role).
/// Research note: Qwen3-Coder-30B-A3B-Instruct — code MoE, 256K ctx.
pub(crate) const DEFAULT_BLACKBOX_MODEL: &str = "Qwen/Qwen3-Coder-30B-A3B-Instruct";

/// TRACE_MATRIX FC2-N16: Default API base — overridable via
/// TURINGOS_SILICONFLOW_ENDPOINT env var (e.g. for the international mirror
/// api.siliconflow.com or for a test localhost stub).
pub(crate) fn endpoint() -> String {
    std::env::var("TURINGOS_SILICONFLOW_ENDPOINT")
        .unwrap_or_else(|_| SILICONFLOW_ENDPOINT.to_string())
}

/// TRACE_MATRIX FC2-N16: Optional thinking (reasoning) mode config.
///
/// When `kind` == "enabled", the request body includes `{"thinking":{"type":"enabled"}}`,
/// which activates DeepSeek reasoning mode. Omitting this field entirely (i.e.,
/// `thinking: None` in `ChatRequest`) disables reasoning mode — the two models
/// support both modes; the toggle is in the request body, not the model name.
#[derive(Debug, Clone, Serialize, Deserialize)]
pub(crate) struct ThinkingConfig {
    /// Serializes as JSON key "type". Set to "enabled" to activate reasoning.
    #[serde(rename = "type")]
    pub kind: String,
}

/// TRACE_MATRIX FC2-N16: Chat message envelope (OpenAI-compatible role+content).
#[derive(Debug, Clone, Serialize)]
pub(crate) struct ChatMessage {
    pub role: String,
    pub content: String,
}

impl ChatMessage {
    /// TRACE_MATRIX FC2-N16: build a "system" role message
    pub fn system(content: impl Into<String>) -> Self {
        Self {
            role: "system".into(),
            content: content.into(),
        }
    }
    /// TRACE_MATRIX FC2-N16: build a "user" role message
    pub fn user(content: impl Into<String>) -> Self {
        Self {
            role: "user".into(),
            content: content.into(),
        }
    }
    /// TRACE_MATRIX FC2-N16: build an "assistant" role message
    pub fn assistant(content: impl Into<String>) -> Self {
        Self {
            role: "assistant".into(),
            content: content.into(),
        }
    }
}

/// TRACE_MATRIX FC2-N16: OpenAI-compatible chat-completion request body.
///
/// Made `pub(crate)` so integration test helpers in the binary can construct
/// it directly (P3 thinking-param unit test, deepseek_thinking_param_serialized.rs).
#[derive(Debug, Serialize)]
pub(crate) struct ChatRequest<'a> {
    pub model: &'a str,
    pub messages: &'a [ChatMessage],
    #[serde(skip_serializing_if = "Option::is_none")]
    pub max_tokens: Option<u32>,
    #[serde(skip_serializing_if = "Option::is_none")]
    pub temperature: Option<f32>,
    /// When `Some(ThinkingConfig { kind: "enabled" })`, the request body includes
    /// `{"thinking":{"type":"enabled"}}` and the response carries `reasoning_content`.
    /// When `None`, the field is omitted entirely (skip_serializing_if), which is
    /// the API signal for non-reasoning (fast) mode.
    #[serde(skip_serializing_if = "Option::is_none")]
    pub thinking: Option<ThinkingConfig>,
}

#[derive(Debug, Deserialize)]
struct ChatResponse {
    choices: Vec<ChatChoice>,
    #[serde(default)]
    usage: Option<Usage>,
}

#[derive(Debug, Deserialize)]
struct ChatChoice {
    message: ChatMessageOwned,
    #[serde(default)]
    finish_reason: Option<String>,
}

#[derive(Debug, Deserialize)]
struct ChatMessageOwned {
    #[allow(dead_code)]
    role: String,
    content: String,
    /// Present when the model is in reasoning mode (thinking.type = "enabled").
    /// Contains the model's internal reasoning trace, separate from `content`.
    #[serde(default)]
    reasoning_content: Option<String>,
}

/// TRACE_MATRIX FC2-N16: OpenAI-compatible token-usage record returned by chat-complete.
#[derive(Debug, Deserialize, Default, Clone)]
pub(crate) struct Usage {
    #[serde(default)]
    pub prompt_tokens: u64,
    #[serde(default)]
    pub completion_tokens: u64,
    #[serde(default)]
    pub total_tokens: u64,
}

/// TRACE_MATRIX FC2-N16: full chat-completion result handed back to CLI callers.
#[derive(Debug)]
pub(crate) struct ChatResult {
    pub content: String,
    /// Raw successful provider response body bytes as received before JSON parse.
    pub raw_response_body: Vec<u8>,
    /// Reasoning trace from the model when thinking mode is enabled.
    /// `None` when thinking is off or when the provider does not emit this field.
    pub reasoning_content: Option<String>,
    pub usage: Usage,
    pub finish_reason: Option<String>,
}

/// TRACE_MATRIX FC2-N16: SiliconFlow client error taxonomy (missing key, HTTP error, transport, decode).
#[derive(Debug)]
pub(crate) enum LlmError {
    MissingApiKey { env_var: String },
    HttpStatus { status: u16, body: String },
    Transport(String),
    DecodeError(String),
    NoChoices,
}

impl std::fmt::Display for LlmError {
    fn fmt(&self, f: &mut std::fmt::Formatter<'_>) -> std::fmt::Result {
        match self {
            Self::MissingApiKey { env_var } => write!(
                f,
                "missing API key: set env var {env_var} to your SiliconFlow API key"
            ),
            Self::HttpStatus { status, body } => {
                let rewritten = maybe_rewrite_deepseek_model_error(body);
                if let Some(msg) = rewritten {
                    write!(f, "{msg}")
                } else {
                    write!(f, "HTTP {status} from SiliconFlow: {body}")
                }
            }
            Self::Transport(e) => write!(f, "HTTP transport error: {e}"),
            Self::DecodeError(e) => write!(f, "response decode error: {e}"),
            Self::NoChoices => write!(f, "SiliconFlow returned 0 choices"),
        }
    }
}

/// TRACE_MATRIX FC2-N16: B1 UX helper — rewrite a DeepSeek model-name 4xx into an actionable message.
///
/// Returns `Some(message)` when the response body contains BOTH:
///   - `"supported API model names"` (DeepSeek direct API error marker)
///   - `"deepseek-v4-"` (direct-API model name prefix)
///
/// Otherwise returns `None` so the caller falls through to the generic path.
/// Detection is pure substring matching — no JSON parse.
pub(crate) fn maybe_rewrite_deepseek_model_error(body: &str) -> Option<String> {
    if body.contains("supported API model names") && body.contains("deepseek-v4-") {
        // Try to extract the rejected model name from "you passed <X>".
        let rejected_model = extract_rejected_model(body).unwrap_or_else(|| "<model>".to_string());
        Some(format!(
            "LLM provider rejected model \"{rejected_model}\".\n\
             \n\
             This usually means the endpoint (TURINGOS_SILICONFLOW_ENDPOINT) expects\n\
             different model strings than the SiliconFlow-style defaults.\n\
             \n\
             If you're targeting DeepSeek direct API, run:\n\
             \
               turingos llm config --workspace <ws> \\\n\
               \
                   --meta-model deepseek-v4-pro \\\n\
               \
                   --blackbox-model deepseek-v4-flash"
        ))
    } else {
        None
    }
}

/// Extract the model name from DeepSeek error messages like
/// "...but you passed deepseek-ai/DeepSeek-V3.2."
///
/// Handles two formats:
///   - Quoted: `you passed "deepseek-ai/DeepSeek-V3.2"` — stop at closing `"`
///   - Unquoted: `you passed deepseek-ai/DeepSeek-V3.2.` — stop at `"`, ` `, `\n`,
///     or a trailing period that ends a sentence (i.e., followed by `"`, space, or end).
fn extract_rejected_model(body: &str) -> Option<String> {
    let marker = "you passed ";
    let start = body.find(marker)? + marker.len();
    let rest = &body[start..];

    // Quoted form: `"model-name"`
    if rest.starts_with('"') {
        let inner = &rest[1..];
        let end = inner.find('"').unwrap_or(inner.len());
        let name = inner[..end].trim();
        return if name.is_empty() {
            None
        } else {
            Some(name.to_string())
        };
    }

    // Unquoted form: stop at whitespace, `"`, `}`, or a sentence-ending `.`
    // (a period that is immediately followed by `"`, `}`, space, newline, or end-of-string).
    let bytes = rest.as_bytes();
    let mut end = bytes.len();
    for (i, &b) in bytes.iter().enumerate() {
        match b {
            b'"' | b'}' | b' ' | b'\n' | b'\r' => {
                end = i;
                break;
            }
            b'.' => {
                // Only treat as sentence-end if next char is a delimiter or end.
                let next = bytes.get(i + 1).copied();
                match next {
                    None | Some(b'"') | Some(b'}') | Some(b' ') | Some(b'\n') | Some(b'\r') => {
                        end = i;
                        break;
                    }
                    _ => {} // e.g. V3.2 — period inside version string, keep going
                }
            }
            _ => {}
        }
    }
    let name = rest[..end].trim();
    if name.is_empty() {
        None
    } else {
        Some(name.to_string())
    }
}

impl std::error::Error for LlmError {}

/// TRACE_MATRIX FC2-N16: canonical provider request bytes for evidence hashing.
pub(crate) fn canonical_chat_request_bytes(
    model: &str,
    messages: &[ChatMessage],
    max_tokens: Option<u32>,
    temperature: Option<f32>,
    thinking: Option<ThinkingConfig>,
) -> Result<Vec<u8>, LlmError> {
    let body = ChatRequest {
        model,
        messages,
        max_tokens,
        temperature,
        thinking,
    };
    serde_json::to_vec(&body).map_err(|e| LlmError::DecodeError(e.to_string()))
}

/// TRACE_MATRIX FC2-N16: async chat-completion against SiliconFlow.
///
/// Call a SiliconFlow chat-completion. Returns the assistant message content +
/// usage tokens. Blocking-friendly: callers wrap with a tokio current-thread
/// runtime (see cmd_spec.rs / cmd_generate.rs).
pub(crate) async fn chat_complete(
    api_key: &str,
    model: &str,
    messages: &[ChatMessage],
    max_tokens: Option<u32>,
    temperature: Option<f32>,
    thinking: Option<ThinkingConfig>,
) -> Result<ChatResult, LlmError> {
    let url = endpoint();
    let request_bytes =
        canonical_chat_request_bytes(model, messages, max_tokens, temperature, thinking.clone())?;

    let client = reqwest::Client::builder()
        // 600s: thinking-on generations (reasoning_content + answer, up to the
        // configured max_tokens) routinely exceed the old 180s cap and the
        // client would drop the connection mid-response ("error sending
        // request"). Matches the SWE-bench probe's Python arm timeout.
        .timeout(Duration::from_secs(600))
        .build()
        .map_err(|e| LlmError::Transport(e.to_string()))?;

    let resp = client
        .post(&url)
        .bearer_auth(api_key)
        .header(reqwest::header::CONTENT_TYPE, "application/json")
        .body(request_bytes)
        .send()
        .await
        .map_err(|e| LlmError::Transport(e.to_string()))?;

    let status = resp.status();
    let text = resp
        .text()
        .await
        .map_err(|e| LlmError::Transport(e.to_string()))?;

    if !status.is_success() {
        return Err(LlmError::HttpStatus {
            status: status.as_u16(),
            body: text,
        });
    }

    let parsed: ChatResponse =
        serde_json::from_str(&text).map_err(|e| LlmError::DecodeError(e.to_string()))?;

    let first = parsed
        .choices
        .into_iter()
        .next()
        .ok_or(LlmError::NoChoices)?;
    Ok(ChatResult {
        content: first.message.content,
        raw_response_body: text.into_bytes(),
        reasoning_content: first.message.reasoning_content,
        usage: parsed.usage.unwrap_or_default(),
        finish_reason: first.finish_reason,
    })
}

/// TRACE_MATRIX FC2-N16: sync wrapper over chat_complete (spins a current-thread tokio runtime).
///
/// Block on chat_complete from a sync context. Spins up a current-thread
/// tokio runtime per call — fine for CLI usage (one or two calls per command).
#[allow(dead_code)]
pub(crate) fn chat_complete_blocking(
    api_key: &str,
    model: &str,
    messages: &[ChatMessage],
    max_tokens: Option<u32>,
    temperature: Option<f32>,
    thinking: Option<ThinkingConfig>,
) -> Result<ChatResult, LlmError> {
    let rt = tokio::runtime::Builder::new_current_thread()
        .enable_all()
        .build()
        .map_err(|e| LlmError::Transport(format!("tokio runtime: {e}")))?;
    rt.block_on(chat_complete(
        api_key,
        model,
        messages,
        max_tokens,
        temperature,
        thinking,
    ))
}

/// TRACE_MATRIX FC2-N16: env-var-only API-key read (NEVER persists to disk).
///
/// Read API key from the configured env var. Returns MissingApiKey if unset
/// or empty (so callers can print a clear setup hint).
pub(crate) fn require_api_key(env_var: &str) -> Result<String, LlmError> {
    match std::env::var(env_var) {
        Ok(v) if !v.is_empty() => Ok(v),
        _ => Err(LlmError::MissingApiKey {
            env_var: env_var.to_string(),
        }),
    }
}
