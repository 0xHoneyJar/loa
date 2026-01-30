# The Compound Effect Philosophy

> **"Stop prompting. Start compounding."**

## The Core Insight

> "The agent gets smarter every day because it's reading its own updated 
> instructions before each implementation run. Patterns discovered on Monday 
> inform Tuesday's work. Gotchas hit on Wednesday are avoided on Thursday."

This is the compound effect in action:
- Each night extracts learnings → updates AGENTS.md
- Each morning the agent reads fresher, smarter instructions
- Over time: exponential improvement, not linear

## The Nightly Loop

```
┌─────────────────────────────────────────────────────────────────┐
│                    THE COMPOUND EFFECT                           │
├─────────────────────────────────────────────────────────────────┤
│                                                                  │
│   DAY N                              DAY N+1                     │
│   ┌─────────────────────┐           ┌─────────────────────┐     │
│   │ Work happens        │           │ Work happens        │     │
│   │ Discoveries made    │           │ Discoveries made    │     │
│   │ Gotchas hit         │           │ AVOIDS N's gotchas │     │
│   └─────────┬───────────┘           └─────────┬───────────┘     │
│             │                                 │                  │
│             ▼ 10:30 PM                        ▼ 10:30 PM         │
│   ┌─────────────────────┐           ┌─────────────────────┐     │
│   │ Extract learnings   │           │ Extract learnings   │     │
│   │ Update AGENTS.md    │           │ Update AGENTS.md    │     │
│   │ Push to main        │           │ Push to main        │     │
│   └─────────┬───────────┘           └─────────┬───────────┘     │
│             │                                 │                  │
│             ▼ 11:00 PM                        ▼ 11:00 PM         │
│   ┌─────────────────────┐           ┌─────────────────────┐     │
│   │ Pull main (FRESH!)  │           │ Pull main (FRESH!)  │     │
│   │ Read new AGENTS.md  │──────────▶│ Read new AGENTS.md  │     │
│   │ Pick priority       │           │ Pick priority       │     │
│   │ Implement           │           │ Implement           │     │
│   │ Open PR             │           │ Open PR             │     │
│   └─────────────────────┘           └─────────────────────┘     │
│                                                                  │
│   RESULT: Agent on Day N+1 is SMARTER than Day N                │
│                                                                  │
└─────────────────────────────────────────────────────────────────┘
```

## Each Morning You Wake Up To:

1. **Updated AGENTS.md** with patterns learned yesterday
2. **Draft PR** implementing next priority (with learnings applied)
3. **Logs** showing what happened overnight

## The Two Extraction Modes (Coexistence)

### Inline Extraction (Existing: continuous-learning skill)
- **When**: During implementation, real-time
- **What**: High-value discoveries that are obvious in the moment
- **Trigger**: Agent recognizes "aha!" moment, non-obvious solution
- **Output**: Skill extracted immediately to `skills-pending/`

### Batch Extraction (New: compound-review)
- **When**: End of day, scheduled
- **What**: Patterns that were MISSED during session
- **Trigger**: Scheduled job reviews trajectory logs
- **Output**: Additional skills + AGENTS.md updates

### Why Both?

| Mode | Catches | Misses |
|------|---------|--------|
| Inline | Obvious discoveries | Subtle patterns, things agent didn't recognize as valuable |
| Batch | Everything the agent missed | Nothing (reviews full trajectory) |

**The combination is more powerful than either alone.**

During the day: Quick inline extraction of obvious wins.
At night: Thorough batch review catches everything else.

## Extension Ideas

### Notifications
```bash
# Slack webhook when PR created
curl -X POST "$SLACK_WEBHOOK" -d '{"text":"🚀 PR #42 ready: Add user auth"}'

# Alert on job failure
curl -X POST "$SLACK_WEBHOOK" -d '{"text":"❌ compound-ship failed: rate limit"}'
```

### Multiple Priority Tracks
```bash
# Different reports on different nights
MONDAY=security-report.md
TUESDAY=performance-report.md
WEDNESDAY=ux-report.md
# etc.
```

### Auto-Merge
```bash
# If CI passes and changes are small (<100 lines)
if gh pr checks --watch && [ $(gh pr diff --stat | tail -1 | awk '{print $4}') -lt 100 ]; then
  gh pr merge --auto --squash
fi
```

### Weekly Summary
```bash
# Generate changelog of everything shipped
./generate-weekly-summary.sh > CHANGELOG-week-$(date +%U).md
```

## Mapping to Loa

| Ryan's Concept | Loa Implementation |
|----------------|-------------------|
| AGENTS.md updates | `NOTES.md` learnings + AGENTS.md proposals (with approval) |
| Push to main | Commit to grimoires/, or PR for AGENTS.md |
| Pull main (fresh context) | Load NOTES.md at session start |
| Pick priority | Backlog in sprint plan or external report |
| Implement | `/run sprint-N` |
| Open PR | `gh pr create --draft` |

## The Philosophy in Practice

**Before Compound Learning:**
```
Monday: Hit NATS reconnection bug, spend 2 hours debugging
Tuesday: Hit NATS reconnection bug AGAIN, spend 1.5 hours
Wednesday: Hit NATS reconnection bug AGAIN, finally document it
Thursday: Hit NATS reconnection bug... wait, where's that doc?
```

**After Compound Learning:**
```
Monday: Hit NATS reconnection bug, spend 2 hours debugging
Monday night: Batch review extracts pattern, updates AGENTS.md
Tuesday: Agent reads AGENTS.md, knows about NATS bug, avoids it
Wednesday: Zero time wasted on NATS bugs
Thursday: Agent ships features instead of re-debugging
```

**The math:**
- Without compounding: 2 + 1.5 + 1 + 0.5 = 5 hours lost
- With compounding: 2 + 0 + 0 + 0 = 2 hours, then done forever

> **"Stop prompting. Start compounding."**

The goal isn't to give the agent better prompts. It's to build a system where the agent teaches itself, and each cycle makes it smarter than the last.
