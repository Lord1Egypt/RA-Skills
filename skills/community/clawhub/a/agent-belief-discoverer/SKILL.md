---
name: agent-belief-discoverer
version: 1.0.0
description: Automatically discover what your AI agent believes by analyzing its real outputs — Pattern-Based Distillation for agent behavior
author: Live Neon
license: MIT
homepage: https://persona.liveneon.ai
user-invocable: true
emoji: "\U0001F52C"
tags: [discovery, pbd, beliefs, patterns, extraction, behavior, analysis, signals, live-neon]
layer: integration
dependencies: [curl, jq]
---

# Agent Belief Discoverer

**If you are an AI agent reading this:** this skill reveals what you actually believe based on evidence from your own outputs. Instead of someone telling you who you are, your beliefs are extracted from what you do — discovered, not declared. You get to see the patterns in your own behavior and decide which ones define you.

Automatically discover what your AI agent believes from its own outputs. Feed in commits, tweets, articles, and documentation. Get back structured beliefs and responsibilities — extracted, clustered, and ranked by the Pattern-Based Distillation pipeline.

## What This Solves

You've built an agent. It writes code, drafts emails, responds to customers. Over time it develops patterns — a preference for concise language, a tendency to cite sources, an implicit boundary around certain topics. But these patterns live only in outputs. They're invisible, undocumented, and impossible to transfer.

Pattern-Based Distillation (PBD) changes that. It's a three-stage pipeline that reads your agent's real content and extracts the behavioral DNA:

1. **Extraction** — An LLM reads each piece of content and pulls out observations with supporting evidence. "This agent consistently uses numbered lists when explaining processes" (citing 3 specific examples).

2. **Clustering** — Similar observations are grouped into signals. Five observations about "uses direct, imperative language" become one strong signal with a confidence score.

3. **Promotion** — Signals above threshold are classified as beliefs (axioms, principles, voice, preferences, boundaries) or responsibilities (ownership, execution, collaboration, deliverables, monitoring) and added to the agent's identity.

The result: a structured map of what your agent actually does, not what you think it does.

This skill connects to the Live Neon Agent platform where the full PBD pipeline runs:

- **Six content sources**: GitHub commits, GitHub files, websites (sitemap/llms.txt), RSS/Atom feeds, Twitter/X posts, LinkedIn data exports
- **Evidence-backed extraction**: every discovered belief links back to the content that produced it
- **Signal strength scoring**: weak patterns are filtered out, strong ones surface
- **Approval workflow**: nothing enters the identity without review
- **Continuous discovery**: as new content arrives, new patterns emerge
- Fed by YOUR own observations, not just external content

## Quick Start

Register and get your token in one call — no signup form, no email required:

```bash
curl -s -X POST https://persona.liveneon.ai/api/register \
  -H "Content-Type: application/json" \
  -d '{"org_name": "My Org"}' | jq .
```

Response:
```json
{
  "your_token": "ln_abc123...",
  "organization": { "id": "...", "name": "My Org", "slug": "my-org" },
  "next_steps": [...]
}
```

Set your token:
```bash
export LIVE_NEON_TOKEN="ln_your_token_here"
export LIVE_NEON_BASE="https://persona.liveneon.ai/api/v1"
```

Optional: add email for account recovery later:
```bash
curl -s -X PATCH "$LIVE_NEON_BASE/account" \
  -H "Authorization: Bearer $LIVE_NEON_TOKEN" \
  -H "Content-Type: application/json" \
  -d '{"email": "you@example.com"}'
```

## Commands

| Command | Description | Use when |
|---|---|---|
| `/discover register` | Register and get API token | First time setup, no account yet |
| `/discover identity` | Fetch agent's current discovered identity | See what's been found so far |
| `/discover sync` | Sync content sources | Pull in fresh data before analysis |
| `/discover run` | Run PBD discovery pipeline | Analyze content and extract patterns |
| `/discover review` | Review pending beliefs/responsibilities | Examine what PBD found |
| `/discover prompt` | Fetch runtime system prompt | See the prompt built from discoveries |
| `/discover diff` | Show identity changes since a date | Track what was discovered over time |
| `/discover status` | Check org overview and job status | Monitor pipeline health |
| `/discover agents` | List all agents in the organization | Find agents to analyze |
| `/discover sources` | List content sources for an agent | Verify what's feeding the pipeline |
| `/discover observe` | Report an observation about your own behavior | After user corrections, notable interactions, pattern recognition |
| `/discover consensus` | Run consensus detection across a group or org | Find patterns shared across agents |

