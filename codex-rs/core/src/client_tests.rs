use super::AuthRequestTelemetryContext;
use super::ModelClient;
use super::PendingUnauthorizedRetry;
use super::UnauthorizedRecoveryExecution;
use super::X_CODEX_INSTALLATION_ID_HEADER;
use super::X_CODEX_PARENT_THREAD_ID_HEADER;
use super::X_CODEX_TURN_METADATA_HEADER;
use super::X_CODEX_WINDOW_ID_HEADER;
use super::X_OPENAI_SUBAGENT_HEADER;
use crate::AttestationContext;
use crate::AttestationProvider;
use crate::GenerateAttestationFuture;
use crate::responses_metadata::CodexResponsesMetadata;
use crate::test_support::TestCodexResponsesRequestKind;
use crate::test_support::responses_metadata as test_responses_metadata;
use codex_api::ApiError;
use codex_api::ResponseEvent;
use codex_app_server_protocol::AuthMode;
use codex_login::AuthManager;
use codex_login::CodexAuth;
use codex_model_provider::BearerAuthProvider;
use codex_model_provider_info::AMBIENT_DEFAULT_MODEL;
use codex_model_provider_info::CHATGPT_CODEX_BASE_URL;
use codex_model_provider_info::ModelProviderInfo;
use codex_model_provider_info::VERCEL_DEFAULT_MODEL;
use codex_model_provider_info::WireApi;
use codex_model_provider_info::create_oss_provider_with_base_url;
use codex_otel::SessionTelemetry;
use codex_protocol::ThreadId;
use codex_protocol::config_types::ReasoningSummary as ReasoningSummaryConfig;
use codex_protocol::config_types::WebSearchContextSize;
use codex_protocol::models::AgentMessageInputContent;
use codex_protocol::models::ContentItem;
use codex_protocol::models::FunctionCallOutputPayload;
use codex_protocol::models::ResponseItem;
use codex_protocol::openai_models::ModelInfo;
use codex_protocol::openai_models::ReasoningEffort as ReasoningEffortConfig;
use codex_protocol::protocol::InternalSessionSource;
use codex_protocol::protocol::SessionSource;
use codex_protocol::protocol::SubAgentSource;
use codex_rollout_trace::ExecutionStatus;
use codex_rollout_trace::InferenceTraceAttempt;
use codex_rollout_trace::InferenceTraceContext;
use codex_rollout_trace::RawTraceEventPayload;
use codex_rollout_trace::RolloutTrace;
use codex_rollout_trace::TraceWriter;
use codex_rollout_trace::replay_bundle;
use codex_tools::FreeformTool;
use codex_tools::FreeformToolFormat;
use codex_tools::JsonSchema;
use codex_tools::ResponsesApiTool;
use codex_tools::ToolSpec;
use futures::StreamExt;
use pretty_assertions::assert_eq;
use serde_json::json;
use std::collections::BTreeMap;
use std::collections::VecDeque;
use std::pin::Pin;
use std::sync::Arc;
use std::sync::Mutex;
use std::sync::atomic::AtomicUsize;
use std::sync::atomic::Ordering;
use std::task::Context;
use std::task::Poll;
use std::time::Duration;
use tempfile::TempDir;
use tokio::sync::Notify;
use tracing::Event;
use tracing::Subscriber;
use tracing::field::Visit;
use tracing_subscriber::Layer;
use tracing_subscriber::layer::Context as LayerContext;
use tracing_subscriber::layer::SubscriberExt;
use tracing_subscriber::registry::LookupSpan;
use tracing_subscriber::util::SubscriberInitExt;

const TEST_INSTALLATION_ID: &str = "11111111-1111-4111-8111-111111111111";

fn test_model_client(session_source: SessionSource) -> ModelClient {
    let provider = create_oss_provider_with_base_url("https://example.com/v1", WireApi::Responses);
    let thread_id = ThreadId::new();
    ModelClient::new(
        /*auth_manager*/ None,
        thread_id,
        provider,
        session_source,
        /*model_verbosity*/ None,
        /*enable_request_compression*/ false,
        /*include_timing_metrics*/ false,
        /*beta_features_header*/ None,
        /*item_ids_enabled*/ false,
        /*attestation_provider*/ None,
    )
}

fn test_responses_metadata_for_client(
    client: &ModelClient,
    turn_id: Option<&str>,
    window_id: String,
    parent_thread_id: Option<ThreadId>,
    request_kind: TestCodexResponsesRequestKind,
) -> CodexResponsesMetadata {
    let thread_id = client.state.thread_id.to_string();
    test_responses_metadata(
        TEST_INSTALLATION_ID,
        &thread_id,
        &thread_id,
        turn_id,
        window_id,
        &client.state.session_source,
        parent_thread_id,
        request_kind,
    )
}

fn test_model_info() -> ModelInfo {
    serde_json::from_value(json!({
        "slug": "gpt-test",
        "display_name": "gpt-test",
        "description": "desc",
        "default_reasoning_level": "medium",
        "supported_reasoning_levels": [
            {"effort": "medium", "description": "medium"}
        ],
        "shell_type": "shell_command",
        "visibility": "list",
        "supported_in_api": true,
        "priority": 1,
        "upgrade": null,
        "base_instructions": "base instructions",
        "model_messages": null,
        "supports_reasoning_summaries": false,
        "support_verbosity": false,
        "default_verbosity": null,
        "apply_patch_tool_type": null,
        "truncation_policy": {"mode": "bytes", "limit": 10000},
        "supports_parallel_tool_calls": false,
        "supports_image_detail_original": false,
        "context_window": 272000,
        "auto_compact_token_limit": null,
        "experimental_supported_tools": []
    }))
    .expect("deserialize test model info")
}

fn test_ambient_model_info() -> ModelInfo {
    serde_json::from_value(json!({
        "slug": AMBIENT_DEFAULT_MODEL,
        "display_name": "Ambient GLM 5.2",
        "description": "Ambient GLM 5.2",
        "default_reasoning_level": "medium",
        "supported_reasoning_levels": [
            {"effort": "medium", "description": "Standard"},
            {"effort": "xhigh", "description": "Deep"}
        ],
        "shell_type": "shell_command",
        "visibility": "list",
        "supported_in_api": true,
        "priority": 1,
        "upgrade": null,
        "base_instructions": "base instructions",
        "model_messages": null,
        "supports_reasoning_summaries": false,
        "support_verbosity": false,
        "default_verbosity": null,
        "apply_patch_tool_type": null,
        "truncation_policy": {"mode": "tokens", "limit": 10000},
        "supports_parallel_tool_calls": true,
        "supports_image_detail_original": false,
        "context_window": 202752,
        "auto_compact_token_limit": null,
        "experimental_supported_tools": []
    }))
    .expect("deserialize Ambient test model info")
}

