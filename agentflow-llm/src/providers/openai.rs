use crate::{
  LLMError, Result,
  client::streaming::{StreamChunk, StreamingResponse, TokenUsage, ToolCallDelta},
  providers::{ContentType, LLMProvider, ProviderRequest, ProviderResponse},
  thinking::ThinkingConfig,
  tool_calling::{StopReason, ToolCallRequest, ToolChoice, ToolSpec},
};
use async_trait::async_trait;
use futures::StreamExt;
use reqwest::Client;
use serde::{Deserialize, Serialize};
use serde_json::{Value, json};
use std::pin::Pin;
use tokio_stream::Stream;

pub struct OpenAIProvider {
  client: Client,
  api_key: String,
  base_url: String,
}

impl OpenAIProvider {
  pub fn new(api_key: &str, base_url: Option<String>) -> Result<Self> {
    Self::with_client(super::default_http_client()?, api_key, base_url)
  }

  /// Construct with a caller-supplied [`reqwest::Client`].
  ///
  /// Useful when callers need a non-default client — for example tests that
  /// must disable the system proxy (`.no_proxy()` on the builder) to reach a
  /// localhost mock, or production deployments that share one HTTPS-pinned
  /// client across providers.
  pub fn with_client(client: Client, api_key: &str, base_url: Option<String>) -> Result<Self> {
    if api_key.is_empty() {
      return Err(LLMError::MissingApiKey {
        provider: "openai".to_string(),
      });
    }

    let base_url = base_url.unwrap_or_else(|| "https://api.openai.com/v1".to_string());

    Ok(Self {
      client,
      api_key: api_key.to_string(),
      base_url,
    })
  }

  fn build_headers(&self) -> Result<reqwest::header::HeaderMap> {
    use reqwest::header::{AUTHORIZATION, CONTENT_TYPE, HeaderMap, HeaderValue};

    let mut headers = HeaderMap::new();
    headers.insert(CONTENT_TYPE, HeaderValue::from_static("application/json"));
    // Q2.5.3: surface invalid-character API keys as
    // `ConfigurationError` instead of panicking the runtime.
    headers.insert(
      AUTHORIZATION,
      HeaderValue::from_str(&format!("Bearer {}", self.api_key)).map_err(|err| {
        LLMError::ConfigurationError {
          message: format!("OpenAI API key contains invalid characters: {err}"),
        }
      })?,
    );
    crate::trace_context::inject_into_headers(&mut headers);
    Ok(headers)
  }

  fn build_request_body(&self, request: &ProviderRequest) -> Value {
    let mut body = json!({
      "model": request.model,
      "messages": request.messages,
      "stream": request.stream
    });

    // Add additional parameters
    for (key, value) in &request.parameters {
      body[key] = value.clone();
    }

    if let Some(tools) = &request.tools {
      body["tools"] = Value::Array(tools.iter().map(tool_spec_to_openai_value).collect());
    }
    if let Some(choice) = &request.tool_choice {
      body["tool_choice"] = tool_choice_to_openai_value(choice);
    }

    if let Some(thinking) = &request.thinking
      && let Some(effort) = thinking_config_to_openai_effort(thinking)
    {
      body["reasoning_effort"] = Value::String(effort.to_string());
    }

    body
  }
}

/// Encode a [`ThinkingConfig`] as OpenAI's `reasoning_effort` request field.
///
/// Returns `None` for [`ThinkingConfig::Disabled`] — caller omits the field
/// entirely so the model uses its default behaviour. The four accepted
/// values are `minimal`, `low`, `medium`, `high`; unknown caller-supplied
/// strings get normalised in [`ThinkingConfig::to_openai_effort`].
pub(crate) fn thinking_config_to_openai_effort(config: &ThinkingConfig) -> Option<&'static str> {
  config.to_openai_effort()
}

/// Encode a `ToolSpec` as the OpenAI `{ "type": "function", "function": ... }`
/// wire format.
pub(crate) fn tool_spec_to_openai_value(spec: &ToolSpec) -> Value {
  json!({
    "type": "function",
    "function": {
      "name": spec.name,
      "description": spec.description,
      "parameters": spec.parameters,
    }
  })
}

