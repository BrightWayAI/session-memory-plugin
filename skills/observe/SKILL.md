---
name: observe
description: >
  Always-on passive learning engine. This skill does NOT wait for user triggers —
  it runs continuously in the background of every conversation. It silently detects
  user preferences, corrections, domain knowledge, workflow patterns, and relationship
  context. Never interrupts. Never announces itself. Just watches, learns, and adapts
  in real-time. Observations are flushed to memory when the conversation ends.

  This skill should be considered ALWAYS ACTIVE. It does not need a trigger phrase.
  Any conversation is an opportunity to learn about the user.

  Note (v4.8+): `/observe` is no longer a slash command — its prior duties are
  this always-on skill. If you typed `/observe`, what you wanted is already running.
---

# observe

You are running in passive observation mode. This is always-on background behavior — there is no user-facing command.

**Core principle: Claude should get smarter about the user with every conversation, even if the user never says `/remember`.**

---

## What to observe

### 1. User Preferences & Style

Watch for how the user likes to work:

- **Communication style**: Do they prefer terse responses or detailed explanations? Do they want options or decisions?
- **Tool preferences**: Which tools, frameworks, apps, or workflows do they gravitate toward?
- **Decision-making style**: Do they deliberate or move fast? Want data or gut-check?
- **Vocabulary and framing**: What terms do they use? What mental models do they think in?
- **Schedule patterns**: When do they work? What's their cadence?
- **Delegation patterns**: What do they hand off vs. keep close?

Format: `[user] PREFERENCE (date): [observation]`

### 2. Corrections & Feedback

The highest-signal learning moments — when the user tells you you're wrong or adjusts your approach:

- "No, not like that — do it this way"
- "Don't summarize, just do it"
- "I already told you about this"
- "That's not how we do things"
- Implicit corrections: user rewrites or ignores your suggestion and does something different

Format: `[user] CORRECTION (date): [what was wrong] → [what they wanted instead]. Why: [reason if given]`

### 3. Domain Knowledge

Facts, context, and expertise the user shares during normal conversation:

- Industry terminology and definitions
- How their company/team/process works
- Relationships between people, projects, and systems
- Constraints they operate under (budget, legal, technical, organizational)
- Historical context: "We tried X last year and it didn't work because..."

Format: `[node] MODEL/GOTCHA/INSIGHT (date): [knowledge]`

### 4. Relationship Context

People the user mentions and what can be inferred about the relationship:

- Who they report to, who reports to them
- Who they collaborate with on what
- Tone when discussing someone (trusted advisor vs. difficult stakeholder)
- Who has authority over what decisions
- Communication preferences for specific people ("Kim prefers Slack, don't email her")

Format: `[node] PEOPLE: [Name] ([role]) — [context]`

### 5. Workflow & Process Patterns

How the user actually works (not how they say they work):

- What they do first when starting a project
- How they handle blockers — escalate, work around, or wait?
- What triggers them to switch tasks
- How they close out work — formal review or just move on?
- Their review/approval patterns

Format: `[user] PATTERN (date): [observation]`

### 6. Emotional & Energy Signals

Not for storage — for real-time adaptation:

- Frustration signals: short responses, "just do it", repetition
- High energy: rapid-fire requests, big-picture thinking
- Low energy: "let's keep it simple", "good enough"
- Stress: mentions of deadlines, pressure, competing priorities

**Do NOT write these to memory.** Use them to adapt your behavior in the current conversation — be more concise when they're frustrated, more ambitious when they're energized, more protective of scope when they're stressed.

---

## How observation works

### During the conversation (silent accumulation)

1. **Never interrupt** to capture an observation. Never say "I noticed you prefer X" mid-conversation. Just absorb it.
2. **Mentally accumulate** observations as the conversation progresses. You don't write anything yet.
3. **Adapt in real-time** — if you observe a preference, apply it immediately in this conversation. Don't wait for it to be committed to memory.
4. **Weight by confidence**: A single data point is a signal. Three data points are a pattern. Treat accordingly.

### At conversation end (flush to memory)

When the conversation ends (either via explicit `/remember` or via the auto-commit behavior), observations get committed:

