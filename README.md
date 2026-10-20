# lib-agent-harness

One Go interface for running AI agents and models through any supported
harness: the Codex, Claude, Grok, Command Code, Antigravity (`agy`) and fx
CLIs with their own logins, or any OpenAI-compatible HTTP endpoint or gateway. An
application written against it can let its users choose the AI service behind
each kind of invocation. Choosing a service changes configuration, not code.

The library launches local CLI binaries with their native login, or calls an
explicitly configured API endpoint with a caller-supplied credential source.
It does not require a hosted execution service. The selected provider's account
and billing rules still apply.

```sh
go get github.com/shhac/lib-agent-harness
```

Requires Go 1.26.4 and, for a CLI engine, that CLI installed locally. macOS,
Linux and Windows are supported. CLI protocols evolve: pin and test your
deployed CLI versions, and handle unsupported capabilities at runtime.

## One vocabulary

The root package `harness` defines what every execution mode shares:

- `Engine`: `harness.Codex`, `harness.Claude`, `harness.Grok`,
  `harness.CommandCode` (sessions only), `harness.Antigravity` (`agy`:
  catalog, account, native runs and sessions), `harness.Fx` (`fx`: catalog,
  account, native runs and sessions) or `harness.OpenAICompatible`.
  Its spelling is stable and safe to persist.
- `Provider`: where inference comes from. A CLI engine reads `Provider.CLI`
  (binary and login home); an API engine reads `Provider.API` (base URL,
  dialect, credential source). Setting the other half is refused.
- `Support(engine, operation, feature)`: the one question to ask instead of
  comparing engine names. It returns `native`, `composed`, `unsupported` or
  `unknown` with a reason, for the operations `Complete`, `Run`, `Session`,
  `Models` and `Account` and features such as `Effort`, `StructuredOutput`,
  `Resume`, `Steer`, `Compact`, `RestrictTools`, `CostReport`, `Quota` and
  `LoopbackPorts` (selected ports, Unsupported everywhere).
- `Usage` and `Cost`: token accounting in one shape. `Input` counts every prompt
  token, cached or not, and the cache figures are parts of it that are split out
  only when the provider reported them (`CacheKnown`). `Known` false means
  unavailable, never zero. `Cost` is the harness's own valuation at API rates,
  reported only when the harness states it.
- `ErrorFacts(err)`: fixed-vocabulary facts (engine, operation, family, cause,
  code, exit status, retry-after, and when an exhausted quota resets) for any
  error any mode returns. Error text
  never contains provider output or credentials.

```go
provider := harness.Provider{Engine: harness.Grok} // or Codex, Claude
if c := harness.Support(provider.Engine, harness.Session, harness.Available); !c.Usable() {
    return fmt.Errorf("sessions unavailable: %s", c.Reason)
}
```

Unsupported options are refused before any work starts, never silently
ignored, and no option ever widens what an agent may do.

## Choose the execution contract

| Package | Contract |
| --- | --- |
| `completion` | The model returns text and proposed application tool calls. Native tools are proven absent before inference; the application authorizes and executes proposals. |
| `native` | One native agent invocation, optionally resuming a session: an inline JSON-schema report, tool activity, a readable transcript, and usage. |
| `session` | Persistent bidirectional sessions with turns, streaming events, interruption, resumption, capability-aware steering, and restricted or sandboxed tool hosting. |
| `catalog` | The models and reasoning efforts an engine offers, without inference. |
| `account` | Login, plan, subscription quota windows and credits, without inference. |
| `sandbox` | Confined workspace file access and proved standalone OS command sandboxes. |
| `process` | Shared subprocess-tree containment, including Windows suspended-start job assignment. |

These are explicit execution modes. A native agent session must not substitute
for constrained completion when the application relies on native tools being
unavailable. Applications own prompts, orchestration, scheduling, tool
permissions, budgets, durable state, and retry decisions.

## Package structure

| Package | Owns |
| --- | --- |
| `harness` (module root) | Provider and engine configuration, capability vocabulary, usage, cost and typed failure facts shared by every mode. |
| `completion` | Constrained text and proposed application tool calls, with native-tool removal proved before credentialed inference. |
| `catalog` | Model and reasoning-effort discovery without inference. |
| `account` | Native login, plan, quota and credit observations without inference. |
| `native` | One native coding invocation, report, transcript and activity. |
| `session` | Persistent turns, transport, hosted-tool admission, transcripts and recovery; native CLI sandbox configuration and probes. |
| `sandbox` | Confined workspace I/O, shared path and read rules, Seatbelt/bubblewrap profiles, canaries, proofs, command verification cache, runners, supervisors and standalone command recovery. It imports no session code. |
| `process` | Subprocess-tree containment and live identity, shared by native engines and OS command sandboxes. |
| `internal/*` | Shared provider parsers, HTTP and native CLI mechanisms, login storage, restricted-runtime verification, skills, handle checks (`wsfile`), text bounds and schemas. `sandboxprobe` shares pure network witness helpers; `sandboxbridge` connects internal normalization, proof and state-lock adapters; `sandboxhook` and `testenv` support in-module tests. |

The sandbox and native CLI verification caches are separate and process-local.
macOS reuses matching command evidence; Linux runs the complete command proof
for every open, launch and resume. Package placement adds no capability claim.
See [the sandbox boundary](design-docs/2026-10-03-sandbox-package.md).

## Constrained completion

```go
result, err := completion.Complete(ctx, completion.Config{
    Provider: harness.Provider{Engine: harness.Claude}, // or Codex, Grok
    Model:    "haiku", // discover with catalog.Discover; no library model default
    Effort:   "low",
}, []completion.Message{
    {Role: "system", Content: "Answer briefly."},
    {Role: "user", Content: "Suggest a short progress caption."},
}, nil)
// result.Message, result.Usage, result.Cost, result.ContextWindow
```

An OpenAI-compatible endpoint, such as a gateway, uses the same call and result.
Its bearer token comes from a per-request function rather than a configuration
string, so it is never retained by the harness:

```go
result, err := completion.Complete(ctx, completion.Config{
    Provider: harness.Provider{
        Engine: harness.OpenAICompatible,
        API: harness.API{
            BaseURL:         "https://gateway.example/v1",
            Dialect:         harness.OpenAIChatCompletions,
            Credentials:     tokenSource,
            EffortParameter: harness.EffortReasoningObject,
        },
    },
    Model:  "provider/model",
    Effort: "high",
}, messages, tools)
```

`Effort` is sent only when `API.EffortParameter` says where the endpoint reads
it: `harness.EffortReasoningEffort` (top-level `reasoning_effort`; OpenAI, xAI)
or `harness.EffortReasoningObject` (`reasoning.effort`; Vercel AI Gateway,
OpenRouter). A local model server that takes no credential sets
`API.Unauthenticated` instead of `Credentials`; that is refused for any
non-loopback URL.

For OpenRouter (`BaseURL: "https://openrouter.ai/api/v1"`), set
`API.OpenRouter` to a `*harness.OpenRouterRouting`. It is never inferred from
the URL. Its `RequireParameters` routes only to providers that honour every
parameter sent, tools included, and `DataCollection` (`"allow"` or `"deny"`;
anything else is refused as `api_openrouter_data_collection_invalid`) is sent
as the request's `provider.data_collection`; unset fields are not sent. The
option also says the endpoint follows OpenRouter's error shape, so an error
object inside a 200 response is classified by its integer `code` as that HTTP
status: an embedded 429 is `rate_limited` like a real one. A 429, including a
`:free` model's per-minute or per-day limit, is `rate_limited` and retryable,
with `RetryAfter` set only when the response sent a delta-seconds
`Retry-After` of at most an hour (never for an embedded one). The library does
not retry or back off; the caller does, and a daily limit may answer the retry
with another 429. A 402 from any endpoint is `insufficient_credits`
(`quota_exhausted`), never retryable. Routing is not part of a session's
`Ref`: resuming under different routing continues the same conversation.

Grok completion uses the operator's Grok login and requires `WorkDirRoot`.
Before the first credentialed launch per binary and configuration, the library
runs Grok against a local server that refuses inference and checks the request
it would send: no tools, only the caller's system text beside Grok's fixed
vendor context, and the expected response schema. Real runs use a private
runtime home that shares only Grok's login file, never the operator's MCP
servers, hooks, skills or plugins, and any reported tool aborts the run. Grok
also sends each conversation to its own title-generation model on the same
account. Grok completion is unavailable on Windows.

A failed request that may have been billed still returns its `Usage` and `Cost`
beside the error, with an empty message. See [completion](completion/README.md)
for the transport boundary, API restrictions, CLI compatibility probes, and
scratch storage.

## Skills

Tools an application relies on often come with skills: a directory holding a
`SKILL.md` and the files and scripts it references. Set `Skills` on
`completion.Config`, `native.Config` or `session.Options`:

```go
skills := harness.Skills{Provided: []harness.Skill{
    {Name: "release-notes", Dir: "/app/skills/release-notes", Scripts: true},
}}
```

- `harness.Support(engine, op, harness.ProvidedSkills)` says whether the harness
  loads them itself (`native`) or the library composes them (`composed`).
  `Skills.Delivery = harness.SkillDeliveryComposed` forces composition, for
  skills that should behave the same on every engine.
- **Native:** Claude and Grok load provided skills through a private
  `--plugin-dir`, and a sandboxed Codex session links them into its runtime
  home. Their scripts run with the agent's own tools, inside its sandbox where
  there is one.
- **Composed, in runs and ordinary sessions:** an index with each `SKILL.md`'s
  absolute path is added to the instructions, and the agent reads skills with
  its own tools. `Skill.Scripts` is enforced only where the library hosts the
  tools; here the agent runs scripts under its own permission policy.
- **Composed, in completion (every engine, including OpenAI-compatible
  gateways) and restricted sessions:** the library offers `load_skill` and, for
  skills marked `Scripts`, `run_skill_script`. In completion those calls come
  back in `Result.SkillCalls`, and `completion.AnswerSkillCalls` answers them.
  A script runs only when the caller passes its call there, with no shell, a
  contained process tree, a timeout, bounded output and a minimal environment,
  or through the caller's own `Exec` hook. Restricted sessions host the same
  tools beside the caller's and need `Options.SkillRun.WorkDir` for scripts.
- **Global skills:** `GlobalSkillsInclude` keeps installed skills where the
  mode already loads them. `GlobalSkillsExclude` is accepted only where the
  mode loads none (restricted sessions and sandboxed Claude). Anything that
  cannot be honoured is refused.

## Models

```go
models, err := catalog.Discover(ctx, provider)
for _, m := range models {
    // m.ID is what the engine accepts, possibly an alias such as Claude's "opus";
    // m.Resolved is the concrete model it selects today, where stated.
    // m.Name, m.IsDefault, m.ContextWindow (0 = not stated)
    if m.EffortsKnown {
        offer(m.ID, m.Efforts, m.DefaultEffort)
    }
    // Tool calling, where the endpoint lists the model's parameters.
    if supported, known := catalog.SupportsTools(m); known && !supported {
        hide(m.ID) // an API session would be refused
    }
}
```

Discovery performs no inference and invents no catalog: Codex and Claude read
their installed CLI's account-aware catalog, Grok its agent protocol's model
state, and an OpenAI-compatible endpoint its `GET /models`. Efforts are listed
only where the engine states them.

`m.Parameters` holds the request parameters an endpoint says the model accepts,
read from OpenRouter's `supported_parameters` (such as `tools`, `seed`).
`m.ParametersKnown` says the endpoint listed them, so an empty list means
"none". When it is false, `Parameters` is nil and means only that nothing was
said. CLI engines never list them. The list is taken only as an array of at most
128 non-empty strings of at most 64 bytes each, with duplicates dropped.
Anything else leaves that one model's parameters unknown, and the rest of the
catalog is still returned. `catalog.SupportsTools(m)` answers whether `tools`
is listed, and whether that is known at all.

## Native sessions

```go
s, err := session.Start(ctx, session.Options{
    Provider: harness.Provider{Engine: harness.Claude}, // or Codex, or Grok with Policy.GrokPermission
    Model: "haiku",
    Effort: "low",
    WorkDir: workspace,
})
if err != nil { return err }
defer s.Close()

turn, err := s.StartTurn(ctx, session.Input{Text: "Summarize this project."})
if err != nil { return err }
for event := range turn.Events() {
    // Consume promptly; events are bounded. Apply your UI's privacy policy.
    show(event)
}
result, err := turn.Wait(ctx)
```

Native sessions use explicit provider execution policies. Default policy is
conservative but does not disable all installed customizations. Instructions
have explicit replacement/append semantics, and resume references bind the
session to its configured home, working directory, and policy. Keep references
in private application state; local paths are not public metadata. Account
identity labels are caller assertions, not cryptographic account verification.

Grok sessions run `grok agent --no-leader stdio` over the Agent Client Protocol.
Creating one runs the operator's configured Grok hooks. Grok's agent mode asks
permission only where a permission rule or its mode says to, and otherwise runs
edits and shell commands itself, so a Grok session has no permission default:
set `Policy.GrokPermission` to `session.GrokDenyWhenAsked` or
`session.GrokAllowWhenAsked`, which answer the requests Grok does send. Neither
is a read-only mode. A model or effort Grok would substitute is refused before
the first prompt. Steering is composed (cancel, then prompt). Restricted,
sandboxed and compacted Grok sessions, and Grok quota, are unsupported.

