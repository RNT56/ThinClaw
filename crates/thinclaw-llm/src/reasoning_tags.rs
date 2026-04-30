//! Response cleaning and thinking-tag stripping for LLM outputs.
//!
//! LLMs may include reasoning/thinking tags (e.g. `<thinking>`, `<|think|>`)
//! in their responses that should be stripped before presenting to users.
//! This module handles:
//! - Regex-based thinking tag detection and removal
//! - Code region awareness (preserves tags inside code blocks)
//! - `<final>` tag extraction
//! - Response cleanup (collapse whitespace, strip artifacts)
//! - Tool call recovery from text content
//! - Success evaluation parsing

use std::sync::LazyLock;

use regex::Regex;
use serde::{Deserialize, Serialize};

use thinclaw_llm_core::{ToolCall, ToolDefinition};

/// Quick-check: bail early if no reasoning/final tags are present at all.
static QUICK_TAG_RE: LazyLock<Regex> = LazyLock::new(|| {
    Regex::new(r"(?i)<\s*/?\s*(?:think(?:ing)?|thought|thoughts|antthinking|reasoning|reflection|scratchpad|inner_monologue|final)\b").expect("QUICK_TAG_RE")
});

/// Matches thinking/reasoning open and close tags. Capture group 1 is "/" for close tags.
/// Whitespace-tolerant, case-insensitive, attribute-aware.
static THINKING_TAG_RE: LazyLock<Regex> = LazyLock::new(|| {
    Regex::new(r"(?i)<\s*(/?)\s*(?:think(?:ing)?|thought|thoughts|antthinking|reasoning|reflection|scratchpad|inner_monologue)\b[^<>]*>").expect("THINKING_TAG_RE")
});

/// Matches `<final>` / `</final>` tags. Capture group 1 is "/" for close tags.
static FINAL_TAG_RE: LazyLock<Regex> =
    LazyLock::new(|| Regex::new(r"(?i)<\s*(/?)\s*final\b[^<>]*>").expect("FINAL_TAG_RE"));

/// Matches pipe-delimited reasoning tags: `<|think|>...<|/think|>` etc.
static PIPE_REASONING_TAG_RE: LazyLock<Regex> = LazyLock::new(|| {
    Regex::new(r"(?i)<\|(/?)\s*(?:think(?:ing)?|thought|thoughts|antthinking|reasoning|reflection|scratchpad|inner_monologue)\|>").expect("PIPE_REASONING_TAG_RE")
});

/// Result of success evaluation.
#[derive(Debug, Clone, Serialize, Deserialize)]
pub struct SuccessEvaluation {
    pub success: bool,
    pub confidence: f64,
    pub reasoning: String,
    #[serde(default)]
    pub issues: Vec<String>,
    #[serde(default)]
    pub suggestions: Vec<String>,
}

/// Extract JSON from text that might contain other content.
pub fn extract_json(text: &str) -> Option<&str> {
    // Find the first { and last } to extract JSON
    let start = text.find('{')?;
    let end = text.rfind('}')?;
    if start < end {
        Some(&text[start..=end])
    } else {
        None
    }
}

/// A byte range in the source text that is inside a code region (fenced or inline).
#[derive(Debug, Clone, Copy)]
struct CodeRegion {
    start: usize,
    end: usize,
}

