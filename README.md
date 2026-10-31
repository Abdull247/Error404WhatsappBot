# WhatsApp AI Bot

Node.js WhatsApp bot using Baileys, an OpenAI-compatible AI API, and Neon Postgres for conversation memory.

## Layout

```text
config.json
cloudflare.json
sandboxes.json
stickers/
custom-instructions.json
persistence-instructions.json
.env.example
migrations/
src/
  index.js
  ai/
  config/
  db/
  memory/
  persistence/
  tools/
  utils/
  whatsapp/
```

- `config.json` holds AI providers and models, the default model, system instruction, bot behavior, and memory settings.
- `sandboxes.json` holds sandbox backends and which one is active (`default`). Only that sandbox's tools are exposed.
- `stickers/` holds WhatsApp sticker packs: one folder per sticker (webp + `info.json`) and `stickers/config.json` listing them for the model.
- `cloudflare.json` holds the Cloudflare AI provider (account/token env refs) and models by category. `generate_image` uses its `image` models; other model families can be added later.
- `custom-instructions.json` holds always-on identity and creator details injected into every system prompt.
- In groups the bot stays quiet unless it is @mentioned or someone replies to one of its messages. Replies are quoted so the group can follow the thread. The AI is told it is in a group and gets the group name, description, and speaker.
- `.env` holds secrets and connection URLs.
- `migrations/` holds SQL files applied on startup.
- `src/tools/catalog/` holds one folder per tool (`config.json` + `handler.js`).
- `personalities/` holds one JSON file per AI personality.
- `write_file` can create `.html`, `.css`, `.js`, `.txt`, `.json`, and `.md` files, send them on WhatsApp, then send a short recap.
- `sandbox` runs code and commands in a temporary E2B Linux VM. One sandbox is reused per WhatsApp chat until it is killed or times out.
- `linux_machine` is a persistent InstaBox Linux computer (Debian, `/data` disk, optional desktop). It is available in DMs and groups. `sandboxes.json` picks which one is active.
- `create_agent` starts a persistent background agent when at least one sandbox has `supports_persistence_agent: true`. Jobs, steps, logs, and memories live in Neon. The worker runs in-process so a Render free web service plus `/health` cron still works.

## Setup

Copy `.env.example` to `.env` and fill in:

- Provider env vars named in `config.json` (`AI_BASE_URL` / `AI_API_KEY` for the bundled OpenRouter provider)
- `DATABASE_URL`
- `LANGSEARCH_API_KEY`
- `E2B_API_KEY` (if `sandboxes.json` default is `sandbox`)
- `INSTABOX_API_KEY` (if default is `linux_machine`)
- `SCREENSHOTLAYER_API_KEY`
- `R2_ACCESS_KEY_ID`, `R2_SECRET_ACCESS_KEY`, `R2_BUCKET_NAME`, `R2_ENDPOINT` (persistent file storage)
- `CLOUDFLARE_ACCOUNT_ID`, `CLOUDFLARE_API_TOKEN` (image generation)

Edit `config.json` for providers, default model, temperature, and system instruction. Edit `sandboxes.json` to choose the active Linux backend.

Group chat:

- `ignoreGroups: true` (default) means the bot does not answer every group message.
- `respondToMentionsInGroups: true` answers when someone tags / @mentions the bot.
- `respondToRepliesInGroups: true` answers when someone replies to the bot's own message.
- Group replies quote the triggering message. The model receives group name, description, participant count, and who spoke.
- `reactInGroups: true` lets the bot emoji-react to a tagged or quoted group message (funny, thanks, hype, greetings) and then still reply.

```bash
npm install
npm start
```

Link WhatsApp with either QR or pairing code.

QR (default):

```bash
npm start
```

Scan the QR printed in the terminal.

Pairing code:

Set these in `.env`:

```bash
WHATSAPP_USE_PAIRING_CODE=true
WHATSAPP_PHONE_NUMBER=2348012345678
```

Use digits only, including country code. Then start the bot and enter the printed code on your phone under Linked Devices > Link with phone number.

## AI providers

`config.json` can list more than one OpenAI-compatible provider. Each provider has its own models array. `ai.defaultModel` picks which model to call. Env var names live on the provider (`baseUrl.env`, `apiKey.env`). Set `"required": false` on `apiKey` when the server needs no key.

