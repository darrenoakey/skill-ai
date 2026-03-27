# daz-agent-sdk — Gotchas & Known Pitfalls

## Anthropic OAuth
- Tokens (sk-ant-oat01-*) require `anthropic-beta: oauth-2025-04-20` header. Refresh via `POST https://platform.claude.com/v1/oauth/token` with `{"grant_type":"refresh_token","refresh_token":"<rt>","client_id":"9d1c250a-e61b-44d9-88ed-5944d1962f5e"}`. Rate limit timestamps are Unix epoch integers.

## claude_agent_sdk Inside Claude Code
- `ClaudeAgentOptions.env` CANNOT unset env vars (SDK merges `{**os.environ, **options.env}`). Pop `CLAUDECODE` from `os.environ` before connecting, restore in finally.
- `claude_agent_sdk` inside Claude Code produces `tool_use ids must be unique` errors — fundamental incompatibility. Use Go MCP binary over stdio JSON-RPC instead.
- Streaming mode: `stream_input()` closes stdin immediately when no hooks/MCP servers configured. Workaround: pass dummy hooks or use `claude --print` subprocess.
- `query()` yields 5 message types. Final answer is in `ResultMessage.result` — NOT in `AssistantMessage` TextBlocks.

## claude_agent_sdk — Python Runtime
- `async for msg in query()` crashes on unknown message types (e.g., `rate_limit_event`). Use manual `__anext__()` with try/except.
- `claude_agent_sdk` from sync code: wrap with `asyncio.run()`. Never use `subprocess.run(["claude", ...])` inside Claude Code sessions.
- `ProcessError` on non-zero exit can happen during teardown after success. Verify via DB/API rather than treating as failure.
- `query()` from FastAPI background thread: use `ThreadPoolExecutor` + `asyncio.run()` inside the thread.

## daz_agent_sdk
- `agent.ask()` prompts saying "Visit this URL" trigger tool calls instead of text blocks → `response.text == ""`. Phrase prompts to avoid tool use.
- Pydantic `schema=` parameter: response has `.parsed` attribute. `resp.text` may be empty — always use `resp.parsed`.
- `schema=` with Claude provider triggers agentic tool use (file writing) which is slow. Provider now sets `max_turns>=2` automatically so the file-write tool can execute, and falls back to parsing JSON from response text. For autonomous loops or high-throughput structured output: skip `schema=`, append JSON schema instructions to the prompt manually, and parse JSON from `result.text` using `parse_json_from_llm()` from `daz_agent_sdk.types`. This is 5-10x faster and avoids the agentic overhead.
- Claude provider now raises `AgentError(kind=INTERNAL)` on empty non-structured responses instead of returning empty string. This triggers the fallback retry system automatically.
- `transparent=True` with spark provider (the default) submits a `background-remove` job to arbiter on spark:8400 (BiRefNet on GPU). With mflux provider, BiRefNet runs locally on CPU — avoid for batch generation (60%+ CPU). Arbiter returns result in `result.data` not `result.image`.