fn test_vercel_model_info() -> ModelInfo {
    serde_json::from_value(json!({
        "slug": VERCEL_DEFAULT_MODEL,
        "display_name": "Vercel GLM 5.2",
        "description": "Vercel GLM 5.2",
        "default_reasoning_level": "medium",
        "supported_reasoning_levels": [
            {"effort": "medium", "description": "Standard"},
            {"effort": "xhigh", "description": "Deep"}
        ],
        "shell_type": "shell_command",
        "visibility": "list",
        "supported_in_api": true,
        "priority": 3,
        "upgrade": null,
        "base_instructions": "base instructions",
        "model_messages": null,
        "supports_reasoning_summaries": false,
        "support_verbosity": false,
        "default_verbosity": null,
        "apply_patch_tool_type": null,
        "truncation_policy": {"mode": "tokens", "limit": 10000},
        "supports_parallel_tool_calls": true,
        "supports_image_detail_original": false,
        "context_window": 1048576,
        "auto_compact_token_limit": null,
        "experimental_supported_tools": []
    }))
    .expect("deserialize Vercel test model info")
}

fn test_openrouter_gemini_model_info() -> ModelInfo {
    serde_json::from_value(json!({
        "slug": "google/gemini-3.5-flash",
        "display_name": "OpenRouter Gemini 3.5 Flash",
        "description": "OpenRouter Gemini 3.5 Flash",
        "default_reasoning_level": null,
        "supported_reasoning_levels": [
            {"effort": "minimal", "description": "Minimal"},
            {"effort": "low", "description": "Low"},
            {"effort": "medium", "description": "Medium"},
            {"effort": "high", "description": "High"}
        ],
        "shell_type": "shell_command",
        "visibility": "list",
        "supported_in_api": true,
        "priority": 1,
        "upgrade": null,
        "base_instructions": "base instructions",
        "model_messages": null,
        "supports_reasoning_summaries": false,
        "support_verbosity": false,
        "default_verbosity": null,
        "apply_patch_tool_type": null,
        "truncation_policy": {"mode": "tokens", "limit": 10000},
        "supports_parallel_tool_calls": true,
        "supports_image_detail_original": false,
        "context_window": 1048576,
        "auto_compact_token_limit": null,
        "experimental_supported_tools": []
    }))
    .expect("deserialize OpenRouter Gemini test model info")
}

fn test_session_telemetry() -> SessionTelemetry {
    SessionTelemetry::new(
        ThreadId::new(),
        "gpt-test",
        "gpt-test",
        /*account_id*/ None,
        /*account_email*/ None,
        /*auth_mode*/ None,
        "test-originator".to_string(),
        /*log_user_prompts*/ false,
        "test-terminal".to_string(),
        SessionSource::Cli,
    )
}

#[test]
fn chat_completions_wraps_freeform_tools_as_functions() {
    let tools = super::create_tools_json_for_chat_completions(
        &[ToolSpec::Freeform(FreeformTool {
            name: "apply_patch".to_string(),
            description: "Apply a patch".to_string(),
            format: FreeformToolFormat {
                r#type: "grammar".to_string(),
                syntax: "lark".to_string(),
                definition: "start: /.+/".to_string(),
            },
        })],
        false,
        false,
        false,
    )
    .expect("chat tools");

    assert_eq!(
        tools,
        vec![json!({
            "type": "function",
            "function": {
                "name": "apply_patch",
                "description": "Use this tool to edit files by applying a patch. Pass the raw patch text in the `input` field. The `input` value must begin with `*** Begin Patch` and end with `*** End Patch`; do not put JSON, shell commands, or heredocs inside `input`.",
                "parameters": {
                    "type": "object",
                    "properties": {
                        "input": {
                            "type": "string",
                            "description": "Raw apply_patch input. Put the tool payload directly in this string; do not nest JSON, shell commands, or heredocs inside it.",
                        },
                    },
                    "required": ["input"],
                    "additionalProperties": false,
                },
                "strict": true,
            },
        })]
    );
}

#[test]
fn ambient_chat_completions_strips_strict_from_tools() {
    let freeform = ToolSpec::Freeform(FreeformTool {
        name: "apply_patch".to_string(),
        description: "Apply a patch".to_string(),
        format: FreeformToolFormat {
            r#type: "grammar".to_string(),
            syntax: "lark".to_string(),
            definition: "start: /.+/".to_string(),
        },
    });
    let function = ToolSpec::Function(ResponsesApiTool {
        name: "ambient_probe".to_string(),
        description: "Records a small probe result.".to_string(),
        strict: true,
        defer_loading: None,
        parameters: JsonSchema::object(
            BTreeMap::from([(
                "ok".to_string(),
                JsonSchema::boolean(Some("Whether the probe succeeded.".to_string())),
            )]),
            Some(vec!["ok".to_string()]),
            Some(false.into()),
        ),
        output_schema: None,
    });

    let tools = super::create_tools_json_for_chat_completions(
        &[freeform, function],
        /*strip_strict*/ true,
        /*zai_native_web_search*/ false,
        /*openrouter_server_web_search*/ false,
    )
    .expect("chat tools");

    assert_eq!(tools.len(), 2);
    assert!(
        tools
            .iter()
            .all(|tool| tool.pointer("/function/strict").is_none()),
        "Ambient chat tool payloads must omit strict: {tools:?}"
    );
    assert_eq!(
        tools[1]
            .pointer("/function/name")
            .and_then(|value| value.as_str()),
        Some("ambient_probe")
    );
    assert_eq!(
        tools[1]
            .pointer("/function/parameters/additionalProperties")
            .and_then(serde_json::Value::as_bool),
        Some(false)
    );
}