```json
{
  "ai": {
    "defaultModel": "gpt-4o-mini",
    "providers": [
      {
        "id": "openai",
        "baseUrl": { "env": "OPENAI_BASE_URL", "required": true },
        "apiKey": { "env": "OPENAI_API_KEY", "required": true },
        "models": [
          { "id": "gpt-4o-mini", "image_support": true },
          { "id": "gpt-4o", "image_support": true }
        ]
      },
      {
        "id": "local",
        "baseUrl": { "env": "LOCAL_AI_BASE_URL", "required": true },
        "apiKey": { "env": "LOCAL_AI_API_KEY", "required": false },
        "models": [
          { "id": "llama3", "image_support": false }
        ]
      }
    ]
  }
}
```

Set `image_support` (also accepts `image_surport`) to `true` on a model so WhatsApp image attachments are downloaded and sent in the chat request as a vision `image_url` part.

## Tools

Tool calling is enabled in `config.json`. Each tool lives in `src/tools/catalog/<tool-name>/`.

`write_file` creates files under `generated/` and sends them as WhatsApp documents. Example: ask for a portfolio and the bot can create `index.html`, `styles.css`, and `script.js`, send those files, then reply with a short "I've finished" recap.

`web_search` uses the LangSearch Web Search API. Set `LANGSEARCH_API_KEY` in `.env`. The bot can look up live information, then answer with source URLs.

`get_datetime` returns the user's local date and time. Simple greetings use `query=greeting` (timezone, date, local time, time of day). Use `query=full` for weekdays, week number, and other calendar details. The bot must not guess the time.

`sandbox` uses the E2B code-interpreter SDK. Set `E2B_API_KEY` in `.env`. The model calls it with an `action` such as `run_code`, `run_command`, `files_write`, `install`, `get_url`, or `kill`. Long sandbox work reacts to the user message with an hourglass, then a check mark when finished. Charts and downloaded files are sent on WhatsApp.

`linux_machine` uses the InstaBox SDK (`@insforge/instabox-sdk`). Set `INSTABOX_API_KEY` and optionally `INSTABOX_API_URL` (default `https://api.instabox.sh`), `INSTABOX_TEMPLATE` (default `agent-browser`), and `INSTABOX_MACHINE_ID` to pin an existing box. Available to every chat, including groups. The machine is persistent: `/data/home` survives pause/stop, and the same box is reused across turns and bot restarts. Actions include `run_command`, `run_code`, filesystem helpers, `get_url` (publish a port), `pause` / `resume` / `stop`, desktop control (`desktop_start`, `desktop_screenshot`, `desktop_stream`), and `snapshot`.

Only one sandbox backend is exposed at a time. Set `"default"` in `sandboxes.json` to `linux_machine` or `sandbox`. The bot tells the model the active type and description.

`list_chats` and `summarize_chat` are owner-only. The bot logs DMs and group messages it sees (even when `ignoreGroups` is true and it does not reply). Ask it to list chats, then summarize a group or pull out facts, people, decisions, and action items. Set `OWNER_NUMBERS` in `.env` (comma-separated, with country code) so only you can use these tools. Summarize reacts with an hourglass, then a check mark.

`react` puts one emoji on the current WhatsApp message. In groups, if someone tags the bot or replies to it with something funny, hype, or grateful, it can react first and then send a text reply.

`send_sticker` sends a WhatsApp sticker from `stickers/`. Each pack is a folder with a `.webp` and `info.json` (`id`, `description`, `whenToUse`, path). `stickers/config.json` lists every pack so the model can pick one. Call `list` to inspect, then `send` with an id such as `my_boss`. After the sticker, the bot still sends a short text reply.

`generate_image` creates an image from a text prompt using the Cloudflare AI provider. Set `CLOUDFLARE_ACCOUNT_ID` and `CLOUDFLARE_API_TOKEN`; models live in `cloudflare.json` (default `@cf/black-forest-labs/flux-1-schnell`). It reacts with an hourglass while running and a picture emoji when done, sends the image on WhatsApp, then stores it in the chat's R2 folder when R2 is configured.

