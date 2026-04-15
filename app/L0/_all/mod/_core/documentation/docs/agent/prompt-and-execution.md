# Prompt And Execution

This doc focuses on how the onscreen agent builds model input and how execution results are fed back into history.

## Primary Sources

- `app/L0/_all/mod/_core/onscreen_agent/AGENTS.md`
- `app/L0/_all/mod/_core/onscreen_agent/prompts/AGENTS.md`
- `app/L0/_all/mod/_core/promptinclude/AGENTS.md`
- `app/L0/_all/mod/_core/onscreen_agent/llm.js`
- `app/L0/_all/mod/_core/onscreen_agent/execution.js`
- `app/L0/_all/mod/_core/onscreen_agent/api.js`
- `app/L0/_all/mod/_core/promptinclude/promptinclude.js`

## Prompt Boot Timing

The overlay no longer assembles full prompt state during plain page-load init.

Current timing:

- init restores config, browser UI state, and saved history
- the first prompt-dependent action such as send, prompt-history open, or another explicit rebuild path then lazily loads the default system prompt, installs the onscreen skill runtime, and runs prompt-section assembly
- later prompt rebuilds reuse the same prompt runtime and only refresh the parts that changed
- incremental history refresh still reuses the same prepared-message builders as the full prompt build, so prompt-history previews and outbound request payloads stay aligned after settled turns

## Prepared Prompt Order

The prepared prompt order is:

```txt
system -> examples -> compacted history summary (when present) -> live history -> transient
```

Important details:

- example messages are ordinary alternating user/assistant messages inserted before live history
- when any example messages exist, the prepared prompt appends one final example-sourced `_____framework` boundary that says `start of new conversation - don't refer to previous contents` before the first live-history turn
- example messages count toward token totals but are never replaced by compaction
- owner modules may prepend extra system-prompt sections before the skill catalog; `_core/promptinclude` currently injects a stable `## prompt includes` instruction block there and then appends readable `*.system.include.md` files as extra system-prompt sections
- transient runtime context is emitted as its own trailing prepared message when present
- `_core/onscreen_agent` currently adds one short lowercase `chat display mode` transient section only in compact mode so the model sees `chat is in compact mode` and `keep replies short unless more detail is needed for correctness or the user asks for it`; full mode adds no display-mode section
- `_core/promptinclude` may also append a `prompt includes` transient section that lists readable `**/*.transient.include.md` files in alphabetical full-path order and renders each file body in its own fenced block

## Message Markers

Prepared user-role messages use explicit wrappers:

- `_____user`: real human submission
- `_____framework`: framework-generated follow-up such as execution output
- `_____transient`: trailing mutable runtime context

These markers matter for prompt inspection, execution flows, and staged widget workflows.

When a real user turn includes attachments, the `_____user` block contains the literal message text plus the `Attachments↓` list, and the `space.chat` runtime instructions for those attachments are emitted as a following `_____framework` block.

## Skill Injection

Prompt construction includes two skill-related sections:

- the top-level skill catalog built from readable `mod/*/*/ext/skills/*/SKILL.md` files
- the auto-loaded skill context for readable top-level `ext/skills/*/SKILL.md` files whose `metadata.loaded` condition currently passes

Both sections are filtered by the current document's live `<x-skill-context>` tags before prompt assembly.

Both `metadata.when` and `metadata.loaded` accept either `true` or a `{ tags: [...] }` condition. The shared helper reads those live tags every time it builds the catalog, resolves an explicit skill load, or assembles auto-loaded prompt context. Auto-loaded prompt discovery is top-level only, and auto-loaded skills may land only in `system` or `transient`, so their missing or invalid placement and explicit `history` all fall back to `system` unless they explicitly set `transient`.

Top-level skill catalog rows use the compact shape:

```txt
skill-id|name|description
```

## Execution Protocol

The agent runs browser-side JavaScript through the execution loop.

Important execution rules:

- execution blocks should be preceded by one short narration line
- `_____javascript` must appear on its own line
- execution output is fed back as `_____framework`
- the live firmware prompt distinguishes runtime identity fields from persisted YAML keys: `space.api.userSelfInfo()` exposes `fullName`, but `~/user.yaml` stores `full_name`, so profile edits should update `full_name`, not `fullName`
- if an execution block returns no result and prints no logs, the transcript says `execution returned no result and no console logs were printed`
- multiline results are labeled with `result↓`
- structured results should prefer YAML over JSON when the shared serializer can express them cleanly
- `space.skills.load(...)` still returns the typed skill object, but `history` placement writes the skill body into history while `system` and `transient` placement only report `skill loaded to system message` or `skill loaded to transient area` and store the skill in runtime prompt context for later requests

## Failure And Retry Behavior

- if a model turn returns no assistant content, the runtime retries the same request once automatically
- only after that retry does it emit a generic protocol-correction user message
- no-result execution output is informational only and should not trigger a synthetic correction message by itself

## LLM Transport

`api.js` owns the final provider call after `llm.js` has built the prepared prompt input.

The transport layer uses one `OnscreenAgentLlmClient` superclass with provider subclasses:

- `OnscreenAgentApiLlmClient` sends the prepared request to an OpenAI-compatible chat-completions endpoint and normalizes standard JSON or SSE streams into text deltas plus completion metadata
- `OnscreenAgentLocalLlmClient` sends the prepared message payload through the shared `_core/huggingface/manager.js` browser runtime, using the configured Hugging Face repo id and dtype

When `llm_provider` is `local`, `llm.js` builds the system section from `LOCAL_ONSCREEN_AGENT_SYSTEM_PROMPT` plus custom instructions instead of the full firmware prompt and skill catalog. The same prepared-prompt machinery still carries examples when present, live history, compacted history, and transient context.

The store and retry loop consume both providers through the same `streamOnscreenAgentCompletion(...)` seam. Provider-specific behavior should stay behind those client classes unless it affects prompt construction, which belongs in `llm.js`.

## Prompt Extension Seams

Feature modules should extend the agent through owner-module seams, not by patching the base prompt blindly.

Important extension families:

- system prompt sections
- example message builders
- history message builders
- transient section builders
- final prompt-input assembly
- execution-plan validation hooks

Current first-party examples include `_core/spaces` for current-space instructions, `_core/promptinclude` for persistent split system/transient include discovery, `_core/memory` for prompt-include-backed `~/memory/` behavior and rolling notes through an auto-loaded system skill, and the `_core/onscreen_agent` display-mode transient hook for compact-mode reply guidance. Module-specific workflow policy still belongs in owner-module skills or owner-module `_core/onscreen_agent/...` JS hooks.