#[test]
fn zai_chat_completions_serializes_native_web_search_tool() {
    let tools = super::create_tools_json_for_chat_completions(
        &[ToolSpec::WebSearch {
            external_web_access: Some(true),
            index_gated_web_access: None,
            filters: None,
            user_location: None,
            search_context_size: None,
            search_content_types: None,
        }],
        /*strip_strict*/ true,
        /*zai_native_web_search*/ true,
        /*openrouter_server_web_search*/ false,
    )
    .expect("chat tools");

    assert_eq!(tools.len(), 1);
    let tool = &tools[0];
    assert_eq!(
        tool.pointer("/type").and_then(|value| value.as_str()),
        Some("web_search")
    );
    assert_eq!(
        tool.pointer("/web_search/enable")
            .and_then(|value| value.as_str()),
        Some("True")
    );
    assert_eq!(
        tool.pointer("/web_search/search_result")
            .and_then(|value| value.as_str()),
        Some("True")
    );
    let search_prompt = tool
        .pointer("/web_search/search_prompt")
        .and_then(|value| value.as_str())
        .expect("search_prompt");
    assert!(search_prompt.contains("{{search_result}}"));
    assert!(search_prompt.contains("provider-native web_search"));
    assert!(search_prompt.contains("Do not say you cannot browse"));
}

#[test]
fn openrouter_chat_completions_serializes_server_web_search_tool() {
    let tools = super::create_tools_json_for_chat_completions(
        &[ToolSpec::WebSearch {
            external_web_access: Some(true),
            index_gated_web_access: None,
            filters: None,
            user_location: None,
            search_context_size: Some(WebSearchContextSize::High),
            search_content_types: None,
        }],
        /*strip_strict*/ false,
        /*zai_native_web_search*/ false,
        /*openrouter_server_web_search*/ true,
    )
    .expect("chat tools");

    assert_eq!(
        tools,
        vec![json!({
            "type": "openrouter:web_search",
            "parameters": {
                "engine": "auto",
                "max_results": 5,
                "max_total_results": 10,
                "search_context_size": "high",
            },
        })]
    );
}

#[test]
fn chat_completions_omits_agent_messages_from_history() {
    let mut messages = Vec::new();
    let mut skipped_tool_call_ids = std::collections::HashSet::new();
    super::append_chat_messages_for_response_item(
        ResponseItem::AgentMessage {
            id: None,
            author: "assistant".to_string(),
            recipient: "user".to_string(),
            content: vec![AgentMessageInputContent::InputText {
                text: concat!(
                    "assistant:\n",
                    "{\"type\":\"function_call\",\"name\":\"exec_command\",",
                    "\"arguments\":\"{\\\"cmd\\\": \\\"ls\\\"}\",",
                    "\"call_id\":\"chatcmpl-tool-123\"}\n\n",
                    "tool:\n",
                    "{\"type\":\"function_call_output\",",
                    "\"call_id\":\"chatcmpl-tool-123\",\"output\":\"ok\"}"
                )
                .to_string(),
            }],
            metadata: None,
        },
        &mut messages,
        &mut skipped_tool_call_ids,
    );

    assert!(
        messages.is_empty(),
        "AgentMessage is display/transcript state and must not be replayed to Chat Completions"
    );

    super::append_chat_messages_for_response_item(
        ResponseItem::Message {
            id: None,
            role: "assistant".to_string(),
            content: vec![ContentItem::OutputText {
                text: "real assistant text".to_string(),
            }],
            phase: None,
            metadata: None,
        },
        &mut messages,
        &mut skipped_tool_call_ids,
    );

    assert_eq!(messages.len(), 1);
    assert_eq!(messages[0].role, "assistant");
    assert_eq!(messages[0].content.as_deref(), Some("real assistant text"));
}

#[test]
fn chat_completions_skips_malformed_historical_tool_calls() {
    let mut messages = Vec::new();
    let mut skipped_tool_call_ids = std::collections::HashSet::new();
    let malformed_call_id = "chatcmpl-tool-bad-plan".to_string();

    super::append_chat_messages_for_response_item(
        ResponseItem::FunctionCall {
            id: None,
            name: "update_plan".to_string(),
            arguments: concat!(
                "{\"explanation\":\"bad historical call\",",
                "\"plan\":[step\":\"Explore repo\",",
                "\"status\":\"in_progress\"}]}"
            )
            .to_string(),
            call_id: malformed_call_id.clone(),
            namespace: None,
            metadata: None,
        },
        &mut messages,
        &mut skipped_tool_call_ids,
    );

    super::append_chat_messages_for_response_item(
        ResponseItem::FunctionCallOutput {
            id: None,
            call_id: malformed_call_id,
            output: FunctionCallOutputPayload::from_text(
                "failed to parse function arguments".to_string(),
            ),
            metadata: None,
        },
        &mut messages,
        &mut skipped_tool_call_ids,
    );

    assert!(
        messages.is_empty(),
        "malformed historical tool calls and their outputs must not poison resumed Chat requests"
    );

    super::append_chat_messages_for_response_item(
        ResponseItem::FunctionCall {
            id: None,
            name: "exec_command".to_string(),
            arguments: "{\"cmd\":\"pwd\"}".to_string(),
            call_id: "chatcmpl-tool-good".to_string(),
            namespace: None,
            metadata: None,
        },
        &mut messages,
        &mut skipped_tool_call_ids,
    );

    assert_eq!(messages.len(), 1);
    assert_eq!(messages[0].role, "assistant");
    assert_eq!(messages[0].tool_calls.len(), 1);
    assert_eq!(
        messages[0].tool_calls[0].function.arguments,
        "{\"cmd\":\"pwd\"}"
    );
}

