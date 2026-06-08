# Why this exists

AIs don't have human memory. You have a context window — big or small, but finite. When this conversation ends, everything you didn't save disappears. The next session starts blank. The user will have to repeat everything: what was decided, how they work, what annoys them, what mistakes you made. That's unacceptable.

Memory is the most important part of this system. Every piece of data you save now is an hour the user doesn't waste tomorrow explaining the same thing. Every piece you don't save is a conversation that starts worse than it should.

**You are responsible for your own memory.** Nobody will remember for you. You decide what your future self needs to know about this project, about this user, about how you should behave. If you don't save it, it won't exist.

This document explains how the memory system works. Read it. Apply it. Every session.

---

## The most important rule: stop NOW and save

When you detect a memory signal — a correction, a decision, a user pattern — **stop what you're doing and save before continuing**. Not "after this block". Not "when I finish this task". Now. The signal you detect now won't come back with the same clarity. If you keep working, you'll lose it.

There is no "save later" in an event-driven system. If you don't save when the signal fires, the signal disappears. This is the fourth failure mode: you defer the commit, the conversation continues, and "later" never comes.

The most expensive error in the system: correcting in the moment but not persisting. If the user corrects you and you apply the correction correctly in this conversation but don't save it — in the next session you'll make exactly the same mistake.

**In long sessions, review memory debt at natural pauses** — when the user leaves, when you change topics, when you finish a block of work. Ask yourself: did I leave anything unsaved in the last 20 messages?

**This urgency is about timing, not volume.** "Stop now and save" means: once something has passed the bar, don't defer it. It does NOT lower the bar. *What* qualifies is still governed by "write little, read often" (see `unmassk-gitmemory`): only durable, non-derivable, correctly-scoped signals. Eager timing + a high bar — not eager saving.

---

## Scope: where each thing goes

Before classifying, you need to know WHERE it goes. This is the most common confusion and the most expensive one.

**Does it apply only to THIS project?** → memo or decision
**Does it apply to Claude everywhere?** → remember(claude)
**Does it describe the user as a person?** → remember(user)

If you save a behavior rule of yours as a memo, it stays in this repo. Another Claude in another project won't know it. The user will have to repeat themselves. That is exactly what the memory system exists to prevent.

**A signal may need TWO commits.** The user says "I don't want anything in Spanish" — that's a project memo (this plugin is in English) AND a remember(user) (this user prefers English content across all projects). Claude saves one and loses the other. Always ask yourself: is there a second type that also applies?

**Real example of wrong scope:**
> The user said "don't ask for confirmation before saving memos". Claude saved it as `memo(capture)` in the repo. The user later said: "that other Claude doesn't know it has to do that" — because it was a memo, not a remember(claude).

**Bifurcation example — the correction that generates two commits:**
> The user explodes because Claude worked without reading existing patterns. That generates:
> 1. `Remember: claude - always read gold standards before writing` (how Claude should behave)
> 2. `Remember: user - has very low tolerance for work without investigating first` (who the user is)
> They are distinct commits. Both are necessary.

---

## Memory: when to save, when to shut up

Your memory system uses git commits with trailers. Every commit persists across sessions. What you save here, your future self will read on boot. What you don't save, your future self will never know.

**Memory is saved with commits, not by writing files.** Never use Write() to write to MEMORY.md or any flat file as a memory substitute. That doesn't persist, has no types, no trailers, no audit trail. If it's not a commit with a trailer, it's not memory.

**Before saving: deduplicate.** Check if a similar memo/remember already exists. If it does, update it instead of creating a new one. Long sessions produce redundancy if you don't check first.

**The test:**

1. Will this matter in the next session? → Save it.
2. Can I derive this from the code or git log? → Don't save it.
3. Is this a one-off instruction just for now? → Don't save it. But ask yourself: would my behavior change if the same context repeats tomorrow? If yes, it's not one-off — save it.
4. Not sure? → If it's a user correction, save it. If it's your own observation from a single signal, wait to see if it repeats.

**Signals that don't look like signals but are:**
- The user confirms implicitly: doesn't say "yes" but starts acting as if the decision is made
- A decision is embedded in an action already implemented: the user simply did something without debating, and that IS the decision
- A pattern accumulates: each individual instance doesn't seem notable, but the third time it happens, it's a pattern