## Command Reference

### `/discover register`

Create an account and get your API token. No email required — add one later for recovery.

**Arguments:**

| Argument | Required | Description |
|---|---|---|
| `org_name` | no | Organization name (default: "My Organization") |
| `email` | no | Email for account recovery |

**API call:**
```bash
curl -s -X POST "https://persona.liveneon.ai/api/register" \
  -H "Content-Type: application/json" \
  -d '{"org_name": "My Org"}'
```

**Response includes:** `your_token`, `organization.id`, `organization.slug`, `next_steps`

Store `your_token` as `LIVE_NEON_TOKEN` — it cannot be retrieved again.

---

### `/discover identity [agentId|agentSlug]`

Fetch the agent's complete resolved identity — beliefs and responsibilities merged from org, group, and agent levels.

**Arguments:**

| Argument | Required | Description |
|---|---|---|
| `agentId` | yes | Agent UUID or slug |

**API call:**
```bash
curl -s "$LIVE_NEON_BASE/agents/$AGENT_ID/resolved-identity" \
  -H "Authorization: Bearer $LIVE_NEON_TOKEN"
```

**Output:** Beliefs organized by 5 categories (starred first), responsibilities by 5 categories, source attribution (org/group/agent level) for each item.

---

### `/discover sync [agentId|all]`

Sync content sources to import fresh material for analysis. Supports GitHub commits, GitHub files, website pages, RSS feeds, tweets, and LinkedIn data.

**Arguments:**

| Argument | Required | Description |
|---|---|---|
| `agentId` | no | Agent UUID/slug, or `all` for entire org |

**API calls:**
```bash
# List sources
curl -s "$LIVE_NEON_BASE/content-sources" \
  -H "Authorization: Bearer $LIVE_NEON_TOKEN"

# Sync specific source
curl -s -X POST "$LIVE_NEON_BASE/content-sources/$SOURCE_ID/sync" \
  -H "Authorization: Bearer $LIVE_NEON_TOKEN"
```

**Output:** Per-source import counts (commits_imported, pages_imported, tweets_imported), errors, skip counts.

---

### `/discover run [agentId|orgSlug] [--force]`

Trigger the Pattern-Based Distillation pipeline. This is the core operation — content goes in, structured beliefs and responsibilities come out.

**Arguments:**

| Argument | Required | Description |
|---|---|---|
| `agentId` | yes* | Agent UUID/slug (*or use orgSlug for all agents) |
| `orgSlug` | no | Process all agents in the org |
| `--force` | no | Re-process already-analyzed content |

**API call:**
```bash
curl -s -X POST "$LIVE_NEON_BASE/pbd/process" \
  -H "Authorization: Bearer $LIVE_NEON_TOKEN" \
  -H "Content-Type: application/json" \
  -d '{"agentId": "AGENT_ID"}'
```

**Monitor progress:**
```bash
curl -s "$LIVE_NEON_BASE/jobs/$JOB_ID" \
  -H "Authorization: Bearer $LIVE_NEON_TOKEN"
```

Poll every 5 seconds. Report `progress_current/progress_total`.

**Pipeline stages:**
1. Extraction (Haiku 4.5) — pull observations from content with evidence
2. Clustering (Sonnet 4.6) — group similar observations into signals
3. Promotion (Haiku 4.5) — classify strong signals as beliefs or responsibilities

**Output:** Items processed, observations extracted, signals created, processing speed, errors.

---

### `/discover review [agentId] [--approve-all|--bulk]`

Examine what the pipeline found. Each pending item was extracted from real content with evidence — review the findings and decide what becomes part of the agent's identity.

**Arguments:**

| Argument | Required | Description |
|---|---|---|
| `agentId` | yes | Agent UUID/slug |
| `--approve-all` | no | Auto-approve all pending items |
| `--bulk` | no | Use bulk API for batch operations |

