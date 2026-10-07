//! Model-aware normalization of OpenAI `reasoning_effort` values.

use serde::{Deserialize, Serialize};

/// OpenAI Responses API reasoning summary verbosity.
#[derive(Debug, Clone, Copy, PartialEq, Eq, Serialize, Deserialize, Default)]
#[serde(rename_all = "lowercase")]
pub enum ReasoningSummaryLevel {
    #[default]
    Detailed,
    Auto,
    Off,
}

impl ReasoningSummaryLevel {
    /// Parse config/env values (`detailed`, `auto`, `off` / `none`).
    #[must_use]
    pub fn parse_str(s: &str) -> Option<Self> {
        match s.trim().to_ascii_lowercase().as_str() {
            "detailed" => Some(Self::Detailed),
            "auto" => Some(Self::Auto),
            "off" | "none" | "false" => Some(Self::Off),
            _ => None,
        }
    }

    /// Value for Responses `reasoning.summary`, or `None` to omit summaries.
    #[must_use]
    pub fn api_value(self) -> Option<&'static str> {
        match self {
            Self::Detailed => Some("detailed"),
            Self::Auto => Some("auto"),
            Self::Off => None,
        }
    }
}

/// Supported reasoning effort levels (OpenAI Responses / reasoning models).
#[derive(Debug, Clone, Copy, PartialEq, Eq, PartialOrd, Ord)]
pub enum ReasoningEffort {
    None,
    Minimal,
    Low,
    Medium,
    High,
    XHigh,
    Max,
}

impl ReasoningEffort {
    /// Parse a provider effort string (case-insensitive).
    #[must_use]
    pub fn parse(s: &str) -> Option<Self> {
        match s.trim().to_ascii_lowercase().as_str() {
            "none" => Some(Self::None),
            "minimal" => Some(Self::Minimal),
            "low" => Some(Self::Low),
            "medium" => Some(Self::Medium),
            "high" => Some(Self::High),
            "xhigh" => Some(Self::XHigh),
            "max" => Some(Self::Max),
            _ => None,
        }
    }

    #[must_use]
    pub const fn as_api_str(self) -> &'static str {
        match self {
            Self::None => "none",
            Self::Minimal => "minimal",
            Self::Low => "low",
            Self::Medium => "medium",
            Self::High => "high",
            Self::XHigh => "xhigh",
            Self::Max => "max",
        }
    }
}

const GPT5_EFFORTS: [ReasoningEffort; 6] = [
    ReasoningEffort::None,
    ReasoningEffort::Minimal,
    ReasoningEffort::Low,
    ReasoningEffort::Medium,
    ReasoningEffort::High,
    ReasoningEffort::XHigh,
];

const O_SERIES_EFFORTS: [ReasoningEffort; 3] = [
    ReasoningEffort::Low,
    ReasoningEffort::Medium,
    ReasoningEffort::High,
];

const DEEPSEEK_EFFORTS: [ReasoningEffort; 5] = [
    ReasoningEffort::None,
    ReasoningEffort::Low,
    ReasoningEffort::Medium,
    ReasoningEffort::High,
    ReasoningEffort::Max,
];

fn model_lower(model: &str) -> String {
    model.trim().to_ascii_lowercase()
}

fn is_gpt5_family(model: &str) -> bool {
    let m = model_lower(model);
    // gpt-5.* and gpt-6.* (e.g. gpt-6-luna) share chat reasoning_effort levels,
    // including `none` required when function tools use /v1/chat/completions.
    m.starts_with("gpt-5")
        || m.contains("gpt-5.")
        || m.starts_with("gpt-6")
        || m.contains("gpt-6.")
}

fn is_o_series(model: &str) -> bool {
    let m = model_lower(model);
    m.starts_with("o1")
        || m.starts_with("o3")
        || m.starts_with("o4")
        || m.contains("-o1")
        || m.contains("-o3")
        || m.contains("-o4")
}

fn is_deepseek_family(model: &str) -> bool {
    model_lower(model).contains("deepseek")
}

/// Whether Chat Completions may send `temperature` / `top_p` / penalties.
///
/// GPT-5 and o-series models reject non-default sampling params.
#[must_use]
pub fn supports_chat_sampling_params(model: &str) -> bool {
    !is_gpt5_family(model) && !is_o_series(model)
}

fn supported_efforts(model: &str) -> &'static [ReasoningEffort] {
    if is_gpt5_family(model) {
        &GPT5_EFFORTS
    } else if is_o_series(model) {
        &O_SERIES_EFFORTS
    } else if is_deepseek_family(model) {
        &DEEPSEEK_EFFORTS
    } else {
        &[]
    }
}