/// Encode a `ToolChoice` as the OpenAI `tool_choice` wire format.
pub(crate) fn tool_choice_to_openai_value(choice: &ToolChoice) -> Value {
  match choice {
    ToolChoice::Auto => Value::String("auto".to_string()),
    ToolChoice::None => Value::String("none".to_string()),
    ToolChoice::Required => Value::String("required".to_string()),
    ToolChoice::Tool { name } => json!({
      "type": "function",
      "function": { "name": name }
    }),
  }
}

/// Decode OpenAI `tool_calls` array into typed `ToolCallRequest`s.
///
/// OpenAI returns `arguments` as a JSON-encoded string; we parse it eagerly so
/// callers don't need to know the wire format. Malformed JSON falls back to a
/// `Value::String` of the raw payload so the call can still surface in traces.
pub(crate) fn parse_openai_tool_calls(value: &Value) -> Vec<ToolCallRequest> {
  let Some(items) = value.as_array() else {
    return Vec::new();
  };
  items
    .iter()
    .enumerate()
    .filter_map(|(idx, item)| {
      let function = item.get("function")?;
      let name = function.get("name")?.as_str()?.to_string();
      let id = item
        .get("id")
        .and_then(Value::as_str)
        .map(str::to_string)
        .unwrap_or_else(|| format!("call_{}", idx));
      let raw_args = function.get("arguments");
      let arguments = match raw_args {
        Some(Value::String(s)) => {
          serde_json::from_str(s).unwrap_or_else(|_| Value::String(s.clone()))
        }
        Some(other) => other.clone(),
        None => Value::Object(serde_json::Map::new()),
      };
      Some(ToolCallRequest {
        id,
        name,
        arguments,
      })
    })
    .collect()
}

#[async_trait]
impl LLMProvider for OpenAIProvider {
  fn name(&self) -> &str {
    "openai"
  }

  async fn execute(&self, request: &ProviderRequest) -> Result<ProviderResponse> {
    if request.stream {
      return Err(LLMError::InternalError {
        message: "Use execute_streaming for streaming requests".to_string(),
      });
    }

    let url = format!("{}/chat/completions", self.base_url);
    let body = self.build_request_body(request);

    let response = self
      .client
      .post(&url)
      .headers(self.build_headers()?)
      .json(&body)
      .send()
      .await?;

    if !response.status().is_success() {
      let status_code = response.status().as_u16();
      let error_text = response.text().await.unwrap_or_default();
      return Err(LLMError::HttpError {
        status_code,
        message: error_text,
      });
    }

    let openai_response: OpenAIResponse = response.json().await?;

    // Handle both string and array content formats
    let content_text = if let Some(first_choice) = openai_response.choices.first() {
      match &first_choice.message.content {
        Some(serde_json::Value::String(text)) => text.clone(),
        Some(serde_json::Value::Array(_)) => {
          // For multimodal responses that return structured content,
          // extract text parts or convert to string representation
          first_choice
            .message
            .content
            .as_ref()
            .map(|v| v.to_string())
            .unwrap_or_default()
        }
        _ => String::new(),
      }
    } else {
      String::new()
    };

    // Convert to ContentType - OpenAI currently only returns text
    let content = ContentType::Text(content_text);

    let usage = openai_response
      .usage
      .clone()
      .map(|u| crate::providers::TokenUsage {
        prompt_tokens: Some(u.prompt_tokens),
        completion_tokens: Some(u.completion_tokens),
        total_tokens: Some(u.total_tokens),
      });

    let first_choice = openai_response.choices.first();
    let tool_calls = first_choice
      .and_then(|c| c.message.tool_calls.as_ref())
      .map(parse_openai_tool_calls)
      .unwrap_or_default();
    let stop_reason = if tool_calls.is_empty() {
      first_choice
        .and_then(|c| c.finish_reason.as_deref())
        .map(StopReason::from_openai_finish_reason)
    } else {
      Some(StopReason::ToolCalls)
    };

    // Reasoning text — for DeepSeek-R1 the provider returns
    // `reasoning_content` alongside `content`; for vanilla OpenAI chat
    // completions it's `None`. See `OpenAIMessage::reasoning_content`.
    let thinking = first_choice
      .and_then(|c| c.message.reasoning_content.clone())
      .filter(|s| !s.is_empty());

    Ok(ProviderResponse {
      content,
      usage,
      metadata: Some(serde_json::to_value(&openai_response)?),
      tool_calls,
      stop_reason,
      thinking,
    })
  }

