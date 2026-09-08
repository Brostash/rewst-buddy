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

### Requirement: Preserve conversation continuity safely

The system SHALL reuse a warm backend conversation for follow-up turns in the
same visible chat when the replayed VS Code history is still at the backend
conversation tip. It SHALL fork a fresh backend conversation when the visible
history has been rewound, and SHALL forget/delete the stale backend conversation
so rolled-back turns are not reattached later.

#### Scenario: Follow-up turn

- **GIVEN** a user has sent a first message and the backend returned a
  conversation id
- **WHEN** the user sends the next message in the same visible chat
- **THEN** the extension sends only the incremental user turn to the existing
  backend conversation
- **AND** it does not re-send the full visible transcript or the transport
  directive

#### Scenario: Restored checkpoint

- **GIVEN** a visible chat has been restored to an earlier checkpoint
- **WHEN** the user asks a different follow-up
- **THEN** the extension starts a fresh backend conversation with a stateless
  visible transcript
- **AND** the old backend conversation is forgotten so hidden rolled-back turns
  cannot leak into the new branch

### Requirement: Cap and frame high-noise tool output in the stateless transcript

When a fresh backend conversation is started with a stateless visible
transcript, the system SHALL serialize editor tool results by tool name. A
tool result whose tool name matches a terminal-reading tool (e.g.
`run_in_terminal`, `get_terminal_output`) SHALL be capped far tighter than
other tool results and prefixed with an explicit note that the content is raw
terminal output likely unrelated to the current request, so leftover
scrollback from an unrelated terminal session (a different Claude Code or CLI
run in the same integrated terminal) is not treated by the backend as an
implicit directive. Other tool results SHALL keep the standard, more generous
per-entry cap.

Source: `src/ui/chat/model/statelessTranscript.ts`.

#### Scenario: Terminal tool output is capped and framed

- **GIVEN** the visible chat history includes a terminal-reading tool's result
  with output far longer than the terminal-specific cap
- **WHEN** the stateless transcript is serialized
- **THEN** that tool result is truncated to the tighter terminal cap
- **AND** it is prefixed with a note marking it as likely-unrelated raw
  terminal output

#### Scenario: Non-terminal tool output is unaffected

- **GIVEN** the visible chat history includes a non-terminal editor tool's
  result (e.g. a file read)
- **WHEN** the stateless transcript is serialized
- **THEN** that tool result keeps the standard per-entry cap and is not
  prefixed with the terminal-output note

### Requirement: Keep every turn message within the backend's length limit

Rewst's conversation API rejects a message longer than its per-message character
limit, which fails the whole turn before any answer streams. The system SHALL
assemble each turn message against a character budget so that limit is never
reached, and SHALL clamp the message at the transport as a last defense.
Each elastic part of a turn SHALL be bounded: the tool manifest, the stateless
visible transcript, an ordinary user turn's own text, and the tool-result
messages fed back into the conversation. Trimming SHALL preserve the newest
content (the request being answered) and SHALL mark what was cut, so the
assistant reads trimmed content as incomplete rather than as the whole story.

Source: `src/utils/messageBudget.ts`,
`src/ui/chat/model/RoboRewstyChatModelProvider.ts`,
`src/ui/chat/model/statelessTranscript.ts`,
`src/ui/chat/model/toolTranslation.ts`,
`src/sessions/conversation/ConversationClient.ts`.

#### Scenario: Full tool registry on an opening turn

- **GIVEN** every Buddy tool is advertised alongside the chat's editor tools
- **WHEN** the user sends the first message of a chat
- **THEN** the assembled message stays within the backend's per-message limit
- **AND** the turn is answered rather than failing with a length error

#### Scenario: Oversized transcript or tool output

- **GIVEN** a visible transcript, user turn, or tool result far larger than the
  message budget allows
- **WHEN** the turn message is assembled
- **THEN** the newest content is kept and the overflow is trimmed with an
  explicit truncation marker

#### Scenario: Transport clamp

- **GIVEN** a message that still exceeds the backend's limit when it reaches the
  conversation transport
- **WHEN** the subscription is started
- **THEN** the message is clamped to the limit and the trimmed amount is logged

### Requirement: Advertise tools as a navigable catalog

The full description and args schema of every advertised tool exceeds what one
message may carry, so the system SHALL render the tool manifest against a
budget, spending it in advertisement order across three tiers: full description
plus exact args schema, then a one-line summary, then the tool's name alone.
Every advertised tool SHALL remain discoverable by name, and spending on an
earlier tool SHALL NOT cost a later tool its name entry — so a registry too
large to summarize still lists every tool and still gives the leading tools
their exact schemas. A Buddy tool that VS Code also passes back under its MCP
name (`mcp_<server>_<tool>`) is the same operation as the in-process spec and
SHALL be advertised once, on the in-process path. When any tool is abbreviated,
the system SHALL advertise a `buddy_tool_details` lookup that returns the full
description and exact args schema for the named tools, SHALL instruct the
assistant to expand a summarized tool before calling it rather than guessing its
args, and SHALL answer that lookup from the tools advertised for the current turn
— including the chat's editor tools — without touching Rewst data. Tools listed
in full SHALL be taken in advertisement order, so the chat's editor tools (used
on nearly every turn) keep their exact schemas.

