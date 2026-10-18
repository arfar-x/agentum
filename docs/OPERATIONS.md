# Operations

## First run

```bash
git clone --recurse-submodules <this-repo-url> agentflow
cd agentflow
cp .env.example .env
scripts/generate-secrets.sh          # paste output into .env
chmod 600 .env
# fill in the rest of .env: image tags, VLLM_BASE_URL/VLLM_API_KEY,
# JIRA_*, ADMIN_EMAIL/ADMIN_USERNAME -- see docs/CONFIGURATION.md
scripts/bootstrap.sh
```

`scripts/bootstrap.sh` is the whole first-run sequence in one idempotent
command: generate `searxng/settings.yml` (gitignored) from its template
with a fresh random `secret_key` if it doesn't exist yet, `docker compose
up -d --build`, wait for `api` to actually report healthy, then create the
admin account (from `ADMIN_EMAIL`/`ADMIN_NAME`/`ADMIN_USERNAME`/
`ADMIN_PASSWORD` in `.env`) via LibreChat's own `config/create-user.js` --
the same officially-shipped tool a human would run by hand, just automated
and safe to rerun. It checks for an existing user first and skips creation
if one is already there, so running it again after a restart or an
upgrade does nothing destructive.

`searxng/settings.yml` follows the same "secret never committed" rule as
`.env`: only `searxng/settings.yml.example` (a placeholder `secret_key`)
is tracked in git; the real file is gitignored and generated locally, same
as `.env` itself.

Two things it does *not* do, because they're already handled elsewhere,
declaratively, with no script needed:

- **The LibreChat app-level Mongo user** is created by
  `mongo-init/init-librechat-user.sh`, mounted into
  `mongodb`'s `/docker-entrypoint-initdb.d/` -- the official mongo image's
  own convention for running init scripts, with the container's env
  already available, exactly once, only when `mongodb_data` is being
  initialized for the first time. It creates the user in `admin`
  (matching `authSource=admin` in `MONGO_URI`), not in `LibreChat` --
  Mongo looks up a user's credentials in whichever database `authSource`
  names, regardless of which database the granted role applies to;
  getting this backwards produces
  `UserNotFound: Could not find user "..." for db "admin"` on every
  connection attempt, LibreChat included.
- **The Mongo root user** is created by the image's own
  `MONGO_INITDB_ROOT_USERNAME`/`MONGO_INITDB_ROOT_PASSWORD` handling,
  same as any mongo image -- nothing custom here at all.

Neither of these fires again on an existing volume, so restoring a backup
or restarting the stack never re-runs them -- see "Backup / restore" below
for what that means for rotating the underlying passwords.

## Volumes -- what each one is worth

| Volume | Contents | Losing it means |
|---|---|---|
| `mongodb_data` | users, conversations, **agent definitions**, MCP tool state | Total loss. This is the volume that matters most. |
| `pgvector_data` | RAG embeddings for user-uploaded files | Re-upload and re-embed affected files. |
| `kb_data` | The knowledge catalog: entries, overrides, sync checkpoints, gap log, run history, and the admin console's **manual records** and source-configuration history | The catalog and its search index rebuild from the sources (`make kb-sync`); the **overrides, checkpoints, gap log, manual records and configuration history do not** -- those are the reason this volume is backed up. |
| `meili_data` | search index | Rebuildable from Mongo; not backup-critical but included for convenience. |
| `librechat_uploads` | user-uploaded files | Those files are gone. |
| `librechat_images` | generated/attached images | Those images are gone. |
| `librechat_logs` | application logs | Logs only. |

## Secrets

`CREDS_KEY`, `CREDS_IV`, `JWT_SECRET`, `JWT_REFRESH_SECRET` encrypt
everything LibreChat stores in Mongo (API keys, MCP credentials, etc).
**Restoring `mongodb_data` alongside a *different* set of these four values
produces a database that opens normally but whose stored credentials cannot
be decrypted, ever.** There is no re-encryption step to recover from this.

Rules that follow from that:

- Back up `.env` **every time** you back up the volumes, as one unit.
  `scripts/backup.sh` does this automatically -- and copies each module's env
  file (`kb/.env`) beside it. The catalog database only accepts the
  passwords it was initialised with, so that file is part of the same unit.
- Never run `scripts/generate-secrets.sh` again on a host that already has
  data in `mongodb_data` -- it refuses to run if `.env` already has secrets
  set, but a manual hand-edit of those four values bypasses that guard.
- Store at least one copy of `.env` (and `kb/.env`) somewhere other than this host.

## Backup / restore

```bash
scripts/backup.sh                    # -> backups/<timestamp>/
scripts/backup.sh /mnt/nas/agentflow # or any other destination
```

Restoring:

```bash
scripts/restore.sh backups/<timestamp>
# then, if the backup's .env differs from your current one -- especially
# the four secrets above -- copy it into place BEFORE starting the stack
docker compose up -d
```

Run this pair once, deliberately, against a disposable copy before you
actually need it in an emergency -- confirming a backup script works is the
only way to know it works.

## Knowledge base migrations

Schema changes live in `kb/migrations/` and are applied by `make kb-init`, which
`make up` runs for you. They are append-only -- a shipped file is never edited --
so an upgrade applies what is new and skips what is already recorded in
`schema_migration`. Rerunning is a no-op.

Migration `004_admin_console.sql` adds the admin console's tables. Everything in
it is operational state, not catalog content, so none of it is rebuilt by a
sync: **`form_record` (manual records) and `kb_source_revision` (the source
configuration's history) are only in the `kb_data` backup.**

**Retention.** `sync_run` and `sync_request` grow by about a hundred small rows
per source per day and are never pruned. That is years of headroom, but if you
want them trimmed:

```bash
docker compose exec kb-db psql -U "$KB_POSTGRES_USER" "$KB_POSTGRES_DB" -c \
  "DELETE FROM sync_request WHERE finished_at < now() - interval '180 days';
   DELETE FROM sync_run WHERE finished_at < now() - interval '180 days';"
