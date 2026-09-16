---
sidebar_label: Meta Model API
description: Configure Meta's Model API to evaluate Muse Spark reasoning models with reasoning effort, multimodal input, tool calling, and search grounding in promptfoo
---

# Meta Model API

The [Meta Model API](https://dev.meta.ai/) (public preview) serves Meta Superintelligence Labs' Muse Spark models through an OpenAI-compatible API. The Meta provider extends the [OpenAI provider](/docs/providers/openai/) and supports its compatible options.

:::note

This provider is for the Meta **Model** API at `api.meta.ai` (Muse models), which supersedes Meta's [Llama API](/docs/providers/llamaApi.md) (`api.llama.com`) as Meta's hosted inference service — the Llama API Public Preview was retired on July 6, 2026.

:::

## Setup

1. Create an API key from the API keys tab on the [Meta Model API dashboard](https://dev.meta.ai/).
2. Set the `MODEL_API_KEY` environment variable — Meta's official variable, the same one its SDKs and quickstart use — or specify `apiKey` (or a custom `apiKeyEnvar`) in your config.

```yaml
providers:
  - id: meta:muse-spark-1.3
```

`meta:<model>` defaults to the [Responses API](#responses-api) — Meta's full-feature surface and the one its docs recommend. Use `meta:chat:<model>` for the OpenAI-compatible chat completions endpoint, or `meta:messages:<model>` for the Anthropic-compatible [Messages API](#messages-api). If you omit the model, the provider defaults to `muse-spark-1.1`; select `muse-spark-1.3` explicitly to use the latest model.

## Available Models

Check the [models page](https://dev.meta.ai/docs/models) for the live list. As of writing:

- `muse-spark-1.3` — latest model for coding and agentic workflows, with a 1,048,576-token context window, text/image/video/PDF input, tool calling, structured output, and search grounding.
- `muse-spark-1.3-contributor` — the same model with discounted pricing. Selecting this ID permits Meta to use your prompts and completions to train future models.
- `muse-spark-1.1` — original Muse Spark model, still supported.

Both 1.3 IDs work with the Responses, Chat Completions, and Messages APIs. Meta notes that audio understanding in 1.3 is not fully supported and may produce degraded responses.

## Configuration

```yaml
providers:
  - id: meta:muse-spark-1.3
    config:
      reasoning_effort: high
      max_completion_tokens: 8192
      temperature: 1.0
```

### Configuration Options

The provider accepts compatible [OpenAI provider](/docs/providers/openai/) options. Notable behavior:

- `reasoning_effort` — `minimal`, `low`, `medium`, `high`, or `xhigh`. When omitted, the model picks its own reasoning depth. Muse Spark does not support `none`; the provider rejects it with a clear error. Reasoning tokens bill at the output rate and count toward the output cap.
- `max_completion_tokens` — caps generation on the chat endpoint (Meta accepts `max_tokens` only as a deprecated alias; if you set it, the provider forwards it as the canonical `max_completion_tokens`). On the [Responses API](#responses-api) the cap is `max_output_tokens`, and the provider maps `max_completion_tokens`/`max_tokens` onto it. When unset, no cap is sent so reasoning can use the full output budget.
- `temperature` — supported (0–2, API default 1.0). Promptfoo sends its deterministic default of `0` unless you override it.
- `response_format` — structured output with guaranteed JSON schema matching.
- `tools` / `tool_choice` — parallel tool calling with streamed arguments.
- `prompt_cache_retention` — `in_memory` or `24h` for prompt caching; cached prompt tokens bill at the cached-input rate.
- `seed` — best-effort determinism.

On Chat Completions and Responses, promptfoo rejects `logprobs`, `n > 1`, `stop`, and `logit_bias` before sending a request. It also rejects `stream` because these integrations expect a complete JSON response. OpenAI-scoped environment defaults (`OPENAI_TEMPERATURE`, `OPENAI_TOP_P`, `OPENAI_MAX_COMPLETION_TOKENS`, penalty variables) are not applied to Meta requests.

### Cost Tracking

Promptfoo computes token cost from Meta's [published pricing](https://dev.meta.ai/docs/pricing-rate-limits), including the discounted rate for cached input:

| Model                              | Input / 1M | Cached input / 1M | Output / 1M |
| ---------------------------------- | ---------- | ----------------- | ----------- |
| `muse-spark-1.3`, `muse-spark-1.1` | $1.25      | $0.15             | $4.25       |
| `muse-spark-1.3-contributor`       | $0.10      | $0.002            | $0.20       |

Contributor pricing requires opting into Meta's training data terms by selecting the Contributor model ID. Override token prices with `cost`, `inputCost`, `outputCost`, or `cacheReadCost` (USD per token) for custom rates. Token cost excludes web-search charges.

## Responses API

`meta:<model>` (the default) and `meta:responses:<model>` target Meta's `/v1/responses` endpoint — the only Meta endpoint that carries reasoning across turns, with built-in web-search grounding:

```yaml
providers:
  - id: meta:responses:muse-spark-1.3
    config:
      reasoning_effort: medium
      tools:
        - type: web_search
```

With `web_search`, the model grounds answers in real-time web results with inline citations. Web search bills separately ($2.50 per 1,000 queries) and is not included in promptfoo's computed token cost.

## Messages API

`meta:messages:<model>` targets Meta's Anthropic-compatible Messages endpoint (`https://api.meta.ai/v1/messages`) — the surface Anthropic-format coding agents such as Claude Code use. Use it to evaluate Muse Spark over the same wire format those agents send:

```yaml
providers:
  - id: meta:messages:muse-spark-1.3
    config:
      max_tokens: 8192
```

The provider extends the [Anthropic provider](/docs/providers/anthropic/), so its options (`max_tokens`, `tools`, image and document content blocks, etc.) apply. It defaults `max_tokens` to 131,072 and enables streaming so the Anthropic SDK can safely handle long generations; streamed output is aggregated before grading. Authentication uses your Meta key as a bearer token (`Authorization: Bearer`), matching Meta's docs — Anthropic-scoped settings like `ANTHROPIC_API_KEY`, `ANTHROPIC_BASE_URL`, `ANTHROPIC_MAX_TOKENS`, `ANTHROPIC_TEMPERATURE`, custom headers, and Claude Code OAuth credentials are deliberately ignored on this surface.

Muse Spark's reasoning arrives on this surface as encrypted `redacted_thinking` blocks, so the provider defaults `showThinking` to `false` to keep the ciphertext out of graded output.

## Using with coding-agent providers

Meta positions Muse Spark as a backend for coding agents, and promptfoo's agentic providers can evaluate those setups end to end. In both recipes, set `apiKey` explicitly: the agent subprocesses inherit your shell environment, and an explicit key guarantees your Meta key is used instead of an ambient `OPENAI_API_KEY` or `ANTHROPIC_API_KEY` that belongs to another service.

### Codex CLI

The [`openai:codex-sdk` provider](/docs/providers/openai-codex-sdk) drives Muse Spark over the Responses API:

```yaml
providers:
  - id: openai:codex-sdk
    config:
      base_url: https://api.meta.ai/v1
      model: muse-spark-1.3
      apiKey: '{{env.MODEL_API_KEY}}'
```

The explicit `apiKey` is required — the provider does not read `MODEL_API_KEY` on its own, and without it an ambient `OPENAI_API_KEY` would be sent to the Meta endpoint instead.

### Claude Code

The [`anthropic:claude-agent-sdk` provider](/docs/providers/claude-agent-sdk/) forwards `config.env` to the agent subprocess. Pass the environment Meta's guide prescribes, with `apiKey` set to your Meta key:

```yaml
providers:
  - id: anthropic:claude-agent-sdk
    # Provider-level `env` outranks the eval's top-level `env`, pinning the
    # routing values a suite-wide ANTHROPIC_BASE_URL (e.g. an Anthropic
    # gateway) would otherwise override — which would send the Meta key there.
    env:
      ANTHROPIC_BASE_URL: https://api.meta.ai
      ANTHROPIC_CUSTOM_HEADERS: ''
    config:
      apiKey: '{{env.MODEL_API_KEY}}'
      env:
        ANTHROPIC_BASE_URL: https://api.meta.ai
        ANTHROPIC_AUTH_TOKEN: '{{env.MODEL_API_KEY}}'
        ANTHROPIC_CUSTOM_HEADERS: ''
        ANTHROPIC_MODEL: muse-spark-1.3
        ANTHROPIC_DEFAULT_OPUS_MODEL: muse-spark-1.3
        ANTHROPIC_DEFAULT_SONNET_MODEL: muse-spark-1.3
        ANTHROPIC_DEFAULT_HAIKU_MODEL: muse-spark-1.3
        CLAUDE_CODE_SUBAGENT_MODEL: muse-spark-1.3
        ENABLE_TOOL_SEARCH: 'true' # Claude Code disables MCP tool search for non-first-party hosts
```

:::warning

Do not omit `apiKey`, the empty `ANTHROPIC_CUSTOM_HEADERS` override, or the provider-level `env` block. The provider forwards its resolved API key into the agent subprocess as `ANTHROPIC_API_KEY` after `env:` is applied — if `apiKey` is unset and a real `ANTHROPIC_API_KEY` is exported in your shell, that Anthropic credential would be transmitted to Meta's endpoint. Clearing `ANTHROPIC_CUSTOM_HEADERS` prevents an inherited gateway or proxy secret from being sent to Meta. The provider-level `env` block matters because the subprocess environment is layered `process.env` < `config.env` < provider/suite `env`: without the pin, a top-level `env.ANTHROPIC_BASE_URL` in the same config would silently re-route the agent — and your Meta key — to that URL.

:::

Pin every model alias as shown — Claude Code otherwise routes background tasks, Plan Mode, or subagents to Claude models the Meta API doesn't serve. See Meta's [coding agents guide](https://dev.meta.ai/docs/coding-agents) for the full setup pattern.

## Example Usage

```yaml
providers:
  - id: meta:muse-spark-1.3
  - id: openai:gpt-5.5

prompts:
  - 'Summarize the following in one sentence: {{text}}'

tests:
  - vars:
      text: 'Promptfoo is an open-source tool for testing and evaluating LLM apps.'
```

Get started with a runnable example:

```bash
npx promptfoo@latest init --example provider-meta
```

## API Details

- Base URL: `https://api.meta.ai/v1` (override with `apiBaseUrl`; the Messages surface uses the bare host `https://api.meta.ai`).
- OpenAI-compatible chat completions (`/chat/completions`) and Responses (`/responses`) endpoints, plus the Anthropic-compatible Messages (`/messages`) endpoint.
- Rate limits apply per team, not per key: 3,000 RPM / 4M TPM for Standard models and 100 RPM / 3M TPM for Contributor models.
- Full [API documentation](https://dev.meta.ai/docs/overview).

## See Also

- [OpenAI Provider](/docs/providers/openai/) — compatible configuration options
- [Llama API Provider](/docs/providers/llamaApi.md) — Meta's hosted Llama models
- [Meta Model API docs](https://dev.meta.ai/docs/overview) and [pricing](https://dev.meta.ai/docs/pricing-rate-limits)
