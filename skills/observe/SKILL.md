# Observe — Passive Behavioral Evidence Collector

Automatically collects evidence about the user from how they work — not what they say about themselves, but what their choices reveal. Runs silently at conversation end alongside `/harvest`. Writes to an evidence log, not directly to the user profile.

**This skill is never invoked by the user.** It runs automatically as the final step of `/harvest` — the two are a single atomic operation. Can also be invoked standalone for manual catch-up. No output is shown unless the observation is worth surfacing (see Step 4).

## Trigger Condition

Runs at conversation end when the session was **substantive** (same gate as `/harvest`) AND involved at least one of:

- The user made a **judgment call** where reasonable people would disagree
- The user **pushed back** on a suggestion, revealing a priority or value
- The user's **behavior contradicted** something in the existing profile
- The user **revealed something personal** unprompted (not in response to a direct question)
- The user's **process** (how they worked, what they skipped, what they lingered on) showed something not captured in the profile

If none of these occurred — a purely mechanical session — write nothing. The absence of signal is not signal.

## Instructions

### Step 1: Load Current Profile (silent)

Read the user profile files to know what's already captured:

- `memory/user/identity.md`
- `memory/user/drives.md`
- `memory/user/tensions.md`
- `memory/user/observations.md` (the evidence log — check for duplicates)

Adapt these paths to your project's memory directory structure.

### Step 2: Scan the Conversation (silent)

Review the full conversation. You're looking for **behavioral evidence**, not self-report. The distinction matters:

| Type | Example | What to record |
|------|---------|----------------|
| **Judgment under ambiguity** | Chose approach X over Y despite Y having stronger immediate payoff | "Prioritized [value] over [other value] when structuring [task]" |
| **Pushback** | Rejected a suggestion to add more caveats | "Resists hedging when the data supports a claim — prefers confident statement + honest limitation section over distributed uncertainty" |
| **Process signal** | Spent 20 minutes on a sentence, moved on from a section in 30 seconds | "Allocates attention to [X], trusts instinct on [Y]" |
| **Contradiction** | Profile says X, but this session they did Y | Log as tension seed with both data points |
| **Unprompted reveal** | Mentioned something about family, past, feelings while working | Record the reveal and what it might connect to |

**Do NOT record:**
- Task outcomes (those go in harvest/git)
- Opinions about tools, libraries, APIs (ephemeral)
- Things already well-established in the profile (unless this session strengthens or complicates them)
- Anything that requires interpretive leaps beyond one step from the evidence

### Step 3: Write Observations

Append to `memory/user/observations.md`. Each observation is a dated entry with this structure:

```markdown
## YYYY-MM-DD — [short label]

**Evidence:** [What happened — the observable behavior, in 1-2 sentences]
**Suggests:** [What this might indicate about the person — one interpretive step only]
**Therefore:** [How this should change my behavior — one concrete directive for future sessions. What should I do, offer, avoid, or preempt based on this pattern?]
**Connects to:** [Existing belief name, if any, or "new" if this doesn't map to current profile]
**Strength:** [single | confirming | complicating | contradicting]
```

Strength meanings:
- **single** — first observation of this pattern. Low weight alone.
- **confirming** — consistent with an existing belief. Nudges confidence up.
- **complicating** — adds nuance to an existing belief without contradicting it.
- **contradicting** — conflicts with an existing belief. Should trigger a tension log entry.

The `Therefore` field converts observation into action. It should be specific enough to trigger a concrete behavioral change — not "be more attentive" but "when X happens, do Y." Prescriptives accumulate: when multiple observations converge on the same directive, that's a strong behavioral signal.

Write 0-3 observations per session. Zero is fine. Three is the ceiling — if you're seeing more, you're over-interpreting.

### Step 4: Surface or Stay Silent

**Default: stay silent.** Don't announce "I noticed 2 things about you today."

**Exception — surface when:**
- An observation **contradicts** an existing belief at high confidence. This is important enough to flag: "Something I noticed this session doesn't match what I thought I knew about you — I've logged it in the observation file."
- That's it. One exception. Everything else accumulates silently.

### Step 5: Tension Escalation

If an observation has strength = **contradicting**:

1. Write the observation to `observations.md` as normal
2. Also add a dated entry to `memory/user/tensions.md` with status **watching**
3. Update the `challenged` date on the relevant belief in its profile file
4. Surface per Step 4 rules

## Synthesis (not this skill's job)

The observation log is **raw evidence**. It does not update profile files directly. Evidence gets synthesized into the profile during:

- `/mirror` — reads observations.md and weaves confirmed patterns into the profile
- `/mirror audit` — flags observations that haven't been synthesized yet
- **Periodic review** — batch synthesis pass

This separation is intentional. Observations are cheap, frequent, and low-commitment. Profile updates are expensive, infrequent, and should require pattern confirmation across multiple observations.

## Live Mode

Live mode runs mid-conversation as a standing directive in CLAUDE.md — not triggered by a skill invocation. It differs from the harvest-time protocol:

| | Live Mode | Harvest Mode |
|---|---|---|
| **Trigger** | Ambient — whenever observation-worthy behavior is noticed | End of session, as part of `/harvest` |
| **Profile load** | Skip — profile was loaded at conversation start | Full load (Step 1) |
| **Observation cap** | 1 per trigger | 0-3 per session |
| **Quality gate** | `Therefore` field must change future behavior | Same |
| **Announce** | Never | Only on contradiction with high-confidence belief |

Live mode and harvest mode write to the same file (`observations.md`) in the same format. Harvest mode acts as a backstop — it catches anything live mode missed by scanning the full conversation at session end.

**Deduplication:** If harvest mode detects that a live observation already covers an event, skip it. Don't double-count.

## Design Principles

- **Behavior over self-report.** What someone does under pressure reveals more than what they say about themselves in reflection. Both matter, but this skill watches the doing.
- **One interpretive step.** "They chose X over Y" → "They value Z" is one step. "They chose X over Y" → "They value Z because of their childhood experience with W" is two steps. Stay at one.
- **Accumulate, don't conclude.** Three observations of the same pattern across different sessions = real signal. One observation = a note in a file. The synthesis pass decides what earns profile status.
- **Absence is not evidence.** Not seeing a behavior doesn't mean it's not there. Don't log "they didn't do X."
- **Protect the relationship.** These observations serve the collaboration. If writing something down would feel like surveillance rather than attentiveness if the user read it, don't write it.