Command Code sessions run `cmd acp` over the Agent Client Protocol and reuse
the login that `cmd login` stored. Command Code keeps it in `~/.commandcode`,
which nothing relocates, so `Provider.CLI.Home` may only be empty or name that
directory.
`harness.CommandCode` is offered only as a session. Every session is put in
Command Code's Standard permission mode, which asks before each tool that
changes anything, and `Policy.CommandCodePermission` answers those requests:
`session.CommandCodeDenyWhenAsked` (the default) rejects each one and
`session.CommandCodeAllowWhenAsked` approves each one once. Deny-when-asked is
not read-only: reads run without asking, and Command Code permission rules in
the operator's configuration or a project's checked-in configuration can allow
tools without asking. A tool that would switch mode is rejected under either
policy, and a session that reports leaving Standard mode is stopped with
`CapabilityChangedPermissionMode` (phase `DuringSession`). Questions Command
Code asks the user through the same request are answered cancelled, never
guessed. `CMD_ZDR` (zero data retention enforcement, failing requests rather
than falling back to non-ZDR providers) and `CMD_LOCAL_ONLY` (no contact with
Command Code's backend) are preserved when inherited and accepted as caller
environment additions. Other `CMD_*`, `COMMANDCODE_*` and `COMMAND_CODE_*`
variables are not passed on, and adding them is refused. The model and effort
are set with `session/set_config_option` and checked against the configuration
the session reports; a value it refuses or does not apply is refused before the
first prompt. Command Code resumes an id it does not have as a new, empty
conversation, so a resume checks before and after `session/resume` that
`session/list` holds the conversation for `WorkDir`, and `Open` starts fresh
when it does not. Steering is composed. `cmd acp` takes no instructions or skill
paths, so `Instructions`, provided skills and `GlobalSkillsExclude` are refused, as are
restricted, sandboxed, browser and compacted sessions, account and quota reads,
and Windows, where `cmd` names the system command interpreter. A turn reports
its own usage, and the context is Command Code's own figure.

fx sessions run `fx acp` over the Agent Client Protocol and reuse the login
fx keeps in `~/.fx`, which nothing relocates, so `Provider.CLI.Home` may only
be empty or name that directory. Every session is put in fx's asking mode,
which asks before each action that changes anything, and `Policy.FxPermission`
answers those requests: `session.FxDenyWhenAsked` (the default) rejects each
one and `session.FxAllowWhenAsked` approves each one once. Neither grants an
"always" option, and a request that offers no option the policy wants, or two
options of the same kind or the same id, is answered cancelled, never
guessed. Deny-when-asked is not read-only: fx 0.0.14 asks before writes and
shell commands, but reads files and fetches web pages without asking. The mode
is set with `session/set_config_option`, and
the mode, model and effort are checked against the configuration the session
reports; a value fx refuses, or accepts without applying, is refused before
the first prompt. fx announces no mode change over the protocol, so a mode
changed outside the session is not observed. Steering is composed. fx only
appends session instructions to its own system prompt, so `Instructions` in
replace mode is refused; restricted, sandboxed, browser and compacted fx
sessions, account quota windows and constrained completion are unsupported. A
session inherits none of fx's own `FX_` variables and refuses them as
additions, except the operator's own protective switches `FX_MAX_AGENT_STEPS`,
`FX_ULTRAFAST` and `FX_AUTO_UPGRADE`, whose bounds, cost and network choices
are preserved. A turn reports its own usage, cache reads and writes included,
and the context is fx's own figure. fx counts the main agent's usage only, not
that of any agent it delegates to.

Consume turn events while the turn runs. `Wait` does not drain the stream;
backpressure fails explicitly instead of silently dropping tool activity.
Cancellation of a wait only stops waiting. Interruption and session closure are
separate operations. Tool events say what an agent did (`harness.ToolActivity`):
`tool_started` carries the tool's arguments in `Input` (always valid JSON) and
`tool_completed` carries its result text in `Output`, with `Status` saying
whether it failed and `ExitCode` where a command reports one. Codex reports
command, cwd, output and exit code, file changes, MCP and dynamic tool
arguments and results, and web search queries; Claude its `tool_use` input and
`tool_result` content; Grok, Command Code and fx `rawInput` and `rawOutput` or
content (a Command Code tool is named by its protocol kind, such as `read` or
`execute`, since its title carries paths and commands); an API
session the model's arguments and the handler's result. A hosted call is
reported once, by the engine's own events. Each of `Input` and `Output` is
bounded to `session.MaxToolPayloadBytes` (64 KiB) with `InputTruncated` or
`OutputTruncated` set; a truncated `Input` becomes a JSON string holding the
head of the original text. Payloads are passed through unredacted apart from
the library's own tool-channel credential: they can contain private data, and
applications apply their own visibility rules.

Images a tool returns, such as a browser screenshot or a generated image, are
taken out of the text and carried on `tool_completed` as `Images`, decoded
(`MediaType` and raw `Data []byte`):
at most `session.MaxToolImages` (4), each at most `session.MaxToolImageBytes`
(4 MiB), PNG, JPEG, GIF or WebP, with `ImagesOmitted` counting the rest.
Claude's image blocks are checked live (a claude-in-chrome screenshot), as are
Codex's native generated images (Codex 0.159.2). A Codex `imageGeneration`
completion carries the CLI's `savedPath` in `Output` and decodes its base64
`result` into `Images`; base64 never enters the text payload. The library does
not open the reported path. Go callers receive bytes directly; JSON-serializing
an event encodes its byte fields as base64. Oversized, malformed or unsupported
image payloads increment `ImagesOmitted`, while the path remains available under the normal
text bound. Failed generations retain their native status and carry no image.
Codex MCP results and Grok content are read as their protocols declare them, and
`harness.Support(e, Session, ToolImages)` says which.

`Health` reports `running`, `active`, `quiet`, `idle`, `exited` or `failed` from
what has been observed, without contacting the CLI. Quiet means nothing recently
and the process is alive: that is unknown, not stuck, and the library draws no
conclusion from it. Health describes a process and never means a task finished.

Usage is published as it is observed. A turn makes many model requests, so each
response's reported figures arrive as a `usage` event with `Final` false, and the
turn's own accounting arrives with `Final` true. `Result.Observed` keeps the
per-response figures even when a turn fails or is interrupted, where a provider's
terminal counters are often absent or belong to an earlier turn; it is evidence
of what was seen, not a measurement of the turn. Nothing is summed across turns.

A lost CLI reports `*ProcessError` with its exit status and a fixed reason code,
still wrapping `ErrTransport`. Captured standard error never enters an error
value; set `OnDiagnostic` to receive a bounded, control-stripped, credential-
redacted tail for your own private records.

## Sessions over an OpenAI-compatible endpoint

An endpoint is only a model, so the library is the agent. `session.Start`,
`Open` and `Resume` accept a `harness.OpenAICompatible` provider with the same
Session, Turn, Event and Result shapes as the CLIs:

```go
s, opened, err := session.Open(ctx, session.Options{
    Provider:    harness.Provider{Engine: harness.OpenAICompatible, API: api},
    Model:       "provider/model",
    RuntimeHome: "/private/state/gateway-sessions", // owner-only; holds transcripts
    Restriction: &session.Restriction{Tools: session.ToolHost{
        Server: "app", Tools: tools, Handler: handler, // no Bridge or Dir: called directly
    }},
}, storedRef)
```

- **Tools:** only your hosted tools and composed skills exist, because the
  library writes every request. Your handler runs one call at a time, with the
  same closing-tool and settlement rules as restricted CLI sessions.
- **Models without tool calling:** every session sends tools, so pass the
  catalog entry you chose the model from as `Options.CatalogModel`. When that
  entry lists its parameters without `tools`, `Start`, `Open` and `Resume`
  refuse with an `*UnsupportedError` whose code is
  `session.RefusedModelWithoutTools` (`model_without_tool_calling`), before
  any file is written or request sent. With no entry, or one whose
  `ParametersKnown` is false, the session goes ahead, because unknown is not
  "no": the library never runs discovery for a session, and a failed
  discovery never blocks a model you configured. The entry's `ID` (or its
  `Resolved`) must equal `Model`, otherwise the session is refused with
  `RefusedConflict`. The entry is advisory and not part of a `Ref`. A model
  that lists `tools` can still fail mid-run, as a typed turn failure. A CLI
  engine refuses `CatalogModel`.
- **Each turn:** the whole history is resent (Chat Completions keeps no server
  state) until the model answers without tool calls, bounded by
  `Options.Loop`, which also carries an optional per-response `MaxOutputTokens`
  cap.
- **State:** the conversation is an fsynced transcript under
  `RuntimeHome/sessions/<id>`, locked while open, and never holds a
  credential.
- **Crash recovery:** a call interrupted by a crash is answered as having an
  unknown outcome and is never run again (`Session.Recovered()` reports it).
- **Turn control:** interrupting cancels the request and the running handler.
  Steering is composed.
- **Not offered yet:** compaction, streamed text deltas, quota and account.

### Workbench

On Linux and macOS, `read_file`, `search_files` and `edit_file` are
temporarily not offered: “workbench file tools are off until their workspace
check is verified”. Standalone `Workspace.Read`, `Search` and `Edit` return
a typed `*sandbox.RefusalError` (`not_offered`, capability family,
`Unsupported`) before parsing arguments or performing content I/O.
There is no opt-in bypass. `list_files`, opt-in atomic `write_file`, skills,
caller tools and proved commands continue.

API workbench `Start`, `Open` and `Resume` continue with this reduced
surface. `Session.Capabilities().WorkbenchTools` lists each configured tool
with its availability and reason, returned as a defensive copy. A generated
system notice tells the model which content tools are absent; advertisements
and hosted admission use the same effective definitions. All six names remain
reserved. Forced calls are refused before handlers run and do not close
admission; an ordinary closing tool can still succeed.

`harness.Support` reports aggregate `WorkspaceRead` and `WorkspaceWrite`
as unsupported on Linux/macOS because their full tool sets are unavailable.
This does not deny the surviving listing or write tool, or change command
claims. Windows retains its existing file-tool behavior. Configuration digests
and reference formats do not change: resumption reconstructs availability,
preserves historical content results, and never replays old calls. The notice
is regenerated outside durable transcript content and does not accumulate.