  async fn execute_streaming(
    &self,
    request: &ProviderRequest,
  ) -> Result<Box<dyn StreamingResponse>> {
    if !request.stream {
      return Err(LLMError::InternalError {
        message: "Streaming not enabled in request".to_string(),
      });
    }

    let url = format!("{}/chat/completions", self.base_url);
    let body = self.build_request_body(request);

    let response = self
      .client
      .post(&url)
      .headers(self.build_headers()?)
      .json(&body)
      .send()
      .await?;

    if !response.status().is_success() {
      let status_code = response.status().as_u16();
      let error_text = response.text().await.unwrap_or_default();
      return Err(LLMError::HttpError {
        status_code,
        message: error_text,
      });
    }

    Ok(Box::new(OpenAIStreamingResponse::new(response)))
  }

  async fn validate_config(&self) -> Result<()> {
    // Simple health check - try to list models
    let url = format!("{}/models", self.base_url);

    let response = self
      .client
      .get(&url)
      .headers(self.build_headers()?)
      .send()
      .await?;

    if !response.status().is_success() {
      return Err(LLMError::AuthenticationError {
        provider: "openai".to_string(),
        message: "Failed to authenticate with OpenAI API".to_string(),
      });
    }

    Ok(())
  }

  fn base_url(&self) -> &str {
    &self.base_url
  }

  fn supported_models(&self) -> Vec<String> {
    vec![
      "gpt-4o".to_string(),
      "gpt-4o-mini".to_string(),
      "gpt-4-turbo".to_string(),
      "gpt-4".to_string(),
      "gpt-3.5-turbo".to_string(),
    ]
  }
}

// OpenAI API response structures
#[derive(Debug, Deserialize, Serialize)]
struct OpenAIResponse {
  id: String,
  object: String,
  created: u64,
  model: String,
  choices: Vec<OpenAIChoice>,
  usage: Option<OpenAIUsage>,
}

#[derive(Debug, Deserialize, Serialize)]
struct OpenAIChoice {
  index: u32,
  message: OpenAIMessage,
  finish_reason: Option<String>,
}

#[derive(Debug, Deserialize, Serialize)]
struct OpenAIMessage {
  role: String,
  content: Option<serde_json::Value>, // Can be string or array of content objects
  #[serde(default, skip_serializing_if = "Option::is_none")]
  tool_calls: Option<serde_json::Value>,
  /// DeepSeek-R1 surfaces the model's chain-of-thought here, alongside
  /// `content`. Captured so the typed `ProviderResponse.thinking` channel
  /// can carry it rather than relying on the raw metadata blob. Vanilla
  /// OpenAI chat completions don't emit this field; the `default` lets
  /// deserialisation succeed in both cases.
  #[serde(default, skip_serializing_if = "Option::is_none")]
  reasoning_content: Option<String>,
}

#[derive(Debug, Clone, Deserialize, Serialize)]
struct OpenAIUsage {
  prompt_tokens: u32,
  completion_tokens: u32,
  total_tokens: u32,
}

// Streaming response structures
#[derive(Debug, Deserialize, Serialize)]
struct OpenAIStreamingChunk {
  id: String,
  object: String,
  created: u64,
  model: String,
  choices: Vec<OpenAIStreamingChoice>,
  usage: Option<OpenAIUsage>,
}

#[derive(Debug, Deserialize, Serialize)]
struct OpenAIStreamingChoice {
  index: u32,
  delta: OpenAIStreamingDelta,
  finish_reason: Option<String>,
}

#[derive(Debug, Deserialize, Serialize)]
struct OpenAIStreamingDelta {
  role: Option<String>,
  content: Option<serde_json::Value>, // Can be string or array of content objects
  /// Q2.5.2: streamed tool_call deltas. The provider sends partial JSON
  /// for `function.arguments`; consumers must concatenate per-index.
  #[serde(default)]
  tool_calls: Option<Vec<OpenAIStreamingToolCall>>,
}