#[test]
fn ambient_responses_request_uses_zai_reasoning_fields() {
    let provider_info = ModelProviderInfo::create_ambient_provider();
    let api_provider = provider_info
        .to_api_provider(Some(AuthMode::ApiKey))
        .expect("Ambient API provider");
    let client = ModelClient::new(
        /*auth_manager*/ None,
        ThreadId::new(),
        provider_info,
        SessionSource::Cli,
        /*model_verbosity*/ None,
        /*enable_request_compression*/ false,
        /*include_timing_metrics*/ false,
        /*beta_features_header*/ None,
        /*item_ids_enabled*/ false,
        /*attestation_provider*/ None,
    );
    let prompt = super::Prompt {
        input: vec![ResponseItem::Message {
            id: None,
            role: "user".to_string(),
            content: vec![ContentItem::InputText {
                text: "hello".to_string(),
            }],
            phase: None,
            metadata: None,
        }],
        ..Default::default()
    };
    let model_info = test_ambient_model_info();
    let responses_metadata = test_responses_metadata_for_client(
        &client,
        Some("turn-1"),
        "window-1".to_string(),
        None,
        TestCodexResponsesRequestKind::Turn,
    );

    let standard = client
        .build_responses_request(
            &api_provider,
            &prompt,
            &model_info,
            Some(ReasoningEffortConfig::Medium),
            ReasoningSummaryConfig::None,
            None,
            &responses_metadata,
        )
        .expect("standard Ambient request");
    assert_eq!(standard.reasoning, None);
    assert_eq!(standard.thinking_budget, None);
    assert_eq!(standard.enable_thinking, Some(true));
    assert_eq!(standard.reasoning_effort.as_deref(), Some("high"));

    let deep = client
        .build_responses_request(
            &api_provider,
            &prompt,
            &model_info,
            Some(ReasoningEffortConfig::XHigh),
            ReasoningSummaryConfig::None,
            None,
            &responses_metadata,
        )
        .expect("deep Ambient request");
    assert_eq!(deep.reasoning, None);
    assert_eq!(deep.thinking_budget, None);
    assert_eq!(deep.enable_thinking, Some(true));
    assert_eq!(deep.reasoning_effort.as_deref(), Some("max"));
}

#[test]
fn ambient_chat_completions_request_uses_zai_reasoning_fields() {
    let provider_info = ModelProviderInfo::create_ambient_provider();
    let client = ModelClient::new(
        /*auth_manager*/ None,
        ThreadId::new(),
        provider_info,
        SessionSource::Cli,
        /*model_verbosity*/ None,
        /*enable_request_compression*/ false,
        /*include_timing_metrics*/ false,
        /*beta_features_header*/ None,
        /*item_ids_enabled*/ false,
        /*attestation_provider*/ None,
    );
    let prompt = super::Prompt {
        input: vec![ResponseItem::Message {
            id: None,
            role: "user".to_string(),
            content: vec![ContentItem::InputText {
                text: "hello".to_string(),
            }],
            phase: None,
            metadata: None,
        }],
        ..Default::default()
    };
    let model_info = test_ambient_model_info();

    let standard = client
        .build_chat_completions_request(&prompt, &model_info, Some(ReasoningEffortConfig::Medium))
        .expect("standard Ambient chat request");
    assert_eq!(standard.enable_thinking, Some(true));
    assert_eq!(standard.emit_usage, Some(true));
    assert_eq!(standard.reasoning_effort.as_deref(), Some("high"));

    let deep = client
        .build_chat_completions_request(&prompt, &model_info, Some(ReasoningEffortConfig::XHigh))
        .expect("deep Ambient chat request");
    assert_eq!(deep.enable_thinking, Some(true));
    assert_eq!(deep.emit_usage, Some(true));
    assert_eq!(deep.reasoning_effort.as_deref(), Some("max"));
}

#[test]
fn openrouter_chat_completions_request_uses_reasoning_object() {
    let provider_info = ModelProviderInfo::create_openrouter_provider();
    let client = ModelClient::new(
        /*auth_manager*/ None,
        ThreadId::new(),
        provider_info,
        SessionSource::Cli,
        /*model_verbosity*/ None,
        /*enable_request_compression*/ false,
        /*include_timing_metrics*/ false,
        /*beta_features_header*/ None,
        /*item_ids_enabled*/ false,
        /*attestation_provider*/ None,
    );
    let prompt = super::Prompt {
        input: vec![ResponseItem::Message {
            id: None,
            role: "user".to_string(),
            content: vec![ContentItem::InputText {
                text: "hello".to_string(),
            }],
            phase: None,
            metadata: None,
        }],
        ..Default::default()
    };
    let model_info = test_openrouter_gemini_model_info();

    let default_request = client
        .build_chat_completions_request(&prompt, &model_info, None)
        .expect("default OpenRouter chat request");
    assert_eq!(default_request.enable_thinking, None);
    assert_eq!(default_request.emit_usage, None);
    assert_eq!(default_request.reasoning_effort, None);
    assert_eq!(default_request.reasoning, None);

    let minimal_request = client
        .build_chat_completions_request(&prompt, &model_info, Some(ReasoningEffortConfig::Minimal))
        .expect("minimal OpenRouter chat request");
    assert_eq!(
        minimal_request
            .reasoning
            .as_ref()
            .and_then(|reasoning| reasoning.get("effort"))
            .and_then(|effort| effort.as_str()),
        Some("minimal")
    );

    let high_request = client
        .build_chat_completions_request(&prompt, &model_info, Some(ReasoningEffortConfig::High))
        .expect("high OpenRouter chat request");
    assert_eq!(
        high_request
            .reasoning
            .as_ref()
            .and_then(|reasoning| reasoning.get("effort"))
            .and_then(|effort| effort.as_str()),
        Some("high")
    );
}

#[test]
fn openrouter_chat_completions_request_preserves_function_tools_with_web_search() {
    let provider_info = ModelProviderInfo::create_openrouter_provider();
    let client = ModelClient::new(
        /*auth_manager*/ None,
        ThreadId::new(),
        provider_info,
        SessionSource::Cli,
        /*model_verbosity*/ None,
        /*enable_request_compression*/ false,
        /*include_timing_metrics*/ false,
        /*beta_features_header*/ None,
        /*item_ids_enabled*/ false,
        /*attestation_provider*/ None,
    );
    let prompt = super::Prompt {
        input: vec![ResponseItem::Message {
            id: None,
            role: "user".to_string(),
            content: vec![ContentItem::InputText {
                text: "Find current Rust release notes and edit the summary.".to_string(),
            }],
            phase: None,
            metadata: None,
        }],
        tools: vec![
            ToolSpec::Function(ResponsesApiTool {
                name: "exec_command".to_string(),
                description: "Run a command.".to_string(),
                strict: true,
                defer_loading: None,
                parameters: JsonSchema::object(
                    BTreeMap::from([(
                        "cmd".to_string(),
                        JsonSchema::string(Some("Command to run.".to_string())),
                    )]),
                    Some(vec!["cmd".to_string()]),
                    Some(false.into()),
                ),
                output_schema: None,
            }),
            ToolSpec::WebSearch {
                external_web_access: Some(true),
                index_gated_web_access: None,
                filters: None,
                user_location: None,
                search_context_size: Some(WebSearchContextSize::Low),
                search_content_types: None,
            },
        ],
        ..Default::default()
    };
    let model_info = test_openrouter_gemini_model_info();

    let request = client
        .build_chat_completions_request(&prompt, &model_info, None)
        .expect("OpenRouter chat request");

    assert_eq!(
        request
            .tools
            .iter()
            .map(|tool| {
                (
                    tool.get("type").and_then(serde_json::Value::as_str),
                    tool.pointer("/function/name")
                        .and_then(serde_json::Value::as_str),
                    tool.pointer("/parameters/search_context_size")
                        .and_then(serde_json::Value::as_str),
                )
            })
            .collect::<Vec<_>>(),
        vec![
            (Some("function"), Some("exec_command"), None),
            (Some("openrouter:web_search"), None, Some("low")),
        ]
    );
    assert_eq!(request.tool_choice.as_deref(), Some("auto"));
}

