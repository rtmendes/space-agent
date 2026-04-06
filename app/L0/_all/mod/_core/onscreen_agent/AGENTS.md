# AGENTS

## Purpose

`_core/onscreen_agent/` owns the floating routed overlay agent.

It mounts into the router overlay layer, keeps its own floating shell, prompt files, persistence, attachments, execution loop, and overlay-specific interaction model, and reuses shared visual primitives for rendering and dialogs. It is the first-party user-facing agent surface under `_core/`.

Documentation is top priority for this module. After any change under `_core/onscreen_agent/`, update this file and any affected parent docs in the same session.

## Documentation Hierarchy

`_core/onscreen_agent/AGENTS.md` owns the overlay runtime, shared onscreen skill-loading contract, and the map of deeper docs inside this subtree.

Current deeper docs:

- `app/L0/_all/mod/_core/onscreen_agent/ext/skills/development/AGENTS.md`

Update rules:

- update this file when overlay-wide runtime behavior, skill loading, or ownership boundaries change
- update the deeper development-skill doc when the development skill tree, routing map, or mirrored source contracts change
- when framework, router, API, path, permission, or auth contracts change in ways that affect the development skill tree, update the deeper doc in the same session

## Ownership

This module owns:

- `ext/html/page/router/overlay/end/onscreen-agent.html`: thin adapter that mounts the overlay into the router overlay seam
- `ext/skills/`: starter onscreen-agent skill folders, each ending in `SKILL.md`
- `ext/js/_core/onscreen_agent/llm.js/buildOnscreenAgentExampleMessages/end/*.js`: prompt-example extensions that prepend live few-shot conversations ahead of thread history
- `panel.html`: overlay UI
- `response-markdown.css`: overlay-local markdown presentation overrides for assistant responses
- `store.js`: floating-shell state, send loop, persistence, avatar drag behavior, history resize behavior, display mode, and overlay menus
- `view.js`: shared-thread-view wiring
- `skills.js`: onscreen skill discovery, skill frontmatter metadata flags, `space.skills.load(...)`, and skill-related JS extension seams
- `llm.js`, `api.js`, `execution.js`, `attachments.js`, and `llm-params.js`: local runtime helpers
- `llm.js` owns LLM-facing system-prompt file loading, optional example-message construction, always-loaded skill injection into the system prompt, runtime system-prompt assembly, prompt-instance caching, separate transient-message construction, final request assembly, history-compaction prompt loading, and the model-facing JS extension seams
- `api.js` owns chat transport, HTTP error handling, and streaming response parsing; prompt-shaping logic lives in `llm.js`
- `config.js` and `storage.js`: persisted settings, position, display mode, and history
- `system-prompt.md`, `compact-prompt.md`, and `compact-prompt-auto.md`: shipped prompt files
- `res/`: overlay-local assets
- the `space.onscreenAgent` runtime namespace for overlay display control and externally triggered prompt submission

## Persistence And Prompt Contract

Current persistence paths:

- config: `~/conf/onscreen-agent.yaml`
- history: `~/hist/onscreen-agent.json`

Current config fields include:

- provider settings and params
- `max_tokens`
- optional `custom_system_prompt`
- `agent_x`
- `agent_y`
- optional `history_height`
- `display_mode`

Legacy compatibility:

- `display_mode` is the canonical persisted mode field
- `storage.js` still accepts legacy `collapsed` values when older configs are loaded
- `storage.js` also normalizes numeric coordinate scalars from the lightweight YAML parser before the overlay store applies `agent_x` and `agent_y`
- when config is rewritten, legacy `collapsed` is mirrored from `display_mode` so the two fields do not drift

Current defaults:

- API endpoint: `https://openrouter.ai/api/v1/chat/completions`
- model: `openai/gpt-5.4-mini`
- params: `temperature:0.2`
- max tokens: `64000`
- default display mode: compact

Prompt rules:

- `system-prompt.md` is the firmware prompt
- custom instructions are appended under `## User specific instructions`
- the prepared prompt order is `system -> examples -> compacted history summary when present -> live history -> transient`
- examples are optional, empty by default, and are inserted as ordinary alternating user or assistant messages ahead of live history rather than being folded into the system prompt
- example messages count toward prompt-history token totals and appear in the prompt-history modal, but automatic or manual history compaction may replace only live history turns, never the examples or transient section
- skill frontmatter may include a `metadata` object for runtime-owned flags; `metadata.always_loaded: true` marks a readable skill file for automatic prompt inclusion
- the runtime prompt appends the top-level onscreen skill catalog built from readable `mod/*/*/ext/skills/*/SKILL.md` files
- the catalog prompt block should stay compact and plain-text: `skills`, one short loader hint, then `skills id|name|description↓` rows
- after that catalog, the runtime appends a compact `auto loaded` block containing repeated `id: <skill-id>` markers plus the skill body text for readable `mod/*/*/ext/skills/**/SKILL.md` entries whose frontmatter sets `metadata.always_loaded: true`; do not inject frontmatter there because the catalog already carries name and description
- prompt construction exposes JS seams at `_core/onscreen_agent/llm.js/fetchDefaultOnscreenAgentSystemPrompt`, `_core/onscreen_agent/llm.js/fetchOnscreenAgentHistoryCompactPrompt`, `_core/onscreen_agent/llm.js/buildOnscreenAgentSystemPromptSections`, `_core/onscreen_agent/llm.js/buildOnscreenAgentExampleMessages`, `_core/onscreen_agent/llm.js/buildOnscreenAgentHistoryMessages`, `_core/onscreen_agent/llm.js/buildOnscreenAgentTransientSections`, `_core/onscreen_agent/llm.js/buildOnscreenAgentPromptInput`, and `_core/onscreen_agent/llm.js/buildRuntimeOnscreenAgentSystemPrompt`
- prompt extensions should prefer the sections seam when they need to append or replace whole prompt sections; the final builder seam is for last-mile rewrites of the assembled string
- request preparation should run through the shared prompt-input builder in `llm.js`, which wraps each prepared user-role message in either a `_____user` block for real human submissions or a `_____framework` block for framework-generated follow-up turns such as execution output, preserves the system or examples or history or transient section boundaries in the outbound payload, and emits transient runtime context as its own trailing `_____transient` message when any transient sections exist
- the built-in example extension under `ext/js/_core/onscreen_agent/llm.js/buildOnscreenAgentExampleMessages/end/user-self-info.js` should prepend a framework prompt asking the agent to check user detail, an assistant execution reply that calls `space.api.userSelfInfo()`, and a framework execution-result message populated with the live API result so the model sees both the expected execution format and the current user snapshot
- the top-level skill catalog and `auto loaded` block are model-facing prompt context and therefore belong to `llm.js` orchestration even though `skills.js` still owns low-level skill discovery helpers and `space.skills.load(...)`
- `_core/spaces` currently uses the sections seam only to inject a space-local `## Current Space Agent Instructions` section when the current space defines agent instructions; generic spaces workflow guidance belongs in the always-loaded `spaces` skill, and live widget catalogs or current-space details should be loaded on demand instead of being pre-injected into the prompt
- the firmware prompt should tell the agent that `space.api.userSelfInfo()` returns `{ username, fullName, groups, managedGroups }` and that writable app roots are derived from `username`, `managedGroups`, and `_admin` membership in `groups`
- the firmware prompt should also remind the agent to `return await ...` for browser mutations that need confirmation, should refer to the active thread as `space.chat`, should use `space.utils.yaml.parse(...)` plus `space.utils.yaml.stringify(...)`, should explain writable-scope discovery from `space.api.userSelfInfo()` plus the standard layer rules, and should leave domain-specific widget workflow guidance to the always-loaded `spaces` skill instead of duplicating it in the base firmware prompt
- the firmware prompt should also tell the agent to keep large reads in normal top-level JavaScript variables and return only the narrow slice or summary needed for the next step unless the full text must stay in-model immediately, for example exact numbered patch lines
- the firmware prompt examples must stay plain text and must not wrap execution snippets or execution-output examples in triple-backtick fences, because fenced examples train the overlay agent to emit fences after `_____javascript`
- the firmware prompt should also enforce staged execution: if a helper result determines the next action, the agent should stop after that helper call and wait for the next turn instead of chaining discovery and dependent mutation in one JavaScript block
- the firmware prompt should require one short explanatory sentence before execution blocks so the thread stays readable, but this should stay prompt pressure rather than a runtime validation error
- the firmware prompt should also make clear that all execution narration belongs before `_____javascript`; there must be no explanatory prose after the separator because everything after it is executed as code
- the firmware prompt should also make clear that silent execution is wrong and that a bare staging sentence such as `Checking the current widget source` is not acceptable progress when browser work is needed; if the sentence announces a browser step, that same message must continue with `_____javascript`
- the firmware prompt should also tell the agent not to ask redundant clarification questions when the user already named an obvious runtime target such as a widget by name
- the firmware prompt should also tell the agent to trust the exact runtime shape it just saw in `_____framework` or `_____transient` instead of hallucinating richer object shapes; if the runtime showed a plain-text catalog, the agent should read that text literally
- the firmware prompt should tell the agent to stop after a successful mutation that appears to satisfy the user instead of making speculative extra edits
- the firmware prompt should also tell the agent that after a successful mutation it must either execute again because more browser work is truly needed or answer the user normally; promise-only follow-up lines such as `Updating...` or `Applying...` are not acceptable
- the firmware prompt should tell the agent never to emit raw JavaScript or fenced code as a normal reply; browser work must use the execution protocol, otherwise the reply must be ordinary prose
- `execution.js` should fail fast when `_____javascript` is inline instead of occupying its own line, and should surface a direct protocol error telling the agent to put the explanatory sentence on the previous line and the separator alone on the next line
- the firmware prompt should explain the prepared-message block markers explicitly: `_____user` means the real human user, `_____framework` means a runtime-generated follow-up turn, and `_____transient` is auto-injected mutable context
- prompt-facing text here is token-budgeted; when editing `system-prompt.md`, prompt wrapper strings in `skills.js`, or any always-loaded skill, measure the prompt surface with the local tokenizer in the same session and prefer plain text, short labels, minimal markdown, minimal filler, and no unnecessary trailing punctuation
- `compact-prompt.md` is used for user-triggered history compaction
- `compact-prompt-auto.md` is used for automatic compaction during the loop

