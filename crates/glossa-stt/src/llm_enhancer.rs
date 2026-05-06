use async_trait::async_trait;
use reqwest::StatusCode;
use tracing::{debug, info};

use glossa_app::{ports::TextEnhancer, AppError};

use crate::dto::{ChatCompletionRequest, ChatCompletionResponse, ChatMessage};

/// OpenAI-compatible chat-completions text enhancer.
#[derive(Debug, Clone)]
pub struct HttpTextEnhancer {
    endpoint: String,
    model: String,
    api_key: String,
    client: reqwest::Client,
}

impl HttpTextEnhancer {
    /// Creates a new HTTP text enhancer.
    #[must_use]
    pub fn new(base_url: String, model: String, api_key: String) -> Self {
        let endpoint = format!("{}/chat/completions", base_url.trim_end_matches('/'));
        Self {
            endpoint,
            model,
            api_key,
            client: reqwest::Client::new(),
        }
    }
}

#[async_trait]
impl TextEnhancer for HttpTextEnhancer {
    fn name(&self) -> &'static str {
        "llm"
    }

    async fn enhance(&self, text: &str) -> Result<String, AppError> {
        debug!(endpoint = %self.endpoint, model = %self.model, "sending text for LLM enhancement");

        let request_body = ChatCompletionRequest {
            model: self.model.clone(),
            messages: build_messages(text),
        };

        let mut request = self.client.post(&self.endpoint).json(&request_body);
        if !self.api_key.is_empty() {
            request = request.bearer_auth(&self.api_key);
        }

        let response = request.send().await.map_err(|error| {
            AppError::message(format!("LLM enhancement request failed: {error}"))
        })?;

        let status = response.status();
        if status != StatusCode::OK {
            return Err(AppError::message(llm_status_error_message(status)));
        }

        let parsed: ChatCompletionResponse = response.json().await.map_err(|error| {
            AppError::message(format!(
                "failed to decode LLM enhancement response: {error}"
            ))
        })?;

        let enhanced = parsed
            .choices
            .first()
            .map(|choice| choice.message.content.trim().to_owned())
            .unwrap_or_default();

        if enhanced.is_empty() {
            return Err(AppError::message("LLM enhancement returned empty text"));
        }

        info!("text enhancement completed");
        Ok(enhanced)
    }
}

fn build_messages(text: &str) -> Vec<ChatMessage> {
    vec![
        ChatMessage {
            role: "system".into(),
            content: SYSTEM_PROMPT.into(),
        },
        ChatMessage {
            role: "user".into(),
            content: "hello world how are you doing today".into(),
        },
        ChatMessage {
            role: "assistant".into(),
            content: "Hello world, how are you doing today?".into(),
        },
        ChatMessage {
            role: "user".into(),
            content: "the quick brown fox jumps over the lazy dog".into(),
        },
        ChatMessage {
            role: "assistant".into(),
            content: "The quick brown fox jumps over the lazy dog.".into(),
        },
        ChatMessage {
            role: "user".into(),
            content: text.into(),
        },
    ]
}

const SYSTEM_PROMPT: &str = r"You are a transcription post-processor. Your ONLY task is to clean and correct the raw speech-to-text output provided by the user.

Rules:
1. Return ONLY the corrected text. No commentary, no explanations, no markdown formatting, no quotes around the entire output.
2. Preserve the original language and intended meaning. Do not translate.
3. Add punctuation and capitalization where appropriate.
4. Correct obvious speech recognition mistakes ONLY when context strongly supports the correction.
5. Remove filler sounds and filler words that do not affect meaning, such as “um”, “uh”, “erm”, “you know”, “like”, when they are used only as hesitation.
6. Remove accidental word repetitions and false starts when they do not add meaning.
7. If a repeated word is intentional or meaningful, preserve it.
8. Do NOT summarize, expand, rewrite stylistically, or add information not present in the original.
9. Keep the speaker’s wording as close as possible, except for punctuation, capitalization, obvious transcription errors, fillers, and accidental repetitions.
10. Do NOT respond with anything other than the corrected text.

Examples:

Input:
um I I think we should start with the report and then move to the questions
Output:
I think we should start with the report, and then move to the questions.

Input:
uh so the meeting is tomorrow tomorrow at three
Output:
The meeting is tomorrow at three.

Input:
well like we can kind of send the file today if everyone agrees
Output:
We can send the file today if everyone agrees.

Input:
I wanted to say that that the client called this morning
Output:
I wanted to say that the client called this morning.

Input:
this is very very important
Output:
This is very, very important.

Input:
so I was going to I mean I wanted to ask about the budget
Output:
I wanted to ask about the budget.";

fn llm_status_error_message(status: StatusCode) -> String {
    let code = status.as_u16();
    let (label, description) = match code {
        400 => Some(("Bad Request", "the request was invalid or malformed")),
        401 => Some((
            "Unauthorized",
            "authentication failed or the API key is invalid",
        )),
        403 => Some((
            "Forbidden",
            "the request is not allowed, possibly due to permissions or region restrictions",
        )),
        404 => Some((
            "Not Found",
            "the requested resource, model, or endpoint could not be found",
        )),
        429 => Some(("Too Many Requests", "rate limit or quota exceeded")),
        500 => Some((
            "Internal Server Error",
            "the provider encountered an internal error",
        )),
        502 => Some((
            "Bad Gateway",
            "the provider received an invalid upstream response",
        )),
        503 => Some((
            "Service Unavailable",
            "the provider is temporarily unavailable or overloaded",
        )),
        504 => Some((
            "Gateway Timeout",
            "the provider timed out while waiting for an upstream response",
        )),
        _ => None,
    }
    .unwrap_or_else(|| (status.canonical_reason().unwrap_or("Unknown Status"), ""));

    if description.is_empty() {
        format!("LLM enhancement request failed with status {code} {label}")
    } else {
        format!("LLM enhancement request failed with status {code} {label}: {description}")
    }
}

#[cfg(test)]
mod tests {
    use reqwest::StatusCode;
    use tokio::io::{AsyncReadExt, AsyncWriteExt};
    use tokio::net::TcpListener;

    use glossa_app::ports::TextEnhancer;

    use super::{
        build_messages, llm_status_error_message, ChatCompletionResponse, HttpTextEnhancer,
    };

    struct CapturedRequest {
        method: String,
        path: String,
        headers: Vec<(String, String)>,
        body: String,
    }

    async fn run_test_server(
        status_code: u16,
        status_text: &str,
        response_body: &str,
    ) -> (String, tokio::task::JoinHandle<CapturedRequest>) {
        let listener = TcpListener::bind("127.0.0.1:0").await.expect("bind");
        let port = listener.local_addr().expect("local addr").port();
        let base_url = format!("http://127.0.0.1:{}", port);
        let status_text = status_text.to_string();
        let response_body = response_body.to_string();

        let handle = tokio::spawn(async move {
            let (mut socket, _) = listener.accept().await.expect("accept");

            let mut buf = vec![0u8; 16384];
            let mut total_read = 0usize;

            loop {
                let n = socket.read(&mut buf[total_read..]).await.expect("read");
                if n == 0 {
                    break;
                }
                total_read += n;

                let data = String::from_utf8_lossy(&buf[..total_read]);
                if let Some(header_end) = data.find("\r\n\r\n") {
                    let body_start = header_end + 4;
                    let content_length = data
                        .lines()
                        .find_map(|line| {
                            let lower = line.to_ascii_lowercase();
                            if lower.starts_with("content-length:") {
                                line.split(':').nth(1)?.trim().parse::<usize>().ok()
                            } else {
                                None
                            }
                        })
                        .unwrap_or(0);

                    if total_read >= body_start + content_length {
                        break;
                    }
                }
            }

            let request_str = String::from_utf8_lossy(&buf[..total_read]);
            let mut lines = request_str.lines();
            let request_line = lines.next().expect("request line").to_string();
            let mut parts = request_line.split_whitespace();
            let method = parts.next().expect("method").to_string();
            let path = parts.next().expect("path").to_string();

            let mut headers = Vec::new();
            for line in lines.by_ref() {
                if line.is_empty() {
                    break;
                }
                if let Some((key, value)) = line.split_once(": ") {
                    headers.push((key.to_string(), value.to_string()));
                }
            }
            let body = lines.collect::<Vec<_>>().join("\n");

            let response = format!(
                "HTTP/1.1 {} {}\r\nContent-Length: {}\r\nContent-Type: application/json\r\nConnection: close\r\n\r\n{}",
                status_code,
                status_text,
                response_body.len(),
                response_body
            );
            socket.write_all(response.as_bytes()).await.expect("write");

            CapturedRequest {
                method,
                path,
                headers,
                body,
            }
        });

        (base_url, handle)
    }