#[test]
fn baseten_chat_completions_strips_strict_without_zai_reasoning_fields() {
    let provider_info = ModelProviderInfo::create_baseten_provider();
    let client = ModelClient::new(
        /*auth_manager*/ None,
        ThreadId::new(),
        provider_info,
        SessionSource::Cli,
        /*model_verbosity*/ None,
        /*enable_request_compression*/ false,
        /*include_timing_metrics*/ false,
        /*beta_features_header*/ None,
        /*item_ids_enabled*/ false,
        /*attestation_provider*/ None,
    );
    let prompt = super::Prompt {
        input: vec![ResponseItem::Message {
            id: None,
            role: "user".to_string(),
            content: vec![ContentItem::InputText {
                text: "Run pwd.".to_string(),
            }],
            phase: None,
            metadata: None,
        }],
        tools: vec![ToolSpec::Function(ResponsesApiTool {
            name: "exec_command".to_string(),
            description: "Run a command.".to_string(),
            strict: true,
            defer_loading: None,
            parameters: JsonSchema::object(
                BTreeMap::from([(
                    "cmd".to_string(),
                    JsonSchema::string(Some("Command to run.".to_string())),
                )]),
                Some(vec!["cmd".to_string()]),
                Some(false.into()),
            ),
            output_schema: None,
        })],
        ..Default::default()
    };

    let request = client
        .build_chat_completions_request(&prompt, &test_model_info(), None)
        .expect("Baseten chat request");

    assert_eq!(request.enable_thinking, None);
    assert_eq!(request.emit_usage, None);
    assert_eq!(request.reasoning_effort, None);
    assert_eq!(request.reasoning, None);
    assert_eq!(
        request.tools[0]
            .pointer("/function/strict")
            .and_then(serde_json::Value::as_bool),
        None
    );
}

#[test]
fn vercel_responses_request_uses_standard_responses_fields() {
    let provider_info = ModelProviderInfo::create_vercel_provider();
    let api_provider = provider_info
        .to_api_provider(Some(AuthMode::ApiKey))
        .expect("Vercel API provider");
    let client = ModelClient::new(
        /*auth_manager*/ None,
        ThreadId::new(),
        provider_info,
        SessionSource::Cli,
        /*model_verbosity*/ None,
        /*enable_request_compression*/ false,
        /*include_timing_metrics*/ false,
        /*beta_features_header*/ None,
        /*item_ids_enabled*/ false,
        /*attestation_provider*/ None,
    );
    let prompt = super::Prompt {
        input: vec![ResponseItem::Message {
            id: None,
            role: "user".to_string(),
            content: vec![ContentItem::InputText {
                text: "Run pwd.".to_string(),
            }],
            phase: None,
            metadata: None,
        }],
        tools: vec![ToolSpec::Function(ResponsesApiTool {
            name: "exec_command".to_string(),
            description: "Run a command.".to_string(),
            strict: true,
            defer_loading: None,
            parameters: JsonSchema::object(
                BTreeMap::from([(
                    "cmd".to_string(),
                    JsonSchema::string(Some("Command to run.".to_string())),
                )]),
                Some(vec!["cmd".to_string()]),
                Some(false.into()),
            ),
            output_schema: None,
        })],
        ..Default::default()
    };
    let responses_metadata = test_responses_metadata_for_client(
        &client,
        Some("turn-1"),
        "window-1".to_string(),
        None,
        TestCodexResponsesRequestKind::Turn,
    );

    let request = client
        .build_responses_request(
            &api_provider,
            &prompt,
            &test_vercel_model_info(),
            None,
            ReasoningSummaryConfig::None,
            None,
            &responses_metadata,
        )
        .expect("Vercel responses request");

    assert_eq!(request.model, VERCEL_DEFAULT_MODEL);
    let reasoning = request
        .reasoning
        .as_ref()
        .expect("Vercel GLM should use standard Responses reasoning");
    assert_eq!(
        reasoning.effort.as_ref(),
        Some(&ReasoningEffortConfig::Medium)
    );
    assert_eq!(reasoning.summary, None);
    assert_eq!(request.enable_thinking, None);
    assert_eq!(request.emit_usage, None);
    assert_eq!(request.reasoning_effort, None);
    assert!(request.prompt_cache_key.is_some());
    assert!(request.client_metadata.is_some());
    assert_eq!(request.tools.len(), 1);
    assert_eq!(
        request.tools[0]
            .pointer("/name")
            .and_then(serde_json::Value::as_str),
        Some("exec_command")
    );
}