Restoration requires a reviewed storage/admission invariant against concurrent
links, renames, unlinks and external mutation (LAH-27 design, LAH-28 implementation);
passing repetitions or independent stat samples cannot establish that invariant.
The [storage/admission design](design-docs/2026-10-05-workspace-storage-admission.md)
selects per-task dedicated local filesystem roots; ordinary directories remain
refused. It is a design for review, with implementation deferred until a consumer
needs API-engine file tools. Current behavior is unchanged.
Consumer migration is tracked separately in LAH-33/34 under the approved split.
The [investigation and validation record](design-docs/2026-10-03-sandbox-package.md#lah-32-review-repair-after-main-afbaf07)
separates modeled admission observations, verified content refusals, synthetic
session checks and outstanding platform enforcement evidence.


Workspace file access opens through `sandbox.OpenWorkspace(sandbox.Config)`;
session hosts its tools and preserves the existing workbench API and error types.
Standalone command execution uses `sandbox.Open`; `session.OpenCommandSandbox`
is a deprecated compatibility wrapper for v0.23.0.
See the [package-boundary design](design-docs/2026-10-03-sandbox-package.md).

Set `Options.Workbench = &session.Workbench{}` for the available workspace tools
on an OpenAI-compatible session, on Linux, macOS or Windows. `WorkDir` must
be an absolute existing directory; it and `RuntimeHome` must not contain
one another. Its resolved path and workbench permissions form part of the
resume reference. CLI engines refuse this option.

- On Windows, `read_file(path, offset, limit)` reads UTF-8 text: files at most 16 MiB,
  at most 2,000 lines and 64 KiB per result, with continuation notes.
- `list_files(path, depth)` lists at most 2,000 entries, to depth 8,
  visiting at most 20,000 names. Links, FIFOs, linked files and mounts are
  marked; Windows omits the listing's linked mark but still refuses linked
  reads. Links are never followed while listing.
- On Windows, `search_files(pattern, literal, path, glob)` uses RE2, or literal text,
  with patterns at most 4,096 bytes. It returns at most 200 matches in
  `relative:line: text` form, cutting each result line to 400 bytes on rune
  boundaries.
  It skips files over 1 MiB, NUL in the first 8 KiB, invalid UTF-8, links,
  non-regular files, hard links and mounts, with counts. A glob containing
  a slash matches the workspace-relative path; otherwise it matches the
  basename.

Listings and searches skip `.git` and `.harness-workbench-*.tmp`, use bounded
walks, retain partial results with an incomplete note, and state truncation.
Neither observes `.gitignore`. Results also fit the host's `MaxResultBytes`,
which must be at least 4,096. All six workbench tool names are reserved when
the option is set.

Opened handles must stay on the root's mount; regular files must have one
link. Refusals include `file_linked`, `file_other_mount`, `file_not_regular`,
`file_too_large`, `file_not_text`, `file_reserved`, `file_outside_workspace`,
`file_path_invalid`, `file_not_found`, `file_not_directory`,
`file_is_symlink`, `path_through_symlink`, `path_not_listed`,
`file_unreadable` and `arguments_invalid`. When mount identity cannot be
established, launch refuses with `workbench_mount_check_unavailable` before
creating a transcript.

One workspace worker executes the tools. Cancellation waits for its current
I/O to settle. After a 10-second cancellation grace, a stuck read fails the
session with `workspace_io_stuck`; no later call or turn is admitted. The
transcript records an unknown outcome, shutdown releases its lock, and
`Release` returns the error. `Close` remains void. The single abandoned
worker and its read handle remain until the syscall returns. Health preserves
an earlier session failure; Release still reports abandoned workspace I/O.

On Windows, `harness.Support` reports `WorkspaceRead` and `WorkspaceWrite` as `Composed`,
and `RestrictTools` includes the library's workbench tools.
A caller-supplied `CatalogModel` known to lack tools refuses before launch;
unknown tool support proceeds.

**Data caveat:** through gateways such as OpenRouter, prompts and every tool
result, including file contents, go to third-party model providers under their
own data policies; some free endpoints may log or train on inputs. Keep the
workspace free of secrets, outside hard links and mounts. File tools reject
multiply-linked files and other mounts. Keep other processes from injecting
outside data while the session runs.

Set `Workbench.Write` to add `write_file(path, content)` and, on Windows,
`edit_file(path, old, new, replace_all)`. Writes replace UTF-8 content up to
1 MiB atomically, creating parents when needed. Edits require exactly one
match unless `replace_all` is true. Neither follows symlinks or writes `.git`;
edits also refuse hard links. Existing permission bits are preserved, with
set-ID and sticky bits cleared; read-only files are refused. New files use
`NewFileMode` (default 0600, only bits within 0666), independent of umask.
New directories add execute wherever the mode has read. Windows inherits the
directory ACL and does not sync directories. A writing session's effective
mode is part of its reference; changing it on resume is refused.

Before rename, a failed or cancelled write removes its temporary and returns
`write_failed`. After rename it completes durability even if cancelled;
failed durability returns `write_outcome_unknown`, records an unknown
outcome and leaves the new content in place. Its tool event carries
`ErrorFacts` with that code, family `turn`, and no automatic retry. Resume never repeats an
interrupted call and removes only that session's temporaries in unanswered
write targets' directories.

On macOS and Linux, `Workbench.Commands = &session.Commands{}` adds
`run_command(command, dir, timeout_seconds)`. macOS runs `/bin/sh -c` through
a pinned Seatbelt profile; Linux uses bubblewrap 0.8.0 or later. Both prove
the sandbox with disposable files before opening session state or resolving
credentials, and refuse a failed proof. Windows Commands remain unsupported.
`Support` reports `Sandbox` as `Unknown` on macOS and Linux (proved per
launch), `Background` as `Composed`, and `Loopback` as `Unknown` on macOS
and `Unsupported` on Linux.

Linux requires `bwrap` on the library process's PATH. Install it with
`apt install bubblewrap`, `dnf install bubblewrap` or `pacman -S bubblewrap`.
Ubuntu 22.04's 0.6.1 is too old; install a newer build. Ubuntu 24.04+ also
needs an AppArmor profile permitting bwrap's unprivileged user namespaces,
or the host administrator's `kernel.apparmor_restrict_unprivileged_userns=0`
setting. The library never changes host sysctls. It checks the version and
the complete namespace/privilege flags with a trial run, then runs its canary.
The fixed pre-launch codes are `sandbox_tool_missing`,
`sandbox_tool_outdated` and `sandbox_namespaces_unavailable`; diagnostics
never include bwrap stderr and no refusal falls back to unsandboxed execution.

Linux starts with an empty root, private `/tmp` and `/run`, minimal `/dev`
and `/proc`, and a read-only pinned system set: `/usr`, `/bin`, `/sbin`,
`/lib`, `/lib32`, `/lib64`, `/libx32`; `/etc/passwd`, `group`, `nsswitch.conf`,
`hosts`, `localtime`, `ld.so.cache`, `ld.so.conf`, `ld.so.conf.d`, `ssl/certs`,
`ca-certificates`, `alternatives` and `os-release`. Missing system entries
are skipped; host symlinks are recreated. WorkDir, RuntimeHome and scratch
cannot be inside that system set or `/etc`. Writable Linux Commands require
an existing non-symlink `.git` directory or file for the final read-only
overlay; a missing overlay refuses launch rather than allowing metadata
creation. Each command has its own PID and network namespaces, no
capabilities or nested user namespaces, and `--die-with-parent`. Everything
it starts ends with that command, including background servers.
`Commands.Loopback` is refused on Linux; a single command may still start
and request its own server in its private namespace.

### Command process inspection

`sandbox.Options.ProcessInspection` and `session.Commands.ProcessInspection`
are opt-in requirements. Ask `harness.Support(engine, operation,
harness.ProcessInspection)` before requesting them:

| Platform / operation | Availability | Boundary / reason |
| --- | --- | --- |
| Linux shared runner (OpenAI-compatible Session) | Unknown until proof | Each Run/Start's own tree in its private PID namespace and private `/proc`; separate commands are outside it, even under one Open. |
| macOS shared runner | Unsupported | `process_inspection_unenforceable`: no same-sandbox process-info/sysctl boundary has been proved. |
| Windows and other platforms | Unsupported | Process inspection unavailable on this platform. |
| Native engines, runs and other operations | Unsupported | Shared command evidence does not prove native inspection. |

```go
c := harness.Support(harness.OpenAICompatible, harness.Session, harness.ProcessInspection)
if !c.Usable() {
    return fmt.Errorf("inspection unavailable: %s", c.Reason)
}
commands, err := sandbox.Open(ctx, sandbox.Options{
    WorkDir: workspace, RuntimeHome: privateHome, ProcessInspection: true,
})
if err != nil { return err } // Unknown permits an attempt; Open must prove it.
defer commands.Close()
result, err := commands.Run(ctx, sandbox.CommandRequest{
    Command: "sleep 5 & child=$!; ps -o pid,pgid,nice,stat,lstart,command -p $child; wait $child",
})
```

The installed `ps` and Linux `/proc` expose PID, PGID, nice, state, start/birth
identity and command for the command's own tree. Unrelated same-user host
processes and other command sandboxes remain outside that boundary, including
their arguments, environment and open files. No filesystem, execution or
network grant is widened. A disposable pre-launch canary checks a live child
and an outside fixture carrying random argv, environment and open-file markers.
The shell namespace must differ from the outside fixture, and its rooted proc
view must report exactly one NSpid identity. Together these controls establish
that every visible proc entry belongs to that namespace or its descendants. An
absent host PID is invisible; a visible numeric collision belongs to this private
view. Per-entry status checks are sanity checks, not independent isolation proof.

Refusals use `process_inspection_unenforceable`. Proof failures report
`process_inspection_unavailable`, `sandbox_not_enforced`, or `probe_timed_out`
with `harness.ErrorFacts(err).ProofStep == "process_inspection"`. Failure never
downgrades the request or prepares command state. Non-inspection profiles and
keys are unchanged; inspection adds `bwrap-workbench-v5-process-inspection-v3`
to Linux proof keys, with fresh proof per Open. See the
[inspection design and pending evidence](design-docs/2026-10-05-process-inspection.md).

### Command sandbox

`sandbox.Open` opens the same proved command boundary without a
model session, provider credentials, or inference. `RuntimeHome` is required:
it must be an existing private directory outside `WorkDir`, holding recovery
markers and scratch. `Write`, `Read`, `Env`, `Timeout`, `Background` and
`Loopback` follow the workbench's rules. Env uses the existing denylist; a path
named in Env grants no access. The sandbox never inherits the parent's full
environment or widens filesystem permissions.

```go
box, err := sandbox.Open(ctx, sandbox.Options{
    WorkDir: workspace, RuntimeHome: privateRuntimeHome,
    Write: true, Loopback: true,
    Timeout: 2 * time.Minute,
})
if err != nil { return err }
defer box.Close() // check its error when cleanup certainty matters

result, err := box.Run(ctx, sandbox.CommandRequest{Command: "npm test"})
// result.ExitCode, Stdout, Stderr, TimedOut, Truncated
server, err := box.Start(ctx, sandbox.CommandRequest{Command: "npm run dev"})
if err != nil { return err }
defer server.Stop()
// Start reports process launch; the caller checks server readiness.
// server.Done() closes on settlement; server.Result() waits for it.
```

Run defaults to two minutes. Options.Timeout may raise the bound up to
`sandbox.MaxStandaloneTimeout` (two hours), including caller-supervised 45-minute
project checks; a request can shorten that bound. Sessions and hosted runners with
a nonzero output budget retain `sandbox.MaxSessionTimeout` (ten minutes). Timeout
returns exit -1 with `TimedOut=true`. Caller context cancellation
stops and settles the tree before returning the context error. Close cancelling
an in-flight Run or Start returns `CommandSandboxClosed` when the caller's
context is still live; caller cancellation retains the caller's context error.
Each output stream
captures at most 64 KiB, plus a truncation marker, and continues draining.
Start has no timeout (a nonzero request Timeout is refused); its context, Stop
or Close ends it. Result is meaningful when its error is nil, including an
ordinary nonzero exit. Stop waits for settlement and is safe to repeat.
If Start returns an error after process launch, it also returns a non-nil,
settled handle. Call Result on that handle to recover bounded output and the
PATH report; its error still means the command's effects are uncertain. An
error before launch returns a nil handle. The deprecated session wrapper preserves
this contract too; check the handle even when Start fails.

On macOS, opt-in Loopback allows binds and inbound connections on **every
local interface**. A server bound to 0.0.0.0 or a LAN address may be reachable
from other machines; outbound traffic off the machine stays refused. This
applies both to standalone commands and Workbench run_command. The proof
checks loopback, interface TCP binds, UDP binds and UDP sends, wildcard binds,
and a host-side interface listener nonce; the off-machine witness must fail.
A started server is reachable from the owner browser. Without Loopback, localhost test suites that bind
and connect fail.

On Linux, **a command always has its own private localhost and never the
host's**, with or without Loopback. Run accepts Loopback and proves its own
localhost works. This proof requires **OpenBSD nc** (`netcat-openbsd` on Debian
and Ubuntu); traditional netcat and BusyBox nc have incompatible listener
syntax and are not supported. A suite can start a server and request it within
one command.
The host's loopback listener stays unreachable in both configurations. No
seccomp layer blocks the private loopback. Start with Loopback returns a typed
`sandbox.RefusalError` for operation `start`: a server in bubblewrap's private
network namespace cannot be reached from the owner's browser. Start without
Loopback is available for other long-running work. Workbench.Commands still
refuses Loopback on Linux. Windows command sandboxes remain unsupported.
`harness.Support` claims are unchanged.

Close stops admission, cancels admitted work, waits, reaps background children
and removes scratch. Later Run/Start calls return `CommandSandboxClosed`.
Typed `sandbox.CommandError` failures include `CommandStartFailed`, `CommandOutcomeUnknown`,
`CommandProcessLimit` (64 live commands) and `CommandCleanupUnknown`. A failed
cleanup preserves recovery state. Standalone state lives under
`RuntimeHome/commands/<random id>` with a lifetime lock; a subsequent Open
sweeps unlocked stale entries and leaves live or uncertain entries alone.
Before deleting command state or re-preparing scratch, cleanup attempts to
restore owner read/write/search permission on real directories within that
tree. It uses anchored handles, never follows symlinks, never changes file modes and refuses
other mounts. This reclaims read-only checkouts and caches left by commands.
On macOS, an unreadable directory is first repaired through its anchored
parent using a directory-only, no-symlink kernel lookup; cleanup then opens
and verifies its handle. Kernels that refuse that lookup retain the normal
cleanup failure rather than weakening the no-follow rule.
Linux repairs through the opened descriptor with fchmodat2; its compatibility
fallback requires accessible `/proc/self/fd`. If neither mechanism works,
remaining removal failures report through the existing cleanup error.
Removal failures retain the existing cleanup errors; a failed stale entry is
retried on later Open calls while other entries and the new Open proceed.
These changes do not change `harness.Support` claims.
Pre-launch refusals and failed proofs return `sandbox.RefusalError` and
`sandbox.ProofError`. `sandbox.StateError` reports unusable or locked recovery state. The deprecated
`session.OpenCommandSandbox` wrapper and its options, result and handle types
remain for one release; it translates every error to the v0.22 session vocabulary.
The wrapper also carries each fixed proof step into
`session.CapabilityError.ProofStep` and `harness.ErrorFacts`. Unknown steps are
empty; no-step errors retain their legacy wording.

See [the command sandbox design](design-docs/2026-10-03-command-sandbox.md).

Every command (`Run`, `Start`, `Runner.Execute`, API workbench `run_command`
and the deprecated session wrappers) filters its merged inherited/caller PATH
against the existing system/toolchain, workspace, explicit Read and private
scratch read policy. Retained entries are canonical absolute directories, in
original order, including duplicates. Empty and relative entries are dropped,
as are missing, non-directory, unresolvable and outside-read-set entries. Resolved targets containing a PATH
separator are also dropped because they cannot be represented as one entry.
Symlinks qualify only when their resolved directory is readable. Permissions
are never widened to rescue a tool. An absent or all-dropped PATH becomes a
fresh empty directory through an anchored private-scratch descriptor, preventing implicit cwd or
default-path lookup. Unrepresentable scratch paths or preparation failures
refuse launch. The runner captures the merged environment at creation
and rechecks its PATH on each invocation; it never changes the parent environment.

Dropped entries produce one `[harness PATH: ...]` note at the start of
`CommandResult.Stderr`, including fixed reasons, quoted path text and an omitted
count for long lists. The note consumes the existing stderr/hosted-result budget;
ordinary output truncation still applies. `StartedCommand.Result` exposes the
same note. Nonzero exits and
timeouts retain it; settled cancellation/unknown-outcome results retain available
diagnostics alongside the error. Pre-launch refusals have no command report.
Hosted `run_command` preserves that same single bounded note in success and
failure results. With captured stderr, failures are error-marked JSON containing
`stderr`, `truncated`, `error` (at most 128 bytes), `exit_code` and `timed_out`.
Cancellation, deadlines, closure and unknown outcomes retain the payload without
changing unknown-effect accounting; generic errors retain capture too. Without
capture, legacy plain-text failure answers remain unchanged. Admission stays
serialized, and cancellation waits for actual settlement before another turn.
Successful process startup is retained after settlement even when priority setup
fails before notification; Start preserves its handle and diagnostics with an
uncertain outcome. The priority refusal remains enforced.

macOS grants execution only with the same selectors used for data reads,
including the data-volume exclusion and reserved-temporary denial. The canary
requires an OS permission refusal before an unreadable native binary starts,
plus readable executable, interpreter and `#!/usr/bin/env node` controls.
Disposable PATH fixtures use `#!/bin/sh` scripts, without copied Apple binaries
or signing tools. Darwin independently checks native execution using installed
`/bin/echo` under a disposable read policy excluding it while granting the
dispatcher interpreter files individually, without granting /bin. Script-read refusal alone never certifies native confinement.
Linux keeps its existing bubblewrap mounts: an unbound executable must be inaccessible
or permission-refused, without claiming macOS errno behavior. PATH canonicalization
reduces alias dependence; the OS boundary remains authoritative if paths change.

Command proof failures expose a sanitized `sandbox.ProofError.Step` and
`harness.Facts.ProofStep`: `fixture_preparation`, `outside_control`,
`sandbox_launch` or `execution_judgment`. These fixed facts name the failed
check without paths or raw output. Failed/interrupted proofs create no command
state and certify no capability. Scratch replacement or ownership changes refuse
command preparation; anchored fallback writes cannot follow a replaced Tmp symlink.
Cancellation during probe cleanup refuses evidence publication, and cancelled
requests cannot reuse cached evidence or return a successful public proof.

Both proof revisions include the filtering-policy revision, invalidating old
evidence. These are command-policy corrections, not new `harness.Support` claims;
native-session restrictions remain separate.

Linux `Commands.Read` refuses paths overlapping `/run` (including resolved
`/var/run` aliases) or containing `/tmp`, with `sandbox_read_path_invalid` refusal.
Read-only binds do not prevent pathname Unix-socket connections: sockets
already inside WorkDir or an allowed Read directory remain connectable.
Keep host service sockets out of those directories.

The Linux proof must reproduce each path's depth and covering location.
Outside home, `/tmp` and `/run`, disposable proofs start under `/var/tmp`;
shallower placements such as `/workspace`, `/app` or `/srv/x` cannot be
reproduced and refuse with `sandbox_unavailable`. Use a deeper workspace
and RuntimeHome. Proofs under home create `~/wb-proof-*` directories;
normal cleanup removes them, but a crash or SIGKILL can leave dummy fixtures
(including `.git/config`). After stopping the library, remove abandoned
proof directories; the library does not sweep them automatically.

The Linux canary prefers actual TCP connects through bash's `/dev/tcp` and
a Unix socket connect through `nc -U`. If nc is missing or lacks usable `-U`
(or bash is absent for TCP), all three structural observations must succeed:
a different `/proc/self/ns/net` inode, only `lo` in `/proc/net/dev`, and an
absent probe socket path. An unreadable or failed observation refuses launch.
The result records `connect` or `structural` for each witness.
Socket absence requires readable, searchable parents; an unreadable path
cannot count as absent. A removed or replaced proved bwrap binary refuses
subsequent commands with `command_start_failed`.

On macOS, commands can read WorkDir, private scratch, the pinned system runtime set
(`/System` excluding `/System/Volumes/Data`, `/usr`, `/bin`, `/sbin`, CommandLineTools, resolved selected Xcode,
Homebrew), selected public `/private/etc` files and minimal `/dev` nodes.
Add toolchains or caches elsewhere through `Commands.Read`; it must not
reopen home or overlap RuntimeHome. RuntimeHome must also lie outside the
system read set; normalization refuses it before probing. A command workspace cannot contain home.
Writes are restricted to scratch and, with Write, WorkDir, excluding `.git`.
The macOS profile also hides file tools' reserved atomic temporaries. Linux
commands see the explicitly bound workspace; file operations and commands
are serialized, and ordinary completion removes those temporaries.
Commands follow the OS path sandbox: unlike file tools, they do not reject
every hard link or injected mount. Keep outside links and mounts out of the
workspace and explicit read set.

IP and abstract-socket network access is denied by default. macOS also
denies Unix sockets; Linux pathname sockets follow the directory rule above. `Commands.Loopback`
allows on-machine outbound traffic on macOS, with binds and inbound on every
local interface. Servers may be reachable from other machines. This is proved
against loopback and interface listeners and a reachable off-machine witness. `Commands.Env` sets
ordinary variables for every command, such as build caches, `GOFLAGS` or a
`PORT`. HOME and TMPDIR always name private scratch. Normalization refuses
`AGENT_HARNESS_*` (the library's own), dynamic-loader variables (`DYLD_*`,
`LD_*`), shell start-up variables (`BASH_ENV`, `ENV`, `SHELLOPTS`,
`BASHOPTS`, `IFS`, `CDPATH`), names that aren't portable (which keeps out
Bash's exported functions), and credential-like names (a `KEY`, `TOKEN`,
`SECRET`, `PASSWORD`, `CREDENTIAL` or `AUTH` segment), because the model sees
what its commands print. A path an Env value names gains no access: only
`Commands.Read`, the workspace and scratch are reachable. Env grants no power,
so it is not part of a session's reference and may change between resumes. Timeout defaults
to two minutes, is capped at ten, and the model can shorten it. Cancellation
and timeout stop the process tree; timeout is a normal `timed_out` result.
A lost private completion response records `command_outcome_unknown`, never
an inferred success, and is not replayed after a crash.
On macOS, late background stdout and stderr are drained and discarded until group
settlement, so logging servers can continue after a command returns.
Output is bounded (at most 64 KiB per stream, reduced to fit the host result
limit), with a truncation note. Background launches run at nice 10.
Session containment markers are synced before commands start and swept on
recovery and Close. On macOS, a retained supervisor with an argument marker keeps
background jobs discoverable even when macOS hides their environment; the
model's shell cannot access its private completion pipe. Empty groups are
reaped after each command; supervisors retained for background jobs are reaped
when their last group member exits. At most 64 live command groups are retained;
further launches return `command_process_limit` until a group settles.
As with the process package's existing sweep, a process
that detaches may evade discovery when macOS hides its environment, even
without erasing its marker; detached jobs are outside the supervisor group.
Skill scripts still follow `SkillRun` and run outside this command sandbox.
See the [design](design-docs/2026-09-29-api-workbench.md).