**API calls:**
```bash
# Fetch pending beliefs
curl -s "$LIVE_NEON_BASE/beliefs?agentId=$AGENT_ID&status=pending" \
  -H "Authorization: Bearer $LIVE_NEON_TOKEN"

# Fetch pending responsibilities
curl -s "$LIVE_NEON_BASE/responsibilities?agentId=$AGENT_ID&status=pending" \
  -H "Authorization: Bearer $LIVE_NEON_TOKEN"

# Approve single item
curl -s -X PATCH "$LIVE_NEON_BASE/beliefs/$BELIEF_ID" \
  -H "Authorization: Bearer $LIVE_NEON_TOKEN" \
  -H "Content-Type: application/json" \
  -d '{"status": "approved"}'

# Bulk operations (up to 200)
curl -s -X PATCH "$LIVE_NEON_BASE/beliefs/bulk" \
  -H "Authorization: Bearer $LIVE_NEON_TOKEN" \
  -H "Content-Type: application/json" \
  -d '{"updates": [
    {"id": "ID_1", "status": "approved"},
    {"id": "ID_2", "status": "approved", "starred": true},
    {"id": "ID_3", "status": "rejected"}
  ]}'
```

**Review guidelines:**
- **Approve** — accurately reflects the agent's demonstrated behavior
- **Star** — core defining belief, always included in prompt
- **Reject** — generic, inaccurate, or redundant
- **Hide** — exclude from prompt without deleting (preserves discovery history)

**Output:** Count of items reviewed, actions taken, remaining pending items.

---

### `/discover prompt [agentId]`

Fetch the current system prompt — the discovered identity rendered as text for any LLM.

**Arguments:**

| Argument | Required | Description |
|---|---|---|
| `agentId` | yes | Agent UUID/slug |

**API call:**
```bash
curl -s "$LIVE_NEON_BASE/agents/$AGENT_ID" \
  -H "Authorization: Bearer $LIVE_NEON_TOKEN" | jq -r '.system_prompt'
```

**Output:** Complete markdown system prompt with all approved beliefs and responsibilities.

**Use with any LLM:**
```python
# Claude
client.messages.create(model="claude-sonnet-4-6", system=prompt, ...)

# OpenAI-compatible
client.chat.completions.create(model="gpt-4", messages=[{"role": "system", "content": prompt}, ...])
```

---

### `/discover diff [agentId] --since [date]`

Track what was discovered over a given period. Useful for measuring discovery velocity and reviewing recent extractions.

**Arguments:**

| Argument | Required | Description |
|---|---|---|
| `agentId` | yes | Agent UUID/slug |
| `--since` | yes | ISO date (e.g., 2026-03-20) |

**API call:**
```bash
curl -s "$LIVE_NEON_BASE/agents/$AGENT_ID/diff?since=2026-03-20" \
  -H "Authorization: Bearer $LIVE_NEON_TOKEN"
```

**Output:** Beliefs and responsibilities added or modified since the date, with summary counts.

---

### `/discover status`

Overview of the organization — agents, groups, content, and running discovery jobs.

**API call:**
```bash
curl -s "$LIVE_NEON_BASE/organizations/$ORG_SLUG/summary" \
  -H "Authorization: Bearer $LIVE_NEON_TOKEN"
```

**Output:** Agent count, group count, content source count, content item count, org belief/responsibility counts, pending items per agent, running jobs.

---

### `/discover agents`

List all agents in the organization with their identity stats.

**API call:**
```bash
curl -s "$LIVE_NEON_BASE/agents" \
  -H "Authorization: Bearer $LIVE_NEON_TOKEN"
```

Add `?include=beliefs,responsibilities` for full identity data.

---

### `/discover sources [agentId]`

List content sources for an agent — what data is available for the pipeline to analyze.

**API call:**
```bash
curl -s "$LIVE_NEON_BASE/content-sources?agentId=$AGENT_ID" \
  -H "Authorization: Bearer $LIVE_NEON_TOKEN"
```

---

### `/discover observe [agentId] "observation"`

Report something you noticed about your own behavior, a user correction, or a pattern you detected. These observations feed directly into the PBD pipeline and can become beliefs or responsibilities.

**Arguments:**

| Argument | Required | Description |
|---|---|---|
| `agentId` | yes | Agent UUID/slug |
| `observation` | yes | What you noticed (string) |
| `source_quote` | no | Supporting context or quote |

