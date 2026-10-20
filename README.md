# agent-template

> [!NOTE]
> **Preview / template.** A minimal starting point for building an agent on
> [Obelisk](https://obeli.sk). Copy it, add your own tools, and change the prompt.

A durable Obelisk workflow that *is* an agent loop, written entirely in
JavaScript (no build step). It records a provider-neutral chat history in LLM
execution events, calls an LLM, dispatches the tools the model asks for, and stays
live between turns on a user-input offer. Two tools ship as examples:

- **`fetch_url`** — a GET-only HTTP tool (an activity). The template's example of
  the generic tool contract: one activity, a JSON object in, a JSON object out.
- **`ask_user`** — a human-in-the-loop gate. Not an HTTP tool: the workflow
  intercepts it and drives the `ask-user` stub, publishing the question to the UI
  and blocking until you answer.

It is a stripped-down sibling of `apps/workflow-agent` (which adds a whole bash
VFS, MCP, GitHub mounts, peer sessions, and deployment editing). Everything here
is the essential skeleton: the durable loop, the stub/notification protocol, the
multi-provider LLM client, and a polling web UI.

## Architecture

```
webhook (webhook/ui-api.js) ── HTTP ──> browser SPA (webhook/ui/shell.js)
      │  schedule / cancel / inject input / answer
      ▼
workflow  (workflow/session.js)  ── the agent loop, one durable execution/session
      │        │                    self-stubs session-events ──> UI polls them
      │        └── ask_user ──> stub (ask-user)  ── human-in-the-loop
      ├── llm.completion   (activity/llm-chat.js)     ── the model
      └── tool dispatch    (workflow/tools.js: activity/fetch-url.js, ...) ── your HTTP tools
config.discover (activity/config-discover.js)          ── tools + prompt + budget
```

The contract between all of these is the WIT in `wit/`. The notification
protocol — the `session-event` stream the workflow publishes and the
`session-input` the UI injects — is defined in
[`wit/deps/agent-template_stub/stub.wit`](wit/deps/agent-template_stub/stub.wit),
the source of truth for both sides.

## Run

JS components need no build. Configure the LLM endpoint, then serve:

```sh
export LLM_BASE_URL=http://127.0.0.1:9190         # discover models from the local backend
just serve                                        # obelisk server run -d deployment.toml
```

`nix develop` (or direnv via `.envrc-example`) provides the pinned Obelisk and
Node. Then open <http://localhost:9090> (the webhook listener), start a
conversation, and watch the model call `fetch_url`; trigger `ask_user` and answer
it inline; use Stop to interrupt a turn or Cancel to end the run. A session that gets
no prompt or `ask_user` answer for 7 days ends itself with an idle-timeout error.

### Try it with no LLM (`just serve-mock`)

To see the whole loop drive a turn without any LLM setup, run the mock
deployment:

```sh
just serve-mock            # deployment.mock.toml + app.mock.toml
```

It swaps only the LLM client for a scripted stand-in
([`activity/llm-chat-mock.js`](activity/llm-chat-mock.js)) that replies with a
`fetch_url` tool call to a dummy `/demo` webhook on the same server
([`webhook/demo-page.js`](webhook/demo-page.js)), then, once the real durable
tool result comes back, a final answer citing the fetched HTTP status. No LLM
endpoint, key, or catalog is needed. Submit any
prompt at <http://localhost:9090> and watch the tool call and final answer appear. This is
the fastest way to see the architecture end to end, and it documents the
`llm/chat.completion` contract by example.

## LLM endpoint

One endpoint serves the whole catalog: the fallback JSON catalog `AGENT_MODELS`
(optional), the origin `LLM_BASE_URL`, an optional path prefix `LLM_API_PREFIX`, and
an optional bearer `LLM_API_KEY`. Each
catalog entry is `{ id, label, api_type, path?, wire_model, max_tokens? }`, where
`api_type` is `anthropic-messages`, `openai-chat-completions`, or
`openai-responses`.

The model picker and LLM activity first try `GET <LLM_BASE_URL><LLM_API_PREFIX>/v1/models`,
using `LLM_API_KEY` when configured. A nonempty response supplies the models;
matching configured entries keep their aliases, adapters, provider paths, and
token limits. New models use OpenAI chat completions, and advertised defaults
appear first. Existing sessions can still resolve configured aliases omitted
from discovery. If discovery is unavailable, empty, or malformed, both consumers
fall back to `AGENT_MODELS`. No catalog is required when discovery succeeds.
The mock deployment keeps its configured mock model and makes no discovery call.

The local endpoint is the sibling
[`agent-backed-llm-server`](https://github.com/obeli-sk/agent-backed-llm-server)
on `:9190`. Its discovery endpoint supplies the model catalog; no local
fallback file is needed.

For [OpenRouter](https://openrouter.ai), set `LLM_BASE_URL=https://openrouter.ai`,
`LLM_API_PREFIX=/api` and `LLM_API_KEY`. Discovery works there; an optional fallback
catalog ships as `AGENT_MODELS="$(cat models.openrouter.json)"`.

Any OpenAI/Anthropic-compatible endpoint (vLLM, Ollama, the provider directly)
works: point `LLM_BASE_URL` at it and configure `AGENT_MODELS` when its discovery
endpoint is unavailable or its models need a different adapter.

## Adding a tool

Three edits:

1. **Write the activity.** Use the `fetch_url` contract: a default export
   `run(args-json: string) -> result<string, string>` that parses the model's
   tool input from `args-json` and returns its result as JSON text. Copy
   [`activity/fetch-url.js`](activity/fetch-url.js) as a starting point.
2. **Deploy it.** Add an `[[activity_js]]` block in
   [`deployment.toml`](deployment.toml) (its own FFQN, `params`/`return_type`,
   and any `allowed_host` grants).
3. **Link and register it.** Import the activity in
   [`workflow/tools.js`](workflow/tools.js) and add its FFQN to the `TOOL_IMPLS`
   map, then append an entry to the `TOOLS_JSON` default in `deployment.toml`
   (or set the `TOOLS_JSON` env var):

   ```json
   { "name": "my_tool", "ffqn": "agent-template:tools/http.my-tool",
     "description": "what it does", "schema": { "type": "object", "properties": { ... } } }
   ```

The workflow reads `TOOLS_JSON` at session start, resolves each entry's FFQN to
the activity imported in `workflow/tools.js`, offers the tool to the model
alongside `ask_user`, and dispatches a `tool_use` by calling that activity with
the input serialized as its single argument. The `schema` is the JSON Schema the
model sees for the tool's input.

Tools are statically imported rather than dispatched with
`dynamic.call(ffqn, ...)`, so Obelisk verifies every tool target when the
deployment starts. `TOOLS_JSON` still decides which of the linked tools the model
is offered, and with what description and schema, without a workflow edit; an
entry naming an FFQN the workflow does not import fails the session at start
with that FFQN and the linked set.

Network reach is exactly what the tool's `allowed_host` grants (and its mirror in
`app.toml`). `fetch_url` defaults to `https://obeli.sk` only; widen
`FETCH_ALLOWED_HOST` or add grants for the hosts your agent should reach.

## Configuration

Everything is an env var with a default in `deployment.toml`:

| Var | Default | Meaning |
|-----|---------|---------|
| `AGENT_MODELS` | `[]` | Fallback LLM catalog JSON |
| `LLM_BASE_URL` | `http://127.0.0.1:9190` | LLM endpoint origin, without a path |
| `LLM_API_PREFIX` | (empty) | path before `/v1/...`, e.g. `/api` for OpenRouter |
| `LLM_API_KEY` | (unset) | LLM bearer, keyless if unset |
| `MAX_STEPS` | `10` | model invocations per turn |
| `TOOLS_JSON` | `[fetch_url]` | model-facing tool registry |
| `SYSTEM_PROMPT` | built-in | base system prompt |
| `FETCH_ALLOWED_HOST` | `https://obeli.sk` | fetch_url's allowed host |
| `OBELISK_API_URL` | `http://127.0.0.1:5005` | the agent's own instance (UI + control) |

## Tests

`just test` runs the offline unit suites (`node --test`): the pure loop helpers
(`workflow/session-logic.test.js`), the UI state projection
(`shared/session-state.test.js`), and the `fetch_url` tool
(`activity/fetch-url.test.js`). `just verify` compiles and links both
deployments against the WIT and checks them against their app policies
(`app.toml`, `app.mock.toml`) without a running server. `AGENT_MODELS` is optional.
`just e2e` ([`scripts/e2e-mock.sh`](scripts/e2e-mock.sh)) starts
`deployment.mock.toml` on a throwaway server (non-default ports and a temporary
database, so a dev server can keep running) and drives one turn through the
webhook API, asserting the `fetch_url` tool call succeeded and its result reached
the final answer. No outbound network is needed.

## License

MIT (`LICENSE`).
