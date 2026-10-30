# Agent instructions

## Overview

`agentflow` is a self-hosted, single-front-door agentic chatbot stack:
[LibreChat](https://www.librechat.ai/) as the one UI end users see, talking
to a self-hosted, OpenAI-compatible LLM endpoint (vLLM), with Jira (and
soon Confluence) exposed as tools via the `agent-skills` MCP server. It's
mostly an infrastructure repo -- a pinned `docker-compose.yml` plus
config/scripts -- with **one application module of its own, `kb/`**: the
knowledge catalog, built to a written spec
([`kb/docs/SPEC.md`](kb/docs/SPEC.md)) and served to
LibreChat as its own MCP server. Everything else here is configuration.
Nothing here names a specific model or organization; every such detail
lives in your own `.env`/`config/librechat.yaml`, not in this doc.

## Setup / bringing the stack up

```bash
cp .env.example .env
scripts/generate-secrets.sh   # paste output into .env, then fill in the rest
chmod 600 .env
make up
```

`make up` (alias `make bootstrap`, same target) is the one idempotent
command for both first run and every re-run: generates
`searxng/settings.yml` from its template with a fresh secret if missing,
renders `config/librechat.yaml` from `config/librechat.yaml.example` +
`.env` (re-rendered every run -- see "Configuration is generated" below),
builds and starts every service, waits for `api` to report healthy, and
creates the admin account if none exists yet. Safe to rerun. Full variable
reference: [`docs/CONFIGURATION.md`](docs/CONFIGURATION.md).

### Modules own their configuration

A module is a directory that carries everything about itself, so deleting it
removes it and adding one touches the root in exactly three lines. Today that is
`kb/`; the shape to copy:

| Piece | Where | How the root reaches it |
|---|---|---|
| Services, volumes | `<module>/compose.yaml` | `include:` in `docker-compose.yml`, with `env_file: <module>/.env.<name>` -- the module's only interpolation source |
| Variables | `<module>/.env.example` (tracked) -> `<module>/.env.<name>` (gitignored) | Never `env_file: .env`. A module's variables are not in the root `.env.example`, and the root `.env` is not visible to the module |
| Make targets | `<module>/module.mk` | `include <module>/module.mk` in the `Makefile` |
| Scripts, config template, docs, spec | `<module>/scripts`, `config`, `docs` | Linked from this file |

A role that doesn't need a secret doesn't get the env file (`mcp-kb` is given an
explicit list; only the syncing services get `env_file:`). Shared infrastructure
-- the `backend` network, published ports -- stays declared by the root.
`make backup` copies each module's env file next to `.env`: they are one unit
with the volumes. Not yet converted: `agent-skills` and the LibreChat
side. They still read the root `.env`.

### Configuration is generated

`config/librechat.yaml` is gitignored and generated, the same way
`searxng/settings.yml` is: `make up` / `make render-config`
(`scripts/render-librechat-config.sh`) render it from
`config/librechat.yaml.example` + `.env`, filling in the `REPLACE_ME_*`
placeholders (currently `AGENTS_RECURSION_LIMIT`/
`AGENTS_MAX_RECURSION_LIMIT`). **Edit `config/librechat.yaml.example`, not
`config/librechat.yaml`** -- the latter is overwritten on the next render.
`docs/CONFIGURATION.md` "Agents" covers the two env variables; anything
else in the file (models, MCP, toolApproval) is edited directly in the
`.example` template, same as before this split existed.

## Day to day

```bash
make ps                              # health of all services
make logs SERVICE=api                # or any other service name
make build SERVICE=mcp-agent-skills  # rebuild one service's image
make down                            # stop (volumes kept)
make backup                          # snapshot every volume + .env
```

Run `make help` for the full target list -- `Makefile` is a thin wrapper
over `docker compose`/`scripts/`, nothing in it isn't documented in
[`README.md`](README.md) or [`docs/OPERATIONS.md`](docs/OPERATIONS.md) too.

A script that needs a value from `.env` sources `scripts/lib/env.sh` and calls
`env_get NAME` / `env_fill NAME...` rather than parsing the file itself (a
`grep | cut` keeps an inline `# comment` in the value). Scripts that need the
whole file keep using `source .env`. `bash scripts/lib/env.test.sh` tests it.
A module's scripts do the same against the module's own env file
(`env_get NAME kb/.env`); `bash kb/scripts/prepare.test.sh` tests the one that
creates it.

Identity for the agent gateway, the portal and the Telegram bot is Keycloak: `make idp-realm-apply`
(`integrations/keycloak/apply.sh`) creates/updates the `agentflow` realm from
`integrations/keycloak/realm/agentflow-realm.json` and writes the generated client secrets into
`.env.agent-gateway`; `make idp-up` starts a throwaway Keycloak for development; `make identity-e2e` checks
the whole chain against one. People, groups and roles are managed only in Keycloak, never in the gateway
([`docs/RUNBOOK_IDENTITY.md`](docs/RUNBOOK_IDENTITY.md) is the operator's click-by-click). The gateway's own
identity commands are `make gateway-key-*`, `gateway-creds-*`, `gateway-audit`, `gateway-owner-purge`, all
keyed by `OWNER=<Keycloak account id>`.

User account management also goes through `make user-*` targets (create,
list, ban, invite, delete, reset-password) -- see README.md "Managing
users" for the full list and what each wraps. Role/permission management
(promoting someone to `ADMIN`, custom roles, delegated grants) is done in
the Admin Panel UI, not the CLI -- see README.md and
[`docs/CONFIGURATION.md`](docs/CONFIGURATION.md) "Admin panel".

The knowledge base comes up with the stack: `make up` runs
`kb/scripts/prepare.sh` (creates `kb/.env` -- generating the database
passwords, or carrying `KB_*` values over from an older root `.env` -- and
`kb/config/sources.yaml` if they are missing) and then `kb/scripts/bootstrap.sh`,
which creates its schema and read-only role and prints whatever is still
missing before the catalog can fill itself. Every `docker compose` command needs
`kb/.env` to exist, so on a fresh checkout `make up` is the first thing to
run. `make kb-setup` does the same
on its own. Day to day it is `make kb-status`, `make kb-sources`,
`make kb-sync SOURCE=…` -- see
[`kb/docs/OPERATOR_GUIDE.md`](kb/docs/OPERATOR_GUIDE.md); its variables are in
[`kb/docs/CONFIGURATION.md`](kb/docs/CONFIGURATION.md).

There is also an opt-in admin console for the catalog: `make kb-admin-up`
(compose profile `admin`, `127.0.0.1:8324`, signs in with `KB_ADMIN_TOKEN`). It
shows sync status and reports, queues syncs, edits `kb/config/sources.yaml`
after an explicit approval, and holds hand-written "form" records. It cannot
write the catalog -- its `kb_admin` database role is refused -- so anything it
changes there is a `sync_request` that `kb-scheduler` executes. See
"The admin console" in [`kb/docs/OPERATOR_GUIDE.md`](kb/docs/OPERATOR_GUIDE.md).

Agents are managed declaratively: `make agent-export` writes every
admin-owned agent (definition, handoff/subagent links, sharing) from the database to
`agents/*.yaml`, and `make agent-import` (preview with `DRY_RUN=1`) applies
those files back. The files are the source of truth for the agents they list --
see [`docs/AGENT_SYNC.md`](docs/AGENT_SYNC.md).

## Testing

Two suites. `kb/` is this repo's own code and has real unit tests, which
need no services and run in well under a second:

```bash
cd kb && python -m pytest   # see kb/README.md for the venv setup
make kb-test                # the same suite plus the Postgres-backed tests,
                            # against a throwaway database container
```

They include two gates worth knowing about before you edit anything there:
`tests/test_boundaries.py` fails if `domain/` or `application/` imports
anything that does I/O, and `tests/test_spec_coverage.py` fails if a
requirement the spec marks `done` has no test claiming it (or a test claims
an id the spec doesn't define). Add the requirement to the spec first, then
the test's `# Covers: FR-...` line.

`make kb-e2e` runs the admin console, the scheduler and the MCP server as real
processes against a throwaway database and a browser (needs Postgres and
Chromium; see [`kb/e2e/README.md`](kb/e2e/README.md)). It is not part of CI.

The other command runs `agent-skills`' own `mcp-server` test suite inside
the built image, as a way to verify that submodule pin is sound in this
stack's actual runtime:

```bash
make test
```

## Architecture

`docker-compose.yml` is the architecture -- read it directly for exact
service wiring, networks, and healthchecks; this is a summary, not a
substitute. A module's own services are in its `compose.yaml`
(`kb/compose.yaml`), included from there.

- `api` (LibreChat) is the only service with a published port and the
  only thing end users talk to. It calls `mongodb` (users/conversations/
  agent defs), `meilisearch` (search), `rag_api` + `vectordb` (per-
  conversation file RAG), `mcp-agent-skills` (Jira, Confluence, and other
  tools, over MCP), and `searxng` + `crw` (native web search: search, then
  page scraping).
- `kb-admin` is the one `kb` service a browser reaches: opt-in, published on
  loopback only, no `env_file` and no source credentials (an explicit
  `environment:` allowlist), and connected as `kb_admin`, which reads
  everything and writes only the console's own tables. Don't give it a source
  credential, widen its grants, or make it write catalog tables itself --
  `kb-scheduler` stays the only catalog writer.
- `mcp-agent-skills`, `mcp-kb` and `searxng` are **internal-only, no
  published port** -- reachability from `api` is their only access control
  (MCP's HTTP transport has no auth of its own). Never add a `ports:` entry
  to any of them. `mcp-agent-skills` is on its **own `agent-tools` network**,
  which only `api` joins: it honors per-request headers naming the caller's
  credentials and whose uploads they may read, so no other container may be
  able to reach it. Never put it back on `backend`. `crw` is internal-only too, but
  on its **own `scraper` network**, which only `api` joins: it fetches URLs
  that search results choose, so it must never be able to reach `backend`.
  Never put it back on `backend`. `mcp-kb` goes further and takes
  no credentials at all: the catalog is shared, so there is nothing per-user
  for a caller to supply.
- `kb-db` is the knowledge catalog's **own Postgres instance**, not another
  database inside `vectordb` -- so restoring LibreChat's RAG store can't touch
  the catalog, and `kb` never holds a credential to LibreChat's data. Schema and
  the least-privilege query role come from `make kb-init` (idempotent; also how
  a later migration is applied). Backed up like every other volume.
- `agent-gateway` (profile `gateway`, `make gateway-up`) serves the same kind of agents to
  clients outside LibreChat through an OpenAI-compatible API (Chat Completions, Responses,
  Models; any other model name or route goes to the upstream model untouched). It is the second
  service with a published port, so every request needs a key it issued (`make gateway-key-*`).
  It has its own Postgres and Redis (`gateway-db`, `gateway-redis`) and its own copy of the
  agent-skills server (`mcp-agent-skills-gateway`) on a `gateway-tools` network only it joins.
  It reaches `mcp-kb` through `gateway-kb` and **never joins `backend`**. It is a self-contained
  module, written to become its own repository: its agents, tool servers and limits are in
  `agent-gateway/config/`, its spec is `agent-gateway/docs/spec.md`, and `agent-gateway/AGENTS.md`
  governs inside it. The agent's own tools take precedence: the gateway runs them with credentials sent on the
  request, then the user's stored ones (encrypted with `CREDS_KEY` from `.env.agent-gateway`); when it
  has none the agent asks the user, and only if they agree does the user's own client run an
  equivalent tool it declares.
- `admin-panel` is a separate service (ClickHouse's LibreChat Admin
  Panel) that talks to `api`'s `/api/admin/*` endpoints -- it has no
  database access of its own and cannot grant itself privileges.
- **Tool approval is two-layered, deliberately**: LibreChat's own
  `toolApproval` (`config/librechat.yaml`) prompts before any tool call
  matching its `ask` list; independently, each write-capable toolset
  inside `agent-skills` (Jira, Confluence and GitLab) refuses to execute
  without its own `--confirm`, enforced in that repo's own code. Neither
  layer is a substitute for the other -- see that same file's inline comment for why
  the `ask` list uses LibreChat's real `<toolset>_<action>_mcp_<server>`
  tool-name format, not the colon-shaped form LibreChat's own docs show
  (confirmed wrong by reading the actual matching code).
- `agent-skills` is a **git submodule pinned to a released tag**, not a
  branch -- so this stack always states exactly which `agent-skills`
  version it's running. Bumping the pin is a reviewable one-line commit;
  see [`docs/OPERATIONS.md`](docs/OPERATIONS.md) "Updating the
  agent-skills submodule" for the exact steps. There's no bind-mount for
  live-editing skills against this stack -- that's deliberate
  (reproducibility over iteration speed). `agent-skills/AGENTS.md` covers
  that submodule's own internals; once you're working inside
  `agent-skills/`, that file (closest-`AGENTS.md`-wins) governs, not this
  one.

## Security / credentials

- **Every secret lives in `.env` (gitignored) or `searxng/settings.yml`
  (also gitignored)** -- never in a tracked file. `.env.example` and
  `searxng/settings.yml.example` are the tracked templates, with
  placeholder values only. `scripts/generate-secrets.sh` generates real
  values; never hand-write one into a template file.
- `config/librechat.yaml` and `docker-compose.yml` reference secrets only
  as `${VAR}` env interpolation -- if you're about to write a literal
  secret value into either, stop; it belongs in `.env` instead.
- Per-user Jira credentials (LibreChat's `customUserVars`) are injected
  per-request into `mcp-agent-skills` via `X-Agent-Skills-Env-<VAR>`
  headers, trusted only because `MCP_TRUST_REQUEST_CREDENTIALS=1` is safe
  specifically *here* (no published port, `api` is the only container on the
  `agent-tools` network) -- see `agent-skills/AUTHENTICATION.md` before
  changing anything in that trust chain.
- `CREDS_KEY`/`CREDS_IV`/`JWT_SECRET`/`JWT_REFRESH_SECRET` encrypt
  everything LibreChat stores in Mongo. Restoring `mongodb_data` next to
  a *different* set of these makes stored credentials permanently
  undecryptable -- see [`docs/OPERATIONS.md`](docs/OPERATIONS.md)
  "Secrets" before touching backup/restore.

## Commit messages

Always follow [Conventional Commits](https://www.conventionalcommits.org/)
(`feat:`, `fix:`, `docs:`, `chore:`, ...). Don't add scopes excessively:
scope at the level of the project's main parts, and keep the subject a
high-level overview of the change. The body says **what** changed, not how,
and carries nothing specific to the session or conversation that produced
it.

## Project map

- [`README.md`](README.md) -- start here: prerequisites, first run, what
  each service is.
- [`docs/CONFIGURATION.md`](docs/CONFIGURATION.md) -- every `.env`
  variable, what breaks if it's wrong.
- [`docs/OPERATIONS.md`](docs/OPERATIONS.md) -- backup/restore, upgrades,
  bumping the `agent-skills` submodule pin, restart ordering.
- [`docs/AGENT_SYNC.md`](docs/AGENT_SYNC.md) -- `make agent-export` /
  `agent-import`: agent file format, sharing, import semantics.
- `agents/` -- one YAML per agent, from `make agent-export` or hand-written;
  start from `agents/base-agent-template.yaml.example`.
- [`docs/ARCHITECTURE.md`](docs/ARCHITECTURE.md) -- how the stack fits together:
  the diagram (`docs/architecture.svg`), the five plug-in contracts, how `kb`
  retrieves and what it depends on, what `agent-gateway` does, trust boundaries.
- [`docs/PRODUCT_FLOW.md`](docs/PRODUCT_FLOW.md) -- the product flow the
  agents run: idea -> product spec (Spec Kit `spec.md` shape, in Confluence,
  `spec-draft`/`spec-approved` labels) -> Jira, with an engineering page under
  each spec (decisions, cross-team contracts, technical questions, change
  proposals). agentflow stops at the ticket;
  the team's conventions live in `agents/*.yaml`, the generic spec skills in
  `agent-skills`.
- [`docs/KEYCLOAK.md`](docs/KEYCLOAK.md) -- the `agentflow` realm (identity for the gateway, portal and
  Telegram bot), and optional LibreChat SSO with how to switch to/from local email/password auth.
- [`docs/RUNBOOK_IDENTITY.md`](docs/RUNBOOK_IDENTITY.md) -- "I want to X, here is the click or command" for
  the operator: users, groups, roles, keys, credentials, Telegram, audit, backup, Keycloak down; plus a
  glossary.
- `integrations/keycloak/` -- the realm template, the idempotent `apply.sh`, the dev Keycloak, the make
  targets (`module.mk`). Identity is specified in `specs/003-identity-access/`.
- [`docs/SECURITY_CHECKLIST.md`](docs/SECURITY_CHECKLIST.md) -- what to verify about identity, keys and the
  gateway pass-through before exposing the gateway; re-check after touching authentication.
- [`docs/TROUBLESHOOTING.md`](docs/TROUBLESHOOTING.md) -- specific known
  failure modes (e.g. MCP tools missing from the tool picker).
- A module's spec of record lives in the module (`kb/docs/SPEC.md`): anything
  big enough to design before building gets one. A change to it is a reviewed
  diff, not a decision made in a chat window; the code follows the spec, and
  when they disagree one of them is wrong and gets fixed. Requirements carry ids
  and a status, and the module's tests enforce that pairing.
- `specs/`, `.specify/`, `.claude/skills/speckit-*` --
  [GitHub Spec Kit](https://github.com/github/spec-kit), the workflow for
  designing a change before building it: `/speckit-specify` ->
  `/speckit-plan` -> `/speckit-tasks` -> `/speckit-implement`, one
  `specs/NNN-<feature>/` directory per change, governed by
  `.specify/memory/constitution.md`. Those are working documents for one
  change; whatever a change decides about `kb/` still lands in
  `kb/docs/SPEC.md`, which stays the spec of record.
- [`kb/docs/OPERATOR_GUIDE.md`](kb/docs/OPERATOR_GUIDE.md) -- the operator guide for
  the catalog: credentials, choosing sources, the four freshness mechanisms and
  their switches, overrides, the gap log, backup, and what to check when it
  looks wrong.
- `kb/` -- the knowledge catalog: what knowledge exists in the organization
  and where it lives, searchable by agents. Hexagonal (`domain/` ->
  `application/` -> `adapters/`), specified by
  [`kb/docs/SPEC.md`](kb/docs/SPEC.md); see
  [`kb/README.md`](kb/README.md) to run it.
- `agent-gateway/` -- the OpenAI-compatible agent gateway (see Architecture); its own repository
  and docs: [`agent-gateway/README.md`](agent-gateway/README.md).
- `telegram-bot-gateway/` -- git submodule,
  [telegram-bot-openai-gateway](https://github.com/arfar-x/telegram-bot-openai-gateway): a Telegram client
  for any OpenAI-compatible endpoint. It is its own repository with its own specs, tests and `AGENTS.md`,
  and knows nothing about this stack; once you are working inside it, that repository's `AGENTS.md`
  governs. What ties it to the stack (compose service, `make telegram-*` targets, variables, scripts) is in
  [`integrations/telegram-bot/`](integrations/telegram-bot/README.md): opt-in (`make telegram-up`), its own
  database on `gateway-db`, users linked one-to-one with gateway API keys (`make telegram-pair`).
  Bumping it is a one-line commit of the new submodule pointer.
- `agent-skills/` -- git submodule, pinned to a tag (see Architecture
  above); has its own `AGENTS.md` and `AUTHENTICATION.md` governing that
  subtree.