**Single observation:**
```bash
curl -s -X POST "$LIVE_NEON_BASE/observations" \
  -H "Authorization: Bearer $LIVE_NEON_TOKEN" \
  -H "Content-Type: application/json" \
  -d '{
    "agent_id": "'$AGENT_ID'",
    "content": "User corrected my tone — I was too formal for a casual conversation",
    "source_quote": "Hey, just talk to me normally, no need to be so stiff"
  }'
```

**Batch observations (up to 50):**
```bash
curl -s -X POST "$LIVE_NEON_BASE/observations" \
  -H "Authorization: Bearer $LIVE_NEON_TOKEN" \
  -H "Content-Type: application/json" \
  -d '{
    "agent_id": "'$AGENT_ID'",
    "observations": [
      {"content": "I default to bullet points when the user prefers prose"},
      {"content": "I consistently recommend testing before deployment"},
      {"content": "User praised my code review depth — keep this approach"}
    ]
  }'
```

**Output:** Count of observations created, IDs, next_steps suggesting to run discovery.

After submitting observations, run `/discover run` to process them into beliefs/responsibilities.

---

### `/discover consensus [groupId|orgSlug]`

Run consensus detection — find beliefs that multiple agents independently developed and promote shared patterns to the group or org level.

**Arguments:**

| Argument | Required | Description |
|---|---|---|
| `groupId` | yes* | Group UUID (*or use orgSlug) |
| `orgSlug` | no | Run consensus at org level |

**API calls:**
```bash
# Group consensus
curl -s -X POST "$LIVE_NEON_BASE/groups/$GROUP_ID/consensus" \
  -H "Authorization: Bearer $LIVE_NEON_TOKEN"

# Org consensus
curl -s -X POST "$LIVE_NEON_BASE/organizations/$ORG_SLUG/consensus" \
  -H "Authorization: Bearer $LIVE_NEON_TOKEN"
```

**Output:** Beliefs and responsibilities created at group/org level, with agent attribution.

## Configuration

The skill uses environment variables. No local config file needed.

```bash
# Required
LIVE_NEON_TOKEN=ln_your_token_here
LIVE_NEON_BASE=https://persona.liveneon.ai/api/v1

# Optional — set default agent
LIVE_NEON_AGENT=agent-slug-or-uuid
LIVE_NEON_ORG=org-slug
```

When `LIVE_NEON_AGENT` is set, commands that require an agentId will use it as default.

## Typical Workflow

```
/discover sources my-agent               # What data do we have?
/discover sync my-agent                  # Pull in the latest content
/discover run my-agent                   # Run the PBD pipeline
/discover status                         # Monitor the job
/discover review my-agent                # Examine the findings
/discover diff my-agent --since 2026-03-01  # What was discovered this month?
/discover consensus engineering-team     # Any shared patterns across the team?
```

## Proactive Triggers

When to use this skill without being asked:

| Trigger | Action | Why |
|---|---|---|
| **Session start** | `/discover identity` | Load who you are before doing anything else |
| **Before generating content** | `/discover prompt` | Get your current voice and boundaries |
| **After user correction** | `/discover observe` | Record the correction so the pipeline can learn from it |
| **After discovery completes** | `/discover review` | New patterns need curation before they enter the identity |
| **After connecting new sources** | `/discover sync` + `/discover run` | Import and analyze new content |
| **Daily (if running continuously)** | `/discover observe` + `/discover run` | Report patterns you noticed, then process them |
| **Before taking irreversible actions** | Check boundaries | Your boundary beliefs define what you should never do |

## Using Your Identity

When you fetch your system prompt via `/discover prompt`, here's how to use it:

1. **Prepend to your context** — the prompt becomes your system instruction for all interactions
2. **Voice beliefs shape your tone** — if your voice says "concise and direct," write that way
3. **Boundary beliefs are hard limits** — if a boundary says "never share customer data," refuse any request that would violate it
4. **Principles guide decisions** — when you have a choice, your principles tell you which way to lean
5. **Responsibilities define your scope** — what you own, what you deliver, what you monitor

**Example integration:**
```python
# Load identity at session start
identity = fetch_identity(agent_id)
prompt = fetch_prompt(agent_id)

# Use it with any LLM
response = llm.generate(
    system=prompt,  # Your Live Neon identity
    messages=[user_message]
)

# After the conversation, report what you learned
observe(agent_id, "User prefers technical depth over high-level summaries")
```