Source: `src/ui/chat/tools/toolCatalog.ts`, `src/ui/chat/tools/toolProtocol.ts`.

#### Scenario: Manifest fits the budget

- **GIVEN** few enough tools that the full manifest fits the budget
- **WHEN** the tool instructions are rendered
- **THEN** every tool is listed with its full description and args schema
- **AND** no catalog section or details lookup is advertised

#### Scenario: Manifest overflows the budget

- **GIVEN** more tools than the manifest budget can list in full
- **WHEN** the tool instructions are rendered
- **THEN** the overflow tools are listed as name-plus-summary catalog entries
- **AND** `buddy_tool_details` is advertised in full as the way to expand them

#### Scenario: Registry too large to summarize

- **GIVEN** so many tools that even a one-line summary each overruns the budget
- **WHEN** the tool instructions are rendered
- **THEN** the editor tools advertised first still carry their exact args schemas
- **AND** the remaining tools are listed by name, expandable on demand

#### Scenario: The same Buddy tool arrives from VS Code and in-process

- **GIVEN** the chat passes a Buddy tool under its MCP name (the user configured
  the extension's own `/mcp` bridge as a chat MCP server)
- **AND** the same operation is available on the in-process Buddy path
- **WHEN** the manifest is rendered
- **THEN** the tool is advertised once, on the in-process path
- **AND** a request naming the MCP-prefixed form is still routed

#### Scenario: Assistant expands a summarized tool

- **GIVEN** a tool the manifest listed by summary only
- **WHEN** the assistant requests `buddy_tool_details` with that tool's name
- **THEN** the extension answers in-process with that tool's full description and
  exact args schema, without calling the capability registry
- **AND** the assistant can then call the tool with correct arguments

#### Scenario: Follow-up turn in a warm conversation

- **GIVEN** a backend conversation that already received the tool manifest for
  the current tool set
- **WHEN** the user sends a follow-up turn that reuses that conversation
- **THEN** the manifest is not re-sent
- **AND** the turn carries only a compact refresher: the protocol rules, the tool
  names available this turn, and how to expand a summarized tool

#### Scenario: Tool set changes mid-chat

- **GIVEN** a warm conversation whose manifest was sent for a different set of
  tools (e.g. the user changed the chat's tool selection)
- **WHEN** the next turn is assembled
- **THEN** the full manifest is sent again for the new tool set

#### Scenario: Unknown name in a details request

- **GIVEN** a `buddy_tool_details` request naming a tool that is not advertised
- **WHEN** the lookup is answered
- **THEN** the reply states that name is unavailable and offers the closest
  advertised names, rather than silently omitting it

### Requirement: Honor conversation type and custom instructions

The system SHALL send the configured conversation type
(`rewst-buddy.ai.conversationType`, `HELP_DOCS` or `WORKFLOW_DIAGNOSIS`) with each
message, and SHALL prepend `rewst-buddy.ai.customInstructions` to every message
when set. Custom instructions SHALL NOT be able to override Rewst's own system
prompt. Because the instructions precede the user's own turn in the message, they
SHALL be bounded, so an unbounded setting can never displace the request being
answered (see `Keep every turn message within the backend's length limit`).

#### Scenario: Workflow diagnosis mode

- **GIVEN** `ai.conversationType` is `WORKFLOW_DIAGNOSIS`
- **WHEN** the user sends a message
- **THEN** the backend conversation is started in workflow-diagnosis mode

#### Scenario: Standing instructions

- **GIVEN** `ai.customInstructions` is set
- **WHEN** any message is sent
- **THEN** those instructions are prepended to the user's message

#### Scenario: Oversized standing instructions

- **GIVEN** `rewst-buddy.ai.customInstructions` is long enough to fill the
  message budget on its own
- **WHEN** a message is sent on either the stateless or the reuse path
- **THEN** the instructions are trimmed with an explicit truncation marker
- **AND** the user's own turn is still carried in the message

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
SHALL use the built-in approval modal and session-scoped mutation cache (see
mcp-bridge's `Reuse approvals only for reusable mutation scopes` requirement).
External MCP calls delegate approval to their AI client and SHALL NOT populate
that editor cache. Buddy tools never surface as native `vscode.lm` tool calls,
so VS Code's own per-tool confirmation/auto-approve UI does not apply to the
built-in chat path.

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

#### Scenario: A catalog lookup is not Rewst tool work

- **GIVEN** an assistant response that requests `buddy_tool_details`
- **WHEN** that round contains no other Buddy tool request
- **THEN** it does not consume a Buddy tool round from
  `rewst-buddy.ai.maxBuddyToolRounds`
- **AND** a response that only ever requests tool details is still stopped by its
  own separate ceiling

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