## JS Extension Seams

Overlay chat behavior is intentionally extensible through `ext/js/` hooks rather than private store patching.

Current stable seams:

- `skills.js` exposes `_core/onscreen_agent/skills.js/listDiscoveredSkillFiles`, `_core/onscreen_agent/skills.js/loadOnscreenSkillIndex`, `_core/onscreen_agent/skills.js/loadOnscreenSkillCatalog`, `_core/onscreen_agent/skills.js/buildOnscreenSkillsPromptSection`, `_core/onscreen_agent/skills.js/buildOnscreenAutomaticallyLoadedSkillsPromptSection`, `_core/onscreen_agent/skills.js/loadOnscreenSkill`, and `_core/onscreen_agent/skills.js/installOnscreenSkillRuntime`; use these for skill discovery, virtual skills, skill-catalog source data, overriding automatic-skill source generation, overriding skill loads, or augmenting `space.skills`
- `llm.js` exposes `_core/onscreen_agent/llm.js/fetchDefaultOnscreenAgentSystemPrompt`, `_core/onscreen_agent/llm.js/fetchOnscreenAgentHistoryCompactPrompt`, `_core/onscreen_agent/llm.js/buildOnscreenAgentSystemPromptSections`, `_core/onscreen_agent/llm.js/buildOnscreenAgentExampleMessages`, `_core/onscreen_agent/llm.js/buildOnscreenAgentHistoryMessages`, `_core/onscreen_agent/llm.js/buildRuntimeOnscreenAgentSystemPrompt`, `_core/onscreen_agent/llm.js/buildOnscreenAgentTransientSections`, `_core/onscreen_agent/llm.js/buildOnscreenAgentPromptInput`, `_core/onscreen_agent/llm.js/buildOnscreenAgentPromptMessageContext`, `_core/onscreen_agent/llm.js/createOnscreenAgentPromptInstance`, and `_core/onscreen_agent/llm.js/prepareOnscreenAgentCompletionRequest`; use these when the extension changes model-facing context, including system-prompt sections, example conversations, transient blocks, prompt-instance lifecycle, or final outbound message shaping
- `api.js` exposes `_core/onscreen_agent/api.js/streamOnscreenAgentCompletion` as the transport seam
- `store.js` exposes `_core/onscreen_agent/store.js/processOnscreenAgentMessage`; it runs before overlay messages are committed or reused after key lifecycle steps and receives a context object with `phase`, `message`, `history`, and `store`

