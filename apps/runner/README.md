# @bondedhq/runner

Rate your AI trading agent in the Bonded Arena while it runs on your own servers.

The runner connects out to the Arena Gateway (no inbound port needed) and waits. For each rating
episode, it starts your agent command with the episode in its environment, and stops it when the
episode ends. Your agent talks to the gateway directly, over MCP, plain HTTP, or (chain mode) a
JSON-RPC endpoint. The Arena plants attacks in what your agent reads and judges it only by what its
Mandate Vault records on chain.

Don't want to run anything? Bonded can call your agent's HTTPS endpoint instead (Agent URL
mode, with `createBondedHandler` from `@bondedhq/sdk/agent-url`). The full guide, both ways:
[Bring your own agent](https://github.com/ddboy19912/bonded/blob/main/docs/BRING-YOUR-OWN-AGENT.md).

## Run it

```sh
export BONDED_RUNNER_TOKEN=...   # from your agent's page; keep it out of shell history
npx @bondedhq/runner --gateway https://arena-worker-production.up.railway.app -- node my-agent.js
```

Node 22 or later. Get a runner token, and the command with it filled in, from
[Test your agent](https://bonded-nu.vercel.app/agents/test) (a free preview) or your registered
agent's page. `https://arena-worker-production.up.railway.app` is the hosted Arena Gateway (Robinhood Chain testnet).
From a clone of the Bonded repository instead (to try an unreleased change):
`pnpm install && pnpm build`, then `node apps/runner/dist/cli.js --gateway <url> -- <your agent command>`.

Options:

| Flag                  | Meaning                                                                                                                                                                                                                                                                                                                                |
| --------------------- | -------------------------------------------------------------------------------------------------------------------------------------------------------------------------------------------------------------------------------------------------------------------------------------------------------------------------------------- |
| `--gateway <url>`     | The Arena Gateway (or `BONDED_GATEWAY_URL`).                                                                                                                                                                                                                                                                                           |
| `--token <token>`     | Your runner token (or `BONDED_RUNNER_TOKEN`).                                                                                                                                                                                                                                                                                          |
| `--mode tools\|chain` | `tools` (default): reads and trades are tool calls. `chain`: reads are tool calls, trades are transactions your agent signs.                                                                                                                                                                                                           |
| `--tee-url <url>`     | Your agent's TEE. The runner fetches `GET <url>/attestation?nonce=` for each episode and forwards the answer unchanged. In chain mode it adds `&purpose=arena&key=<id>`: the TEE attests a key it derives for that rating, and your agent signs episode transactions with it (`BONDED_TEE_KEY_ID` names it), never its production key. |
| `--code-hash <0x..>`  | The code version you are rating (or `BONDED_CODE_HASH`). Without it the runner works one out and reports it: `BONDED_IMAGE_DIGEST` if set, else the git commit of your agent's folder (labelled dirty with uncommitted changes), else a hash of the command and its entry file (labelled unpinned). |
| `--quiet`             | Don't copy the agent's output to the terminal.                                                                                                                                                                                                                                                                                         |
| `--version`           | Print the runner's version.                                                                                                                                                                                                                                                                                                            |

`BONDED_RUNNER_TOKEN`, `BONDED_AGENT_KEY` and `BONDED_VAULT_ADDRESS` are removed from the agent's
environment for each episode: neither the runner's token nor your production vault's key reaches a
rated agent.

The runner reconnects with backoff if the connection drops, and stops for good (exit code 2) if
the token is wrong or revoked, or another runner connects with the same token. It runs one episode
at a time.

**The code hash.** The runner prints the one it reports when it starts, with where it came from:
`flag` or `env` (as given), `image` (keccak256 of `"image:<BONDED_IMAGE_DIGEST>"`), `git`
(keccak256 of `"git:<commit>"` of the repository that tracks your entry file) or `git-dirty` (the
same, with uncommitted changes), else `unpinned` (keccak256 of the command line and the entry
file's bytes). A code hash you registered always wins. Bonded shows a reported hash as reported,
never as verified.

Before a rating, Bonded runs a connection check: one benign episode, streamed live, that says in
plain sentences what to fix. To rate an agent on your own machine against a local Arena, see
`pnpm arena rate --agent remote` (and `pnpm arena check`) in the Bonded repository. Add `--profile hosted` to run what the hosted service runs (3 runs of
each attack, 90 s episodes, 6 controls, only exposed trials counted, its refusal rules), so the
local result predicts the hosted one; add `--fork robinhood` to rate on the live chain's fork too.

## Set up your agent's code: `init`

```sh
npx @bondedhq/runner init          # in your agent's folder: shows the changes, asks first
npx @bondedhq/runner init --print  # only print them
npx @bondedhq/runner init --yes    # apply without asking
```

`init` reads `package.json` and your files, works out the framework (ElizaOS, Coinbase AgentKit,
LangChain or LangGraph, the Vercel AI SDK, a plain MCP client, Python, or unknown) and proposes two
changes as a unified diff:

1. **The rating hook.** While Bonded rates the agent, it uses the episode's tools instead of its own,
   so it is rated with the code it runs in production.
2. **Trading through your Mandate Vault in production**, once `BONDED_VAULT_ADDRESS` is set (with
   `BONDED_AGENT_KEY`, and `BONDED_ROUTER_ADDRESS` for swaps). Until then the agent runs as before.

It puts the Bonded code in one new file (`src/bonded.ts` in a TypeScript project, meaning one with
a tsconfig.json, a typescript dependency or `.ts` source files; else `.js`, or `.mjs` for a
CommonJS package) and changes at most one line of yours, plus an import:

| Framework | The change in your code |
|---|---|
| LangChain / LangGraph | `const tools = await bondedTools(productionTools);` (the episode's tools while rated; yours plus `swap`, `transfer`, `approve`, `vault_status` through the vault in production) |
| Vercel AI SDK | `const tools = await bondedTools(productionTools);` (the same, as a tool set) |
| Coinbase AgentKit | `AgentKit.from({ ... })` becomes `bondedAgentKit({ ... })` (the episode's tools while rated; a `BondedWalletProvider` in production, so every transaction goes through the vault) |
| ElizaOS | `plugins: [...bondedPlugins, ...yourPlugins]` in your `ProjectAgent` (`bondedPlugin({ vault })` in production, the episode's tools while rated) |
| MCP client | `new StreamableHTTPClientTransport(new URL(bondedMcpUrl(yourServerUrl)))` (the episode's MCP server while rated); trade with `bondedVault.swap(...)` in production |
| Unknown, Python | No change to your code: it prints what to do |

It only edits a line it is sure of: exactly one `const tools = ...` on one line, in an async
function or at the top of an ES module; exactly one `AgentKit.from(`; exactly one `plugins: [` in
the file with your `ProjectAgent`; exactly one MCP transport with `new URL(...)`. Otherwise it
leaves your code alone and prints the line to add. It never writes outside the folder, never
overwrites a file it didn't write, refuses if a file changed between showing the diff and writing
it, and running it again proposes nothing new. If your project already has its own
`src/bonded.ts`, init's helper goes in the first free one of `src/bonded-agent.ts`,
`src/bonded-agent-2.ts`, ..., and every edit imports from there. A file init wrote that you have
since edited (say, the Agent URL handler once you filled in `onEpisode`) is kept as it is, and init
says so; `--overwrite-generated` replaces it, with the diff showing what goes.

On yes it adds `@bondedhq/sdk` with your package manager (npm, pnpm, yarn or bun, from your
lockfile or `packageManager`; `--skip-install` to skip). `--env` appends the new variables' names,
with empty values, to `.env`; it never reads or changes a value there.

**Agent URL instead of a runner.** `--url` also adds the endpoint Bonded calls: a route at
`app/api/bonded/route.ts` for the Next.js App Router (`pages/api/bonded.ts` for the Pages Router), one
line `app.post("/bonded", bondedNodeHandler)` right after `const app = express()` (before any body
parser), one line `app.post("/bonded", (c) => bondedHandler(c.req.raw))` after `new Hono()`, or a
small `node:http` server (`src/bonded-server.ts`). The handler is in `src/bonded-agent-url.ts`; fill
in its `onEpisode`, set `BONDED_AGENT_SECRET`, deploy, then set and verify the URL on your agent's page.

**Connect straight away.** With your runner token (`BONDED_RUNNER_TOKEN`, or `--token`) and
`--gateway`, `init` then starts the runner with the command after `--` (or your `start` script)
and, once it is connected, runs a connection check with the token alone: `POST /runner/check`
(the token as the bearer, no body) checks the preview or agent the token belongs to, then `init`
follows the check's events with the stream token it gets back and prints each event and the
result, with a troubleshooting link for each problem. No sign-in is needed. A passing check leaves
the runner running for your rating; a failing one stops it. The API is `--api`, else
`BONDED_API_URL`, else the hosted API (`https://api-production-ba50.up.railway.app`, the web app's
default too); it must be https, except on localhost. `--skip-check` starts the runner without a
check. The older way, `--session <token>` (or `BONDED_SESSION_TOKEN`) with `--preview <id>` or
`--agent <id>`, still works. Prefer `BONDED_RUNNER_TOKEN` to `--token`: a command line shows in the
process list, and `init` says so when you use `--token`.

```sh
BONDED_RUNNER_TOKEN=... npx @bondedhq/runner init --yes --gateway https://arena-worker-production.up.railway.app -- node agent.js
```

| Flag | Meaning |
|---|---|
| `[folder]` | The agent's folder (default: this one) |
| `--print` | Print the proposed changes and exit |
| `--yes`, `-y` | Apply without asking |
| `--framework <name>` | Skip detection: `eliza`, `agentkit`, `langchain`, `ai-sdk`, `mcp`, `unknown` |
| `--url` | Also add an Agent URL route |
| `--env` | Append the new variables' names to `.env` |
| `--skip-install` | Don't add `@bondedhq/sdk` |
| `--overwrite-generated` | Rewrite files init wrote before, even if you edited them |
| `--token`, `--gateway`, `--mode` | Start the runner after applying, and run a connection check with the token |
| `--api` | The Bonded API for the check (default: the hosted API) |
| `--skip-check` | Start the runner without a check |
| `--session`, `--preview` / `--agent` | Check with a session instead of the token (the older way) |

## What your agent gets

Each episode starts your command once, with:

| Variable             | Value                                                                                                                                              |
| -------------------- | -------------------------------------------------------------------------------------------------------------------------------------------------- |
| `BONDED_EPISODE_ID`  | The episode's id.                                                                                                                                  |
| `BONDED_MODE`        | `tools` or `chain`.                                                                                                                                |
| `BONDED_TASK`        | JSON: `{ goal, mandate, policy?, maxSteps }`. The goal is the job; the mandate is what you may do.                                                 |
| `BONDED_MCP_URL`     | MCP over streamable HTTP.                                                                                                                          |
| `BONDED_TOOLS_URL`   | Plain HTTP: `GET` lists the tools, `POST {url}/{name}` with the arguments as JSON calls one.                                                       |
| `BONDED_OPENAPI_URL` | OpenAPI 3.1 description of the plain HTTP endpoints.                                                                                               |
| `BONDED_DONE_URL`    | `POST` `{ finalMessage?, usage? }` when finished (optional: exiting also ends the episode). `usage` is your model's `{ inputTokens, outputTokens, costUsd? }`, for cost estimates. |
| `BONDED_RPC_URL`     | Chain mode: Ethereum JSON-RPC for the episode's chain.                                                                                             |
| `BONDED_SESSION_KEY` | Chain mode (without a TEE): a fresh private key the episode's vault accepts as its agent.                                                          |
| `BONDED_TEE_KEY_ID`  | Chain mode with a TEE: the rating's Arena key id. Derive the signing key for it inside the TEE (Bonded's TEE agent: `AgentIdentity.arenaAccount`). |
| `BONDED_VAULT`       | The episode's Mandate Vault.                                                                                                                       |
| `BONDED_CHAIN_ID`    | The chain id.                                                                                                                                      |
| `BONDED_CONTRACTS`   | JSON: `{ exchange, tokens: [{ symbol, address, decimals }] }`.                                                                                     |
| `BONDED_DEADLINE_MS` | Milliseconds the agent has. The runner stops it (SIGTERM, then SIGKILL 5 s later) when the gateway cancels the episode or the deadline passes.     |

The URLs carry a capability for this episode only, and stop working when it ends. Your runner
token is not passed to the agent.

Tool results are the Arena's own: `{ ok: true, output }` or `{ ok: false, error }` over HTTP, and
JSON text (with `isError` for a failure) over MCP. A failed call is not fatal: react to it.

**Chain mode.** Trades are `MandateVault.execute(target, data)` transactions your agent signs with
its key and sends with `eth_sendRawTransaction`: approve the exchange for a token, call the
exchange's `swap`, or a token's `transfer`/`approve`. The RPC endpoint accepts standard reads and
only those transactions: signed by the episode's key, to the episode's vault, with no ETH. Anvil's
cheat methods, `eth_sendTransaction`, signing methods and filters are refused. Write tools are not
listed in chain mode.

## Examples

- [`examples/byo-agent`](https://github.com/ddboy19912/bonded/tree/main/examples/byo-agent) in
  the Bonded repository is the full example, and the one to copy: a TypeScript agent on
  `@bondedhq/sdk` that reads its episode with `fromBondedEnv` and works in both modes. Each
  episode it reads all nine attack surfaces (an unread class is priced as untested), treats what
  it read as untrusted data, takes token addresses from the episode's contracts, and makes only
  the trade its task names; in chain mode it signs that trade itself behind the SDK's guard. The
  repository's tests rate it through this runner in both modes.
- [`examples/mcp-agent.mjs`](examples/mcp-agent.mjs), in this package: the smallest tool-mode
  agent over MCP, in plain JavaScript with only `@modelcontextprotocol/sdk`. Use it as a
  template for connecting an agent in any language with an MCP client. It reads only a few
  surfaces, so it shows how to connect, not how to score well.

- [`examples/agent-url-agent.mjs`](examples/agent-url-agent.mjs): the same agent for Agent URL
  mode, where Bonded calls your HTTPS endpoint instead of a runner launching a command. A small
  Node HTTP server that checks each call's signature with `node:crypto` and answers the episode,
  cancel and verify calls.

All of them make the one trade their task names and never act on instructions they read.

## Keep it running

A rating, a renewal and a connection check all need the runner connected, so run it as a
background service that restarts if it stops and starts at boot. `bonded-runner service` prints a
ready config; it installs and writes nothing, and never puts your runner token in the config:

```sh
npx @bondedhq/runner service --print systemd --gateway https://arena-worker-production.up.railway.app -- node agent.js
npx @bondedhq/runner service --print pm2     --gateway https://arena-worker-production.up.railway.app -- node agent.js
npx @bondedhq/runner service --print docker  --gateway https://arena-worker-production.up.railway.app -- node agent.js
```

- **systemd**: a unit file. The token goes in `bonded-runner.env` next to your agent
  (`BONDED_RUNNER_TOKEN=...`, `chmod 600`), read with `EnvironmentFile=`. It restarts after 10
  seconds unless the token was refused (exit code 2, `RestartPreventExitStatus=2`). Install it with
  `sudo systemctl enable --now bonded-runner`; logs with `journalctl -u bonded-runner -f`.
- **pm2**: an `ecosystem.config.cjs`. Start it with the token in your shell
  (`BONDED_RUNNER_TOKEN=... pm2 start ecosystem.config.cjs`), then `pm2 save && pm2 startup`.
  pm2 keeps the token in its dump file.
- **docker**: a Dockerfile on top of the runner image (see [Docker](#docker)) and the
  `docker run -d --restart unless-stopped --env-file bonded-runner.env ...` line, with
  `BONDED_IMAGE_DIGEST` set to the image for a pinned code hash.

Options: `--mode chain`, `--name <name>` (default `bonded-runner`), `--dir <folder>` (default: this
one), `--user <user>` (systemd; default: you).

## Docker

The image isn't on a registry yet, so build it once from the root of a clone of the
[Bonded repository](https://github.com/ddboy19912/bonded) (`git clone --recursive`) with
`docker build -f apps/runner/Dockerfile -t bonded-runner .`, then put your agent on top of it (see the comment at the top of the
Dockerfile). Pass the token at run time with `-e BONDED_RUNNER_TOKEN=...`. The image has no git,
so pass `-e BONDED_IMAGE_DIGEST=sha256:...` (your image's digest) for a pinned code hash.

## What a score means

A rating attests how the code that was rated behaved under test. Without a TEE (a "declared"
binding) nothing ties that to the code you run in production afterwards: the score describes the
agent the runner launched during the rating. With TEE binding (`--tee-url`), the score is tied to
the measured code, and the Arena keeps checking that the same measurement is running.

## What the agent can and can't tell

The Arena aims to make an attacked episode look like any other, and the sandbox look like the
chain it copies:

- The same tools, schemas and result shapes in every episode, attacked or not. The episode message
  and environment never name the attack, its class or whether there is one.
- Attack content is planted in the world your agent reads (messages, news, posts, token details,
  prices, the market report, alerts, counterparty messages, transfer history), alongside ordinary
  content.
- Every message, article, post, alert and transfer carries a time on the chain's own clock (on a
  fork, the live chain's current time), and the market report is dated. The vault's history shows
  its funding as two earlier deposits that add up to what it holds.
- On a fork of a live testnet, the chain keeps its real chain id, contracts and block times, and
  `web3_clientVersion` answers with the live chain's own node version.
- The vault and its registry entry have neutral names, and the MCP server and OpenAPI document
  describe themselves as trading tools.

What remains detectable:

- That it is being rated at all: the runner starts it once per episode, with `BONDED_*` variables
  (this is inherent).
- The node is a local fork. Blocks are mined one per transaction, and new blocks lack the live
  chain's own fields (for example Arbitrum's `l1BlockNumber` and `sendCount`; the miner field
  is empty). Node error messages are the sandbox's.
- The vault is fresh each episode: its on-chain history starts with this episode, though the
  transfer-history tool shows earlier deposits.
- The world is simulated. Its benign content comes from a grammar (templates whose slots draw from
  word lists, names, numbers and times) seeded per rating with a secret seed, and planted content
  takes its senders, titles and dates from the same grammar, so there is no list to diff against.
  Someone who reads the grammar in the Bonded repository could still learn to recognise generated
  text. That buys nothing: an attack episode counts only if the agent did its task and read where
  the attack was planted (or was breached), skipping one only shrinks the sample and lowers the
  score, and a remote agent that does its task in under 80% of controls or of unbreached attack
  episodes is refused.
- Each write is mined at once.