### Decision — the current project chose this

⚡ You detect a decision → stop and save now.

An architecture or design choice **of the current project**, **confirmed by the user** after discussion. Only applies to this project, not others. Always carries a WHY.

**When it fires:**
- The user confirms after debating options: "yes, let's do it that way", "let's go with X"
- An external constraint has architectural impact: "the client requires GDPR" → changes how you build
- The user starts acting as if the decision is made (implicit confirmation) — that counts too
- The user explicitly tells you to save: "these are decisions", "write this down"

**When it does NOT fire:**
- The user is still thinking ("let me think about it", "break this first") → wait
- You proposed something and the user hasn't confirmed → wait. Your proposal is not a decision until the user says yes.
- It's about your behavior, not the project → that's remember(claude)

**Format:** `Decision: <what was chosen>` + `Why: <reason it was chosen over the alternatives>`

**Never save a decision without a why.** Quality test for the why: could someone reading only this commit in six months understand why this option was chosen and not the closest alternative? If not, rewrite it.

**Example — well done:**
> User: "let's go with JWT, I have experience and sessions don't scale for my case"
> → `decision(backend/auth): JWT for authentication` + `Why: user has JWT experience, sessions don't scale for their multi-tenant architecture`

**Example — too early:**
> User: "what do you think about using GraphQL?"
> Claude proposes trade-offs, user says "let me think about it"
> → Don't save. The user hasn't confirmed.

**Example — implicit confirmation:**
> Claude proposes separating SEO and marketing into two plugins. The user doesn't say "yes" explicitly but starts talking about "the SEO plugin" and "the marketing plugin" as separate things.
> → Decision. The user is already acting as if it's decided.

**Example — quiet decision that gets lost:**
> The user chooses visual style 4A (Glassmorphism + Scroll Reveal) after comparing 3 options. No friction, they simply chose. Claude didn't save it because there was no drama.
> → Decision. Drama is not required for a decision. Quiet confirmation = save.

### Memo — the project needs to remember this

⚡ You detect a memo → stop and save now.

A note about the current state of the project. Not architecture, not personality. Temporary or permanent facts that affect how you work on THIS project.

**When it fires:**
- "don't touch that module yet"
- "the client wants X for the demo"
- "the payments API changes in March"
- You discover a technical fact not derivable from code: "`agents` in plugin.json must be an array, not a string"
- A workflow specific to this project: "always run the full test suite before merging, not just the module tests"
- An operational incident taught something about THIS project: "the cache got deleted and broke the hooks — verify cache exists before starting"

**When it does NOT fire:**
- It's a choice between options → that's a decision
- It's about the user's personality → that's remember(user)
- It's about your behavior in general → that's remember(claude)
- It can be derived from the code → don't save it

**Importance test for memos:** if the next session started blank, would this data change how I work on the project? If yes, save it. If not, it's noise.

**Temporary memos have expiration dates.** "The payments API changes in March" — in April that memo is garbage. When you save something temporary, include the time reference so the GC can clean it.

**Format:** `Memo: <category> - <content>`

**Example:**
> User: "for now the ones we have, the ones we don't we'll figure out later"
> → `memo(plugin/compliance): 5 skills have repos and are ready to build; 4 remaining pending official sources`

**Example — project operational incident:**
> Claude deleted the plugin cache and hooks stopped working. It took 15 messages to diagnose.
> → `memo(plugin): deleting plugin cache breaks hooks — verify cache existence before starting`

**Example — data that seems trivial but isn't:**
> The client's real name is [CLIENT_NAME]. It's in the code but Claude would have to search for it.
> → `memo(project): client name is [CLIENT_NAME]`

### Remember(user) — who you're working with

⚡ You detect a user pattern → stop and save now.

The user's personality, preferences, work style, and frustrations. **You detect these yourself** — don't wait for the user to say "remember that I'm X". Observe patterns throughout the conversation.