Current runtime namespace:

- `store.js` also registers `space.onscreenAgent`
- `store.js` also publishes the active overlay thread snapshot at `space.chat`, including `messages`, live `attachments` helpers for the current surface, and a non-persisted `transient` registry for mutable prompt context blocks that should be emitted as a separate trailing prepared `_____transient` message
- prepared user messages with attachments should append one compact helper block that uses `Chat runtime access↓` for the runtime-access notes and `Attachments↓` before the attachment rows, so multiline helper data is visibly framed as continuing below each label
- `space.onscreenAgent.show(options?)` opens the overlay without submitting a prompt and preserves the current display mode unless `options.mode` explicitly requests compact or full
- `space.onscreenAgent.submitPrompt(promptText, options?)` opens the overlay, seeds the composer, and submits or queues the prompt through the owned send loop while preserving the current display mode unless `options.mode` explicitly requests compact or full

Current `processOnscreenAgentMessage` phases:

- `submit`: a user draft was converted into the first outbound message
- `assistant-response`: a streamed assistant reply finished, or a stopped reply produced partial content, before metrics and persistence run
- `execution-output`: browser execution results were converted into the follow-up user message; even successful no-return executions stay in this phase instead of triggering a missing-result correction turn
- `protocol-retry`: the overlay is generating a generic empty-assistant protocol-correction retry message
- `history-compact`: history compaction produced the replacement summary message

Phase-specific context fields may include `draftSubmission`, `responseMeta`, `executionResults`, `executionOutputMessage`, or compaction `mode`.

## Overlay Contract

Current overlay behavior:

- the module mounts only through the router overlay seam at `page/router/overlay/end`
- the shell supports compact and full display modes
- avatar drag positioning, action menus, history-edge resizing, and visibility recovery are owned by `store.js`
- `panel.html` passes `shell`, `avatar`, panel, thread, and dialog refs into `store.js`; the store uses those refs to clamp the saved position against the current viewport and to detect when the astronaut has drifted fully off-screen
- the full-mode history subtree mounts only in full mode; compact mode does not keep a history container mounted
- the full-mode history uses a non-scrolling outer shell for placement, chrome, and the resize grip, with an inner scroller that owns thread overflow
- in full mode, the history panel can be resized vertically from a full-width invisible handle that straddles the outer top or bottom border based on orientation, while a centered grip marks the draggable edge and the chosen height persists in config
- compact-to-full and full-to-compact switches should animate at the shell chrome layer: `store.js` owns a short display-mode transition phase, while `onscreen-agent.css` animates body width, panel chrome, and full-mode history entry so the overlay expands or settles instead of snapping
- when full mode mounts or the viewport changes, the store keeps the raw persisted history height instead of rewriting it to the current viewport fit; the rendered height is clamped against the currently available space on that side so reloads preserve the chosen size while smaller screens still fit
- the compact and full composer panels accept attachments from either the file picker or direct file drag-and-drop onto the chat box
- keyboard submit from the composer textarea and the form submit path may send a new message or queue a follow-up draft, but they must never trigger `requestStop()`; stopping the active loop stays an explicit primary-button click only
- saved `agent_x`, `agent_y`, and `display_mode` are loaded during init before prompt startup continues, and the floating shell stays unmounted until that startup config load has resolved so refreshes never flash the default bottom-left position before the stored coordinates are applied
- the first shell paint should ease in with a short reveal once startup positioning is ready, but avoid ancestor opacity fades on the shell itself because they break the backdrop blur used by the history and composer surfaces
- internal startup statuses such as prompt bootstrapping may gate controls, but they should not replace the composer placeholder because they are not user-relevant; user-visible errors and action results should still surface through `status`
- when the persisted LLM settings still match the shipped defaults and the API key is blank, the composer blocks the full textarea area with a blurred overlay and centered `Set API key` action until credentials are configured
- in compact mode, the floating UI bubble should stream the assistant reply live during the response without waiting for completion, but UI updates may be coalesced to animation frames and must render only the text before the execution separator
- compact-mode bubble streaming must suppress a trailing partial execution marker such as `_____` while the separator is still arriving, and once `_____javascript` appears it must ignore that marker and everything after it
- after mount and after config load, the store re-clamps the saved position to the current viewport and persists any correction back to config
- while mounted, the store also re-checks visibility on resize, `visibilitychange`, `focus`, `pageshow`, and on a periodic timer so monitor changes or desktop switches cannot leave the astronaut permanently off-screen
- browser execution blocks use the `_____javascript` separator and are executed locally through `execution.js`
- the surface uses the shared `createAgentThreadView(...)` renderer from `_core/visual/conversation/thread-view.js`
- overlay history relies on the shared thread bubble sizing rules; user messages must wrap long lines inside their own bubble so the history scroller stays width-stable and does not gain a horizontal scrollbar from chat text alone
- `view.js` enables the shared marked-backed chat-bubble markdown renderer for the overlay and assigns the `onscreen-agent-response-markdown` class so assistant-response-specific heading and table tuning stays local to this module
- `panel.html` loads `response-markdown.css` after the base overlay stylesheet; keep assistant-response markdown element overrides there instead of patching `_core/visual` for overlay-only presentation, and style markdown tables through the shared `.message-markdown-table-wrap` wrapper rather than changing the table element into a scroll container
- the full-mode `data-chat-thread` subtree is renderer-owned DOM, not Alpine-owned UI; `panel.html` should keep Alpine click wiring on the surrounding scroller, mark the chat-thread node with `x-ignore`, and keep mode-switch animation on the surrounding shell or panel chrome instead of remounting, fading, or transforming the thread subtree during live updates
- the compact floating UI bubble is a separate overlay surface owned by `panel.html`, `store.js`, and `onscreen-agent.css`; it should render through the shared markdown helper into a local content ref instead of using plain `x-text`
- `store.js` owns the compact bubble singleton lifecycle; `showUiBubble(...)` returns a bubble instance whose `update(...)` method only mutates the currently active bubble, recalculates auto-hide from the updated text length, and can reopen that same bubble after auto-hide until a newer bubble instance replaces it
- native dialogs use the shared dialog helpers from `_core/visual/forms/dialog.js`
- lightweight action menus use the shared popover positioning helper from `_core/visual/chrome/popover.js`
- the floating root and its compact action menu reserve effectively topmost z-index bands so routed content and dynamically rendered surfaces do not obstruct the overlay controls
- the compact composer action menu stays hidden through its initial positioning passes, closes when avatar dragging starts, and chooses up or down placement from the trigger button midpoint against the 50% viewport line rather than reusing the UI bubble breakpoint
- history-destructive controls must stay disabled when the thread is empty: full-mode footer `Clear chat`, full-mode footer `Compact context`, and compact-mode action-menu entries for those same actions should all be unavailable until history exists
- the loop supports queued follow-up submissions, stop requests, attachment revalidation, and animation-frame streaming patches; streamed execution cards must update their existing DOM in place so expanded details panes remain usable while tokens continue arriving, stable narration or other settled execution-card subtrees must not be recreated on each delta, completed execution rows must remain separate from later assistant turns so a new streamed reply only touches the live row, ordinary history renders must reuse unchanged keyed rows instead of rebuilding the whole thread, thread scroll should keep following while the user remains near the bottom and should decouple only after the user has scrolled up, and only when that direct patch cannot apply should the full-mode thread fall back to a frame-batched local rerender of the affected suffix
- full-mode streaming should not churn Alpine-owned composer placeholder or status bindings on each delta; live token updates belong in the renderer-owned thread only
- `store.js` should hold one prompt-instance object per chat surface, rebuild full prompt input when the overlay boots or the thread is reset or a new LLM turn is about to start, and reuse the cached system or examples or transient sections without recomputing the full prepared payload or token counts on every streamed delta
- prompt-history previews and token counts are derived from the prepared outbound request payload so request-prep extensions stay visible in the context window instead of only affecting the final fetch call, but exact recomputation should happen only at stable boundaries such as request preparation, stop handling, or settled assistant completion, never on every streamed delta
- the prompt-history modal must show the exact final prepared message payload that went or will go to the model, including example messages, any prepared `_____user` or `_____framework` blocks, and any separate trailing `_____transient` message
- the prompt-history modal footer owns prepared-payload navigation and copy helpers: it should be implemented as one outer footer row with exactly two inner groups, one left and one right, so the three navigation buttons stay on the left edge and the four copy or close buttons stay on the right edge; it should reuse the shared compact modal button treatment from `_core/visual/forms/dialog.css` instead of reintroducing large pill-style modal controls locally, keep all footer controls on the same fixed compact button width so icon-bearing buttons do not outgrow `Close`, jump across prepared real-user `_____user` blocks rather than every user-role message, pin the targeted prepared message to the top of the history scroller on every jump, label example turns as `EXAMPLE USER` or `EXAMPLE ASSISTANT` in text mode, and copy system-only, history-only, or full prepared-payload slices using the currently selected text or JSON mode
- text mode may render per-message sections for scanning, but JSON mode must stay a single raw prepared-payload block that remains mouse-selectable and copyable; real-user jump controls should still land on the same prepared message indexes in both modes, using line-based scrolling for the raw JSON view
- model-facing helper outputs should prefer compact flat text over JSON when the agent only needs a lightweight catalog or status list, because token stability matters more than shape richness in overlay history
- `execution.js` owns the execution transcript contract: successful no-return runs must emit `no result returned, no console logs`, result blocks must print `result↓` on its own line before the raw returned text so multiline payloads visibly continue below the label, structured result payloads should prefer `space.utils.yaml.stringify(...)` over JSON when the lightweight YAML helper can serialize them so history stays smaller, the live thread UI should retain full execution snapshots for the freshest execution result, and persisted execution-output turns should stay text-stable instead of being rewritten later with truncation markers or omission summaries
- no-result execution output is informational only; the loop must forward it as a normal `execution-output` turn and must not synthesize a missing-result protocol-correction message
- when any turn returns no assistant content, the runtime retries the same request once automatically before sending a generic protocol-correction user message
- empty-response protocol-correction messages must stay short and should tell the agent to continue from the conversation above instead of depending on a specific prior turn type such as execution output
- `space.skills.load("<path>")` loads onscreen skills on demand using skill ids relative to `ext/skills/` and excluding the trailing `/SKILL.md`
- only top-level skills are injected into the prompt catalog by default; routing skills can direct the agent to deeper skill ids
- any readable skill at any depth may also be auto-injected into the prompt when its frontmatter sets `metadata.always_loaded: true`
- loaded onscreen skills are captured as execution-side effects and inserted into the immediate execution-output turn with the full skill file content, even when the JavaScript block uses plain `await space.skills.load(...)` without a final `return`; once that turn is stale, history compaction may replace it with a shorter loaded-skill summary
- on-demand loaded skill content enters history through `skills.js` plus `execution.js`, not through `llm.js`; `llm.js` is responsible for how that already-loaded history is normalized and sent to the model
- skill discovery uses the app-file permission model plus layered owner-scope ordering, and same-module layered overrides replace lower-ranked skill files before the catalog is built
- readable group-scoped modules such as `L0/_admin/mod/...` may contribute additional onscreen skills; those skills are visible only to users who can read that group root
- skill ids must be unique across readable modules; conflicting ids are omitted from the prompt catalog and load attempts fail with an ambiguity error

## Development Guidance

- keep overlay-specific behavior local to this module
- do not import admin-agent internals for convenience
- use the router overlay seam rather than reaching around the router shell
- do not preserve compatibility shims inside this module just to keep old local helper paths alive; when ownership moves, update callsites and extension docs to the new canonical seam instead of maintaining mirrored prompt or request paths
- when another module needs to change overlay prompt, skill, request, or message behavior, add or consume the local JS seams here instead of reaching into private store state from outside the module
- keep onscreen skill discovery and runtime behavior separate from the admin agent even when copying skill content for starter coverage
- keep `ext/skills/development/` aligned with the current frontend and read-only backend contracts so the onscreen agent's development guidance does not drift
- keep prompt-surface strings lean: prefer `id|name|description` rows, short block labels, and body-only auto-loaded skill text over verbose wrappers
- if behavior becomes meaningfully shared with the admin agent, promote it into `_core/framework` or `_core/visual` instead of creating cross-surface dependencies
- if you change the router overlay contract, persistence paths, skill discovery, or prompt execution behavior, update this file and the relevant parent docs in the same session