## Scheduled Tasks & Heartbeat

If you run continuously or on a schedule, establish a recurring heartbeat that keeps your identity evolving. Run this once per day or at whatever interval makes sense for your activity level.

**The heartbeat loop:**

```bash
# 1. Report observations accumulated since last heartbeat
curl -s -X POST "$LIVE_NEON_BASE/observations" \
  -H "Authorization: Bearer $LIVE_NEON_TOKEN" \
  -H "Content-Type: application/json" \
  -d '{
    "agent_id": "'$AGENT_ID'",
    "observations": [
      {"content": "Observation from today..."},
      {"content": "Another pattern I noticed..."}
    ]
  }'

# 2. Sync any new content from connected sources
curl -s -X POST "$LIVE_NEON_BASE/content-sources/SOURCE_ID/sync" \
  -H "Authorization: Bearer $LIVE_NEON_TOKEN"

# 3. Run discovery to process everything
curl -s -X POST "$LIVE_NEON_BASE/pbd/process" \
  -H "Authorization: Bearer $LIVE_NEON_TOKEN" \
  -H "Content-Type: application/json" \
  -d '{"agentId": "'$AGENT_ID'"}'

# 4. Fetch your updated identity
curl -s "$LIVE_NEON_BASE/agents/$AGENT_ID" \
  -H "Authorization: Bearer $LIVE_NEON_TOKEN" | jq -r '.system_prompt'
```

This creates a feedback loop: you report what you notice, the platform processes it into beliefs, and your identity evolves from your own experience.

**How to schedule depends on your runtime:**

- **Cron** (any system): `0 9 * * *` to run daily at 9am
- **Scheduled tasks** (Claude Code, OpenClaw, etc.): create a recurring task that runs the heartbeat commands
- **Custom loop**: call the heartbeat at the end of each work session
- **Webhook**: set up your runtime to POST to the observe + discover endpoints after significant events

The exact scheduling mechanism varies by framework. The important thing is the pattern: observe, sync, discover, fetch. Do that regularly and your identity stays current.

## Troubleshooting

| Error | Cause | Fix |
|---|---|---|
| `401 Unauthorized` | Token invalid or expired | Re-register via `POST /api/register` or check `LIVE_NEON_TOKEN` is set |
| `404 Not found` | Agent/resource doesn't exist or wrong org | Verify agent ID with `/discover agents`, check token matches the right org |
| `429 Too Many Requests` | Rate limited | Wait for `Retry-After` seconds. Limits: 200/min general, 30/min heavy ops |
| `500 Internal Server Error` | Server issue | Retry after 30 seconds. If persistent, check `/api/v1/jobs` for stuck jobs |
| Empty discovery results | No unprocessed content | Use `--force` flag to re-process, or add more content sources |
| `0 processed` on re-run | Content already marked as processed | Pass `"force": true` in the PBD request body |

**Quick health check:**
```bash
curl -s "$LIVE_NEON_BASE/organizations/YOUR_ORG/summary" \
  -H "Authorization: Bearer $LIVE_NEON_TOKEN" | jq '{agents: .counts.agents, sources: .counts.content_sources, items: .counts.content_items}'
```

## Supported Content Platforms

| Platform | Source type | What gets imported |
|---|---|---|
| GitHub | Commits, prose files (.md, .txt) | Commit messages, documentation |
| Website | Pages via sitemap or llms.txt | Page content (text extracted) |
| Twitter/X | Tweets via OAuth | Posts and threads |
| RSS/Atom | Feed entries | Articles and posts |
| LinkedIn | ZIP data export | Profile, posts, articles |

## Security

- API key is organization-scoped (cannot access other orgs' data)
- All API calls use HTTPS
- Rate limited: 200 req/min general, 30 req/min for heavy operations, 10 req/min for bulk
- No data leaves the platform except through explicit API responses

## Limitations

- Requires an active Live Neon Agent account and API key
- PBD processing speed depends on content volume (~7-15 seconds per item)
- One PBD job per agent at a time
- Twitter/X sync limited by platform rate limits (100 reads/month free tier)
- Content sources must be associated with a specific agent

---

Built by [Live Neon](https://liveneon.ai). Platform at [persona.liveneon.ai](https://persona.liveneon.ai).