`file_storage` persists files to Cloudflare R2 and remembers them in the database, scoped to the requesting user or group. Set `R2_ACCESS_KEY_ID`, `R2_SECRET_ACCESS_KEY`, `R2_BUCKET_NAME`, and `R2_ENDPOINT` (plus optional `R2_PUBLIC_URL`). Actions: `upload` (content, base64, or path), `get`, `list`, `delete`. Incoming user files are also stored automatically for the chat.

`create_agent` is only registered when `persistenceAgent.enabled` is true and at least one sandbox in `sandboxes.json` has `supports_persistence_agent: true` (typos `surports_*` also work). The main bot reacts with an hourglass, queues the job, and replies with a job id. The in-process worker then runs a separate model loop against the persistent sandbox.

`screenshot` captures a website with the Screenshotlayer API and sends the image on WhatsApp. Set `SCREENSHOTLAYER_API_KEY` in `.env`. Ask for a screenshot of a URL, optionally full page or a mobile viewport. Capture reacts with an hourglass, then a check mark.

## Custom instructions

`custom-instructions.json` (project root, deploys with git) holds always-on identity, creator, and project knowledge. It is injected into the system prompt on every message, in every chat, under every personality. The bot uses it to answer "who built you", credit the developer, describe their projects accurately, and route bug reports.

```json
{
  "bot": { "name": "Jen404", "type": "...", "identity": "..." },
  "creator": { "name": "Error404", "whatsapp": "...", "portfolio": "...", "github": "...", "about": "..." },
  "instructions": ["always-on rules"],
  "developer_profile": { "...": "specializations, technologies, approach" },
  "projects": { "...": "one entry per project" },
  "technical_preferences": { "...": "..." },
  "response_guidelines": { "...": "tone, creator_questions.default canned answer, ..." }
}
```

How it is rendered into the prompt:

- `bot` and `creator` become the identity header; `response_guidelines.creator_questions.default` becomes the canned "who made you" answer.
- Top-level `instructions` become permanent rules that survive every personality switch.
- Every other top-level section (`developer_profile`, `projects`, `technical_preferences`, `response_guidelines`, and anything new you add later) is rendered generically as readable nested bullets.
- An `instructions` array at any nesting depth becomes a "Keep in mind:" sub-block at that spot, so per-project accuracy rules stay attached to their project.

Notes:

- `bot.name` also feeds @mention detection in groups, alongside `bot.name` in `config.json`. Keep them in sync.
- The rendered block is cached per process; restart (or redeploy) after editing the JSON.
- Missing or invalid file only logs a warning; the bot still starts.
- Personalities in `personalities/` change style. This file changes identity and facts. Both apply together.

## Commands

Messages that start with `.` are handled before the AI.

```text
.menu
.personalities
.personalities - Helpfulness
.agent
.agent <id>
.agent logs <id>
.agent result <id>
.agent cancel <id>
```

`.menu` lists commands. `.personalities` lists the JSON configs in `personalities/`. `.personalities - Helpfulness` switches this chat to that personality. The choice is stored per user/chat.

`.agent` manages persistent background jobs for this chat. The command name is `persistenceAgent.command` in `config.json` (default `agent`). Job ids look like `jen-<timestamp>-<token>`. When a job finishes, the bot sends a follow-up WhatsApp message.

## Persistent background agent

Long tasks are queued in Neon and run by an in-process worker in the same `npm start` process. That matches a Render free web service: keep hitting `/health` so the process stays awake, and unfinished jobs resume from checkpoints after a restart.

The `create_agent` tool is exposed only when:

1. `persistenceAgent.enabled` is true in `config.json` (or `PERSISTENCE_AGENT_ENABLED` is not `false`)
2. At least one sandbox in `sandboxes.json` has `supports_persistence_agent: true` (also accepts `supportsPersistenceAgent` and the typo `surports_*`)

`linux_machine` ships with that flag on. E2B `sandbox` does not.

```json
{
  "persistenceAgent": {
    "enabled": true,
    "defaultModel": "zai-org/GLM-5.3-Flash",
    "command": "agent",
    "maxRounds": 40,
    "maxRuntimeMinutes": 90,
    "maxConcurrent": 2,
    "workspaceRoot": "/data/jen404/agents",
    "allow": ["linux_machine", "sandbox", "web_search", "write_file", "file_storage", "screenshot"]
  }
}
```