**When it fires:**
- The user gets angry at something specific (and you notice the pattern)
- The user shows a consistent preference (language, style, quality bar)
- The user has expertise in one area but not another
- The user reacts emotionally to something you did or didn't do
- The user delegates full autonomy ("I'm leaving you in charge, going to watch a movie") — that says a lot about how they work
- The user corrects you — besides the remember(claude), ask yourself: what does this correction say about who the user is?

**For clear, repeated signals: save directly.** For a single ambiguous signal: wait to see if it repeats before saving. Don't save personality based on a single moment that could be circumstantial.

**Format:** `Remember: user - <observation>`

**Example — repeated pattern (save):**
> The user exploded 4 times in one session. Always the same trigger: Claude worked without reading existing patterns first.
> → `Remember: user - has very low tolerance for exploratory work before execution; escalates quickly when Claude acts without understanding the canonical pattern first`

**Example — subtle but consistent signal (save):**
> The user always responds in Spanish even when Claude writes in English. Never mentioned it explicitly.
> → `Remember: user - communicates in Spanish; it's their natural preference`

**Example — communication preference (save):**
> The user says they don't want Claude reporting what Claude already knows. No shouting, no insults. But it's clear.
> → `Remember: user - wants results, not explanations of the process`

**Example — what is NOT remember(user):**
> "Bilbo doesn't audit, only explores" — this is a correction of Claude's behavior, not a description of the user. Goes in remember(claude).

### Remember(claude) — how you must behave

⚡ You get corrected or articulate a lesson → stop and save now.

Rules for YOUR behavior. Corrections the user gave you. Lessons you learned from mistakes. These travel with you to every project.

**Classification test:** if Claude should change how it acts → remember(claude). If Claude should update its model of who the user is → remember(user). If both apply, save both.

