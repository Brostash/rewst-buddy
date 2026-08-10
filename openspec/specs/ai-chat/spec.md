# AI Chat Specification

## Purpose

The extension surfaces Rewst's AI assistant ("Cage-Free Rewsty") as a VS Code
chat model, lets the assistant run a bounded set of in-process "Buddy" tools, and
lets users apply the assistant's suggested edits behind a diff preview. This
capability covers the chat provider, its settings, the tool protocol, and the
related commands.

Source: `src/ui/chat/` (`model/RoboRewstyChatModelProvider.ts`,
`tools/toolProtocol.ts`, tool specs), `src/commands/ui/AskRewstAI.ts`,
`src/commands/ui/ResumeRewstAiConversation.ts`,
`src/commands/ui/ApplyRewstAiEdit.ts`.

## Requirements

### Requirement: Provide a Rewst-backed chat model

The system SHALL register a VS Code chat model (vendor `rewst-buddy`, displayed
as "Cage-Free Rewsty") that streams responses from Rewst's AI backend for the
active organization's session.

#### Scenario: User chats with the model

- **GIVEN** an authenticated session
- **WHEN** the user selects the Cage-Free Rewsty model and sends a message
- **THEN** the message is sent to Rewst's AI backend and the streamed response is
  shown in the chat view

### Requirement: Seed a fresh conversation for every ask

The system SHALL create a fresh backend conversation for every ask and write the
replayed visible chat history into it as role-aware seed messages via the
`createConversationMessage` mutation before sending the actual message. It SHALL
NOT look up, reuse, or continue prior backend conversations, and SHALL delete
each conversation after its stream completes (or is cancelled or errors). The
backend reads mutation-written records on the first ask only, so every ask
(including tool-round continuations and retries) seeds a brand-new conversation.

Source: `src/ui/chat/model/RoboRewstyChatModelProvider.ts`,
`src/sessions/conversation/ConversationClient.ts` (seedConversation).

#### Scenario: Follow-up turn

- **GIVEN** a user has sent a first message and the backend returned a
  conversation id
- **WHEN** the user sends the next message in the same visible chat
- **THEN** the extension creates a fresh backend conversation, reseeds the full
  visible history as role-aware chunks, and sends the new user turn
- **AND** the previous conversation is deleted after its stream completes

#### Scenario: System prompt is never seeded

- **GIVEN** the replayed VS Code history includes a System-role message (the
  VS Code-generated system prompt)
- **WHEN** the history is serialized into seeds
- **THEN** the System message is skipped entirely and no seed carries it

#### Scenario: Backend error

- **GIVEN** an ask errors before any output has streamed and no in-process
  Buddy tool has run
- **WHEN** the backend reports an error
- **THEN** the extension retries once with another fresh conversation
- **AND** the failed conversation is deleted

### Requirement: Cap and frame high-noise tool output in the seed transcript

When the visible chat history is serialized into seed chunks for a fresh
backend conversation, the system SHALL serialize editor tool results by tool
name. A
tool result whose tool name matches a terminal-reading tool (e.g.
`run_in_terminal`, `get_terminal_output`) SHALL be capped far tighter than
other tool results and prefixed with an explicit note that the content is raw
terminal output likely unrelated to the current request, so leftover
scrollback from an unrelated terminal session (a different Claude Code or CLI
run in the same integrated terminal) is not treated by the backend as an
implicit directive. Other tool results SHALL keep the standard, more generous
per-entry cap. Each seed chunk SHALL stay within the backend's per-message
character limit (chunks are split at entry boundaries, and the total history
is capped by dropping the oldest entries with an explicit omission marker).

Source: `src/ui/chat/model/statelessTranscript.ts`.

#### Scenario: Terminal tool output is capped and framed

- **GIVEN** the visible chat history includes a terminal-reading tool's result
  with output far longer than the terminal-specific cap
- **WHEN** the seed transcript is serialized
- **THEN** that tool result is truncated to the tighter terminal cap
- **AND** it is prefixed with a note marking it as likely-unrelated raw
  terminal output

#### Scenario: Non-terminal tool output is unaffected

- **GIVEN** the visible chat history includes a non-terminal editor tool's
  result (e.g. a file read)
- **WHEN** the seed transcript is serialized
- **THEN** that tool result keeps the standard per-entry cap and is not
  prefixed with the terminal-output note

#### Scenario: History larger than the seed budget