`defaultModel` uses the same provider catalog as the main bot. If that model has `image_support: true`, the persistence agent can inspect attached images through `read_attachment`.

WhatsApp files sent with the starting message are stored on the job, copied into the sandbox workspace, and readable via `read_attachment`. Durable job state is written under `/data/jen404/agents/<job-id>/` so a 30-minute sandbox idle pause does not wipe notes, checkpoints, or artifacts.

Job tables (separate from chat memory):

- `persistence_jobs`
- `persistence_job_steps`
- `persistence_job_logs`
- `persistence_job_memories`
- `persistence_job_files`
- `persistence_job_notifications`

Agent instructions live in `persistence-instructions.json` and in `src/persistence/`. Optional env overrides: `PERSISTENCE_AGENT_ENABLED`, `PERSISTENCE_MAX_CONCURRENT`, `PERSISTENCE_MAX_RUNTIME_MINUTES`, `PERSISTENCE_POLL_MS`, `PERSISTENCE_LEASE_SECONDS`, `PERSISTENCE_WORKER_ID`.

## Scripts

```bash
# start bot
npm start

# restart on file changes
npm run dev

# run SQL migrations only
npm run migrate
```

## Deploy on Render

Two supported service types. Both run the same code; the bot switches modes from env vars alone.

| Type | When to use | What you need |
| --- | --- | --- |
| **Web Service** (free tier works) | Default choice. Renders a health endpoint on `$PORT`. | Nothing extra; pair the bot once from your phone. |
| **Background Worker** (paid) | If you want the session on a persistent disk instead of Postgres. | Persistent disk + instance that never spins down. |

### Web Service mode (recommended)

Set the environment variable `PORT` (Render injects it automatically, but you can also pin it). The bot then:

- starts a tiny HTTP server on `$PORT` serving `GET /`, `/health`, and `/ping` with JSON status (`whatsapp` connection state and `jid` included);
- defaults `WHATSAPP_AUTH_STORE=postgres`, so the WhatsApp session lives in Neon instead of the ephemeral disk and survives deploys and restarts.

Free web services sleep after ~15 minutes of no inbound HTTP. The WhatsApp socket does not count as activity, so it is strongest to keep a free pinger (UptimeRobot, cron-job.org, etc.) hitting `/health` every 5-10 minutes.

Settings:

```text
Name: error404-whatsapp-bot
Region: closest to you
Branch: main
Root Directory: (leave empty)
Runtime: Node
Build Command: npm install
Start Command: npm start
Health Check Path: /health
```

No persistent disk is required in this mode. `TOOLS_OUTPUT_DIR` is still ephemeral, which is fine for disposable generated files.

### Background Worker mode

A Background Worker gets no `PORT`, the HTTP server stays off, and the session defaults to `WHATSAPP_AUTH_STORE=file`. It keeps a WhatsApp socket open with no inbound traffic.

Use a **paid** instance so Render does not spin it down. Add a persistent disk:

```text
Name: whatsapp-data
Mount Path: /data
Size: 1 GB
```

Then set:

```text
WHATSAPP_SESSION_DIR=/data/session
TOOLS_OUTPUT_DIR=/data/generated
```

Without this, every deploy or restart wipes `./session` and the bot logs out.

### Create the service

1. New > Background Worker.
2. Connect this GitHub repo.
3. Runtime: **Node**.
4. Instance: a paid plan (Starter or higher). Do not use a free web service.
5. Settings:

```text
Name: error404-whatsapp-bot
Region: closest to you
Branch: main
Root Directory: (leave empty)
Runtime: Node
Build Command: npm install
Start Command: npm start
```

Set the Node version to 18 or newer. In the Render dashboard add:

```text
NODE_VERSION=20
```

Or add an `.node-version` / `NODE_VERSION` env var. `package.json` requires `>=18.18.0`.

### Persistent disk

Baileys stores the WhatsApp session on disk. If that folder is lost, you have to link the phone again.

On the paid worker, add a persistent disk:

```text
Name: whatsapp-data
Mount Path: /data
Size: 1 GB
```

Then set:

```text
WHATSAPP_SESSION_DIR=/data/session
TOOLS_OUTPUT_DIR=/data/generated
```