/// Detect fenced code blocks (``` and ~~~) and inline backtick spans.
/// Returns sorted `Vec<CodeRegion>` of byte ranges. Tags inside these ranges are
/// skipped during stripping so code examples mentioning `<thinking>` are preserved.
fn find_code_regions(text: &str) -> Vec<CodeRegion> {
    let mut regions = Vec::new();

    // Fenced code blocks: line starting with 3+ backticks or tildes
    let mut i = 0;
    let bytes = text.as_bytes();
    while i < bytes.len() {
        // Must be at start of line (i==0 or previous char is \n)
        if i > 0 && bytes[i - 1] != b'\n' {
            if let Some(nl) = text[i..].find('\n') {
                i += nl + 1;
            } else {
                break;
            }
            continue;
        }

        // Skip optional leading whitespace
        let line_start = i;
        while i < bytes.len() && (bytes[i] == b' ' || bytes[i] == b'\t') {
            i += 1;
        }

        let fence_char = if i < bytes.len() && (bytes[i] == b'`' || bytes[i] == b'~') {
            bytes[i]
        } else {
            // Not a fence line, skip to next line
            if let Some(nl) = text[i..].find('\n') {
                i += nl + 1;
            } else {
                break;
            }
            continue;
        };

        // Count fence chars
        let fence_start = i;
        while i < bytes.len() && bytes[i] == fence_char {
            i += 1;
        }
        let fence_len = i - fence_start;
        if fence_len < 3 {
            // Not a real fence
            if let Some(nl) = text[i..].find('\n') {
                i += nl + 1;
            } else {
                break;
            }
            continue;
        }

        // Skip rest of opening fence line (info string)
        if let Some(nl) = text[i..].find('\n') {
            i += nl + 1;
        } else {
            // Fence at EOF with no content — region extends to end
            regions.push(CodeRegion {
                start: line_start,
                end: bytes.len(),
            });
            break;
        }

        // Find closing fence: line starting with >= fence_len of same char
        let content_start = i;
        let mut found_close = false;
        while i < bytes.len() {
            let cl_start = i;
            // Skip optional leading whitespace
            while i < bytes.len() && (bytes[i] == b' ' || bytes[i] == b'\t') {
                i += 1;
            }
            if i < bytes.len() && bytes[i] == fence_char {
                let close_fence_start = i;
                while i < bytes.len() && bytes[i] == fence_char {
                    i += 1;
                }
                let close_fence_len = i - close_fence_start;
                // Must be at least as long, and rest of line must be empty/whitespace
                if close_fence_len >= fence_len {
                    // Skip to end of line
                    while i < bytes.len() && bytes[i] != b'\n' {
                        if bytes[i] != b' ' && bytes[i] != b'\t' {
                            break;
                        }
                        i += 1;
                    }
                    if i >= bytes.len() || bytes[i] == b'\n' {
                        if i < bytes.len() {
                            i += 1; // skip the \n
                        }
                        regions.push(CodeRegion {
                            start: line_start,
                            end: i,
                        });
                        found_close = true;
                        break;
                    }
                }
            }
            // Not a closing fence, skip to next line
            if let Some(nl) = text[cl_start..].find('\n') {
                i = cl_start + nl + 1;
            } else {
                i = bytes.len();
                break;
            }
        }
        if !found_close {
            // Unclosed fence extends to EOF
            let _ = content_start; // suppress unused warning
            regions.push(CodeRegion {
                start: line_start,
                end: bytes.len(),
            });
        }
    }

    // Inline backtick spans (not inside fenced blocks)
    let mut j = 0;
    while j < bytes.len() {
        if bytes[j] != b'`' {
            j += 1;
            continue;
        }
        // Inside a fenced block? Skip
        if regions.iter().any(|r| j >= r.start && j < r.end) {
            j += 1;
            continue;
        }
        // Count opening backtick run
        let tick_start = j;
        while j < bytes.len() && bytes[j] == b'`' {
            j += 1;
        }
        let tick_len = j - tick_start;
        // Find matching closing run of exactly tick_len backticks
        let search_from = j;
        let mut found = false;
        let mut k = search_from;
        while k < bytes.len() {
            if bytes[k] != b'`' {
                k += 1;
                continue;
            }
            let close_start = k;
            while k < bytes.len() && bytes[k] == b'`' {
                k += 1;
            }
            if k - close_start == tick_len {
                regions.push(CodeRegion {
                    start: tick_start,
                    end: k,
                });
                j = k;
                found = true;
                break;
            }
        }
        if !found {
            j = tick_start + tick_len; // no match, move past
        }
    }

    regions.sort_by_key(|r| r.start);
    regions
}

/// Check if a byte position falls inside any code region.
fn is_inside_code(pos: usize, regions: &[CodeRegion]) -> bool {
    regions.iter().any(|r| pos >= r.start && pos < r.end)
}

