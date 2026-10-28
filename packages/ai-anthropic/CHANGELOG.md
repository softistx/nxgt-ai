# @nxgt/ai-anthropic

## 0.2.0

### Minor Changes

- [#65](https://github.com/softistx/nxgt-ai/pull/65) [`ee9324f`](https://github.com/softistx/nxgt-ai/commit/ee9324ffcf12842f7b33e39838a6da8d669f37bc) Thanks [@SteveGT96](https://github.com/SteveGT96)! - Add adaptive thinking and effort: `ThinkingOptions` `mode: 'adaptive'` is sent as `thinking: { type: 'adaptive' }`, `effort` as `output_config.effort` (effort alone sends no `thinking`), and `display` is passed through. Options that contradict each other (adaptive with `budgetTokens`, `display` with effort alone) throw `INVALID_REQUEST` before the call; what only some models refuse is left to the API's 400, with the known limits in the troubleshooting page.

### Patch Changes

- [#65](https://github.com/softistx/nxgt-ai/pull/65) [`ee9324f`](https://github.com/softistx/nxgt-ai/commit/ee9324ffcf12842f7b33e39838a6da8d669f37bc) Thanks [@SteveGT96](https://github.com/SteveGT96)! - Document that a non-default `temperature` is an API 400 on the newest models, with or without thinking (README, guide, Troubleshooting link).

- [#65](https://github.com/softistx/nxgt-ai/pull/65) [`ee9324f`](https://github.com/softistx/nxgt-ai/commit/ee9324ffcf12842f7b33e39838a6da8d669f37bc) Thanks [@SteveGT96](https://github.com/SteveGT96)! - Overriding `thinking` through `providerOptions` is now treated like the typed option: `temperature` is dropped, a `budget_tokens` below 1024 is raised, and `max_tokens` is resized for the budget, each unless `providerOptions` names that key. Documented in the README, the guide and the troubleshooting page.
- Updated dependencies [[`ee9324f`](https://github.com/softistx/nxgt-ai/commit/ee9324ffcf12842f7b33e39838a6da8d669f37bc), [`ee9324f`](https://github.com/softistx/nxgt-ai/commit/ee9324ffcf12842f7b33e39838a6da8d669f37bc), [`ee9324f`](https://github.com/softistx/nxgt-ai/commit/ee9324ffcf12842f7b33e39838a6da8d669f37bc), [`ee9324f`](https://github.com/softistx/nxgt-ai/commit/ee9324ffcf12842f7b33e39838a6da8d669f37bc)]:
  - @nxgt/ai-core@0.2.0

## 0.1.0

### Minor Changes

- [#41](https://github.com/softistx/nxgt-ai/pull/41) [`2b697ad`](https://github.com/softistx/nxgt-ai/commit/2b697add8f56c7fadd9d68b49582b6c96d2c2983) Thanks [@SteveGT96](https://github.com/SteveGT96)! - Keep `redacted_thinking` blocks across turns (streamed and non-streamed) and send them back unchanged, keep non-streamed `thinking` blocks, and split `eventsFromStream` into smaller functions.

- [#41](https://github.com/softistx/nxgt-ai/pull/41) [`2b697ad`](https://github.com/softistx/nxgt-ai/commit/2b697add8f56c7fadd9d68b49582b6c96d2c2983) Thanks [@SteveGT96](https://github.com/SteveGT96)! - Add `anthropic()`, a `ModelAdapter` for the Anthropic Messages API on Bun `fetch`: request mapping (system, messages, tool calls and results, tools, sampling), `AnthropicError` classification of HTTP failures, and retries honouring `retry-after` and the abort signal.

- [#41](https://github.com/softistx/nxgt-ai/pull/41) [`2b697ad`](https://github.com/softistx/nxgt-ai/commit/2b697add8f56c7fadd9d68b49582b6c96d2c2983) Thanks [@SteveGT96](https://github.com/SteveGT96)! - Stream Anthropic responses over SSE (robust to any byte split, `error` events as `AnthropicError`), add extended thinking with signatures kept for later turns, `cache: 'auto'` prompt-cache breakpoints on the tools, system prompt and last user turn, `countTokens` via `/v1/messages/count_tokens`, and map `pause_turn` and `model_context_window_exceeded`. A local `smoke:anthropic` script tries the adapter against the real API.

### Patch Changes

- [#41](https://github.com/softistx/nxgt-ai/pull/41) [`2b697ad`](https://github.com/softistx/nxgt-ai/commit/2b697add8f56c7fadd9d68b49582b6c96d2c2983) Thanks [@SteveGT96](https://github.com/SteveGT96)! - Deep-review fixes before the first publish: tool calls on a step that ends `max-tokens`, `end` or `refusal` get error results so the next Anthropic turn is valid; a tool input cut by `max_tokens` ends the call `max-tokens` instead of `MODEL_ERROR`; `Usage.inputTokens` counts cached tokens too; `ProposedActionPart.expiresAt` is required; `'proposed'` leaves `RunEndReason`; `AI_ERROR_CODES` is exported and the event schema accepts unknown codes; `start` on text and thinking deltas keeps consecutive blocks apart; `parseRetryAfter` is no longer exported; the retry wait removes its abort listener; `WireErrorCode` and `WireRunEndReason` type event error codes and `done.reason` open (a newer server's value parses) while `AiError.code` stays strict.
- Updated dependencies [[`2b697ad`](https://github.com/softistx/nxgt-ai/commit/2b697add8f56c7fadd9d68b49582b6c96d2c2983), [`2b697ad`](https://github.com/softistx/nxgt-ai/commit/2b697add8f56c7fadd9d68b49582b6c96d2c2983), [`2b697ad`](https://github.com/softistx/nxgt-ai/commit/2b697add8f56c7fadd9d68b49582b6c96d2c2983), [`2b697ad`](https://github.com/softistx/nxgt-ai/commit/2b697add8f56c7fadd9d68b49582b6c96d2c2983), [`2b697ad`](https://github.com/softistx/nxgt-ai/commit/2b697add8f56c7fadd9d68b49582b6c96d2c2983), [`2b697ad`](https://github.com/softistx/nxgt-ai/commit/2b697add8f56c7fadd9d68b49582b6c96d2c2983), [`2b697ad`](https://github.com/softistx/nxgt-ai/commit/2b697add8f56c7fadd9d68b49582b6c96d2c2983), [`2b697ad`](https://github.com/softistx/nxgt-ai/commit/2b697add8f56c7fadd9d68b49582b6c96d2c2983)]:
  - @nxgt/ai-core@0.1.0