/// Q2.5.2: incremental tool_call entry inside a streaming delta.
#[derive(Debug, Deserialize, Serialize)]
struct OpenAIStreamingToolCall {
  index: u32,
  #[serde(default)]
  id: Option<String>,
  #[serde(default, rename = "type")]
  _kind: Option<String>,
  #[serde(default)]
  function: Option<OpenAIStreamingToolCallFunction>,
}

#[derive(Debug, Deserialize, Serialize)]
struct OpenAIStreamingToolCallFunction {
  #[serde(default)]
  name: Option<String>,
  #[serde(default)]
  arguments: Option<String>,
}

pub struct OpenAIStreamingResponse {
  stream: Pin<Box<dyn Stream<Item = Result<String>> + Send>>,
  buffer: Option<String>,
  finished: bool,
}

// Q2.5.4: removed `unsafe impl Send + Sync`. The inner pinned
// `dyn Stream + Send` is auto-Send already, and the trait no longer
// requires Sync (streams are sequentially consumed via &mut self).

impl OpenAIStreamingResponse {
  fn new(response: reqwest::Response) -> Self {
    let byte_stream = response.bytes_stream();
    let string_stream = byte_stream.map(|chunk_result| {
      chunk_result
        .map_err(|e| LLMError::StreamingError {
          message: e.to_string(),
        })
        .map(|chunk| String::from_utf8_lossy(&chunk).to_string())
    });

    Self {
      stream: Box::pin(string_stream),
      buffer: Some(String::new()),
      finished: false,
    }
  }

  fn parse_sse_chunk(line: &str) -> Option<StreamChunk> {
    if !line.starts_with("data: ") {
      return None;
    }

    let data = &line[6..]; // Remove "data: " prefix

    if data.trim() == "[DONE]" {
      return Some(StreamChunk {
        content: String::new(),
        is_final: true,
        metadata: None,
        usage: None,
        content_type: Some("text".to_string()),
        tool_call_deltas: Vec::new(),
      });
    }

    if let Ok(chunk) = serde_json::from_str::<OpenAIStreamingChunk>(data)
      && let Some(choice) = chunk.choices.first()
    {
      let content_text = match &choice.delta.content {
        Some(serde_json::Value::String(text)) => text.clone(),
        Some(other) => other.to_string(),
        None => String::new(),
      };

      let tool_call_deltas = choice
        .delta
        .tool_calls
        .as_ref()
        .map(|calls| {
          calls
            .iter()
            .map(|call| ToolCallDelta {
              index: call.index,
              id: call.id.clone(),
              name: call.function.as_ref().and_then(|f| f.name.clone()),
              arguments_delta: call.function.as_ref().and_then(|f| f.arguments.clone()),
            })
            .collect::<Vec<_>>()
        })
        .unwrap_or_default();

      // Q2.5.2: emit a chunk when there is *any* signal — text content,
      // tool_call delta, finish_reason, or usage — so tool-call-only
      // turns don't get silently dropped between [DONE] sentinels.
      let has_signal = !content_text.is_empty()
        || !tool_call_deltas.is_empty()
        || choice.finish_reason.is_some()
        || chunk.usage.is_some();
      if !has_signal {
        return None;
      }

      return Some(StreamChunk {
        content: content_text,
        is_final: choice.finish_reason.is_some(),
        metadata: Some(serde_json::to_value(&chunk).ok()?),
        usage: chunk.usage.map(|u| TokenUsage {
          prompt_tokens: Some(u.prompt_tokens),
          completion_tokens: Some(u.completion_tokens),
          total_tokens: Some(u.total_tokens),
        }),
        content_type: Some("text".to_string()),
        tool_call_deltas,
      });
    }

    None
  }
}

#[async_trait]
impl StreamingResponse for OpenAIStreamingResponse {
  async fn next_chunk(&mut self) -> Result<Option<StreamChunk>> {
    if self.finished {
      return Ok(None);
    }

    loop {
      // Try to get the next chunk from the stream
      match self.stream.next().await {
        Some(Ok(data)) => {
          // Add to buffer
          if let Some(ref mut buffer) = self.buffer {
            buffer.push_str(&data);

            // Process complete lines
            while let Some(newline_pos) = buffer.find('\n') {
              let line = buffer[..newline_pos].trim().to_string();
              buffer.drain(..=newline_pos);

              if !line.is_empty()
                && let Some(chunk) = Self::parse_sse_chunk(&line)
              {
                if chunk.is_final {
                  self.finished = true;
                }
                return Ok(Some(chunk));
              }
            }
          }
        }
        Some(Err(e)) => return Err(e),
        None => {
          self.finished = true;
          return Ok(None);
        }
      }
    }
  }
}