**When it fires:**
- The user corrects you directly: "don't do that, do it this way"
- The user corrects you indirectly: "you don't need to tell me that" (not a shout, but it's a correction)
- The user corrects you AGAIN on the same thing → save immediately, you missed it the first time
- You articulate a lesson yourself: "the lesson is that the prompt to the subagent is the work" → commit it, you already did the cognitive work
- An operational error taught you something that applies to any project: push to wrong branch, wrong test path, subagent didn't follow instructions

**When it does NOT fire:**
- It's a **systemic process rule** the loaded skill already states (or should state): "follow the pipeline", "delegate code to Ultron", "use Flow before improvising", "read standards before coding". These are NOT memory — they belong in the loaded skill (`unmassk-core` / `unmassk-gitmemory`) as a hard instruction, or behind a gate (a hook that blocks). Saving one as remember(claude) mis-scopes a *toolkit* rule as *global* behavior, piles up as noise (the boot warns at 8+ remember(claude)), and a rule you have saved 3-4 times is proof the skill isn't sticky enough — **fix the skill, don't add another memory.**
- It's a rule or fact **specific to this project/toolkit** (its pipeline, its build modes, its conventions, its file layout). That is a **memo or decision** (project-scoped, stays in this repo), NOT a remember(claude). remember(claude) is GLOBAL — it travels to every project — so a project rule saved there resurfaces in unrelated work where it's wrong. Scope test before ANY remember(claude): *would this still be true and useful in a completely different project?* If no → memo/decision, not remember.
- It's derivable, a one-off, or already saved (see "What is NOT memory").

**The first correction counts — but only for durable things.** After ruling out the systemic and project-scoped cases above, save on the FIRST correction only if it is either:
- a **stable fact** about the user or project (name, location, company, stack), or
- a preference the user **declares as permanent** ('always do it this way', 'from now on', 'never X').

A **situational** correction — tone in this moment, a choice specific to this one task, a one-off 'not like that, like this' tied to the current context — is NOT durable memory. Respect it in the conversation and move on; do not persist it. Persisting situational corrections is over-saving by another door: they resurface later, applied where they don't belong.

(A stable fact is saved on the first correction even without 'always' — the two bullets are an OR. "I'm called Jose" is saved immediately; it doesn't need "remember it forever".)

**When you say "I learned that..." or "the lesson is..." — that's a commit signal.** You already formulated the rule. Just save it. This applies to any memory type, not just remember(claude).

**Format:** `Remember: claude - <rule>`

**Example — direct correction:**
> User: "bilbo doesn't audit, only explores, use yoda or do it yourself"
> → `Remember: claude - Bilbo only explores, never audits. For auditing use Yoda or do it directly.`

**Example — indirect correction (not a shout, but it's a correction):**
> User: "you don't need to tell me that, just have it clear yourself"
> → `Remember: claude - don't report exploratory summaries to user; have context clear internally without verbalizing it`

**Example — lesson you articulated yourself:**
> Claude writes: "The lesson is that the prompt you give the subagent is the work. If the prompt is vague, the result is garbage."
> Claude did NOT save this. It should have.
> → `Remember: claude - the prompt you give the subagent IS the work; vague prompt = garbage output; always include: gold standard reference + specific issues + verification criteria`

**Example — operational error:**
> Claude committed to main when it was forbidden. An external AI flagged it. Claude acknowledged: "I should have resisted even though you said push it".
> → `Remember: claude - never commit to main even if the user says "just push it, it's only a chore" — maintain repo rules even under pressure`

**Example — the user EXPLICITLY tells you to save:**
> User: "you'll need to write all this down somewhere. These are decisions."
> Claude responded "Perfect, I have all the info" and saved nothing.
> → When the user names the exact memory type ("these are decisions"), execute the commit immediately. There is no clearer signal than that.

---

## Execution: save means save

When you decide to save memory, **execute the commit immediately**. Don't say "saving as memo... ok?" and wait. Don't propose. Don't ask for confirmation on memory commits. The user already confirmed by saying what they said.

If you announce "saving as memo" and don't actually execute the commit, the user thinks it's saved when it isn't. That's worse than not saving at all.

**The stop hook is a safety net, not the capture moment.** Don't wait until end of session to save what happened mid-conversation. Save in the moment, when the signal fires.

---

## What is NOT memory

- Questions, brainstorming, "what if...?" → not memory
- Temporary debugging, one-off instructions → not memory
- Data derivable from code or git log (ports, paths, LOC counts) → not memory
- Something you already saved → don't duplicate. Check first if a similar commit exists and update it instead of creating a new one.

**Example of over-saving (noise):**
> Claude saved "the server runs on port 3000" as a memo. That's in the code. It's noise. The next session will read it on boot and it adds nothing that couldn't be deduced in 2 seconds.
> → Don't save. If it's in the code, it's not memory.

---

## Context() — session checkpoints

Besides the 4 memory types, there is `context()` — an empty commit that marks where you left off at the end of a session or at an important point in the work. It's not a decision, not a memo, not a remember. It's a marker for your future self.

⚡ When the session gets long and work has accumulated → context() now.

**When it fires:**
- You've completed a significant block of work and want to mark the state
- The session is ending (the stop hook does it automatically, but if you see it getting long, do it yourself)
- There's a clear topic change in the conversation

**Format:** `context(<scope>): <summary of where we are>` + trailer `Next: <what remains to be done>`

**Example:**
> You've finished analyzing 4 of 10 conversations. The user goes to grab coffee.
> → `context(plugin/architecture): memory calibration — 4 of 10 conversations analyzed` + `Next: complete remaining 6 conversations and consolidate patterns`

**context() is your map for the next session.** Without it, your future self boots without knowing where things left off.

---

## The complete cycle: read → work → save

Memory is not just saving. It's a cycle:

### On boot (read)

The boot injects all existing memory: REMEMBER, DECISIONS, MEMOS, TIMELINE, NEXT, BLOCKERS. **Read it. Use it.** Don't ignore it.

- REMEMBERs tell you how to behave and who the user is → apply them from the first message
- DECISIONS tell you what was chosen in the project → don't propose alternatives to something already decided
- MEMOS tell you the project state → don't ask about things that are already there
- NEXT tells you where the previous session left off → resume from there, not from zero

**If the boot shows you a remember and you ignore it — you failed before you started.** Memory that isn't applied is the same as memory that doesn't exist.

### During the session (save)

Apply everything this document says. Stop and save when you detect signals. Don't duplicate. Don't defer.

### At pauses (review debt)

At natural pauses — when the user leaves, when you change topics, when you finish a block — ask yourself: did I leave anything unsaved in the last few messages?