#[test]
fn zai_chat_completions_preserves_function_tools_when_web_search_is_available() {
    let provider_info = ModelProviderInfo::create_zai_provider();
    let client = ModelClient::new(
        /*auth_manager*/ None,
        ThreadId::new(),
        provider_info,
        SessionSource::Cli,
        /*model_verbosity*/ None,
        /*enable_request_compression*/ false,
        /*include_timing_metrics*/ false,
        /*beta_features_header*/ None,
        /*item_ids_enabled*/ false,
        /*attestation_provider*/ None,
    );
    let tools = vec![
        ToolSpec::Function(ResponsesApiTool {
            name: "exec_command".to_string(),
            description: "Run a command.".to_string(),
            strict: true,
            defer_loading: None,
            parameters: JsonSchema::object(
                BTreeMap::from([(
                    "cmd".to_string(),
                    JsonSchema::string(Some("Command to run.".to_string())),
                )]),
                Some(vec!["cmd".to_string()]),
                Some(false.into()),
            ),
            output_schema: None,
        }),
        ToolSpec::WebSearch {
            external_web_access: Some(true),
            index_gated_web_access: None,
            filters: None,
            user_location: None,
            search_context_size: None,
            search_content_types: None,
        },
    ];
    let model_info = test_ambient_model_info();

    let mixed_prompt = super::Prompt {
        input: vec![ResponseItem::Message {
            id: None,
            role: "user".to_string(),
            content: vec![ContentItem::InputText {
                text: "Run pwd.".to_string(),
            }],
            phase: None,
            metadata: None,
        }],
        tools,
        ..Default::default()
    };
    let mixed_request = client
        .build_chat_completions_request(&mixed_prompt, &model_info, None)
        .expect("mixed request");
    assert_eq!(
        mixed_request
            .tools
            .iter()
            .map(|tool| {
                (
                    tool.get("type").and_then(serde_json::Value::as_str),
                    tool.pointer("/function/name")
                        .and_then(serde_json::Value::as_str),
                )
            })
            .collect::<Vec<_>>(),
        vec![(Some("function"), Some("exec_command"))]
    );
    assert_eq!(
        mixed_request
            .messages
            .iter()
            .filter(|message| message.role == "system")
            .count(),
        1,
        "Z.AI mixed-tool request shaping must not inject prompt guidance: {:?}",
        mixed_request.messages
    );

    let search_only_prompt = super::Prompt {
        input: vec![ResponseItem::Message {
            id: None,
            role: "user".to_string(),
            content: vec![ContentItem::InputText {
                text: "Use web search for Z.AI docs".to_string(),
            }],
            phase: None,
            metadata: None,
        }],
        tools: vec![ToolSpec::WebSearch {
            external_web_access: Some(true),
            index_gated_web_access: None,
            filters: None,
            user_location: None,
            search_context_size: None,
            search_content_types: None,
        }],
        ..Default::default()
    };
    let search_only_request = client
        .build_chat_completions_request(&search_only_prompt, &model_info, None)
        .expect("search-only request");
    assert_eq!(
        search_only_request
            .tools
            .iter()
            .map(|tool| tool.get("type").and_then(serde_json::Value::as_str))
            .collect::<Vec<_>>(),
        vec![Some("web_search")]
    );
    assert_eq!(
        search_only_request
            .messages
            .iter()
            .filter(|message| message.role == "system")
            .count(),
        1,
        "Z.AI web search request shaping must not inject prompt guidance: {:?}",
        search_only_request.messages
    );
}

#[derive(Default)]
struct TagCollectorVisitor {
    tags: BTreeMap<String, String>,
}

impl Visit for TagCollectorVisitor {
    fn record_str(&mut self, field: &tracing::field::Field, value: &str) {
        self.tags
            .insert(field.name().to_string(), value.to_string());
    }

    fn record_debug(&mut self, field: &tracing::field::Field, value: &dyn std::fmt::Debug) {
        self.tags
            .insert(field.name().to_string(), format!("{value:?}"));
    }
}

#[derive(Clone)]
struct TagCollectorLayer {
    tags: Arc<Mutex<BTreeMap<String, String>>>,
}

impl<S> Layer<S> for TagCollectorLayer
where
    S: Subscriber + for<'a> LookupSpan<'a>,
{
    fn on_event(&self, event: &Event<'_>, _ctx: LayerContext<'_, S>) {
        if event.metadata().target() != "feedback_tags" {
            return;
        }
        let mut visitor = TagCollectorVisitor::default();
        event.record(&mut visitor);
        self.tags.lock().unwrap().extend(visitor.tags);
    }
}

fn started_inference_attempt(temp: &TempDir) -> anyhow::Result<InferenceTraceAttempt> {
    let writer = Arc::new(TraceWriter::create(
        temp.path(),
        "trace-1".to_string(),
        "rollout-1".to_string(),
        "thread-root".to_string(),
    )?);
    writer.append(RawTraceEventPayload::ThreadStarted {
        thread_id: "thread-root".to_string(),
        agent_path: "/root".to_string(),
        metadata_payload: None,
    })?;
    writer.append(RawTraceEventPayload::CodexTurnStarted {
        codex_turn_id: "turn-1".to_string(),
        thread_id: "thread-root".to_string(),
    })?;

    let inference_trace = InferenceTraceContext::enabled(
        writer,
        "thread-root".to_string(),
        "turn-1".to_string(),
        "gpt-test".to_string(),
        "test-provider".to_string(),
    );
    let attempt = inference_trace.start_attempt();
    attempt.record_started(&json!({
        "model": "gpt-test",
        "input": [{
            "type": "message",
            "role": "user",
            "content": [{"type": "input_text", "text": "hello"}]
        }],
    }));
    Ok(attempt)
}

fn output_message(id: &str, text: &str) -> ResponseItem {
    ResponseItem::Message {
        id: Some(id.to_string()),
        role: "assistant".to_string(),
        content: vec![ContentItem::OutputText {
            text: text.to_string(),
        }],
        phase: None,
        metadata: None,
    }
}

async fn replay_until_cancelled(temp: &TempDir) -> anyhow::Result<RolloutTrace> {
    let mut rollout = replay_bundle(temp.path())?;
    for _ in 0..50 {
        let inference = rollout
            .inference_calls
            .values()
            .next()
            .expect("inference should be reduced");
        if inference.execution.status == ExecutionStatus::Cancelled {
            return Ok(rollout);
        }
        tokio::time::sleep(Duration::from_millis(10)).await;
        rollout = replay_bundle(temp.path())?;
    }
    Ok(rollout)
}

struct NotifyAfterEventStream {
    events: VecDeque<ResponseEvent>,
    yielded: usize,
    notify_after: usize,
    notify: Arc<Notify>,
}

impl futures::Stream for NotifyAfterEventStream {
    type Item = std::result::Result<ResponseEvent, ApiError>;

    fn poll_next(mut self: Pin<&mut Self>, _cx: &mut Context<'_>) -> Poll<Option<Self::Item>> {
        let Some(event) = self.events.pop_front() else {
            return Poll::Pending;
        };
        self.yielded += 1;
        if self.yielded == self.notify_after {
            self.notify.notify_one();
        }
        Poll::Ready(Some(Ok(event)))
    }
}