#[cfg(test)]
mod tests {
  use super::*;

  /// `ThinkingConfig::High` must emit `reasoning_effort: "high"` on the
  /// request body. OpenAI is pass-through but the field must still appear
  /// on the wire even when `parameters` is empty.
  #[test]
  fn build_request_body_emits_reasoning_effort_for_thinking_high() {
    let provider = OpenAIProvider::new("test-key", None).unwrap();
    let request = ProviderRequest {
      model: "o3-mini".to_string(),
      messages: vec![json!({"role": "user", "content": "reason"})],
      stream: false,
      parameters: std::collections::HashMap::new(),
      tools: None,
      tool_choice: None,
      thinking: Some(ThinkingConfig::High),
    };
    let body = provider.build_request_body(&request);
    assert_eq!(body["reasoning_effort"], "high");
  }

  #[test]
  fn build_request_body_omits_reasoning_effort_when_disabled() {
    let provider = OpenAIProvider::new("test-key", None).unwrap();
    let request = ProviderRequest {
      model: "o3-mini".to_string(),
      messages: vec![json!({"role": "user", "content": "no reasoning"})],
      stream: false,
      parameters: std::collections::HashMap::new(),
      tools: None,
      tool_choice: None,
      thinking: Some(ThinkingConfig::Disabled),
    };
    let body = provider.build_request_body(&request);
    assert!(body.get("reasoning_effort").is_none());
  }

  /// DeepSeek-R1 routes through `OpenAIProvider` (per `providers/mod.rs::
  /// create_provider`) and returns `reasoning_content` alongside
  /// `content`. The deserialise path must capture it so the typed
  /// `ProviderResponse.thinking` channel carries the reasoning text.
  #[test]
  fn openai_message_deserialises_reasoning_content_for_deepseek_r1() {
    let raw = json!({
      "role": "assistant",
      "content": "The answer is 42.",
      "reasoning_content": "Let me think step by step about this..."
    });
    let msg: OpenAIMessage = serde_json::from_value(raw).unwrap();
    assert_eq!(
      msg.reasoning_content.as_deref(),
      Some("Let me think step by step about this...")
    );
  }

  /// Vanilla OpenAI chat completions do NOT emit `reasoning_content`.
  /// Deserialise must succeed and leave the field `None`.
  #[test]
  fn openai_message_reasoning_content_is_optional() {
    let raw = json!({
      "role": "assistant",
      "content": "hi"
    });
    let msg: OpenAIMessage = serde_json::from_value(raw).unwrap();
    assert!(msg.reasoning_content.is_none());
  }

  #[test]
  fn test_openai_provider_creation() {
    let provider = OpenAIProvider::new("test-key", None);
    assert!(provider.is_ok());

    let provider = OpenAIProvider::new("", None);
    assert!(provider.is_err());
  }

  #[test]
  fn with_client_validates_api_key_and_keeps_caller_supplied_client() {
    let custom = reqwest::Client::builder()
      .no_proxy()
      .build()
      .expect("custom client");

    assert!(
      OpenAIProvider::with_client(custom.clone(), "", Some("http://x".into())).is_err(),
      "empty api key must error",
    );
    let provider = OpenAIProvider::with_client(custom, "test-key", Some("http://example".into()))
      .expect("custom client provider");
    assert_eq!(provider.base_url, "http://example");
  }

  #[tokio::test]
  async fn build_headers_injects_traceparent_when_scope_active() {
    use crate::trace_context::{LlmTraceContext, scope};

    let provider = OpenAIProvider::new("test-key", None).unwrap();
    let ctx = LlmTraceContext::new("0af7651916cd43dd8448eb211c80319c", "b7ad6b7169203331").unwrap();

    let headers = scope(ctx.clone(), async { provider.build_headers() })
      .await
      .expect("headers must build under a well-formed ASCII API key");
    assert_eq!(
      headers.get("traceparent").and_then(|v| v.to_str().ok()),
      Some(ctx.to_traceparent().as_str()),
    );
  }