- **GIVEN** the visible chat history exceeds the total seed ceiling
- **WHEN** the seed transcript is serialized
- **THEN** the oldest entries are dropped and an explicit
  "(N earlier message(s) omitted)" marker is seeded in their place

### Requirement: Honor conversation type and custom instructions

The system SHALL send the configured conversation type
(`rewst-buddy.ai.conversationType`, `HELP_DOCS` or `WORKFLOW_DIAGNOSIS`) with each
message, and SHALL prepend `rewst-buddy.ai.customInstructions` to every message
when set. Custom instructions SHALL NOT be able to override Rewst's own system
prompt.

#### Scenario: Workflow diagnosis mode

- **GIVEN** `ai.conversationType` is `WORKFLOW_DIAGNOSIS`
- **WHEN** the user sends a message
- **THEN** the backend conversation is started in workflow-diagnosis mode

#### Scenario: Standing instructions

- **GIVEN** `ai.customInstructions` is set
- **WHEN** any message is sent
- **THEN** those instructions are prepended to the user's message

### Requirement: Control activity visibility

The system SHALL show the assistant's live activity (searches, tool calls) when
`rewst-buddy.ai.showActivity` is on, and otherwise suppress those intermediate
activity lines. This setting SHALL NOT disable answer streaming itself; answer
text may still appear incrementally as the backend produces it.

#### Scenario: Activity hidden

- **GIVEN** `ai.showActivity` is false
- **WHEN** the assistant runs tools mid-response
- **THEN** intermediate activity is not surfaced
- **AND** answer text may still stream normally

### Requirement: Run in-process Buddy tools with a per-response cap

The system SHALL let the assistant request local "Buddy" tools via fenced
`vscode-tool` JSON blocks that the extension intercepts and routes through the
capability registry, and SHALL cap the number of Buddy tool rounds per
response at `rewst-buddy.ai.maxBuddyToolRounds` (1–100, default 8).
Cage-Free Rewsty SHALL have its contributed Buddy tools available in-process
whenever the model is used, regardless of `rewst-buddy.mcp.enable`; that setting
controls the external `/mcp` bridge, not the chat model's local tool
contribution. The in-process path SHALL still honor the capability registry's
write-tool, dangerous-GraphQL, working-scope, approval, throttle, and
per-capability gates. Each in-process Buddy tool call that mutates Rewst data
SHALL be confirmed through the same custom approval modal and session-scoped
mutation-scope reuse cache that mcp-bridge's external MCP transport uses (see
mcp-bridge's `Reuse approvals only for reusable mutation scopes` requirement) —
Buddy tools never surface as native `vscode.lm` tool calls, so VS Code's own
per-tool confirmation/auto-approve UI does not apply to this path. Approving a
mutation scope from chat also satisfies it for the external MCP transport
within the same extension session, and vice versa.

#### Scenario: Assistant requests a tool

- **GIVEN** an in-progress assistant response
- **WHEN** the assistant emits a `vscode-tool` block
- **THEN** the extension parses it, runs the named Buddy tool in-process, and
  feeds the result back as the next turn

#### Scenario: External MCP disabled

- **GIVEN** `rewst-buddy.mcp.enable` is false
- **AND** the user is chatting with the Cage-Free Rewsty model
- **WHEN** the model is prepared for a turn
- **THEN** read-tier Buddy tools are still advertised through the local
  `vscode-tool` protocol
- **AND** write-tier and dangerous tools follow their own explicit toggles rather
  than the external MCP bridge toggle

#### Scenario: Round cap reached

- **GIVEN** an assistant response that keeps requesting tools
- **WHEN** the number of Buddy tool rounds reaches the configured cap
- **THEN** further tool rounds are stopped for that response

### Requirement: Parse the local tool protocol defensively

The system SHALL only treat line-start fenced `vscode-tool` JSON blocks as local
tool requests. It SHALL accept a single request object, an array of request
objects, and the shorthand shape where tool arguments live at the top level. It
SHALL ignore malformed blocks, non-line-start fences, and prose wrappers, and
SHALL cap the number of parsed requests from one assistant reply.

#### Scenario: Multiple local tool requests

- **GIVEN** an assistant reply with a `vscode-tool` block containing an array of
  valid requests
- **WHEN** the reply is parsed
- **THEN** each request is routed in order up to the per-reply request cap

#### Scenario: Invalid protocol text

- **GIVEN** an assistant reply with malformed JSON or an inline non-line-start
  `vscode-tool` fence
- **WHEN** the reply is parsed
- **THEN** no local tool request is emitted from that text

