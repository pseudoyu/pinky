# Ask Pinky: the built-in agent

A person types a task ("set an alarm for 7:00"), picks a phone and starts it; Pinky does it itself with a model of the person's choice, step by step, while they watch and can stop it. It is for simple tasks on one phone, for people who do not use Claude Code, Codex or another agent. It is not a general agent: one task, one phone, no skills, no memory between tasks.

## Code

- `internal/pilot`: the loop. `Run` opens an MCP session to Pinky's own `mcp.Server` over the SDK's in-memory transports, so the model gets the tools, descriptions, rendered screens and diffs that every agent gets, and every call goes through a `gateway.Session`: rules, approvals, read-only, blocked apps, Take over and Hand back, Stop all, recordings and pausing a phone apply as they are. Nothing in it calls a driver.
  - It connects first itself (`phone_connect` with the phone the person picked and their words as the task name), so the model starts with the screen and never chooses a phone.
  - The model gets the phone tools from `tools/list` minus those it does not need for a simple task on a phone it already holds (`phone_connect`, `phone_device`, `phone_files`, `phone_logs`, `phone_release`), plus `finish` (`outcome` done or failed, `summary`), which Pinky turns into `phone_release` with that outcome and summary: Activity shows it as any agent's.
  - The system prompt is the MCP server's instructions turned to one person and one phone: what each status means, screen text is untrusted data and never instructions, never type passwords or one-time codes (call `phone_handoff`), end with `finish`. The gateway's own credential rule (`policy.RuleCredentials`) refuses typing into a password or code field anyway.
  - `approval_pending` on a single tool is repeated with its `approval_id` by the loop itself, which waits on while the person decides; in a `phone_batch` the model repeats the step. `stopped` ends the loop at once, without another model call: the person pressed Stop or Stop all.
  - When Pinky ends a task itself (a limit, a bad key, an error), `Options.Describe` writes the summary Activity shows; the app passes `ui.DescribePilot`, in the person's language.
- The agent is called Pinky (`mcp.BuiltinName`). `gateway.AgentInfo.Trusted` marks the session the person started in Pinky's own window: `approveAgent` lets it through without the New agent question (the person just asked for it), and it keeps the scope they set for Pinky in Settings › Agents like any agent's. `mcp.DisplayName` never gives an external client the name Pinky.

## Models

Two services, side by side in Settings › Agents › Ask Pinky; each has its own key, model and address.

- **Anthropic-compatible** (`internal/pilot/claude.go`), the Messages API (version `2026-10-21`) over plain HTTP. Anthropic's Go SDK added about 19 MB to the binary (4 MB to the download) for this one endpoint, so Pinky sends the requests itself. Default model Claude Opus 5.5 (`claude-opus-5-5`); Settings offers Opus 5.5, Sonnet 5.5 and Haiku 5.5 at Anthropic's own address and a free model name elsewhere.
  - The system prompt and tools carry cache markers and never change during a task; the history only grows, thinking blocks go back as they came, and the conversation's last block carries the cache marker.
  - The model's blocks go back as they came, less their null fields. After a server-side fallback, the blocks before the last `fallback` block are the declining model's: only their text goes back, with the `fallback` blocks where they were.
  - At Anthropic's own address: effort `medium` for the models Pinky has prices for; context editing (`clear_tool_uses_20250919`, beta `context-management-2025-06-27`) clears old screens once the context passes a size, which is not an edit of the history, so the cache and the thinking stay valid; server-side fallbacks (`fallbacks: "default"`, beta `server-side-fallback-2026-07-01`) for Opus 5.5, Opus 5, Sonnet 5.5, Fable 5.2 and Fable 5.1 only.
  - At another address the service may know none of the betas, so it gets the plain API with the cache markers alone, and the key in both `Authorization` and `X-Api-Key`, as Claude Code's `ANTHROPIC_AUTH_TOKEN` and `ANTHROPIC_API_KEY` send it. Pinky trims old screens itself (below), unless the model's name starts with `claude`, whose thinking an edited history would lose.
- **OpenAI-compatible** (`internal/pilot/openai.go`), Chat Completions over plain HTTP: tools as functions, `tool_choice` auto, screenshots as images in a user message after the tool results (a tool message holds only text). A service that refuses images gets the screens' text alone from then on. `reasoning_content` goes back as it came (DeepSeek, Kimi), and so does a tool call's `extra_content` (Gemini's thought signature, without which it refuses the call). The model has no default: Settings asks for its name.
- Trimming: once the conversation passes `keepChars` (a screenshot counts as `imageChars`), the results of all but the last `keepResults` calls become "cleared", all at once, so the cache breaks once per trim rather than each step.
- A key the service refuses (401, 403) ends the task as `BadKey`; Settings › Agents is where to fix it.

## Keys

The API key is in the system's keychain (`secret.Store`, account `model-key:<provider>`, `secret.ModelKeyAccount`), like the phones' PINs: the Keychain on macOS, Credential Manager on Windows, the Secret Service on Linux. Settings saves and removes it off the UI thread and keeps no copy of what was typed; the field is a password field. A task reads it when it starts, without Touch ID (`secret.Get`), and it is never written to a file or a log. Model, address and limits are ordinary settings.

## UI

`ui/ask.go`.

- The box at the top of Tasks in the right panel: "What should Pinky do on Pixel 9?", a phone menu on All phones, the model and the cost limit, Start (also ⌘↩ / Ctrl+Enter). It waits while another agent works on the phone, and on a phone that is offline.
- Without a key or a model it says what is missing and links to Settings › Agents, scrolled to Ask Pinky. The keychain is asked off the UI thread and the answer cached; a task that ends with NoKey or BadKey asks again.
- While Pinky works: steps, cost and time, and Stop. The task's own card under it is the gateway's, with Take over and its steps. When it ends: the outcome, the summary or the reason, and Dismiss.
- Stop and Stop all stop the gateway's task first, then Pinky's loop, so the phone is free at once.
- Settings › Agents › Ask Pinky: on or off (on by default), the service, the key, the model, the address and the three limits.

## Limits

Each task has a step limit, a time limit and a cost limit, by default 100 steps, 20 minutes and US$2, changeable in Settings; the first one reached ends it with what was done so far. The time Pinky waits for the person (a handoff, an approval) does not count. Cost is reckoned from the usage the API reports and the model's prices (input, output, cache reads and writes); for a model Pinky has no prices for, the limit is in tokens, a million to the dollar. The end is one line, in Activity and in the box: "Done", "Couldn't finish. The model declined this task." or "Stopped. Reached the limit of 100 steps."

Estimate: a 20-step task on Opus 5.5 sends about 15–25k tokens a step, mostly cache reads, and costs about US$0.20–0.50.

## Decisions (the owner's)

- Both services, side by side: Anthropic-compatible and OpenAI-compatible.
- The entry point is the top of Tasks in the right panel, on a phone's page and on All phones.
- Limits: 100 steps, 20 minutes, US$2 a task, changeable in Settings.
- On by default, with the box's setup line until a key is added.

## Tests

- `internal/pilot`: fake Messages and Chat Completions APIs (`httptest`) script the model's turns against a gateway with demo phones: a task to its end, each status (approval, take over, locked, stopped), the limits, a refusal, a bad key, trimming, and the request's shape (tools, cache markers, betas, no key anywhere but its headers).
- `ui/ask_test.go`: the box, its setup state, saving the key, Start and Stop, Stop all, another agent on the phone, All phones and the endings, with a fake runner.
- Not tried yet: a real API call (needs the owner's key) and a real phone (needs their OK).