    #[test]
    fn enhancer_name_should_be_llm() {
        let enhancer = HttpTextEnhancer::new(
            "http://localhost:11434/v1".into(),
            "llama3".into(),
            String::new(),
        );
        assert_eq!(enhancer.name(), "llm");
    }

    #[test]
    fn build_messages_should_include_system_and_few_shot() {
        let messages = build_messages("test input");
        assert_eq!(messages.len(), 6);
        assert_eq!(messages[0].role, "system");
        assert_eq!(messages[1].role, "user");
        assert_eq!(messages[2].role, "assistant");
        assert_eq!(messages[3].role, "user");
        assert_eq!(messages[4].role, "assistant");
        assert_eq!(messages[5].role, "user");
        assert_eq!(messages[5].content, "test input");
    }

    #[test]
    fn response_parsing_should_extract_content() {
        let json = r#"{"choices":[{"message":{"content":"  Hello, world!  "}}]}"#;
        let parsed: ChatCompletionResponse = serde_json::from_str(json).expect("should parse");
        assert_eq!(parsed.choices.len(), 1);
        assert_eq!(parsed.choices[0].message.content, "  Hello, world!  ");
    }

    #[test]
    fn empty_choices_should_default_to_empty_string() {
        let json = r#"{"choices":[]}"#;
        let parsed: ChatCompletionResponse = serde_json::from_str(json).expect("should parse");
        let content = parsed
            .choices
            .first()
            .map(|c| c.message.content.trim())
            .unwrap_or("");
        assert_eq!(content, "");
    }

    #[test]
    fn known_status_should_render_code_and_description() {
        assert_eq!(
            llm_status_error_message(StatusCode::TOO_MANY_REQUESTS),
            "LLM enhancement request failed with status 429 Too Many Requests: rate limit or quota exceeded"
        );
    }

    #[test]
    fn unknown_status_should_fall_back_to_reason_phrase() {
        assert_eq!(
            llm_status_error_message(StatusCode::IM_A_TEAPOT),
            "LLM enhancement request failed with status 418 I'm a teapot"
        );
    }

    #[test]
    fn documented_statuses_should_use_expected_messages() {
        let cases = [
            (
                400,
                "LLM enhancement request failed with status 400 Bad Request: the request was invalid or malformed",
            ),
            (
                401,
                "LLM enhancement request failed with status 401 Unauthorized: authentication failed or the API key is invalid",
            ),
            (
                403,
                "LLM enhancement request failed with status 403 Forbidden: the request is not allowed, possibly due to permissions or region restrictions",
            ),
            (
                404,
                "LLM enhancement request failed with status 404 Not Found: the requested resource, model, or endpoint could not be found",
            ),
            (
                429,
                "LLM enhancement request failed with status 429 Too Many Requests: rate limit or quota exceeded",
            ),
            (
                500,
                "LLM enhancement request failed with status 500 Internal Server Error: the provider encountered an internal error",
            ),
            (
                502,
                "LLM enhancement request failed with status 502 Bad Gateway: the provider received an invalid upstream response",
            ),
            (
                503,
                "LLM enhancement request failed with status 503 Service Unavailable: the provider is temporarily unavailable or overloaded",
            ),
            (
                504,
                "LLM enhancement request failed with status 504 Gateway Timeout: the provider timed out while waiting for an upstream response",
            ),
        ];

        for (code, expected) in cases {
            let status = StatusCode::from_u16(code).expect("status should be valid");
            assert_eq!(llm_status_error_message(status), expected);
        }
    }