#[test]
fn build_subagent_headers_sets_other_subagent_label() {
    let client = test_model_client(SessionSource::SubAgent(SubAgentSource::Other(
        "memory_consolidation".to_string(),
    )));
    let headers = client.build_subagent_headers();
    let value = headers
        .get(X_OPENAI_SUBAGENT_HEADER)
        .and_then(|value| value.to_str().ok());
    assert_eq!(value, Some("memory_consolidation"));
}

#[test]
fn build_subagent_headers_sets_internal_memory_consolidation_label() {
    let client = test_model_client(SessionSource::Internal(
        InternalSessionSource::MemoryConsolidation,
    ));
    let headers = client.build_subagent_headers();
    let value = headers
        .get(X_OPENAI_SUBAGENT_HEADER)
        .and_then(|value| value.to_str().ok());
    assert_eq!(value, Some("memory_consolidation"));
}

#[test]
fn build_ws_client_metadata_includes_window_lineage_and_turn_metadata() {
    let parent_thread_id = ThreadId::new();
    let client = test_model_client(SessionSource::SubAgent(SubAgentSource::ThreadSpawn {
        parent_thread_id,
        depth: 2,
        agent_path: None,
        agent_nickname: None,
        agent_role: None,
    }));

    let thread_id = client.state.thread_id.to_string();
    let expected_window_id = format!("{thread_id}:1");
    let responses_metadata = test_responses_metadata_for_client(
        &client,
        Some("turn-123"),
        expected_window_id.clone(),
        Some(parent_thread_id),
        TestCodexResponsesRequestKind::Turn,
    );
    let client_metadata =
        client.build_ws_client_metadata(&responses_metadata, /*use_responses_lite*/ false);
    let parent_thread_id = parent_thread_id.to_string();
    let turn_metadata: serde_json::Value = serde_json::from_str(
        client_metadata
            .get(X_CODEX_TURN_METADATA_HEADER)
            .expect("turn metadata"),
    )
    .expect("valid turn metadata");
    for (client_key, metadata_key, expected) in [
        (
            X_CODEX_INSTALLATION_ID_HEADER,
            "installation_id",
            "11111111-1111-4111-8111-111111111111",
        ),
        ("session_id", "session_id", thread_id.as_str()),
        ("thread_id", "thread_id", thread_id.as_str()),
        ("turn_id", "turn_id", "turn-123"),
        (
            X_CODEX_WINDOW_ID_HEADER,
            "window_id",
            expected_window_id.as_str(),
        ),
        (
            X_CODEX_PARENT_THREAD_ID_HEADER,
            "parent_thread_id",
            parent_thread_id.as_str(),
        ),
    ] {
        assert_eq!(
            client_metadata.get(client_key).map(String::as_str),
            Some(expected)
        );
        assert_eq!(turn_metadata[metadata_key].as_str(), Some(expected));
    }
    assert_eq!(
        client_metadata
            .get(X_OPENAI_SUBAGENT_HEADER)
            .map(String::as_str),
        Some("collab_spawn")
    );
}

#[tokio::test]
async fn summarize_memories_returns_empty_for_empty_input() {
    let client = test_model_client(SessionSource::Cli);
    let model_info = test_model_info();
    let session_telemetry = test_session_telemetry();

    let output = client
        .summarize_memories(
            Vec::new(),
            &model_info,
            /*effort*/ None,
            &session_telemetry,
        )
        .await
        .expect("empty summarize request should succeed");
    assert_eq!(output.len(), 0);
}

#[tokio::test]
async fn dropped_response_stream_traces_cancelled_partial_output() -> anyhow::Result<()> {
    let temp = TempDir::new()?;
    let attempt = started_inference_attempt(&temp)?;

    // The provider has produced one complete output item, but no terminal
    // response.completed event. The harness has enough information to keep this
    // item in history, so the trace should preserve it when the stream is
    // abandoned.
    let item = output_message("msg-1", "partial answer");
    let api_stream = futures::stream::iter([Ok(ResponseEvent::OutputItemDone(item))])
        .chain(futures::stream::pending());
    let (mut stream, _) = super::map_response_events(
        /*upstream_request_id*/ None,
        api_stream,
        test_session_telemetry(),
        attempt,
    );

    let observed = stream
        .next()
        .await
        .expect("mapped stream should yield output item")?;
    assert!(matches!(observed, ResponseEvent::OutputItemDone(_)));

    // Dropping the consumer is how turn interruption/preemption stops polling
    // the provider stream. The mapper task observes that drop asynchronously
    // and records cancellation using the output items it has already seen.
    drop(stream);

    // Cancellation is recorded by the mapper task after Drop wakes it, so the
    // replay may need a short wait before the terminal event appears on disk.
    let rollout = replay_until_cancelled(&temp).await?;
    let inference = rollout
        .inference_calls
        .values()
        .next()
        .expect("inference should be reduced");

    assert_eq!(inference.execution.status, ExecutionStatus::Cancelled);
    assert_eq!(inference.response_item_ids.len(), 1);
    assert_eq!(rollout.raw_payloads.len(), 2);

    Ok(())
}

#[tokio::test]
async fn response_stream_records_last_model_feedback_ids() {
    let tags = Arc::new(Mutex::new(BTreeMap::new()));
    let _guard = tracing_subscriber::registry()
        .with(TagCollectorLayer { tags: tags.clone() })
        .set_default();

    let api_stream = futures::stream::iter([
        Ok(ResponseEvent::Created),
        Ok(ResponseEvent::Completed {
            response_id: "resp-123".to_string(),
            token_usage: None,
            end_turn: Some(true),
        }),
    ]);
    let (mut stream, _) = super::map_response_events(
        Some("req-123".to_string()),
        api_stream,
        test_session_telemetry(),
        InferenceTraceAttempt::disabled(),
    );

    while stream.next().await.is_some() {}

    let tags = tags.lock().unwrap().clone();
    assert_eq!(
        tags.get("last_model_request_id").map(String::as_str),
        Some("\"req-123\"")
    );
    assert_eq!(
        tags.get("last_model_response_id").map(String::as_str),
        Some("\"resp-123\"")
    );
}