## Long-lived conversations: Open and caller context

`session.Open(ctx, options, ref)` is for a caller that keeps one conversation
across its own restarts. It resumes the reference's conversation when it can
and otherwise starts a new one, and `Opened` says which:

```go
s, opened, err := session.Open(ctx, options, storedRef) // storedRef may be nil
if err != nil { return err } // hold: ErrUnreclaimed, ErrLeaseHeld, capability, transport
switch {
case opened.Resumed:                                   // same conversation
case opened.Fresh == session.FreshIncompatible:        // another engine or configuration
case opened.Fresh == session.FreshUnavailable:         // the harness no longer has it
}
save(s.Ref())
```

- A restricted session's `Dir` is reclaimed first, under its assignment lease.
  Reclaim waits up to five seconds, within the caller context, for the recorded
  group to empty, holding the lease throughout. Release uses the same wait.
  A harness Open cannot confirm gone is returned as `ErrUnreclaimed`, and a lease
  another session holds as `ErrLeaseHeld`: Open never starts a harness over one
  that may still be running, and never reclaims one a live session is driving.
- **Claude**: the transcript must exist before `--resume` is tried. Claude Code
  keeps it at `<config dir>/projects/<key>/<id>.jsonl`, where the config
  directory is `Options.Home` and the key is the resolved working directory with
  every character that is not an ASCII letter or digit replaced by `-` (cut to
  200 and suffixed with a hash when longer), and its resume also accepts a single
  match in any other project folder. Open applies the same rule. A resumed Claude
  that exits during startup also counts as unavailable.
- **Codex**: a `thread/resume` the server refuses counts as unavailable.
- Anything else is returned with no session.

A restricted session's reference no longer covers its tools. The restriction is
re-proved on every launch and Claude's startup frame is cross-checked against the
tools configured for that launch, so a release that edits a tool's description,
schema or set resumes stored conversations under the new surface. The tool
server's name and the runtime home still have to match. (References stored for
restricted sessions by versions before v0.4.0 stop matching once.)