/// Clean up LLM response by stripping model-internal tags and reasoning patterns.
///
/// Some models (GLM-4.7, etc.) emit XML-tagged internal state like
/// Try to extract tool calls from content text where the model emitted them
/// as XML tags instead of using the structured tool_calls field.
///
/// Handles these formats:
/// - `<tool_call>tool_name</tool_call>` (bare name)
/// - `<tool_call>{"name":"x","arguments":{}}</tool_call>` (JSON)
/// - `<|tool_call|>...<|/tool_call|>` (pipe-delimited variant)
/// - `<function_call>...</function_call>` (function_call variant)
///
/// Only returns calls whose name matches an available tool.
pub fn recover_tool_calls_from_content(
    content: &str,
    available_tools: &[ToolDefinition],
) -> Vec<ToolCall> {
    let tool_names: std::collections::HashSet<&str> =
        available_tools.iter().map(|t| t.name.as_str()).collect();
    let mut calls = Vec::new();

    for (open, close) in &[
        ("<tool_call>", "</tool_call>"),
        ("<|tool_call|>", "<|/tool_call|>"),
        ("<function_call>", "</function_call>"),
        ("<|function_call|>", "<|/function_call|>"),
    ] {
        let mut remaining = content;
        while let Some(start) = remaining.find(open) {
            let inner_start = start + open.len();
            let after = &remaining[inner_start..];
            let Some(end) = after.find(close) else {
                break;
            };
            let inner = after[..end].trim();
            remaining = &after[end + close.len()..];

            if inner.is_empty() {
                continue;
            }

            // Try JSON first: {"name":"x","arguments":{}}
            if let Ok(parsed) = serde_json::from_str::<serde_json::Value>(inner)
                && let Some(name) = parsed.get("name").and_then(|v| v.as_str())
                && tool_names.contains(name)
            {
                let arguments = parsed
                    .get("arguments")
                    .cloned()
                    .unwrap_or(serde_json::Value::Object(Default::default()));
                calls.push(ToolCall {
                    id: format!("recovered_{}", calls.len()),
                    name: name.to_string(),
                    arguments,
                });
                continue;
            }

            // Bare tool name (e.g. "<tool_call>tool_list</tool_call>")
            let name = inner.trim();
            if tool_names.contains(name) {
                calls.push(ToolCall {
                    id: format!("recovered_{}", calls.len()),
                    name: name.to_string(),
                    arguments: serde_json::Value::Object(Default::default()),
                });
            }
        }
    }

    calls
}

/// `<tool_call>tool_list</tool_call>` or `<|tool_call|>` in the content field
/// instead of using the standard OpenAI tool_calls array. We strip all of
/// these before the response reaches channels/users.
///
/// Pipeline:
/// 1. Quick-check — bail if no reasoning/final tags
/// 2. Build code regions (fenced blocks + inline backticks)
/// 3. Strip thinking tags (regex, code-aware, strict mode for unclosed)
/// 4. If `<final>` tags present: extract only `<final>` content
///    Else: use the thinking-stripped text as-is
/// 5. Strip pipe-delimited reasoning tags (code-aware)
/// 6. Strip tool tags (string matching — no code-awareness needed)
/// 7. Collapse triple+ newlines, trim
pub fn clean_response(text: &str) -> String {
    // 1. Quick-check
    let mut result = if !QUICK_TAG_RE.is_match(text) {
        text.to_string()
    } else {
        // 2 + 3. Build code regions, strip thinking tags
        let code_regions = find_code_regions(text);
        let after_thinking = strip_thinking_tags_regex(text, &code_regions);

        // 4. If <final> tags present, extract only their content
        if FINAL_TAG_RE.is_match(&after_thinking) {
            let fresh_regions = find_code_regions(&after_thinking);
            extract_final_content(&after_thinking, &fresh_regions).unwrap_or(after_thinking)
        } else {
            after_thinking
        }
    };

    // 5. Strip pipe-delimited reasoning tags (code-aware)
    result = strip_pipe_reasoning_tags(&result);

    // 6. Strip tool tags (string matching, not code-aware)
    for tag in TOOL_TAGS {
        result = strip_xml_tag(&result, tag);
        result = strip_pipe_tag(&result, tag);
    }

    // 7. Collapse triple+ newlines, trim
    collapse_newlines(&result)
}

/// Tool-related tags stripped with simple string matching (no code-awareness needed).
const TOOL_TAGS: &[&str] = &["tool_call", "function_call", "tool_calls"];

/// Strip thinking/reasoning tags using regex, respecting code regions.
///
/// Strict mode: an unclosed opening tag discards all trailing text after it.
fn strip_thinking_tags_regex(text: &str, code_regions: &[CodeRegion]) -> String {
    let mut result = String::with_capacity(text.len());
    let mut last_index = 0;
    let mut in_thinking = false;

    for m in THINKING_TAG_RE.find_iter(text) {
        let idx = m.start();

        if is_inside_code(idx, code_regions) {
            continue;
        }

        // Check if this is a close tag by looking at capture group
        let caps = THINKING_TAG_RE.captures(&text[idx..]);
        let is_close = caps
            .and_then(|c| c.get(1))
            .is_some_and(|g| g.as_str() == "/");

        if !in_thinking {
            // Append text before this tag
            result.push_str(&text[last_index..idx]);
            if !is_close {
                in_thinking = true;
            }
        } else if is_close {
            in_thinking = false;
        }

        last_index = m.end();
    }

    // Strict mode: if still inside an unclosed thinking tag, discard trailing text
    if !in_thinking {
        result.push_str(&text[last_index..]);
    }

    result
}