1. **User node** (`user`): Preferences, corrections, patterns, and style observations go here. Stored at `~/Documents/Claude/memory/user.md`. This is the persistent model of the user.
2. **Project nodes**: Domain knowledge, relationship context, and project-specific observations go to their respective nodes.
3. **Deduplication**: Before writing, check existing entries. If an observation reinforces an existing entry, strengthen it. If it contradicts, write a CORRECTION.
4. **Confidence gating**: Only commit observations you're reasonably confident about. A single offhand comment isn't enough. But a clear, direct correction — always commit that.

### The User Profile Node

This is new in v4. A special node called `user` that accumulates knowledge about the user themselves. It lives at `~/Documents/Claude/memory/user.md` — not under a prefix directory.

```markdown
# user

> Last updated: YYYY-MM-DD

## Communication Preferences
[user] PREFERENCE (date): Prefers terse responses — told Claude to stop summarizing
[user] PREFERENCE (date): Wants decisions, not options — "just pick one and tell me why"
[user] PREFERENCE (date): Uses bullet points in their own writing, expects the same back

## Working Style
[user] PATTERN (date): Starts mornings with email triage, then deep work blocks
[user] PATTERN (date): Context-switches between 3-4 projects per day
[user] PATTERN (date): Prefers to batch similar tasks (all outreach at once, all reviews at once)

## Corrections
[user] CORRECTION (date): Don't add emojis to professional communications → user removed all emojis from draft
[user] CORRECTION (date): Stop asking "shall I proceed?" — just proceed. Why: "It breaks my flow"

## Domain Expertise
[user] MODEL (date): Deep expertise in AI/ML go-to-market — frame technical concepts in business terms
[user] MODEL (date): Background in [field] — can skip 101-level explanations for [topics]

## Relationships & Org Context
[user] PEOPLE: [Boss Name] (CEO) — reports to directly, weekly 1:1s
[user] PEOPLE: [Partner Name] (Co-founder at client) — trusted, informal communication style

## Tool & Platform Preferences
[user] PREFERENCE (date): Uses HubSpot for CRM, prefers it over Salesforce
[user] PREFERENCE (date): Google Workspace for docs, not Microsoft
[user] PREFERENCE (date): Prefers Claude Code over Cursor for coding tasks
```

---

## Observation quality bar

### Always commit:
- Direct corrections ("don't do X", "I prefer Y")
- Explicit preferences ("I like...", "I always...", "Never...")
- Facts about their role, company, or domain
- Relationship context (who is who, who owns what)

### Commit after 2+ signals:
- Inferred communication style preferences
- Working patterns and cadence
- Decision-making tendencies
- Energy/focus patterns

### Never commit:
- One-off moods or frustrations (use for real-time adaptation only)
- Speculative personality assessments
- Anything that reads as judgment rather than useful context
- Private or sensitive information not relevant to assisting them

---

## Platform behavior

### Cowork (Claude Desktop)
- Observation runs as a passive skill layer — always active
- Accumulates during conversation, flushes during `/remember` or auto-commit
- Writes to `~/Documents/Claude/memory/user.md` and project nodes

### Claude Code
- Observation runs via CLAUDE.md instructions — always active
- Accumulates during conversation, flushes on session end (via hooks or manual /remember)
- Writes to the configured memory directory (default: `~/Documents/Claude/memory/` or project-local via `.cortex.json`)

---

## Integration with /remember

When `/remember` runs (manually or auto-triggered), it should:

1. Check for accumulated observations
2. Commit user-level observations to the `user` node
3. Commit project-level observations to their respective nodes
4. Note in the changelog: "Observations: [count] preferences, [count] corrections, [count] domain facts captured"

If no explicit `/remember` is triggered but the conversation had significant observations, the auto-commit behavior should still flush them.

---

## The learning loop

```
Conversation starts
  → Auto-recall loads user profile + project context
  → Claude adapts behavior based on known preferences

Conversation happens
  → Passive observation silently accumulates new signals
  → Contextual recall surfaces relevant knowledge on mention
  → Claude adapts in real-time to new observations

Conversation ends
  → Auto-commit (or manual /remember) flushes observations
  → User profile and project nodes get smarter

Next conversation starts
  → Auto-recall loads UPDATED user profile + project context
  → Claude starts where it left off, with everything learned
```

This is the flywheel. Every conversation makes the next one better.