    #[tokio::test]
    async fn enhance_should_post_to_chat_completions_and_extract_content() {
        let response = r#"{"choices":[{"message":{"content":"  Hello, world!  "}}]}"#;
        let (base_url, handle) = run_test_server(200, "OK", response).await;

        let enhancer = HttpTextEnhancer::new(base_url, "test-model".into(), "test-key".into());
        let result = enhancer.enhance("hello world").await;

        assert_eq!(result.expect("should succeed"), "Hello, world!");

        let captured = handle.await.expect("server finished");
        assert_eq!(captured.method, "POST");
        assert_eq!(captured.path, "/chat/completions");

        let parsed: serde_json::Value = serde_json::from_str(&captured.body).expect("valid json");
        assert_eq!(parsed["model"], "test-model");
        let messages = parsed["messages"].as_array().expect("messages array");
        assert_eq!(messages.last().unwrap()["content"], "hello world");
    }

    #[tokio::test]
    async fn enhance_should_return_error_on_non_200_status() {
        let response = r#"{"error":"invalid request"}"#;
        let (base_url, handle) = run_test_server(400, "Bad Request", response).await;

        let enhancer = HttpTextEnhancer::new(base_url, "test-model".into(), "test-key".into());
        let result = enhancer.enhance("hello world").await;

        assert!(result.is_err());
        let err = result.unwrap_err().to_string();
        assert!(err.contains("400"));
        assert!(err.contains("Bad Request"));

        let _ = handle.await;
    }

    #[tokio::test]
    async fn enhance_should_return_error_on_empty_choices() {
        let response = r#"{"choices":[]}"#;
        let (base_url, handle) = run_test_server(200, "OK", response).await;

        let enhancer = HttpTextEnhancer::new(base_url, "test-model".into(), "test-key".into());
        let result = enhancer.enhance("hello world").await;

        assert!(result.is_err());
        let err = result.unwrap_err().to_string();
        assert!(err.contains("empty text"));

        let _ = handle.await;
    }

    #[tokio::test]
    async fn enhance_should_return_error_on_blank_content() {
        let response = r#"{"choices":[{"message":{"content":"   "}}]}"#;
        let (base_url, handle) = run_test_server(200, "OK", response).await;

        let enhancer = HttpTextEnhancer::new(base_url, "test-model".into(), "test-key".into());
        let result = enhancer.enhance("hello world").await;

        assert!(result.is_err());
        let err = result.unwrap_err().to_string();
        assert!(err.contains("empty text"));

        let _ = handle.await;
    }

    #[tokio::test]
    async fn enhance_should_omit_authorization_when_api_key_empty() {
        let response = r#"{"choices":[{"message":{"content":"Hi"}}]}"#;
        let (base_url, handle) = run_test_server(200, "OK", response).await;

        let enhancer = HttpTextEnhancer::new(base_url, "test-model".into(), String::new());
        let result = enhancer.enhance("hi").await;

        assert_eq!(result.expect("should succeed"), "Hi");

        let captured = handle.await.expect("server finished");
        let auth_header = captured
            .headers
            .iter()
            .find(|(k, _)| k.eq_ignore_ascii_case("authorization"));
        assert!(auth_header.is_none());
    }

    #[tokio::test]
    async fn enhance_should_include_bearer_auth_when_api_key_set() {
        let response = r#"{"choices":[{"message":{"content":"Hi"}}]}"#;
        let (base_url, handle) = run_test_server(200, "OK", response).await;

        let enhancer = HttpTextEnhancer::new(base_url, "test-model".into(), "secret-key".into());
        let result = enhancer.enhance("hi").await;

        assert_eq!(result.expect("should succeed"), "Hi");

        let captured = handle.await.expect("server finished");
        let auth_header = captured
            .headers
            .iter()
            .find(|(k, _)| k.eq_ignore_ascii_case("authorization"))
            .map(|(_, v)| v.as_str());
        assert_eq!(auth_header, Some("Bearer secret-key"));
    }
}