/// Extract content inside `<final>` tags. Returns `None` if no non-code `<final>` tags found.
///
/// When `<final>` tags are present, ONLY content inside them reaches the user.
/// This discards any untagged reasoning that leaked outside `<think>` tags.
fn extract_final_content(text: &str, code_regions: &[CodeRegion]) -> Option<String> {
    let mut parts: Vec<&str> = Vec::new();
    let mut in_final = false;
    let mut last_index = 0;
    let mut found_any = false;

    for m in FINAL_TAG_RE.find_iter(text) {
        let idx = m.start();

        if is_inside_code(idx, code_regions) {
            continue;
        }

        let caps = FINAL_TAG_RE.captures(&text[idx..]);
        let is_close = caps
            .and_then(|c| c.get(1))
            .is_some_and(|g| g.as_str() == "/");

        if !in_final && !is_close {
            // Opening <final>
            in_final = true;
            found_any = true;
            last_index = m.end();
        } else if in_final && is_close {
            // Closing </final>
            parts.push(&text[last_index..idx]);
            in_final = false;
            last_index = m.end();
        }
    }

    if !found_any {
        return None;
    }

    // Unclosed <final> — include trailing content
    if in_final {
        parts.push(&text[last_index..]);
    }

    Some(parts.join(""))
}

/// Strip pipe-delimited reasoning tags, respecting code regions.
fn strip_pipe_reasoning_tags(text: &str) -> String {
    if !PIPE_REASONING_TAG_RE.is_match(text) {
        return text.to_string();
    }

    let code_regions = find_code_regions(text);
    let mut result = String::with_capacity(text.len());
    let mut last_index = 0;
    let mut in_tag = false;

    for m in PIPE_REASONING_TAG_RE.find_iter(text) {
        let idx = m.start();

        if is_inside_code(idx, &code_regions) {
            continue;
        }

        let caps = PIPE_REASONING_TAG_RE.captures(&text[idx..]);
        let is_close = caps
            .and_then(|c| c.get(1))
            .is_some_and(|g| g.as_str() == "/");

        if !in_tag {
            result.push_str(&text[last_index..idx]);
            if !is_close {
                in_tag = true;
            }
        } else if is_close {
            in_tag = false;
        }

        last_index = m.end();
    }

    if !in_tag {
        result.push_str(&text[last_index..]);
    }

    result
}

/// Strip `<tag>...</tag>` and `<tag ...>...</tag>` blocks from text.
/// Used for tool tags only (no code-awareness needed).
fn strip_xml_tag(text: &str, tag: &str) -> String {
    let open_exact = format!("<{}>", tag);
    let open_prefix = format!("<{} ", tag); // for <tag attr="...">
    let close = format!("</{}>", tag);

    let mut result = String::with_capacity(text.len());
    let mut remaining = text;

    loop {
        // Find the next opening tag (exact or with attributes)
        let exact_pos = remaining.find(&open_exact);
        let prefix_pos = remaining.find(&open_prefix);
        let start = match (exact_pos, prefix_pos) {
            (Some(a), Some(b)) => a.min(b),
            (Some(a), None) => a,
            (None, Some(b)) => b,
            (None, None) => break,
        };

        // Add everything before the tag
        result.push_str(&remaining[..start]);

        // Find the end of the opening tag (the closing >)
        let after_open = &remaining[start..];
        let open_end = match after_open.find('>') {
            Some(pos) => start + pos + 1,
            None => break, // malformed, stop
        };

        // Find the closing tag
        if let Some(close_offset) = remaining[open_end..].find(&close) {
            let end = open_end + close_offset + close.len();
            remaining = &remaining[end..];
        } else {
            // No closing tag, discard from here (malformed)
            remaining = "";
            break;
        }
    }

    result.push_str(remaining);
    result
}

/// Strip `<|tag|>...<|/tag|>` pipe-delimited blocks from text.
/// Used for tool tags only (no code-awareness needed).
fn strip_pipe_tag(text: &str, tag: &str) -> String {
    let open = format!("<|{}|>", tag);
    let close = format!("<|/{}|>", tag);

    let mut result = String::with_capacity(text.len());
    let mut remaining = text;

    while let Some(start) = remaining.find(&open) {
        result.push_str(&remaining[..start]);

        if let Some(close_offset) = remaining[start..].find(&close) {
            let end = start + close_offset + close.len();
            remaining = &remaining[end..];
        } else {
            remaining = "";
            break;
        }
    }

    result.push_str(remaining);
    result
}

/// Collapse triple+ newlines to double, then trim.
fn collapse_newlines(text: &str) -> String {
    let mut result = text.to_string();
    while result.contains("\n\n\n") {
        result = result.replace("\n\n\n", "\n\n");
    }
    result.trim().to_string()
}