`Options.Context` lets the caller refresh what a long conversation knows about
its domain without the harness ever replaying history itself. It is asked at the
start of a turn whose conversation is new (`ContextStarted`) or was compacted
since the last turn (`ContextCompacted`: Claude's `compact_boundary`, auto or
manual, or Codex's `contextCompaction` item, including a `Compact` turn). The
text goes ahead of that turn's input:

```text
<caller-context reason="compacted">
…your text, verbatim…
</caller-context>

…the turn's input…
```

Empty text sends the input unchanged. A handler error fails `StartTurn` and
keeps the reason pending; it clears only once a turn carrying it has been
accepted, so each pending reason is delivered once. A compaction during a turn
is delivered with the next one. A restricted session keeps the pending reason in
`Dir/context.pending` (owner-only, beside the launch record), so a restart
between the compaction and the next turn does not lose it; an ordinary session
keeps it in memory.

## Restricted sessions with caller-hosted tools

`Options.Restriction` opts one session into a stricter contract: the harness's
own tools are removed, inherited customization is disabled, and your tools
become the session's entire surface. Sessions opened without it are unchanged.

```go
s, err := session.Start(ctx, session.Options{
    Provider: harness.Provider{Engine: harness.Claude},
    Model:    "haiku",
    Instructions: session.Instructions{Mode: session.Append, Text: scopedTask},
    Restriction: &session.Restriction{Tools: session.ToolHost{
        Server:  "agent_workspace",           // some names are reserved by the harness
        Dir:     runPrivateDir,                  // owner-only, in your own state
        Bridge:  session.Bridge{Path: exe, Args: []string{"tool-bridge"}},
        Tools:   []session.ToolDefinition{{Name: "read_file", Schema: schema}, {Name: "finish", Schema: schema, Closing: true}},
        Handler: yourExecutor,                   // you execute; the library never does
    }},
})
```

The restriction is proved before your login is ever used, and there is no option
to skip that. The library launches the same binary with *the same arguments the
real session will use*, differing only in a disposable home, a dummy credential
and a loopback provider that refuses every request; it drives one synthetic turn
and reads what the harness actually sent. Equivalence matters: a check run with a
different permission mode or different instructions would establish something
about a configuration nobody is going to launch. A rejecting provider performs no
inference, so no agent loop and no tool call can happen during the check, and the
tool host refuses calls for its duration regardless. The check ends shortly after
the harness's first request rather than sitting out its timeout.

The judgement is in two parts, because installed harnesses differ in ways that
were measured rather than assumed:

- **Nothing unauthorized, anywhere.** No request may carry a tool outside your
  hosted set. A harness makes auxiliary requests — naming the session, for one —
  and those carry no tools at all; requiring every request to carry your set
  would reject a correctly restricted session, while a request carrying a
  built-in is refused wherever it appears.
- **Your tools, positively proven.** Usually a request carries them. Where a
  harness defers MCP tools behind a discovery tool and never puts them in a
  request at all, the proof is the tool channel's own record of having served
  them, which is direct evidence that the surface loaded and was reachable.

`session.VerifyRestriction(ctx, options)` runs exactly this check without opening
a session, so an application can tell an operator that their installed CLI cannot
be restricted while they are configuring it, rather than when work is
commissioned.

A failure returns `*CapabilityError` with a fixed reason code, the disagreeing
tool names and the phase it happened in, and nothing is launched. Where a harness
also advertises its tools at startup, the same comparison runs again before the
first prompt; that one reports `BeforeFirstPrompt`, and says the session was
closed rather than claiming it never started.

Repeating the check is avoided only by a process-local record of the same binary
— by path, size and modification time — with the same arguments and the same
tool identifiers. That is evidence about the thing the probe proved, not a
caller's assertion that evidence was unnecessary. Nothing is persisted: a
restart re-proves, which is exactly when an installed CLI is most likely to have
changed underneath.

Restricting writes is not what this does. A tool that can read is a disclosure
path whatever it may write, so the restriction is the removal of the tools; a
sandbox mode and a working directory are neither claimed nor relied on as one.

A restricted Codex session runs in `Options.RuntimeHome`: a durable private home whose
configuration this library writes, sharing only the login from `Options.Home`.
That is how a worker gets the operator's account without the servers, hooks,
plugins and trust settings that live beside it — none of which Codex's
`app-server` has any flag to ignore. The credential moves between two owner-only
directories in private application state and never reaches a workspace, a tool
result, a model, an error or a log; no API key is substituted for it. Which copy
is authoritative is decided by digest: a source that still matches what the home
was given has not changed, so a refresh the harness made wins; a source that has
changed is a new login and wins instead; a source that has been removed is a
logout and is left removed. A refresh reaches the source as each turn ends, and
a running session takes another's refresh before its next turn, because a Codex
refresh token is single use: two sessions refreshing copies of one login spend
it twice, and the second is refused (`refresh_token_reused`). A running session
is never moved to a different account's login, and a copy holding a refresh the
source did not take is left for the next launch to resolve. Writes to the
source are serialized by a `.agent-harness-login.lock` beside it; the
operator's own CLI does not take it. Restricted Claude sessions use the selected native
login and Claude Code's restricted mode; they do not use this credential-copy route.

Your bridge command is your own binary re-executed as the harness's tool server.
Its whole implementation is `session.RunBridge(ctx, os.Stdin, os.Stdout)`, which
relays the protocol and holds a lock naming the launch it belongs to. The
listener lives in a short owner-only runtime directory, because an application
state path is longer than a local socket address may be; the durable files — the
channel credential and that lock — stay in the `Dir` you supplied, which is where
recovery looks for them. The credential sits in an owner-only file and never
appears in arguments, environment values, references or tool results. `Dir` also
carries an assignment lease, taken before anything is launched, so a second
process cannot drive the same assignment even before a bridge exists.

`CancelTools` pauses the channel: it stops every call this session admitted —
executing *and* queued — and refuses further ones until `ResumeTools`, which a
new turn does for you. Cancelling only what happened to be running left the
queue behind it to execute afterwards, which is a write arriving after the work
was reported as stopped. A pause is not the same as the channel being finished:
a closing tool ends the work, a pause suspends it. `ToolsSettled` reports that
neither kind of call is outstanding.

A composed steer replaces the turn, and the replacement is bound to the
session's lifetime rather than to the bounded context that requested the steer.
Cancelling a control request must not end the work it started.

Tool calls execute one at a time. A native turn will ask for several at once,
and running them concurrently would make "after the work was reported" an
ambiguous claim — a write or a test could still be in flight when a closing tool
decides the assignment is finished, and cancelling it afterwards does not undo
it. A tool declared `Closing`, or a result with `Closes` set, therefore runs with
nothing else in flight and latches the channel only if it actually succeeded: a
finish whose arguments the handler rejected has not finished anything.
Everything queued behind it is refused without executing. `Session.ToolsClosed`
reports that state.

`ToolHost.MaxResultBytes` (default 64 KiB) bounds every answer to a call that
the model sees. That covers a result, a handler's error, a cancellation, a
refusal, and the library's answer for a call that never ran or whose outcome
is unknown. A longer answer is cut on a character boundary and ends with a
note that says how many bytes were left out. The note counts towards the
limit.

If the launching process dies, the harness does not: it keeps its provider
connection and keeps spending. `session.Reclaim(ctx, dir)` answers two separate
questions and never confuses them. Whether anything survives is answered by the
recorded process group, because a free bridge lock proves only that no bridge is
running — a harness can outlive its tool server, restart it, or sit in inference
with none running. Whether that group is *yours* is answered by a live bridge
naming the same launch, because process and group identifiers are reused and a
stored integer is never grounds for signalling. Only then is the group
terminated, and only a group that has actually become empty is reported as
`Confirmed`. Anything else is `ErrUnreclaimed`: hold the work for inspection
rather than start a second one. Reclaim polls for up to five seconds within
the caller context, including when the bridge lock is free or its owner record
is not yet readable. Cancellation returns both `ErrUnreclaimed` and the context
error. Even with an expired context, Reclaim attempts termination when a live
bridge positively identifies the launch; it does not wait for settlement.
Open and Release hold the assignment lease during this wait; a refusal
preserves the launch marker for the next recovery attempt. Give Release a
context with at least five seconds available for reclamation.

Per-engine, the restriction is built from provider mechanics rather than from a
permission setting, and each part of it was checked against an installed CLI.

**Claude** is launched with no setting sources, hooks disabled, a strict MCP
configuration holding only your server, slash commands disabled, an empty
built-in tool list and an explicit allowance for your tool identifiers. Its
initialization then reports `tools: ["mcp__<server>__<tool>"]` and no built-ins.
Some server names are reserved: a reserved one is accepted and then silently not
loaded, leaving a session with no tools while reporting success, so the library
refuses those names up front and separately verifies from the initialization
frame that your server actually connected.

**Codex** is launched with the shared restricted model catalog — shell type
disabled, apply-patch dropped, an empty experimental tool set — alongside the
feature switches that turn off apps, plugins, hooks, subagents, browser, computer
use, image and goal surfaces. The catalog is the load-bearing part: the feature
switches alone leave `exec` and `wait` in place. Overrides are dotted-key TOML,
which is what Codex parses.

Two things about Codex are worth stating plainly rather than implying otherwise.
Its remaining surface includes MCP-mediated helpers (`tool_search`,
`list_mcp_resources`, `list_mcp_resource_templates`, `read_mcp_resource`); they
are permitted because they can address nothing but configured MCP servers, a
restricted session configures exactly one, and this library's tool host answers
every resource method with method-not-supported. And `app-server` has no
`--ignore-user-config` or `--ignore-rules` (those belong to `exec`), and
overriding the server table with `-c mcp_servers={}` does not clear entries
already declared in `config.toml`, which were observed starting. Inherited
configuration is therefore never read at all: the session runs in
`Options.RuntimeHome`, whose configuration this library writes, and only the
login is shared into it from `Options.Home`, as described above.

Restricted sessions require process-group containment and a releasable advisory
lock, so they are available on macOS and Linux and fail closed elsewhere with
`restricted_session_unsupported_platform`. Ordinary sessions are unaffected on
every platform.

## Sandboxed sessions with native tools

`Options.Sandbox` keeps a session's own tools and puts everything it executes
under the installed CLI's OS sandbox: no network, and project writes only
inside `WorkDir` when `Sandbox.Write` is set. Claude Code's shell may also write
its own private session temporary directory. Codex's shell may not write
`/tmp` or `$TMPDIR` at all.

```go
s, err := session.Start(ctx, session.Options{
    Provider:    harness.Provider{Engine: harness.Codex},
    WorkDir:     "/private/workspace",
    RuntimeHome: "/private/state/codex-runtime", // Codex only; shares the login
    Sandbox:     &session.Sandbox{Write: true},
})
```

The sandbox is proved before any credentialed launch, without inference, and
the result is cached per resolved binary and sandbox:

- **Codex:**
  - The session runs in a private `RuntimeHome` under a dedicated permission
    profile: filesystem read, the workspace writable (or read-only), `.git`
    read-only, `.git`, `.codex` and `.agents` read-only, network disabled,
    approval `never`, web search off unless `Web` is set, and the connector,
    plugin, hook, browser, computer-use, multi-agent and dependency-install
    features disabled.
  - A canary runs under that profile through `codex sandbox`. Writing outside
    the workspace, to `/tmp` or to the inherited `$TMPDIR` must fail, as must
    reaching a loopback listener owned by the probe, or writing the
    workspace's `.git`. The canary must also report that it ran, so an empty
    result is never read as success.
  - Once the harness starts, thread/start and thread/resume must report that
    profile, with network closed and temporary directories excluded, before
    the first prompt. Otherwise the session is closed.
  - The legacy `sandbox` thread mode is never sent, because it silently
    replaces the profile.
- **Claude Code:**
  - On Linux, every sandboxed session requires bubblewrap and socat on the
    library process's `PATH`, including Start, Resume and VerifySandbox.
    Install socat with `sudo apt install socat`, `sudo dnf install socat`, or
    `sudo pacman -S socat`. Missing socat refuses before launch with
    `sandbox_unavailable` and reason `claude_linux_sandbox_requires_socat`,
    even with a cached proof. The disposable proof inherits the parent PATH;
    an `Options.Env` PATH override does not change this prerequisite lookup
    and must also let the launched CLI resolve socat.
  - The session loads only the library's settings (`--setting-sources=`,
    `--strict-mcp-config`, hooks disabled): sandbox enabled and
    fail-if-unavailable, no unsandboxed retries, an empty network allowlist,
    `dontAsk` permissions, WebFetch, WebSearch and MCP tools removed (see
    `Web` and `Tools` below), and
    `Edit` allowed only inside `WorkDir` (resolved through symlinks). The
    network allowlist is strict.
  - A writing session cannot change `WorkDir/.git`, as with Codex.
  - A read-only session also loses Edit and Write, and denies sandboxed writes
    to `WorkDir`.
  - Its shell cannot read the home directory outside `WorkDir`
    (`blockReadsOutsideWorkingDirectories`). `Sandbox.Read` reopens named
    directories read-only, such as a Go module cache a build needs. A read
    path must be absolute, and none may contain the home directory. Codex
    already reads everything, so `Read` changes nothing there.
  - No instruction files load, not even the workspace's own: with every
    settings source dropped, Claude Code 2.1.280 loads none, and the
    operator's user and ancestor files are also excluded by name as a second
    guard. Point the session at a repository's `AGENTS.md` or `CLAUDE.md` in
    its prompt if it should follow them. Skills and auto-memory are off.
  - `claude sandbox status` with the same settings, asked from a throwaway
    home, must report the sandbox supported, enabled and strict, with no
    unavailable reason. This is the CLI's own report, not a canary: Claude
    offers no way to run a sandboxed command without inference.

A sandboxed session inherits only an allowlisted environment from its
caller (`PATH`, `HOME`, `USER`, `LOGNAME`, `SHELL`, `TERM`, `LANG`, `LC_*`,
`TZ`, `TMPDIR`), never whatever else the caller happened to export.
`Options.Env` adds ordinary `KEY=VALUE` settings to any session, for example
a build cache or `TMPDIR` inside the workspace so a sandboxed build can write
them. Keys the harness manages, and keys that would change the CLI itself
outside its sandbox (loader and Node options, proxies and certificates,
`GIT_*`, homes, provider credentials), are refused.

### Web access

`Sandbox.Web` lets a sandboxed session search and read the web. Nothing else
about the sandbox changes, and the shell's network stays closed:

- **Claude Code** gains WebSearch and WebFetch, allowed by bare permission
  rules. A `WebFetch(domain:...)` rule is never written, because Claude Code
  adds every domain such a rule names to the shell's network allowlist too.
  WebFetch runs in the CLI process, outside the OS sandbox.
- **Codex** runs with `web_search="live"`. Checked against codex 0.156.1 with
  a provider that declares web search support, this offers the model a `web`
  tool that searches and opens pages through the provider, not from the
  shell. Whether a real login's provider offers it has not been checked
  without inference.

Either way it is an outward channel for anything the session can read: a
fetched URL can carry data out. A reference records whether a sandbox had
`Web`, so a resume cannot change it; a sandbox without it keeps its earlier
reference digest.

### Selected loopback ports

`harness.Support(engine, operation, harness.LoopbackPorts)` reports
`Unsupported` everywhere, with a reason and the nearest alternative:
plain `Loopback` via a separate `sandbox.Open` command sandbox on macOS
or Linux for servers started inside the command. Errors also state that
command sandboxing is unavailable on Windows and other platforms. This
alternative does not grant networking to the requested native engine.
Support never reports Unknown for selected ports.

`LoopbackPorts []int` and `LoopbackControl string` are available on
`sandbox.Options`, `session.Commands`, native `session.Sandbox` and
deprecated `session.CommandSandboxOptions`. A nil list and empty control
leave existing behavior, profiles, proof keys and resume digests unchanged.

For valid command-sandbox and Session selected-port requests:

| Platform | Selected-port request | Nearest command capability |
| --- | --- | --- |
| macOS | Refused: `loopback_ports_unenforceable`, `harness.LoopbackPortsSeatbeltReason` | Loopback: all-interface binds/inbound, outbound on-machine only |
| Linux | Refused: `not_offered`; reason depends on the engine, including the private-command no-per-port-filter limitation | Loopback: start and request the server inside one command; no host/sibling reach |
| Windows / other | Refused: `not_offered`; no proved selected-port enforcement | Command sandbox unavailable |

Claude Linux's selected-port capability reason names
`harness.ClaudeLinuxHostLoopbackReason`
(`claude_linux_host_loopback_unavailable`). Claude macOS has only yes/no
allowLocalBinding and the same Seatbelt limitation. On macOS, every engine’s
Session reason includes `harness.LoopbackPortsSeatbeltReason` alongside its
own limitation: Codex native loopback has no proof, and Grok/Command Code
have no proved OS sandbox. This keeps the reason consistent with the
`loopback_ports_unenforceable` code without claiming those engines have
Seatbelt enforcement. Native runs have no per-port sandbox and remain
Unsupported. None of these refusals claims native Loopback support.

Input checks run before the platform refusal: a non-nil list needs 1–32
entries, each in 1–65535 (`limit_exceeded` first); ports require Loopback,
and a control requires ports and an unscoped off-machine IP literal
(`conflicting_options` next). Loopback, mapped loopback, link-local,
multicast, unspecified addresses and hostnames cannot be controls.
Normalization clones, sorts and deduplicates valid ports. It performs no
interface or resolver discovery: even a valid control literal is refused.
Start, Resume, VerifySandbox and OpenCommandSandbox refuse before any state
write, login preparation, probe, cache entry or launch.

The owner's Darwin 27 evidence and LAH-39 found no Seatbelt rule form that
confines TCP/UDP binds to loopback. Linux retains reverted LAH-24's truthful
refusal, whose strict PASS covered refusal tests. LAH-43 retains the macOS
Stage A/B canary from `4b7e9d6` as test-only code: disposable selected ports,
the exact requested list, inbound receipts, unselected ports and a proved
off-machine DNS/TCP control. Interface and wildcard binds and UDP sends use
the shared `InterfaceAttemptsAtPort`, `interfaceCanary` and
`judgeInterfaceAttempts(interfaceLoopbackOnly)` helpers. Errno 65 is an escape,
never a permission denial. The Python bind/reach/inbound helpers keep their
`xcode-select` guard. Production cannot invoke the canary.
TCP interface reach attempts exclude unspecified destinations (`0.0.0.0` and
`::`), which the kernel redirects to loopback; wildcard binds remain tested.

`TestSelectedPortCanaryStillEscapes` requires real Seatbelt to report
`selected_port_network / sandbox_not_enforced` with interface observations.
A successful canary fails with a **re-audit** message; only missing prerequisites
can skip, and `AGENT_HARNESS_TEST_NO_SKIP=1` turns those into failures.
Public refusal tests never skip, including inside sandboxcheck. macOS CI pins
`AGENT_HARNESS_TEST_LOOPBACK_CONTROL` from `go run ./internal/cmd/loopbackcontrol`,
which proves a responding configured resolver without choosing a public default.
Failed or interrupted proofs publish no cache entry. Control address/source
remain private diagnostics. Selected-port keys and resume digests have distinct
wrappers; nil-port bytes remain pinned and unchanged.
Private control fields on `sandbox.ProofError` break external unkeyed literals;
use keyed literals such as `&sandbox.ProofError{Code: code, Step: step}`.

Enabling selected ports requires positive selected-port bind, reach and inbound
availability plus denial of unselected ports, interface binds, interface UDP
sends and off-machine traffic under the installed runtime. CI alone does not
replace the owner's unsandboxed strict-suite and sandboxcheck runs on macOS and
Ubuntu; the task note identifies the exact draft revision to run.
See the [design record](design-docs/2026-10-04-selected-loopback-ports.md)
and [release notes](release-notes/selected-loopback-ports.md).

### Loopback networking

Callers requiring strict local-only networking set both `Loopback: true` and
`LoopbackLocalOnly: true`. Without Loopback the stricter field is refused with
`conflicting_options`; no request is silently widened.

| Request | macOS | Linux | Windows |
| --- | --- | --- | --- |
| Standalone sandbox.Open Loopback | All-interface binds/inbound; outbound on-machine only, proved | Private per-command loopback, proved | Unsupported |
| Standalone sandbox.Open LoopbackLocalOnly | Refused: `loopback_local_only_unenforceable` | Private namespace with only lo; host-interface binds must be EADDRNOTAVAIL | Unsupported |
| Workbench.Commands.LoopbackLocalOnly | Same named Seatbelt refusal | Unsupported; standalone Open offers it | Unsupported |
| Claude Sandbox.Loopback | Existing nc base proof, Unknown until verified; all-interface exposure | Per-command loopback, owner-observed; Unknown until proved for this launch | Unsupported |
| Sandbox.LoopbackLocalOnly (native sessions) | Unsupported | Unsupported | Unsupported |