#### Scenario: Mixed Buddy and VS Code tools

- **GIVEN** a parsed reply requests both in-process Buddy tools and VS Code native
  editor tools
- **WHEN** Buddy tools are available
- **THEN** Buddy requests run through the in-process path first
- **AND** native VS Code tool calls are deferred or surfaced only when they are
  the remaining available route

### Requirement: Redirect backend-native Rewst tool attempts

When local Buddy tools are available, including when the external MCP bridge is
disabled, the system SHALL prevent backend-native Rewst tool activity from being
rendered as the final path. It SHALL interrupt the native attempt, send a neutral
correction that names the local `vscode-tool` transport, carry through any
resolved native tool arguments, and suppress abandoned native output. A repeated
native-tool attempt within the same backend turn sequence SHALL escalate through
the configured redirect-attempt budget — each subsequent correction states its
attempt number, still within the same neutral, transport-focused wording rules —
before finally giving up and surfacing a stop message; the ceiling is
intentionally high because surfacing that stop message is a last resort, not an
expected outcome.

#### Scenario: Backend tries a native Rewst tool

- **GIVEN** Buddy tools are advertised locally
- **WHEN** the backend emits activity for a native Rewst tool
- **THEN** the extension sends a correction turn in the same backend conversation
  explaining the local fenced protocol
- **AND** the abandoned native tool card and output are not shown to the user

#### Scenario: External MCP disabled but Buddy tools available

- **GIVEN** `rewst-buddy.mcp.enable` is false
- **AND** Cage-Free Rewsty has local Buddy tools available
- **WHEN** the backend emits native Rewst tool activity
- **THEN** the extension redirects that native attempt to the local `vscode-tool`
  transport

#### Scenario: Buddy tools disabled

- **GIVEN** no Buddy tools are available locally
- **WHEN** the backend emits native Rewst tool activity
- **THEN** that native activity is allowed to stream normally

#### Scenario: A later correction attempt succeeds

- **GIVEN** the backend has repeated a native Rewst tool attempt across several
  corrections, still below the configured redirect-attempt budget
- **WHEN** the backend finally follows a later correction and answers using the
  local tool protocol instead
- **THEN** the final answer streams normally and no stop message is shown

#### Scenario: The redirect ceiling is exhausted

- **GIVEN** the backend has repeated a native Rewst tool attempt
  until the configured redirect-attempt budget is exhausted despite escalating
  corrections
- **WHEN** the native tool is attempted once more
- **THEN** the extension gives up and shows the stop message asking the user to
  ask again, instead of attempting another correction

### Requirement: Surface sources and context usage

The system SHALL append backend-provided sources to final answers and SHALL track
backend context-window usage so the status bar can show the current org's usage
percentage and token counts.

#### Scenario: Sources returned

- **GIVEN** the backend completes an answer with source references
- **WHEN** the answer is rendered
- **THEN** the visible response includes the source list after the answer

#### Scenario: Context usage returned

- **GIVEN** the backend reports context usage for an org
- **WHEN** the event is processed
- **THEN** the current context usage state is updated
- **AND** the context usage status bar shows the rounded percentage and token
  breakdown

### Requirement: Open the assistant quickly

The system SHALL provide a `Rewst Buddy: Ask Rewst AI` command (bound to
Ctrl+Alt+R / Cmd+Alt+R) that opens the chat view, and a command to resume a
prior conversation.

#### Scenario: Ask Rewst AI

- **WHEN** the user presses Ctrl+Alt+R
- **THEN** the chat view opens ready for a message

#### Scenario: Resume a conversation

- **GIVEN** prior conversations exist for the org
- **WHEN** the user runs `Rewst Buddy: Resume Rewst AI Conversation`
- **THEN** recent conversations are listed and the chosen one's transcript opens
  as a markdown document

### Requirement: Apply suggested edits behind a diff preview

The system SHALL apply an assistant-suggested code change only after showing a
diff and an explicit confirmation, and SHALL NOT auto-save the result (leaving
save — and any resulting sync — to the user).

#### Scenario: User applies a suggestion

- **GIVEN** an assistant answer containing a code block and an active file
- **WHEN** the user runs `Rewst Buddy: Apply Rewst AI Suggestion`
- **THEN** a diff of the proposed change is shown, and on confirmation the edit is
  applied to the file without saving it

#### Scenario: Multiple code blocks

- **GIVEN** an assistant answer with several code blocks
- **WHEN** the user applies a suggestion
- **THEN** the user is prompted to choose which block to apply