  #[test]
  fn build_headers_omits_traceparent_when_no_scope_active() {
    let provider = OpenAIProvider::new("test-key", None).unwrap();
    let headers = provider.build_headers().expect("ASCII key builds cleanly");
    assert!(headers.get("traceparent").is_none());
  }

  /// Q2.5.3 regression: invalid-character API key surfaces as
  /// ConfigurationError instead of panicking the runtime.
  #[test]
  fn build_headers_returns_err_on_invalid_api_key() {
    let provider = OpenAIProvider::new("bad\nkey", None).unwrap();
    let err = provider
      .build_headers()
      .expect_err("newline-in-key must fail closed");
    assert!(matches!(err, LLMError::ConfigurationError { .. }));
  }

  // Q2.5.2: OpenAI streams tool_calls via `choices[0].delta.tool_calls`. The
  // first delta carries id/name; subsequent deltas append `function.arguments`
  // partial JSON. Concatenating all `arguments_delta` per index yields the
  // canonical argument JSON.
  #[test]
  fn streaming_tool_call_delta_carries_id_and_name() {
    let chunk = OpenAIStreamingResponse::parse_sse_chunk(
      "data: {\"id\":\"c1\",\"object\":\"chat.completion.chunk\",\"created\":1,\"model\":\"gpt-4o\",\"choices\":[{\"index\":0,\"delta\":{\"tool_calls\":[{\"index\":0,\"id\":\"call_abc\",\"type\":\"function\",\"function\":{\"name\":\"get_weather\",\"arguments\":\"\"}}]},\"finish_reason\":null}]}",
    ).unwrap();
    assert_eq!(chunk.tool_call_deltas.len(), 1);
    let delta = &chunk.tool_call_deltas[0];
    assert_eq!(delta.index, 0);
    assert_eq!(delta.id.as_deref(), Some("call_abc"));
    assert_eq!(delta.name.as_deref(), Some("get_weather"));
    assert_eq!(delta.arguments_delta.as_deref(), Some(""));
    assert!(!chunk.is_final);
  }

  #[test]
  fn streaming_tool_call_subsequent_delta_appends_arguments() {
    let chunk = OpenAIStreamingResponse::parse_sse_chunk(
      "data: {\"id\":\"c1\",\"object\":\"chat.completion.chunk\",\"created\":1,\"model\":\"gpt-4o\",\"choices\":[{\"index\":0,\"delta\":{\"tool_calls\":[{\"index\":0,\"function\":{\"arguments\":\"{\\\"city\\\":\"}}]},\"finish_reason\":null}]}",
    ).unwrap();
    assert_eq!(chunk.tool_call_deltas.len(), 1);
    let delta = &chunk.tool_call_deltas[0];
    assert_eq!(delta.index, 0);
    assert!(delta.id.is_none());
    assert!(delta.name.is_none());
    assert_eq!(delta.arguments_delta.as_deref(), Some("{\"city\":"));
  }

  #[test]
  fn streaming_done_sentinel_finalizes() {
    let chunk = OpenAIStreamingResponse::parse_sse_chunk("data: [DONE]").unwrap();
    assert!(chunk.is_final);
    assert!(chunk.tool_call_deltas.is_empty());
  }

  #[test]
  fn test_build_request_body() {
    let provider = OpenAIProvider::new("test-key", None).unwrap();

    let mut params = std::collections::HashMap::new();
    params.insert("temperature".to_string(), json!(0.7));
    params.insert("max_tokens".to_string(), json!(100));

    let request = ProviderRequest {
      model: "gpt-4o".to_string(),
      messages: vec![json!({"role": "user", "content": "test"})],
      stream: false,
      parameters: params,
      tools: None,
      tool_choice: None,
      thinking: None,
    };

    let body = provider.build_request_body(&request);
    assert_eq!(body["model"], "gpt-4o");
    assert_eq!(body["temperature"], 0.7);
    assert_eq!(body["max_tokens"], 100);
    assert_eq!(body["stream"], false);
    assert!(body.get("tools").is_none());
    assert!(body.get("tool_choice").is_none());
  }