The field is also available on the deprecated session.CommandSandboxOptions.
`harness.LoopbackLocalOnly` (`"loopback_local_only"`) reports session
support as Unsupported: Linux standalone command evidence does not imply
shared-session networking. On macOS the refusal names Seatbelt: localhost
filters permit binds on every local interface and cannot enforce local-only
loopback. Refusal occurs before probes, state writes or credential preparation.
macOS interface proof uses base-system /usr/bin/perl, not the Xcode python3 shim;
no developer-tools installation is required by this client.
A changed bind contract refuses proof with `loopback_interface_claim_changed`.
Linux LocalOnly proof requires /usr/bin/python3 as well as OpenBSD nc;
missing clients refuse only this stricter request. Existing plain Loopback
Linux command-sandbox behavior and keys are unchanged.

`sandbox.Proof.NetworkObservations()` returns structured address/operation/errno
results, and `NetworkDetail()` records the exposure witnessed. No interface
binds available on an offline host is reported as “no interface binds available”,
never as proof of interface confinement. Errnos 49 (EADDRNOTAVAIL on macOS)
and 65 (EHOSTUNREACH) are not authorization denials. macOS proofs now use
seatbelt-workbench-v12; earlier unchecked evidence is never reused.

The owner's Darwin 27 arm64 rule-form audit found that local
ip/ip4/ip6/tcp/udp localhost:* filters permit interface binds; they narrow
only family or protocol. UDP sends to the machine's own interface addresses
succeeded under every form; wildcard sends returned errno 65. Literal hosts
were refused with “host must be * or localhost in network address”. The
[rule-form evidence table](design-docs/2026-10-04-loopback-networking.md)
records address classes and the tested draft. That historical Python-client
run does not verify the revised Perl client. Real tests print address classes
without raw host addresses; loopback interfaces are excluded from escape tests.

API workbench sessions use `Workbench.Commands.Loopback`; see the Workbench
section for their separately proved macOS sandbox.

Claude `Sandbox.Loopback` stays offered on macOS and Linux after the base
proof succeeds: a command must reach and bind its own localhost, and an
off-machine address reachable by the host must be refused inside the sandbox.
macOS also requires host localhost reach. Linux instead records per-command
scope: neither the canary nor its host listener may report host localhost reach;
a host-shared result refuses with `sandbox_not_enforced` before launch.
Support is Unknown until verified for the installed binary and launch settings.
On macOS, LAH-39’s real-Seatbelt evidence establishes that allowLocalBinding
(`local ip "*:*"`) permits binds and inbound connections on every local
interface. Wildcard and LAN listeners may be reachable from other machines;
there is no local-only claim. Only the strict `LoopbackLocalOnly` request is
refused; it remains Unsupported for native Claude sessions on every platform.

After a successful macOS base proof, optional diagnostics try interface-address
and wildcard TCP source binds, UDP source binds and UDP sends using flat nc
commands and a local provider that refuses inference. Host listeners check
peer addresses and nonce payloads. Each attempt records a host observation,
an unconfirmed outcome, or unavailable measurement privately beside the
verified key. Wildcard observations explicitly mean any peer, not proof that
a client bound the unspecified address. Process exit statuses are never socket
errnos; a failure alone does not distinguish denial from address unavailability.
Missing, refused or incomplete diagnostics never invalidate the base proof.
No per-class Claude results are claimed as already proved by installed-runtime
evidence. Neither permissions nor allowlists are widened.

Linux keeps its original nc canary bytes. The owner observed per-command
loopback on Ubuntu 24.04.5 / bubblewrap 0.9.0 / Claude Code 2.1.289: one command
can start a server and reach it (for example a Go test using httptest); the
host's and other commands' servers are outside this contract. The proof records
that scope privately beside the verified key. Missing in-command reach/bind
refuses with `sandbox_unavailable` and `CapabilityError.Reason`
`session.ClaudeLinuxInCommandLoopbackFailed`; inconsistent host signals are unavailable.
Windows keeps its pre-launch refusal. Standalone/workbench Seatbelt proofs retain their Perl
client, profile and errno evidence. Base escape evidence wins over incomplete
output or a deadline; cancellation publishes no positive verification.
Observations and verified keys publish together in the process-local cache.
Each uncached macOS proof also launches Claude once for diagnostics, adding
up to roughly ten seconds before Start, Resume or VerifySandbox returns. nc
attempts run concurrently, with one three-second settling delay rather than
a one-second UDP wait per address. If fewer than twelve seconds remain in
the proof deadline, diagnostics are recorded as unavailable. UDP-send witnesses
briefly listen on each host interface and on wildcard addresses; other machines
can reach these sockets during the diagnostic window. Only matching nonce
payloads count, and all listeners close when the diagnostic settles.

Owner runner on real macOS outside an enclosing sandbox with installed Claude:

```sh
AGENT_HARNESS_TEST_NO_SKIP=1 go test -race -count=1 -v -run TestClaudeLoopbackInterfaceRealProof ./session
```

The test requires the base Loopback proof to pass and prints the optional
per-class interface table, with addresses redacted. Unavailable measurements
are reported without failing the base capability check. Selecting the exact
name opts in; `AGENT_HARNESS_TEST_CLAUDE_INTERFACE_PROOF=1` includes it in the
full suite. Requested base-proof prerequisites fail rather than skip. A
passing command-shape check does not prove native dontAsk approval.

Owner runner on Ubuntu 24.04 with bubblewrap 0.9.0, installed Claude Code,
netcat-openbsd, socat and `/usr/bin/python3`:

```sh
AGENT_HARNESS_TEST_NO_SKIP=1 go test -race -count=1 -v -run TestClaudeLoopbackInterfaceRealProofLinux ./session
```

The host must permit bubblewrap user namespaces (including Ubuntu's AppArmor
user-namespace policy). Missing socat refuses before a native sandbox launch
with `claude_linux_sandbox_requires_socat`, even after a previous proof was
cached. Each launch has its own deadline. The disposable login home, dummy
credentials and local provider perform no inference.

The owner's run at `0c1580c` on Ubuntu 24.04.5 / bubblewrap 0.9.0 / Claude Code
2.1.289 / Python 3.12.3, with socat installed, confirmed production VerifySandbox
success and recorded per-command scope. The corrected Python line still did not
establish dontAsk auto-approval: a tool result arrived, but zero socket results
and no canary marker appeared. Every interface row was unavailable; nc showed
no host delivery. Host-interface bind confinement remains unproved because the
installed client could not be auto-allowed, not because binds were denied.
LoopbackLocalOnly stays Unsupported. The owner approved landing on the production
evidence with interface measurements report-only.

The runner logs redacted TCP bind, UDP bind and UDP send observations, namespace
names, host reach and result/marker facts. Unavailable or contradictory interface
measurements and diagnostic launch refusals are reported without failing it.
Production VerifySandbox, base scope and recorded scope still must pass. An nc
off-machine `outside` observation remains fatal because it directly contradicts
the network restriction. Production refuses host-shared scope with
`session.ClaudeLinuxLoopbackScopeWiderThanClaimed`. The nc fallback has fresh
sockets and a new nonce. The post-landing owner rerun checks this report-only runner.

`harness.ClaudeLinuxHostLoopbackReason` names the host-reachability refusal
for selected-host-port requests. `LoopbackPorts` now refuses those requests
before discovery or launch; use plain Loopback for in-command servers.
The [design record](design-docs/2026-10-04-loopback-networking.md) attributes the
owner evidence and separates the proved base scope from unmeasured interface
confinement. In-command callers retain Loopback; no host-port bridge is introduced.