```

(`kb_source_revision` is the source configuration's history; keep it.)

**If `kb/config/sources.yaml` is damaged.** The console verifies every write
and puts the old file back if it cannot complete one, so this takes a crash in
the middle of a write or a hand edit gone wrong. The scheduler skips a file it
cannot read and says so; the console's Sources page shows the error. Every
change the console ever made, with the file before and after, is in
*Sources → History*, and in the database:

```bash
docker compose exec kb-db psql -U "$KB_POSTGRES_USER" "$KB_POSTGRES_DB" -At -c \
  "SELECT after_text FROM kb_source_revision ORDER BY id DESC LIMIT 1" > kb/config/sources.yaml
```

Restart order after an upgrade: `kb-db` first, then `mcp-kb` and
`kb-scheduler` (and `kb-admin`, if you run it). All of them replace a lost
database connection on their own, so `docker compose up -d` in any order works,
and a database restart or failover needs nothing from you: a call that was cut
off mid-way fails and is logged (a scheduler tick, one console request), and the
next one reconnects. Only the `kb-admin` health check reports the outage
meanwhile (503 until the database answers).

## Upgrades

1. Pick the new `LIBRECHAT_IMAGE_TAG` / `RAG_API_IMAGE_TAG`, and read that
   release's notes and `UPGRADING.md` in
   [LibreChat-AI/LibreChat](https://github.com/LibreChat-AI/LibreChat) -- a
   release can need a one-off migration (v0.8.8 does, below).
2. `make backup` first, always.
3. Update `.env`, then `docker compose pull api rag_api`.
4. Run any migration the release calls for, with the stack's `api` stopped
   (see below).
5. `make up` -- it also re-renders `config/librechat.yaml` from the template.
6. Watch `make logs SERVICE=api` through startup; confirm the chat UI loads
   and an existing conversation is still visible before considering the
   upgrade done. `make agent-import DRY_RUN=1` should report nothing to change.

To roll back: put the old tag back in `.env` and `make up`. If a migration
already ran, restore the pre-upgrade backup instead (`make restore`) -- an
older LibreChat isn't guaranteed to run against a migrated database.

### v0.8.7 -> v0.8.8

- **Registry.** Images now come from `registry.librechat.ai/librechat-ai/...`
  (the project moved to the LibreChat-AI org); `docker-compose.yml` already
  points there. The old `ghcr.io/danny-avila/...` images stop at v0.8.7.
- **Tenant-index migration.** A database created on v0.8.7 or earlier has
  legacy unique indexes that conflict with v0.8.8's, and `api` logs
  `Index build failed` on every start until they're replaced. LibreChat never
  does this at startup; `make librechat-migrate` wraps its own command:

  ```bash
  make librechat-migrate             # dry run: lists what it would replace
  make librechat-migrate APPLY=1     # stops api, migrates, starts api again
  ```

  Run both after step 3 (the migration lives in the new image). The dry run
  only lists indexes; it doesn't check for duplicate data, so an `APPLY=1`
  can still fail -- then `api` is left stopped, nothing old has been dropped,
  and rerunning after fixing the reported problem completes it. A database
  that has already run v0.8.8 shows `0 planned`, and `APPLY=1` is a no-op.
- **Config.** `config/librechat.yaml.example` is at schema `version: 1.3.17`;
  nothing in it changed meaning. What v0.8.8 turns on by default (including
  `ask_user_question`) is in [`CONFIGURATION.md`](CONFIGURATION.md) "Agents".

## Updating the `agent-skills` submodule

Skill changes live in the `agent-skills` GitHub repo, not in this one.
Pulling in a new skill, a fixed toolset, or a version bump means moving the
submodule's pinned commit:

```bash
cd agent-skills
git fetch --tags
git checkout <new-tag-or-commit>       # e.g. git checkout v0.9.0
cd ..
git add agent-skills
git commit -m "chore: bump agent-skills to v0.9.0"
docker compose up -d --build mcp-agent-skills
```

Confirm the new tool list after rebuilding (`docs/TROUBLESHOOTING.md` has
the exact command) -- especially after adding a toolset to `MCP_TOOLSETS`,
since a missing `requirements.txt` install shows up as tools silently
missing from the picker, not as a build failure.

Note `doc_gen`'s enum of document types (`prd`, `trd`, `adr`, `rfc`, ...) is
built once at container startup. A new document-generation skill in
`agent-skills` always needs `docker compose up -d --build mcp-agent-skills`,
never just a config reload.

## Logs and health

```bash
docker compose ps                              # health status of all six services
docker compose logs -f api                     # LibreChat app logs
docker compose logs -f mcp-agent-skills         # MCP server logs, incl. per-toolset introspection warnings
```

## Restart / recovery ordering

`depends_on: condition: service_healthy` in `docker-compose.yml` already
enforces the right order on a normal `docker compose up -d` -- `api` will
not start against a cold `mongodb` or an unreachable `mcp-agent-skills`. If
something is stuck, bring the dependency-only services up first and confirm
they're healthy before touching `api`:

```bash
docker compose up -d mongodb meilisearch vectordb mcp-agent-skills
docker compose ps        # wait for "healthy" on all four
docker compose up -d rag_api api
```