/// Normalize a parsed effort for the given model, downgrading to the nearest
/// lower supported value when the model does not accept the requested level.
#[must_use]
pub fn normalize_reasoning_effort(model: &str, effort: ReasoningEffort) -> Option<String> {
    let supported = supported_efforts(model);
    if supported.is_empty() {
        return None;
    }
    if supported.contains(&effort) {
        return Some(effort.as_api_str().to_string());
    }
    // Downgrade to the highest supported effort not exceeding the request.
    let chosen = supported
        .iter()
        .rev()
        .find(|&&e| e <= effort)
        .copied()
        .unwrap_or(supported[0]);
    Some(chosen.as_api_str().to_string())
}

/// Parse and normalize a string effort for the given model.
#[must_use]
pub fn normalize_reasoning_effort_str(model: &str, effort: &str) -> Option<String> {
    ReasoningEffort::parse(effort).and_then(|e| normalize_reasoning_effort(model, e))
}

pub fn clamp_reasoning_effort(effort: ReasoningEffort, max: ReasoningEffort) -> ReasoningEffort {
    if effort <= max { effort } else { max }
}

/// Clamp a string effort to a maximum allowed level.
#[must_use]
pub fn clamp_reasoning_effort_str(effort: &str, max: &str) -> Option<String> {
    let effort = ReasoningEffort::parse(effort)?;
    let max = ReasoningEffort::parse(max)?;
    Some(clamp_reasoning_effort(effort, max).as_api_str().to_string())
}

/// Map OpenAI-style `reasoning_effort` to Anthropic extended-thinking `budget_tokens`.
///
/// Returns `None` when thinking should be omitted (`none`, empty, or unrecognized).
#[must_use]
pub fn anthropic_thinking_budget_tokens(effort: &str, max_tokens: u32) -> Option<u32> {
    let parsed = ReasoningEffort::parse(effort)?;
    if parsed == ReasoningEffort::None {
        return None;
    }
    let budget = match parsed {
        ReasoningEffort::None => return None,
        ReasoningEffort::Minimal => 1024,
        ReasoningEffort::Low => 2048,
        ReasoningEffort::Medium => 8192,
        ReasoningEffort::High => 16_384,
        ReasoningEffort::XHigh => 32_000,
        ReasoningEffort::Max => 32_000,
    };
    Some(budget.min(max_tokens.saturating_sub(1).max(1024)))
}

#[cfg(test)]
mod tests {
    use super::*;

    #[test]
    fn gpt5_accepts_full_range() {
        for effort in GPT5_EFFORTS {
            assert_eq!(
                normalize_reasoning_effort("gpt-5.4", effort).as_deref(),
                Some(effort.as_api_str())
            );
        }
    }

    #[test]
    fn gpt6_luna_keeps_none_for_tools() {
        assert_eq!(
            normalize_reasoning_effort_str("gpt-6-luna", "none").as_deref(),
            Some("none")
        );
        assert!(!supports_chat_sampling_params("gpt-6-luna"));
    }

    #[test]
    fn o_series_downgrades_none_to_low() {
        assert_eq!(
            normalize_reasoning_effort("o4-mini", ReasoningEffort::None).as_deref(),
            Some("low")
        );
    }

    #[test]
    fn o_series_downgrades_xhigh_to_high() {
        assert_eq!(
            normalize_reasoning_effort("o3-mini", ReasoningEffort::XHigh).as_deref(),
            Some("high")
        );
    }

    #[test]
    fn non_reasoning_model_returns_none() {
        assert!(normalize_reasoning_effort("gpt-4o", ReasoningEffort::High).is_none());
    }

    #[test]
    fn deepseek_accepts_max_effort() {
        assert_eq!(
            normalize_reasoning_effort("deepseek-v4-flash", ReasoningEffort::Max).as_deref(),
            Some("max")
        );
        assert_eq!(
            normalize_reasoning_effort_str("runinfra:deepseek-v4-flash", "max").as_deref(),
            Some("max")
        );
    }

    #[test]
    fn anthropic_thinking_budget_scales_with_effort() {
        assert_eq!(anthropic_thinking_budget_tokens("low", 4096), Some(2048));
        assert_eq!(anthropic_thinking_budget_tokens("none", 4096), None);
        assert_eq!(anthropic_thinking_budget_tokens("high", 4096), Some(4095));
    }

    #[test]
    fn reasoning_summary_level_api_values() {
        assert_eq!(
            ReasoningSummaryLevel::Detailed.api_value(),
            Some("detailed")
        );
        assert_eq!(ReasoningSummaryLevel::Auto.api_value(), Some("auto"));
        assert_eq!(ReasoningSummaryLevel::Off.api_value(), None);
    }

    #[test]
    fn gpt5_and_o_series_reject_chat_sampling_params() {
        assert!(!supports_chat_sampling_params("gpt-5.6-luna"));
        assert!(!supports_chat_sampling_params("openai:gpt-5.6-luna"));
        assert!(!supports_chat_sampling_params("o3-mini"));
        assert!(supports_chat_sampling_params("gpt-4o"));
    }
}