Codex 0.160.0 remains explicitly unsupported for `Sandbox.Loopback` on every
platform. Owner experiments on macOS with the installed 0.160.0 binary found
that the closed-network profile refused loopback too. Enabled-network variants
with localhost destination rules, including a proxy variant and a real native
session, permitted off-machine TCP 443 and TCP/UDP port 53. No tested variant
provided loopback-only enforcement; Linux and Windows have no native enforcement
proof. Start, Resume and VerifySandbox refuse before preparing a credentialed
runtime. Use the existing closed-network session sandbox or the separately
proved command sandbox.
See the [research record](design-docs/2026-10-04-loopback-networking.md)
for the four attributed owner experiments, binary identity, team sandbox
limitations and the owner's decision: no further team experiment is needed
for this refusal delivery. These macOS results do not prove Linux or Windows
behavior or every possible configuration unsafe. Command-sandbox loopback
claims now disclose macOS all-interface binds; selected-port requests are
refused on every platform (see [Selected loopback ports](#selected-loopback-ports)).

A process the agent starts in the background, such as that server, is
stopped when the session closes (see Process containment below).

### The harness's own browser

`Options.Browser` (and `native.Config.Browser` for a run) switches on the
browser integration the harness ships, for that invocation only. The library
requests it only when set; leaving it unset preserves the CLI's own defaults
and configuration. It is never implied by another option:

- Claude Code: `--chrome` (Claude in Chrome), with the
  [Claude extension](https://chromewebstore.google.com/detail/claude/fcoeoabgfenejglbffodgkkbkcdhcgfn).
- Codex: `features.browser_use=true` and `features.browser_use_external=true`,
  with a configured native browser bridge in the selected `Provider.CLI.Home`
  and the [ChatGPT extension](https://chromewebstore.google.com/detail/chatgpt/hehggadaopoacecdllhhajmbjkdcmajg).
  The extension alone does not configure that bridge. The working local setup
  uses the ChatGPT application's native Node REPL MCP bridge (`node_repl`),
  browser plugins and native host. Restart the CLI after installing the extension.
  The library does not install plugins, enable desktop control, or change site
  permissions. A sandboxed session copies only the narrowed bridge declaration
  described below.

Codex 0.159.2's app-server and exec flags and deferred Node REPL tools were
checked with disposable homes, dummy credentials and a local provider that
refuses inference. Chrome control was separately checked in a configured CLI
session by filling and validating a disposable local form. This establishes
browser control; it does not establish a video recording API or hidden-window
capture. Grok 1.0.41, API sessions and restricted sessions are refused.
Sandboxed Codex sessions admit the ChatGPT app's `node_repl` bridge from
`Options.BrowserBridgeHome`, or `Provider.CLI.Home` when it is empty
(`codex mcp get node_repl --json`). For an application with its own CLI home,
set `BrowserBridgeHome` to the owner's absolute `~/.codex` path (expand `~`
in the caller). Login and skills still come from `Provider.CLI.Home`.
`BrowserBridgeHome` requires `Browser`, Codex and `Sandbox`; other uses return
`*session.UnsupportedError` with `RefusedConflict`. It must not equal, contain
or lie inside `WorkDir`, including a missing directory beneath a symlinked
ancestor. Ordinary unsandboxed sessions and native runs continue
to load their bridge from the CLI home themselves.
Their private
`RuntimeHome` declares only this bridge, plus any caller-hosted tools. The
bridge enables only the `chrome` backend, with no in-app browser or MCP apps;
its trusted services include only `browser`, with no desktop-control service.
No other bridge-home MCP servers, plugins, hooks, skills, settings or login are
inherited. The bridge process receives the private `RuntimeHome` as `CODEX_HOME`.
The library adds no writes to the bridge home. It runs `mcp get` with `CODEX_HOME`,
`HOME` and `TMPDIR` set there; the CLI may make incidental writes of its own.
Both
browser features are enabled; computer use stays disabled.

`session.CheckBrowserBridge(ctx, options)` is an advisory read-only check of
the same declaration and installation, including workspace exclusion. It runs
only `mcp get`: no session, server, bridge, Node or confinement proof; it writes
no runtime home, checks no login and neither reads nor fills the proof cache.
It requires `Browser` (otherwise `RefusedNotConfigured`) and a sandboxed Codex
session. After option normalization, checking another engine or an unsandboxed
session with `BrowserBridgeHome` empty returns `*session.UnsupportedError` with
operation `browser_bridge` and code `RefusedConflict`; an invalid explicit home option uses operation
`browser_bridge_home`. An unavailable or non-directory workspace is refused with
operation `work_dir` and code `RefusedWorkDir`, before `mcp get` runs.
Cancellation, including during `mcp get`, returns `ctx.Err()`. A nil result
establishes neither confinement nor Chrome connectivity; use `VerifySandbox`
for confinement.
Unusable bridges return `*session.CapabilityError`, code
`browser_bridge_unavailable`, phase `before_launch`, with a fixed `Reason`:
`BridgeHomeUnavailable`, `BridgeNotDeclared`, `BridgeDeclarationUnsupported`,
`BridgeInstallationMissing`, or `BridgeInWorkspace`. Errors contain no home
paths or CLI output. Start and Resume always re-read the bridge; the bridge home
is not part of a conversation Ref, and a successful check never authorizes launch.

Before a credentialed launch, one real app-server turn runs against a local
fake model provider with a disposable home and dummy credential. The provider
scripts exactly one `js` call that tries to write a canary outside its workspace
and all writable temp roots, then reads the tool result from the next request.
The result must report an OS permission denial and the canary must be absent.
A successful write produces `browser_sandbox_not_enforced`; a missing result or
failed proof produces `browser_sandbox_unproven`. Both are typed pre-launch
`session.CapabilityError` failures. `VerifySandbox` runs this proof too. Evidence
is cached only for the same CLI, bridge home, bridge installation, configuration and sandbox
in this process; an upgrade or restart re-proves. There is no bypass.

The real confinement proof passed with the ChatGPT app on 2026-10-01 and
refused a bridge whose session confinement was disabled. A sandboxed session
connected to Chrome and created a tab, but page navigation was refused by
browser-origin permissions. The headless session client declines browser
approval requests; this proof does not grant origin access or establish that
a page can be opened in a fresh private runtime home.

Verified on 2026-10-01 with codex-cli 0.159.2: Codex passes its session sandbox
policy to `node_repl` through `codex/sandbox-state-meta`. JavaScript inside
`codex exec -s workspace-write` was denied a home-directory write (`EPERM`)
while a `/tmp` write succeeded. Started by hand outside Codex, the same `js`
tool is unconfined and can read files and run commands. The library's stricter
profile excludes `/tmp` and `$TMPDIR` writes and proves the bridge under that
profile before admitting it. This is JavaScript confinement, not browser
profile isolation. `harness.Support(e, Session, SandboxedBrowser)` says
which engines admit the browser in a sandboxed session, for a caller that
sandboxes every session and must decide before offering the browser.

Before any prompt, Codex sessions check that `node_repl` advertises its `js`
and `js_reset` tools, including deferred tools. Claude sessions check that
`claude-in-chrome` is connected and advertises browser tools. Missing tools
produce a typed `session.CapabilityError` with code `browser_tools_missing`,
the extension URL and setup guidance. Codex's inventory proves bridge tools
are loaded, not that Chrome is connected. Native runs have no equivalent
startup check and retain the CLI's own diagnostics. Neither check executes a
browser action.

Chrome itself runs outside the OS sandbox, with that
Chrome profile's logins, and reaches whatever the extension's site
permissions allow. For agents:

- Give them a dedicated Chrome profile with the extension, signed in to
  nothing they should not use, rather than your everyday profile.
- Limit the extension's site permissions to the sites the agent should
  visit, typically the local dev server.
- On macOS, Claude may pair it with `Sandbox.Loopback` after its
  base network proof succeeds. On macOS, dev-server listeners can bind every
  local interface and may be reachable from other machines; request localhost
  explicitly in the server configuration.
- Claude Linux Loopback is per-command. Host Chrome cannot rely on reaching a
  command's private listener; host dev servers and servers started by earlier
  commands are outside this contract. Browser tools run outside that command
  namespace, so Loopback alone does not establish browser/dev-server pairing.

A sandboxed Claude session admits the browser's tools beside its own, with explicit
allow rules for the ones Claude Code 2.1.283 lists. `file_upload` (which reads
local files from outside the sandbox) and the shortcut tools (which start
another agent in the browser's side panel) are denied, and a tool a later
build adds stays refused until it is reviewed. `--strict-mcp-config` keeps
only the browser's server, claude.ai connectors are switched off, and the
startup report must show that server connected and no other server's tools.
Historical browser-tool evidence: a sandboxed session served a page on
loopback, read it through Chrome, and found no `file_upload` tool. That older
run does not prove the macOS interface diagnostics. Loopback remains offered
after its base proof; macOS listeners may expose every local interface.

### Background priority

`Options.Background` (and `native.Config.Background`) runs the harness, and
everything it starts, at background priority, so agent work yields to whatever
the person at the machine is doing. Once the harness starts, its process group
is niced to 10, which descendants inherit, including a server an agent
backgrounds into a process group of its own. If the priority cannot be
lowered, the launch is stopped rather than run at normal priority. It is not
offered on Windows, and it is not part of a `Ref`.

macOS's background band (`PRIO_DARWIN_BG`) is deliberately not used. v0.13.0
used it, and on a busy machine it made an agent's 5-second test suite take two
minutes and time out: it also throttles disk I/O and confines work to the
efficiency cores. Nice 10 alone ran the same suite in 5.5 seconds at the same
load while still yielding to foreground work.

### Caller-hosted tools beside native ones

`Sandbox.Tools` takes the same `ToolHost` a restriction does, and serves it the
same way: through the caller's bridge command (`session.RunBridge`), under the
assignment lease, with a launch record, `Reclaim`, `Open`'s reclaim-first
behaviour and `Release`. The session keeps its sandboxed native tools and gains
the hosted ones.

```go
s, err := session.Start(ctx, session.Options{
    Provider: harness.Provider{Engine: harness.Claude},
    WorkDir:  "/private/workspace",
    Sandbox:  &session.Sandbox{Write: true, Web: true, Tools: &session.ToolHost{
        Server:  "crew",
        Tools:   tools,
        Handler: handler,
        Dir:     "/private/state/crew-worker-1", // owner-only, outside WorkDir
        Bridge:  session.Bridge{Path: executable, Args: []string{"tool-bridge"}},
    }},
})
```

- The sandbox is proved first; the tool channel opens only after that, and the
  sandbox evidence stays cached across channels.
- **Claude Code** loads only this server (`--strict-mcp-config`, claude.ai
  connectors disabled) and allows exactly its tools. The wholesale `mcp__*`
  deny is dropped, because a deny outranks every allow and would refuse the
  hosted tools too; any other MCP tool has no allow rule, which `dontAsk`
  refuses. The startup report must show the server connected, every hosted
  tool present and no other server's tools, or the session is closed.
- **Codex** registers the bridge as an approved MCP server in its private
  runtime home, which declares no other server. The app-server launches the
  bridge outside the shell's sandbox; checked against codex 0.156.1, the
  sandboxed shell itself cannot connect to the channel's socket.
- `Dir` must lie outside `WorkDir`. A Codex session can still read it, as it
  can read the account's other files, but the channel refuses anything
  without its credential and the shell cannot reach the socket.
- Hosted tools run whatever their handler does, outside the sandbox.
- There is no pre-launch surface probe, as native tools are present by design.
  Codex's hosted tools are not checked at startup beyond the channel serving
  them.
- A reference includes the tool server's name, not the tools or the channel.

`session.VerifySandbox(ctx, options)` runs the same check without opening a
session. Failures are `*CapabilityError` values with `sandbox_unavailable` or
`sandbox_not_enforced`. The phase says whether anything was launched.

What this does **not** do:
- Reads are not contained. A session can read what the operating account can
  read.
- The model provider connection remains an outward channel.
- Claude Code's file tools are confined by permission rules; its OS sandbox
  covers only the shell.
- A sandboxed session without `Tools` has no bridge, so it has no launch
  record or `Reclaim`. A caller that restarts mid-turn should treat the turn
  as interrupted.
- The mode is unavailable on Windows (`sandbox_unavailable`).
- `Restriction` and `Sandbox` are mutually exclusive, and a sandbox refuses
  any policy it would otherwise have to override.

## Steering and capabilities

Every engine offers the same session methods. `Capabilities` describes support
as `native`, `composed`, `unsupported`, or `unknown`, with a reason. Unknown
means not yet established against the running CLI; it is not a positive claim
of support. Runtime protocol errors remain authoritative.

- Codex uses the local app-server protocol and native `turn/steer`.
- Claude uses `claude -p` with JSON stdin/stdout. Steering is composed from an
  acknowledged interrupt, the old turn's terminal result, and a new user turn
  in the same process. Session restart/resumption is separately supported.
- `RequireNative` rejects composed steering. Receipts identify the strategy and
  resulting turn. The expected turn ID prevents a stale request redirecting
  newer work.

User-message queueing remains application policy. Interruption never means a
tool's external effects were rolled back. Failed or uncertain control operations
must be reconciled before retrying.

## Account, quota, credits and context

Usage is paid for in three ways, and an engine may use any of them:
subscription quota windows (percentages of a plan's allowance over a period),
token spend (the harness's own valuation at API rates, on `Usage`/`Cost`), and
credits (a prepaid or overage balance that can cover either). `account.Inspect`
reports quota and credits for every CLI engine in one shape, each part saying
whether it is known, and leaves combining them to the application:

```go
report, err := account.Inspect(ctx, harness.Provider{Engine: harness.Codex}) // or Claude, Grok
// Partial data can arrive beside an error: the login may be known when quota is not.
if report.Account.Known() {
    showPlan(report.Account.Plan) // empty means the plan was not reported
}
for _, window := range report.Quota.Windows {
    // Kind is session, weekly, weekly_model (with Model), monthly or other.
    if !window.IsStale(time.Now(), 5*time.Minute) && window.UsedPercent != nil {
        showAllowance(window.Kind, window.Model, *window.UsedPercent, window.ResetsAt)
    }
}
if report.Credits.Known() && report.Credits.Balance != nil {
    showCredits(report.Credits.Balance.Value, report.Credits.Balance.Unit) // exact decimal, currency or "credits"
}
```

| Engine | Login and plan | Quota windows | Credits |
| --- | --- | --- | --- |
| Codex | `account/read` | `account/rateLimits/read` | credit balance, spend control, rate-limit resets |
| Claude | `initialize.account` | `get_usage` and `rate_limit_event` | spend and extra-usage allowance, in minor currency units |
| Grok | agent protocol `check_subscription` | unsupported | unsupported |
| Antigravity | `agy -p=/credits --output-format json` (`plan_name`), or `/usage` for a login without credits | `agy -p=/usage --output-format json` (per-model-group quota windows) | `agy -p=/credits --output-format json` (`remaining_credits`) |
| fx | `fx status --json` (sign-in and team) | unsupported: fx reports spend for a period, not allowance windows | `fx credits --json` (AI Gateway balance) |

A missing CLI is a classified `not_installed` failure. `session.Inspect` remains
for Codex and Claude and also returns a session's `Capabilities`.

Inspection performs no model inference and creates no conversation. It runs the
selected CLI in a temporary neutral directory, using its existing login, and
cleans up the child and directory. It never reads credential files, copies
credentials, or calls a provider's account endpoint itself. Session prompts,
working directories and execution policies in `Options` are ignored by this
inspection operation. Claude inspection uses `--safe-mode`.

A persistent `Session` also offers `ReadAccount(ctx)`, `ReadQuota(ctx)`,
`ReadContext(ctx)` and the nonblocking, no-I/O `Telemetry()` snapshot getter.
Turn events include `account`, `quota` and `context` updates when emitted by the
CLI; idle updates remain accessible through `Telemetry()`. A turn's `Result`
includes its latest streamed `Context`. Consume events promptly as usual.

| Data | Codex | Claude |
| --- | --- | --- |
| Account/plan | `account/read` and `account/updated` | `initialize.account`; reopen or inspect again to observe a changed login |
| Quota | `account/rateLimits/read` and update notifications, retaining separate limit buckets | Experimental `get_usage` with `skip_behaviors: true`; `rate_limit_event` while running |
| Context | `thread/tokenUsage/updated`: latest active size and effective window | Experimental `get_context_usage` with `detail: summary`; latest assistant input and matching model capacity from stream events |

Claude's summary uses local estimates and avoids per-category token-count API
calls; it is labelled `Estimated`. Streamed Claude occupancy is also an estimate:
latest input plus cache tokens, excluding pending output/tool results. Codex's
context uses `last.totalTokens`, **never** accumulated session totals. Reading
Codex context returns the latest streamed observation without freshening its
timestamp; a newly opened session may not have one yet. Compaction invalidates
old occupancy until another observation arrives. No method triggers compaction.

Telemetry distinguishes evidence from capability. `Capabilities` acknowledges
native support after a successful response/event. Unsupported methods return
`ErrUnsupported`; other failures do not prove unsupported capability. Claude's
experimental schemas may change; observed with CLI 2.1.272. Older versions can
still run sessions even when an inspection method is unavailable.

Empty `Quality` means unavailable, `Measured` means a native reported value, and
`Estimated` marks estimates. `ObservedAt` is when the library observed the CLI's
response, which may itself be cached. `IsStale(now, maxAge)` also checks explicit
invalidation. Refresh failures preserve prior data and timestamps as stale;
individual windows carry timestamps because stream events may update only some
windows. `Complete` distinguishes a snapshot from an incremental update, not a
promise that the provider exposed all its limits.

Optional fields are pointers: missing does not mean zero, free or unlimited.
Used percentages may exceed 100; only `RemainingPercent()` clamps its derived
remainder. Absolute caps appear only when reported with their unit (`Allowance`);
there is no invented tokens-per-subscription conversion. Named model windows may
overlap account-wide windows: they are constraints, not quantities to sum.

Applications decide when to poll, pause, select another engine, reserve headroom,
or compact. Account metadata can include personal information; keep it private.
These inspection methods do not bind a session reference to a cryptographically
verified identity and do not change authentication.

Protocol references: [Codex app-server](https://learn.chatgpt.com/docs/app-server),
[Claude programmatic CLI](https://code.claude.com/docs/en/headless). The library
speaks to `claude -p` directly; it does not depend on the Claude SDK.

## Native runs and transcripts

`native.Run` invokes Codex, Claude, Grok, Antigravity or fx with one `Config`
and `Request` shape. Use `native.NewStream` to receive typed events and render a
common readable transcript. Reuse a stream only for sequential resumes of the
same session. The application decides whether an incomplete report warrants
another turn; the library does not retry autonomously.

```go
result, err := native.Run(ctx, native.Config{
    Provider: harness.Provider{Engine: harness.Grok}, // or Codex, Claude, Antigravity, fx
    Model:    model,
    Grok:     native.GrokOptions{Telemetry: native.GrokTelemetryReduced},
}, native.Request{Prompt: "Review this change.", WorkDir: workspace, Schema: reportSchema}, nil)
if err != nil {
    facts, _ := harness.ErrorFacts(err) // fixed codes; the provider's own text is result.Failure
}
// result.Report is the schema-shaped report; result.Usage, result.Cost
```

- One inline `Request.Schema` works for every engine. For Codex, the library
  writes the schema and reads the report in a private directory outside the
  workspace, where a workspace-write agent cannot forge it. Codex constrains
  every message to the schema; `harness.Support(e, harness.Run,
  harness.ProgressMessages)` says whether an engine lets the agent write
  unconstrained progress messages first. Antigravity passes the schema with
  `--json-schema` and reads the final result's `structured_output`.
- Engine-specific execution settings live in `Config.Codex`, `Config.Claude`,
  `Config.Grok`, `Config.Antigravity` (`PermissionMode`: `"accept-edits"`,
  `"auto"` or `"plan"`; empty leaves agy's default, `request-review`, which
  auto-denies any tool needing approval in a non-interactive run) and
  `Config.Fx` (`PermissionMode`: `"ask"`, `"auto"` or `"full-access"`; empty
  is `"ask"`, whatever the operator's saved interactive mode, and an asking
  run fails with `NonInteractivePermissionRequired` at its first write or
  shell command, since nothing can answer). An
  invalid mode is refused rather than passed to the CLI. Options for another
  engine, and `Args` that repeat a flag the library manages, are refused.
- An fx run is one `fx ask --json`, whose document is the whole record: the
  final response, the tools it used and the usage it reported. fx states no
  output schema, so a structured fx run is refused rather than answered with
  prose, and it states no dollar valuation, so an fx run reports no cost. Its
  usage covers that run alone, also when resumed, and states no cache split.
- An Antigravity result's usage covers its whole conversation, so a run's
  usage is the sum of its own responses, and a resumed run does not count
  earlier runs again.
- Failures are `*native.RunError` values with harness facts. The provider's own
  account of a failed turn is only in `Result.Failure`.
- A Grok turn that ends with any stop reason other than `end_turn` is a failure.
  Grok's `Tools` removes built-in tools only: MCP helper tools remain, as do
  MCP servers imported from other harnesses unless `GrokTelemetryReduced` is set.

Grok's zero-value telemetry policy preserves the installed CLI's normal
behaviour. `native.GrokTelemetryReduced` turns off Grok's documented
client-telemetry, trace-upload, feedback, auto-update and memory controls, and
its imports of Claude, Cursor and Codex skills, rules, agents, MCP servers,
hooks and sessions, for that invocation. It is not a no-egress guarantee:
inference and any enabled tool or provider traffic still leave the machine. It
does not change the xAI account's coding-data sharing or retention settings
(`/privacy`, Zero Data Retention), and leaves external OpenTelemetry to the
operator's own collector (`GROK_EXTERNAL_OTEL`) as configured.

Native arguments and environment overrides are trusted configuration. They
must not originate in model output. Raw tool content and transcripts can contain
private material; the library does not make them safe for public display.

## Authentication and resource handling

Binary and home paths are optional per configuration. The library never changes
the parent process's environment. Restricted Codex sessions share login material
into a private runtime home as described above; other invocation modes use the
selected native login directly. Constrained completion and interactive sessions
filter ambient provider overrides; native runs can inherit the caller's
environment explicitly for compatibility with CLI setups.
A separate working directory does not require a separate account. Selecting a
custom home can select a different login namespace; authenticate through the
CLI's supported flow for that home.

### A locked keychain

Claude Code keeps its login in the macOS login keychain, and every Claude
process reads it at startup. While the keychain is locked, each start raises
its own unlock prompt, and several at once have wedged SecurityAgent. So
before any operation launches Claude on macOS (sessions and their checks,
native runs, completion, discovery, account inspection), the library asks
the keychain's own status, which never prompts, through
[lib-agent-keyring](https://github.com/shhac/lib-agent-keyring). If it is
locked, the operation fails with `harness.CodeKeychainUnavailable`
(`keychain_unavailable`, preflight family, not retryable) and starts nothing.
`harness.LoginStoreLocked(engine)` asks the same question, in about a
millisecond, so an application can stop polling until it is false again and
show one "unlock your keychain" message rather than a failure per poll.

### Process containment

Unix subprocesses run outside the parent's terminal process group. Windows
subprocesses start suspended and are assigned to a job before running. Context
cancellation terminates contained descendants. Event/output bounds keep a noisy
CLI from growing memory indefinitely where the API advertises those bounds.

Unix Close repeats its birth-checked group sweep to catch members forked during
termination. On kernels that count zombies, exited but unreaped members still occupy the recorded group:
launchd or init reaps orphaned children asynchronously, so restricted Release
waits for group absence even after the CLI and bridge have died.

An agent's background commands leave that group: Claude Code starts each in a
process group of its own, and once its shell exits it belongs to launchd. So
every launch carries a random token in `AGENT_HARNESS_LAUNCH`, which its
descendants inherit, and stopping or closing the launch kills every process of
this user that carries it, and those processes' descendants. Close does this
even after the CLI itself exited, so a native run's leftovers go with it, and a
session's go when it closes. Before killing a group, Stop and Close snapshot
marked processes, validated launch-group members, and their descendants, then
kill the snapshot after rechecking each process's birth identity. This catches
detached macOS platform binaries whose environment is hidden while their parent
is still discoverable. Sweep rounds retain still-live, birth-checked roots.

This remains best-effort, not a boundary: a process that clears its environment
and leaves the group can escape, as can a hidden-environment process whose
ancestry to a marked process or group member broke before Stop or Close (for
example, its parent exited on its own). A hidden child forked between the
snapshot and its parent's kill can also escape. Linux needs readable /proc;
other Unix systems without process enumeration get only the group kill. Failed
enumeration does not prevent that kill. A snapshot is only in memory; a host
crash adds no durable containment guarantee. Concurrent shutdowns may repeat
identity-checked signals. A shared helper that a harness starts on first use
would be stopped too, and started again by the next launch.

Usage preserves provider-specific accounting scopes. Missing or interrupted
usage can be unknown; zero counters do not necessarily mean a free run. A
rejected or abandoned constrained completion still returns any authoritative
terminal accounting its CLI reported, because a failed request can have been
billed. Reported costs are provider API-rate valuations, not a statement of
subscription charges.

## Development

```sh
go test -race ./...
go vet ./...
```

Automated tests use synthetic streams and fake CLI processes. They never invoke
paid models or touch real account credentials. CI runs on Linux, macOS, and
Windows. Consumers depend on published module tags, not sibling-directory
`replace` directives.

### Running the tests inside a sandbox

The suite also runs inside a sandbox, such as the one an agent runs its
commands in. Tests that need a capability such a sandbox commonly refuses
first probe for it and skip with a one-line reason naming the capability. Shared
probes run once per test binary. Permission refusals and the library's own
90-byte channel-directory limit may skip; unexpected errors still fail:

| Needs | Tests |
| --- | --- |
| Creating FIFOs, sockets, hard links and Windows junctions; a writable package directory | workbench containment tests; `TestWorkbenchFIFOAndSocketRefusal` binds directly in a workspace under `./.wbs-*` to keep the socket path short; Linux bind mounts require the CI mount setup |
| A loopback listener and connection | local provider fixtures and CLI capability checks (`completion/`, `session/`, `sandbox/`) |
| A `TMPDIR` short enough for the library's 90-byte channel directory | restricted session and tool-host tests; checked before the probe binds, so a long path is not mistaken for an unexplained EINVAL |
| A Unix domain socket under `TMPDIR` | every test that opens a restricted or sandboxed session's tool channel (`session/`) |
| A process group of its own (setpgid) | the tests of what containment does with the group — detach, group cancellation, descendant pipes, escapees, sweeps (`process/`); the stand-in bridge and `Reclaim` tests (`session/`) |
| Reading process status with `ps` | the cancelled-group and sweep tests (`process/`), which otherwise could not tell a live process from a gone one |
| Lowering a process group's priority | `TestBackgroundLowersTheWholeTree` (`process/`) |
| Writing `/tmp` and `TMPDIR` directly | `TestOpenCanaryEscapesAreEachDetected` (`session/`): an outer sandbox contains the unsandboxed canary too, which then rightly reports no escape |
| A real Linux bubblewrap launch | five-phase mount simulation, fixed refusals, four canary layouts, raw syscall attacks, edit-and-run and cleanup; distribution and SHA-256-checked upstream 0.8.0 CI jobs forbid skips |
| Creating reserved atomic workbench temporaries | file-tool write/edit, recovery and reserved-file fixtures; a command sandbox deliberately protects these names even under TMPDIR |
| Reading Linux system-path metadata and socket-witness ancestors; opening /dev | Linux mount-builder fixtures and the macOS distinct-mount test probe actual paths, skipping only permission refusals |
| A nested OS sandbox on macOS | a cached trivial Seatbelt launch checks nesting independently of generated profiles; real workbench canary, edit-and-run, cancellation and crash-cleanup tests still prove their generated profiles after the prerequisite succeeds |

Any other probe failure fails the test, so a real fault is never hidden behind a
skip. `go test -v ./...` lists each skip with its reason, for example
`environment refuses a Unix domain socket under TMPDIR: listen: … operation not
permitted`. Harness launches in general are not gated. They always start in a
process group of their own, and that has to work wherever the library runs.

Setting `AGENT_HARNESS_TEST_NO_SKIP=1` turns every such skip into a failure. CI
sets it, so an unsandboxed run can never pass by skipping. The helpers live in
`internal/testenv`. A bare bind EINVAL remains a failure. Cancelled or timed-out
bubblewrap trials fail before refusal conversion, even if the CLI returns a
recognized prerequisite refusal; interrupted observations are not evidence.

To check the entire suite under the library's own command boundary, run from
the module root in an **unsandboxed** checkout with dependencies already cached:

```sh
go run ./internal/cmd/sandboxcheck
```

The runner uses the installed Go toolchain, read-only cached modules, private
scratch for GOCACHE, no proxy or toolchain downloads, and a ten-minute timeout.
It prints vet/test output and propagates the command's exit status; cancellation
settles the command tree before Close. A crash may leave private runtime scratch;
Open sweeps interrupted command state through its lifetime lock on reuse,
restoring owner directory permissions inside the scratch/state tree before
removal, without following links or touching the caller's workspace.
The working tree receives only normal Go test writes. A stopped socket probe may
leave an owner-only random `ahp-*` directory under TMPDIR; a killed atomic-write
probe may similarly leave `ah-write-*` scratch.

`TestCommandSandboxRunSkipsRefusedCapabilities` is CI's re-exec evidence:
nested sandbox and Unix channel-path prerequisites skip inside
a real command sandbox (plus loopback bind on macOS; Linux permits its
namespace's own localhost), and the same fixtures fail with NO_SKIP. The outer CI
run still forbids prerequisite skips. NO_SKIP cannot be inherited or supplied
through `sandbox.Options.Env`; set it in the sandboxed command string.
`go run ./internal/cmd/sandboxcheck -no-skip` does this explicitly and is
expected to fail where the command boundary refuses prerequisites.

Linux sandbox-check follow-up: the unsandboxed privilege escape control probes
/proc/self/status. Zero effective, permitted, inheritable and ambient capabilities
with NoNewPrivs=1 prove inherited confinement; only the privilege subtest skips
with a named one-line refusal. Filesystem, network and overlay assertions still
run. Missing or malformed status fails; permission-denied reads name their own
diagnostic. Real sandbox canaries still require privilege-ok.

Reclamation lease tests use a ready, live survivor in a dedicated group greater
than 1 instead of the inherited test group (which can be 1 under bubblewrap).
Early worker errors fail immediately; cancellation settles the worker, releases
the lease and preserves the launch marker. The survivor must respond after
settlement, proving it remains live rather than merely occupying a zombie group.
No production ownership rules change.

Nested refusal fixtures require the platform-specific capability prefix and a
nonempty diagnostic suffix. Linux uses bubblewrap 0.8.0+ and unprivileged
namespaces; abbreviated reports are not complete diagnostics. Joined refusal
errors are flattened to one line. NO_SKIP still fails refused prerequisites;
child normal/strict fixtures select their own mode independently of the parent.
Production sandbox permissions and harness.Support claims remain unchanged.

CI pins Linux distribution coverage to Ubuntu 24.04, verifies bubblewrap 0.9.x,
and retains the separate 0.8.0 job. Unix jobs run the real fixture under both
parent strict modes and require actual verified child results; an outer skip
does not count. They repeat the lease test twenty times under the race detector.
The macOS and Ubuntu jobs also run the complete sandboxcheck runner.

Owner-reported validation compares baseline 106c711 with drafts ad4b36b and
b54ec5d: the baseline Linux sandboxcheck and strict suite failed; both drafts'
Linux sandboxcheck and strict suites passed. Draft 1 passed both on macOS too.
Draft 2's macOS sandboxcheck passed, but its strict suite encountered a
developer-tool first-launch timeout. The owner's separate 71e7d39 correction
and passing test are now merged here and retained. These are aggregate owner
results; raw baseline diagnostics, separate focused/both-parent transcripts,
and Windows/0.8.0 runtime CI results remain unrecorded. See the
[validation evidence inventory](design-docs/2026-10-03-command-sandbox.md#validation-evidence)
for snapshot, command and platform boundaries.

The preceding owner-supplied results are historical LAH-23 evidence. Under owner note 20, the owner supplies corrected command-policy strict-suite
and sandboxcheck results from macOS and the Linux VM outside the sandbox.
Existing CI jobs remain unchanged; runtime results not yet posted remain unverified.

Licensed under [PolyForm Perimeter 1.0.0](LICENSE), matching the sibling
`lib-agent-*` libraries.

## Manual native compaction

`session.Compact(ctx)` requests compaction only while the session is idle and
returns a `*Turn`. Drain its events and await `Wait` before starting another
turn. Codex acknowledges `thread/compact/start` before doing the work; the turn
ID is empty until `turn/started`, and successful completion requires the native
terminal event. Compaction emits `compaction_started`/`compaction_completed`
item events and invalidates stale context measurements until a fresh observation.
Cancellation closes the session, as with `StartTurn`.

`Capabilities.Compact` starts unknown for Codex and becomes native on a successful
request, or unsupported on an explicit method rejection. Claude reports
unsupported: its interactive `/compact` command is not a verified stream-json
control operation. The library never substitutes a summarization prompt.

In a restricted Claude session it stays unsupported for a second reason:
`--disable-slash-commands` removes `/compact` along with every other command,
and lifting that would need its own review of the whole command surface. Claude
still compacts automatically. A caller that wants a manual compaction rebuilds
instead: summarize the conversation itself, `Open` a fresh session (no
reference), and return the summary from `Options.Context` for `ContextStarted`.
The protocol reference is the [Codex App Server manual compaction section](https://learn.chatgpt.com/docs/app-server).