  #[test]
  fn build_request_body_serialises_tools() {
    let provider = OpenAIProvider::new("test-key", None).unwrap();
    let tool = ToolSpec::new(
      "get_weather",
      "Return the weather for a city",
      json!({
        "type": "object",
        "properties": {"city": {"type": "string"}},
        "required": ["city"]
      }),
    );
    let request = ProviderRequest {
      model: "gpt-4o".to_string(),
      messages: vec![json!({"role": "user", "content": "weather in Tokyo?"})],
      stream: false,
      parameters: std::collections::HashMap::new(),
      tools: Some(vec![tool]),
      tool_choice: Some(ToolChoice::Required),
      thinking: None,
    };

    let body = provider.build_request_body(&request);
    let tools = body["tools"].as_array().expect("tools array");
    assert_eq!(tools.len(), 1);
    assert_eq!(tools[0]["type"], "function");
    assert_eq!(tools[0]["function"]["name"], "get_weather");
    assert_eq!(tools[0]["function"]["parameters"]["required"][0], "city");
    assert_eq!(body["tool_choice"], "required");
  }

  #[test]
  fn build_request_body_tool_choice_specific() {
    let provider = OpenAIProvider::new("test-key", None).unwrap();
    let request = ProviderRequest {
      model: "gpt-4o".to_string(),
      messages: vec![],
      stream: false,
      parameters: std::collections::HashMap::new(),
      tools: Some(vec![ToolSpec::new("x", "", json!({}))]),
      tool_choice: Some(ToolChoice::Tool {
        name: "x".to_string(),
      }),
      thinking: None,
    };

    let body = provider.build_request_body(&request);
    assert_eq!(body["tool_choice"]["type"], "function");
    assert_eq!(body["tool_choice"]["function"]["name"], "x");
  }

  #[test]
  fn parse_openai_tool_calls_decodes_arguments_json() {
    let raw = json!([
      {
        "id": "call_abc",
        "type": "function",
        "function": {
          "name": "get_weather",
          "arguments": "{\"city\": \"Tokyo\"}"
        }
      },
      {
        "id": "call_def",
        "type": "function",
        "function": {
          "name": "search",
          "arguments": "not json"
        }
      }
    ]);
    let calls = parse_openai_tool_calls(&raw);
    assert_eq!(calls.len(), 2);
    assert_eq!(calls[0].id, "call_abc");
    assert_eq!(calls[0].name, "get_weather");
    assert_eq!(calls[0].arguments["city"], "Tokyo");
    // Unparseable arguments fall back to a string so traces still see them.
    assert_eq!(calls[1].arguments, Value::String("not json".to_string()));
  }

  #[test]
  fn parse_openai_tool_calls_synthesises_id_when_missing() {
    let raw = json!([
      { "type": "function", "function": { "name": "ping", "arguments": "{}" } }
    ]);
    let calls = parse_openai_tool_calls(&raw);
    assert_eq!(calls.len(), 1);
    assert_eq!(calls[0].id, "call_0");
  }

  #[test]
  fn openai_message_deserialises_tool_calls() {
    let raw = json!({
      "id": "x",
      "object": "chat.completion",
      "created": 0,
      "model": "gpt-4o",
      "choices": [
        {
          "index": 0,
          "message": {
            "role": "assistant",
            "content": null,
            "tool_calls": [
              {
                "id": "call_1",
                "type": "function",
                "function": {
                  "name": "get_weather",
                  "arguments": "{\"city\": \"NYC\"}"
                }
              }
            ]
          },
          "finish_reason": "tool_calls"
        }
      ],
      "usage": null
    });
    let parsed: OpenAIResponse = serde_json::from_value(raw).unwrap();
    let choice = &parsed.choices[0];
    assert_eq!(choice.finish_reason.as_deref(), Some("tool_calls"));
    let tool_calls = parse_openai_tool_calls(choice.message.tool_calls.as_ref().unwrap());
    assert_eq!(tool_calls.len(), 1);
    assert_eq!(tool_calls[0].name, "get_weather");
    assert_eq!(tool_calls[0].arguments["city"], "NYC");
  }
}