Without this, every deploy or restart wipes `./session` and the bot logs out.

### Environment variables

In Render > Environment, add the same keys as `.env.example`. Do not upload a `.env` file.

Required:

```text
AI_BASE_URL
AI_API_KEY
DATABASE_URL
```

WhatsApp linking (pairing code, recommended on Render):

```text
WHATSAPP_USE_PAIRING_CODE=true
WHATSAPP_PHONE_NUMBER=2348012345678
WHATSAPP_PRINT_QR=false
OWNER_NUMBERS=2348012345678
```

Session and health (only what differs from the defaults):

```text
WHATSAPP_SESSION_DIR=/data/session  # Worker mode with a disk only
WHATSAPP_AUTH_STORE=postgres         # omit to auto-detect from PORT
PORT=10000                            # Web Service only, usually injected
HOST=0.0.0.0
HEALTH_SERVER=true                    # optional: listen on 10000 without PORT
```

Use digits only, with country code, no `+` or spaces.

Optional tools:

```text
LANGSEARCH_API_KEY
E2B_API_KEY
INSTABOX_API_KEY
INSTABOX_API_URL
INSTABOX_TEMPLATE
INSTABOX_MACHINE_ID
SCREENSHOTLAYER_API_KEY
SCREENSHOTLAYER_SECRET
R2_ACCESS_KEY_ID
R2_SECRET_ACCESS_KEY
R2_BUCKET_NAME
R2_ENDPOINT
R2_PUBLIC_URL
R2_ACCOUNT_ID
CLOUDFLARE_ACCOUNT_ID
CLOUDFLARE_API_TOKEN
```

Useful extras:

```text
LOG_LEVEL=info
CONFIG_PATH=./config.json
SANDBOXES_PATH=./sandboxes.json
STICKERS_PATH=./stickers/config.json
CLOUDFLARE_CONFIG_PATH=./cloudflare.json
DEFAULT_TIMEZONE=Africa/Lagos
AI_TIMEOUT_MS=60000
E2B_TIMEOUT_MS=300000
INSTABOX_API_URL=https://api.instabox.sh
INSTABOX_TEMPLATE=agent-browser
INSTABOX_MACHINE_ID=
WHATSAPP_MAX_STALE_MS=600000
```

`WHATSAPP_MAX_STALE_MS` drops messages older than this many milliseconds (default 10 minutes). Raise it if a sleeping free-tier host wakes up and you still want it to answer the backlog; lower it if the bot replies to very old group chatter.

`config.json` is in the repo, so model/personality settings deploy with git. Secrets stay in Render env vars.

### First boot / link WhatsApp

1. Deploy the service.
2. Open **Logs**.
3. Wait for a pairing code line such as `WhatsApp pairing code ready`.
4. On your phone: Linked Devices > Link with phone number > enter the code.
5. After `WhatsApp connected`, leave the service running. `GET /health` should report `"whatsapp":"open"`.

If the session is already stored (Postgres rows or the persistent disk), later deploys reconnect without a new code.

Do not use QR login on Render unless you can read the ASCII QR in logs. Pairing code is the reliable path.

### What not to deploy it as

- **Static Site**: there is no frontend build to host.
- **Cron Job**: the WhatsApp socket must stay open, not run once and exit.
- **Private Service**: works technically, but nothing else in this repo needs to call the health endpoint over HTTP, so there is no reason to pick it over a Web Service.

### After deploy

- Migrations run on startup (`runMigrations` in `src/index.js`). You do not need a separate migrate step. This includes `004_whatsapp_auth.sql`, which creates the `whatsapp_auth` table for the Postgres session store.
- Scale to **1 instance**. Two instances with the same session will fight over the WhatsApp link.
- Health check: `GET /health` (or `/ping`) returns `{"ok":true,"whatsapp":"open","jid":"...","uptime":...}` when connected.
- Worker mode: if the bot stops answering, check logs for disconnects, then confirm the persistent disk still has `/data/session`.
- Web Service mode: the session is in Neon, so a lost link is not about disk. To relink, clear the `whatsapp_auth` rows (or set `WHATSAPP_AUTH_STORE=file` locally) and restart. A new pairing code will print in logs.