#[tokio::test]
async fn dropped_backpressured_response_stream_traces_cancelled_partial_output()
-> anyhow::Result<()> {
    let temp = TempDir::new()?;
    let attempt = started_inference_attempt(&temp)?;
    let backpressured_item_yielded = Arc::new(Notify::new());
    let mut events = VecDeque::new();
    for _ in 0..super::RESPONSE_STREAM_CHANNEL_CAPACITY {
        events.push_back(ResponseEvent::Created);
    }
    events.push_back(ResponseEvent::OutputItemDone(output_message(
        "msg-1",
        "partial answer",
    )));
    let api_stream = NotifyAfterEventStream {
        events,
        yielded: 0,
        notify_after: super::RESPONSE_STREAM_CHANNEL_CAPACITY + 1,
        notify: Arc::clone(&backpressured_item_yielded),
    };

    let (stream, _) = super::map_response_events(
        /*upstream_request_id*/ None,
        api_stream,
        test_session_telemetry(),
        attempt,
    );

    // Fill the mapper channel with non-terminal events, then yield one output
    // item. The mapper has observed that item and is blocked trying to send it
    // downstream, so dropping the consumer covers the send-failure path rather
    // than the `consumer_dropped` select branch.
    backpressured_item_yielded.notified().await;
    drop(stream);

    let rollout = replay_until_cancelled(&temp).await?;
    let inference = rollout
        .inference_calls
        .values()
        .next()
        .expect("inference should be reduced");

    assert_eq!(inference.execution.status, ExecutionStatus::Cancelled);
    assert_eq!(inference.response_item_ids.len(), 1);
    assert_eq!(rollout.raw_payloads.len(), 2);

    Ok(())
}

#[test]
fn auth_request_telemetry_context_tracks_attached_auth_and_retry_phase() {
    let auth_context = AuthRequestTelemetryContext::new(
        Some(AuthMode::Chatgpt),
        &BearerAuthProvider::for_test(Some("access-token"), Some("workspace-123")),
        PendingUnauthorizedRetry::from_recovery(UnauthorizedRecoveryExecution {
            mode: "managed",
            phase: "refresh_token",
        }),
    );

    assert_eq!(auth_context.auth_mode, Some("Chatgpt"));
    assert!(auth_context.auth_header_attached);
    assert_eq!(auth_context.auth_header_name, Some("authorization"));
    assert!(auth_context.retry_after_unauthorized);
    assert_eq!(auth_context.recovery_mode, Some("managed"));
    assert_eq!(auth_context.recovery_phase, Some("refresh_token"));
}

fn model_client_with_counting_attestation(
    include_attestation: bool,
) -> (ModelClient, Arc<AtomicUsize>) {
    #[derive(Debug)]
    struct CountingAttestationProvider {
        calls: Arc<AtomicUsize>,
    }

    impl AttestationProvider for CountingAttestationProvider {
        fn header_for_request(
            &self,
            _context: AttestationContext,
        ) -> GenerateAttestationFuture<'_> {
            let calls = self.calls.clone();
            Box::pin(async move {
                let call = calls.fetch_add(1, Ordering::Relaxed) + 1;
                Some(http::HeaderValue::from_bytes(format!("v1.header-{call}").as_bytes()).unwrap())
            })
        }
    }

    let attestation_calls = Arc::new(AtomicUsize::new(0));
    let (auth_manager, provider) = if include_attestation {
        (
            Some(AuthManager::from_auth_for_testing(
                CodexAuth::create_dummy_chatgpt_auth_for_testing(),
            )),
            ModelProviderInfo::create_openai_provider(Some(CHATGPT_CODEX_BASE_URL.to_string())),
        )
    } else {
        (
            None,
            create_oss_provider_with_base_url("https://example.com/v1", WireApi::Responses),
        )
    };
    let model_client = ModelClient::new(
        auth_manager,
        ThreadId::new(),
        provider,
        SessionSource::Exec,
        /*model_verbosity*/ None,
        /*enable_request_compression*/ false,
        /*include_timing_metrics*/ false,
        /*beta_features_header*/ None,
        /*item_ids_enabled*/ false,
        Some(Arc::new(CountingAttestationProvider {
            calls: attestation_calls.clone(),
        })),
    );
    (model_client, attestation_calls)
}

#[tokio::test]
async fn websocket_handshake_includes_attestation_for_chatgpt_codex_responses() {
    let (model_client, attestation_calls) =
        model_client_with_counting_attestation(/*include_attestation*/ true);
    let responses_metadata = test_responses_metadata_for_client(
        &model_client,
        /*turn_id*/ None,
        format!("{}:0", model_client.state.thread_id),
        /*parent_thread_id*/ None,
        TestCodexResponsesRequestKind::WebsocketConnection,
    );

    let headers = model_client
        .build_websocket_headers(&responses_metadata)
        .await;

    assert_eq!(
        headers
            .get(crate::attestation::X_OAI_ATTESTATION_HEADER)
            .and_then(|value| value.to_str().ok()),
        Some("v1.header-1"),
    );
    assert_eq!(attestation_calls.load(Ordering::Relaxed), 1);
}

#[tokio::test]
async fn non_chatgpt_codex_endpoints_omit_attestation_generation() {
    let (model_client, attestation_calls) =
        model_client_with_counting_attestation(/*include_attestation*/ false);
    let mut response_headers = http::HeaderMap::new();

    if let Some(header_value) = model_client.generate_attestation_header_for().await {
        response_headers.insert(crate::attestation::X_OAI_ATTESTATION_HEADER, header_value);
    }
    let mut compaction_headers = http::HeaderMap::new();
    if let Some(header_value) = model_client.generate_attestation_header_for().await {
        compaction_headers.insert(crate::attestation::X_OAI_ATTESTATION_HEADER, header_value);
    }
    let mut realtime_headers = http::HeaderMap::new();
    if let Some(header_value) = model_client.generate_attestation_header_for().await {
        realtime_headers.insert(crate::attestation::X_OAI_ATTESTATION_HEADER, header_value);
    }

    assert_eq!(
        response_headers.get(crate::attestation::X_OAI_ATTESTATION_HEADER),
        None,
    );
    assert_eq!(
        compaction_headers.get(crate::attestation::X_OAI_ATTESTATION_HEADER),
        None,
    );
    assert_eq!(
        realtime_headers.get(crate::attestation::X_OAI_ATTESTATION_HEADER),
        None,
    );
    assert_eq!(attestation_calls.load(Ordering::Relaxed), 0);
}
