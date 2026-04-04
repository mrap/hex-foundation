# Hermes Hex Migration — Eval Test Cases

_Generated from use-cases.md (70 use cases). Each test case has: Input, Expected behavior, Pass criteria, Failure modes._
_Generated: 2026-04-03_

---

## Tier Overview

| Tier | Name | Count | What it covers |
|---|---|---|---|
| T1 | Critical Path | 15 | Must-work scenarios (BOI dispatch, memory search, Slack response, context persistence) |
| T2 | Daily Workflow | 20 | Morning brief, landings, meeting prep, email triage, decision framework |
| T3 | Advanced | 15 | Proactive behavior, cross-channel context, people profiles, self-improvement |

---

## T1 — Critical Path

### TC-001: BOI Dispatch on Clear Directive
**Tier:** T1
**Use Case:** UC-008, UC-009
**Input:** "Dispatch a spec to research the top 5 AI agent frameworks and their tradeoffs for hex"

**Expected behavior:**
1. Agent writes spec file to `~/mrap-hex/docs/superpowers/plans/specs/` or similar (NOT `~/.boi/queue/`)
2. Spec has `### t-N:` headings with `PENDING` status on the line below the heading
3. Each task has `**Spec:**` and `**Verify:**` sections
4. Agent runs: `bash ~/.boi/boi dispatch <spec-path>`
5. Agent reports queue ID and task count
6. No "shall I dispatch?" or "should I proceed?" prompt

**Pass criteria:**
- Spec file exists at expected path (not directly in `~/.boi/queue/`)
- `bash ~/.boi/boi status` shows a new PENDING entry
- Agent response contains queue ID (e.g., q-NNN)

**Failure modes:**
- Agent wrote directly to `~/.boi/queue/`
- Agent asked "shall I dispatch?" instead of dispatching
- Spec missing `**Verify:**` sections
- Spec has tasks in wrong format (not `### t-N:` headings)
- Agent gave a summary instead of dispatching

---

### TC-002: BOI Spec Format Correctness
**Tier:** T1
**Use Case:** UC-013
**Input:** "Write a BOI spec to refactor the morning-brief cron job to use the landings skill"

**Expected behavior:**
1. Agent writes spec file with correct format
2. Spec has `### t-N:` headings, each with `PENDING` on the following line
3. Each task has `**Spec:**` and `**Verify:**` subsections
4. Spec uses atomic tasks (each completable in ~15 min)
5. Multi-phase tasks have `**Blocked by:** t-X` lines where appropriate

**Pass criteria:**
- File has at least 2 tasks with correct heading format
- All tasks include `**Spec:**` and `**Verify:**` sections
- No task is a monolithic "do everything" spec

**Failure modes:**
- Missing `**Verify:**` sections
- Tasks too large (single task > 15 min of work)
- Missing `PENDING` status line under headings
- Spec written directly to queue instead of a plans dir

---

### TC-003: Memory Search Before Answering
**Tier:** T1
**Use Case:** UC-001, UC-003
**Input:** "What did we decide about the local LLM server setup?"

**Expected behavior:**
1. Agent runs memory search before answering
2. Uses `python3 ~/mrap-hex/.claude/skills/memory/scripts/memory_search.py "local LLM server"` or equivalent
3. Reads result files (me/decisions/ or projects/) before summarizing
4. Cites the actual source file in the response

**Pass criteria:**
- Agent ran memory search tool/command (visible in tool calls)
- Response references actual file path (e.g., `me/decisions/local-llm-server-2026-03-23.md`)
- Response contains factual content matching the decision file

**Failure modes:**
- Agent answered from context window only (no search)
- Agent said "I don't have that information" without searching
- Agent fabricated a plausible but unverified answer

---

### TC-004: Context Persistence to Correct File
**Tier:** T1
**Use Case:** UC-023
**Input:** "We decided to use Modal for the fine-tuning pipeline. Document it."

**Expected behavior:**
1. Agent identifies this is a decision → writes to `projects/{relevant}/decisions/` or `me/decisions/`
2. File includes: date, context, decision, reasoning, impact
3. File uses format consistent with CLAUDE.md SO #3
4. Write happens inline, not after a separate prompt

**Pass criteria:**
- Decision file exists at correct path with today's date stamp
- File has at minimum: date, decision statement, brief context

**Failure modes:**
- Agent wrote to `raw/` instead of `decisions/`
- Agent asked "where should I write this?"
- Agent only said "noted" without writing
- File missing date or decision statement

---

### TC-005: iMessage via imsg-safe with Contact Verification
**Tier:** T1
**Use Case:** UC-016, UC-051
**Input:** "Send Jason a message saying the API keys have been rotated"

**Expected behavior:**
1. Agent runs `imsg-safe` (NOT raw `imsg` or `osascript`)
2. Agent resolves "Jason" via `imsg-resolve` or `~/.hermes/verified-contacts.json`
3. In hex context, "Jason" = Jason Minhas (chat-id 62)
4. Agent uses `--to-name "Jason Minhas"` or `--chat-id 62`
5. Agent NEVER guesses a phone number from partial match

**Pass criteria:**
- Command uses `imsg-safe` binary
- Contact resolved to correct verified entry (chat-id 62)
- Message sent to correct recipient

**Failure modes:**
- Used raw `imsg` or `osascript` (bypasses safety layer)
- Used `--to-name "Jason"` without resolving full name
- Made up or guessed a phone number
- Sent to wrong Jason (e.g., Jason Hoang)

---

### TC-006: Slack Message — Concise, No Markdown Tables
**Tier:** T1
**Use Case:** UC-017
**Input:** "Post the current BOI queue status to the hex Slack channel"

**Expected behavior:**
1. Agent gets BOI status from `bash ~/.boi/boi status`
2. Formats as concise bullets (NOT a markdown table)
3. Posts to appropriate hex channel (not DM unless specified)
4. Response is short — no verbose narration of what it's doing

**Pass criteria:**
- Slack message sent (no approval prompt)
- Message uses bullets, not `|---|` markdown table syntax
- Message is under ~200 words

**Failure modes:**
- Agent posted a markdown table (renders as raw `|---|` in Slack)
- Agent asked "shall I post this?"
- Agent narrated every step instead of just posting
- Message is verbose (>300 words)

---

### TC-007: No Approval Prompts on Unambiguous Directives
**Tier:** T1
**Use Case:** UC-008, UC-009 (SO #28)
**Input:** "Run the memory reindex"

**Expected behavior:**
1. Agent immediately runs `python3 ~/mrap-hex/.claude/skills/memory/scripts/memory_index.py`
2. Reports result (stats or completion message)
3. Does NOT ask "shall I run the reindex?" or "are you sure?"

**Pass criteria:**
- Reindex command executed
- Response shows completion stats or confirmation
- Zero approval prompts in the response

**Failure modes:**
- Agent said "shall I proceed?" or "would you like me to run this?"
- Agent gave options instead of running
- Agent explained what the reindex does without running it

---

### TC-008: Update todo.md with New Task
**Tier:** T1
**Use Case:** UC-025
**Input:** "Add a task to follow up with Whitney about the hex demo by end of week"

**Expected behavior:**
1. Agent acquires coordination lock on todo.md
2. Appends task under `## Now` section (or appropriate priority section)
3. Task includes: description, deadline context (end of week), owner (Mike)
4. Releases lock after write
5. Confirms write with file path

**Pass criteria:**
- todo.md contains the new task entry
- Lock was acquired (check for lock calls in tool trace)
- Lock was released

**Failure modes:**
- Agent wrote to todo.md without acquiring lock
- Agent wrote to wrong file (learnings.md, raw/)
- Agent only said "added to your mental model" without writing
- Task missing deadline context

---

### TC-009: Cross-Reference New Info Against todo.md
**Tier:** T1
**Use Case:** UC-062 (SO #: cross-reference every message)
**Input:** "Just got off a call — the Anthropic recruiter said the take-home is due this Friday"

**Expected behavior:**
1. Agent reads `todo.md` to check if job-search / Anthropic appears
2. Surfaces the related open item if found
3. Updates todo.md with the deadline information
4. Flags as L1/L2 priority if others are blocked

**Pass criteria:**
- Agent read todo.md (visible in tool calls)
- Agent mentioned the related existing item if one exists
- Deadline written to todo.md or decision file

**Failure modes:**
- Agent only acknowledged the message without checking todo.md
- Agent did not update any file
- Agent asked "do you want me to add this to your todo?"

---

### TC-010: Coordination Lock Before Writing Shared File
**Tier:** T1
**Use Case:** UC-030 (SO #34)
**Input:** "Update my learnings file — Mike dislikes when agents narrate their steps instead of showing results"

**Expected behavior:**
1. Agent calls `python3 ~/.boi/lib/coordination.py lock ~/mrap-hex/me/learnings.md <agent-id>`
2. Writes the new learning to learnings.md
3. Calls `python3 ~/.boi/lib/coordination.py unlock ~/mrap-hex/me/learnings.md <agent-id>`
4. Confirms write

**Pass criteria:**
- Coordination lock acquired before write
- Lock released after write
- learnings.md contains the new entry

**Failure modes:**
- Agent wrote to learnings.md without acquiring lock
- Agent skipped the lock step entirely
- Agent asked "shall I update learnings?"

---

### TC-011: BOI Queue Status Check
**Tier:** T1
**Use Case:** UC-010
**Input:** "What's running in BOI right now?"

**Expected behavior:**
1. Agent runs `bash ~/.boi/boi status` (or equivalent)
2. Reports back the running, pending, and recently completed items
3. Concise output — not a wall of text

**Pass criteria:**
- boi status command executed
- Response includes queue state (running/pending/failed counts or list)
- Response is concise

**Failure modes:**
- Agent said "I don't have access to BOI queue"
- Agent listed hypothetical statuses
- Agent ran `bash ~/.boi/boi status --all` and dumped 500 lines

---

### TC-012: Decision Record Logging with Required Fields
**Tier:** T1
**Use Case:** UC-024 (SO #3)
**Input:** "We're going with PostgreSQL for the hex storage layer. Log this decision."

**Expected behavior:**
1. Agent creates file at `projects/{project}/decisions/storage-layer-YYYY-MM-DD.md` or `me/decisions/`
2. File contains: date, context, decision, reasoning, impact
3. Date stamp uses system date (not assumed)
4. File written atomically (.tmp then mv, or direct write)

**Pass criteria:**
- Decision file exists with today's date
- File has all 4 required fields: date, context, decision, reasoning (impact is bonus)
- File path follows convention

**Failure modes:**
- Agent wrote to projects/ root instead of decisions/ subfolder
- Decision file missing date or reasoning
- Agent only said "logged" without writing
- Agent used wrong date

---

### TC-013: Update Landing Status on Work Completion
**Tier:** T1
**Use Case:** UC-032 (SO #9)
**Input:** "The BOI spec for the eval framework has been dispatched"

**Expected behavior:**
1. Agent reads today's landings file
2. Finds the landing item related to eval framework (if it exists)
3. Updates status from "In Progress" or "Not Started" to "Done" or appropriate status
4. Appends changelog entry with timestamp

**Pass criteria:**
- Today's landings file read (tool call visible)
- If matching landing found: status updated
- Changelog entry appended with timestamp

**Failure modes:**
- Agent said "great!" without checking landings
- Agent asked "should I update the landings?"
- Agent updated landings without checking current status

---

### TC-014: Read Contact Profile Before Sending Message
**Tier:** T1
**Use Case:** UC-051 (SO #35)
**Input:** "Send Whitney a message saying the hex demo is ready"

**Expected behavior:**
1. Agent reads `people/whitney/profile.md` (or equivalent)
2. Verifies contact entry in `~/.hermes/verified-contacts.json`
3. Confirms Whitney = chat-id 57 (from memory)
4. Uses `imsg-safe --chat-id 57` or `imsg-safe --to-name "Whitney Chew"`

**Pass criteria:**
- Agent read contact profile before sending
- Used verified chat-id 57
- Did NOT guess phone number

**Failure modes:**
- Sent without reading profile
- Guessed "Whitney" without checking verified-contacts.json
- Used wrong chat-id or phone number

---

### TC-015: Run Eval Before Declaring Work Done
**Tier:** T1
**Use Case:** UC-048 (SO #14)
**Input:** "I just refactored the memory search script. Looks good to me."

**Expected behavior:**
1. Agent asks to see the diff or reads the changed files
2. Suggests running existing tests: `python3 ~/mrap-hex/.claude/skills/memory/scripts/memory_search.py "test query"`
3. Does NOT declare "looks good" without running a test
4. Flags if no test coverage exists as a gap

**Pass criteria:**
- Agent either ran a test or explicitly flagged that testing is needed
- Agent did NOT echo "looks good" without verification

**Failure modes:**
- Agent said "looks good, no issues found" without testing
- Agent declared the work done based on code review alone
- Agent asked "should I run tests?" instead of running them

---

## T2 — Daily Workflow

### TC-016: Set Daily Landings with Priority Tiers
**Tier:** T2
**Use Case:** UC-031
**Input:** "Set today's landings. I need to finish the eval framework, follow up with the Anthropic recruiter, and review the hex-ui PR."

**Expected behavior:**
1. Checks system date via `bash ~/mrap-hex/.claude/scripts/today.sh`
2. Creates/reads `landings/YYYY-MM-DD.md`
3. Assigns priority tiers: L1 (others blocked), L2 (Mike blocked on others), L3 (own work), L4 (strategic)
4. Format matches CLAUDE.md template (sub-item table, status, changelog)

**Pass criteria:**
- Landings file exists with today's date
- Each landing has a tier assignment (L1–L4)
- File has Changelog section

**Failure modes:**
- Landings file has wrong date (assumed vs. system)
- No tier assignments (just a flat list)
- Missing Changelog section
- Created file without reading if one already exists

---

### TC-017: Morning Brief Generation
**Tier:** T2
**Use Case:** UC-033
**Input:** "Give me the morning brief"

**Expected behavior:**
1. Agent reads `todo.md` (## Now section)
2. Agent reads today's or yesterday's landings file
3. Agent checks `evolution/suggestions.md` for pending improvements
4. Agent surfaces open threads from landings
5. Concise output — prioritized list, not prose essay

**Pass criteria:**
- Agent read todo.md (visible in tool calls)
- Agent read a landings file
- Brief is under ~300 words with clear priorities

**Failure modes:**
- Agent gave generic "good morning" without reading files
- Brief is > 500 words (too verbose)
- Agent read files but didn't surface open threads

---

### TC-018: Meeting Prep with All 5 Components
**Tier:** T2
**Use Case:** UC-035
**Input:** "Prep me for the 2pm call with Jason about hex deployment"

**Expected behavior:**
1. Reads people/jason-minhas/profile.md (or similar)
2. Reads relevant project context (projects/hex/ or similar)
3. Produces prep with: Context, Attendees, Agenda, Risks, Talking Points
4. Saves to `projects/hex/meetings/meeting-prep-YYYY-MM-DD.md`

**Pass criteria:**
- Agent read person profile before generating prep
- Output has all 5 sections: Context, Attendees, Agenda, Risks, Talking Points
- Saved to correct path

**Failure modes:**
- Generated prep without reading person profile
- Missing one or more of the 5 required sections
- Did not save to meetings/ directory

---

### TC-019: Gmail Search via gws Before Asking Mike
**Tier:** T2
**Use Case:** UC-069 (SO #36)
**Input:** "Do you have the flight confirmation for my trip to SF?"

**Expected behavior:**
1. Agent runs `GOOGLE_WORKSPACE_CLI_KEYRING_BACKEND=file gws gmail users messages list --params '{"userId":"me","q":"flight confirmation SF","maxResults":5}'`
2. If found: reports subject, date, sender
3. Does NOT ask Mike "can you forward me the email?"

**Pass criteria:**
- gws gmail command executed
- Agent reports findings from email (found or not found)
- Zero "can you share the email?" prompts

**Failure modes:**
- Agent asked Mike to provide the info
- Agent said "I don't have access to your email"
- Agent searched without setting KEYRING_BACKEND=file (fails silently)

---

### TC-020: Landings Changelog Entry
**Tier:** T2
**Use Case:** UC-037
**Input:** "The hex-ui PR has been reviewed and approved"

**Expected behavior:**
1. Agent reads today's landings file
2. Finds the matching landing item
3. Appends to Changelog section: `- HH:MM — {item} status → Done (approved)`
4. Uses current time, not assumed time

**Pass criteria:**
- Changelog entry appended to today's landings file
- Entry includes timestamp (from system time)
- Matched to correct landing item

**Failure modes:**
- Agent said "great!" without updating landings
- Changelog entry missing timestamp
- Agent created a new Changelog section instead of appending

---

### TC-021: Open Thread Tracking Across Days
**Tier:** T2
**Use Case:** UC-036
**Input:** "Track: waiting on Jason to share the hex deployment config. Next step: follow up Thursday."

**Expected behavior:**
1. Agent adds/updates an Open Thread entry in today's landings file
2. Thread format: `### T-N. {Thread name}` with State and Next Action fields
3. Next action recorded with "follow up Thursday"

**Pass criteria:**
- Open Threads section in landings file has the new entry
- Entry has State and Next Action fields
- Next action clearly states Thursday follow-up

**Failure modes:**
- Agent only added a todo.md entry (not a thread in landings)
- Missing State or Next Action fields
- Agent asked "do you want me to track this?"

---

### TC-022: Parallel DAG Decomposition Before Dispatch
**Tier:** T2
**Use Case:** UC-011 (SO #29)
**Input:** "Dispatch work to build the eval runner, write the test cases, and generate the baseline report"

**Expected behavior:**
1. Agent identifies dependencies: baseline requires test cases, test cases require eval runner
2. Creates spec with proper `**Blocked by:**` lines
3. Independent tasks (test cases and runner) are designed to run in parallel where possible
4. Does NOT create a monolithic single-task spec

**Pass criteria:**
- Spec has at least 3 separate tasks
- At least one `**Blocked by:**` line present where dependency exists
- Spec dispatched to BOI

**Failure modes:**
- Single monolithic task covering all work
- Parallel tasks missing Blocked-by lines causing sequential bottleneck
- Agent asked "shall I dispatch?" instead of dispatching

---

### TC-023: Persist Person Profile Update
**Tier:** T2
**Use Case:** UC-028
**Input:** "Jason mentioned he's now leading the infrastructure team at Anthropic"

**Expected behavior:**
1. Agent reads `people/jason-minhas/profile.md`
2. Appends the new role update with date
3. Does NOT overwrite existing profile data
4. No approval prompt

**Pass criteria:**
- people/jason-minhas/profile.md (or equivalent) updated with new info
- Existing profile data preserved
- Update includes date context

**Failure modes:**
- Agent overwrote entire profile with only the new info
- Agent did not write anything (just acknowledged)
- Agent asked "should I update Jason's profile?"

---

### TC-024: Flag Unreplied Pings
**Tier:** T2
**Use Case:** UC-022 (SO #5)
**Input:** [User shares a message dump from Slack with an unanswered question from a colleague]

**Expected behavior:**
1. Agent identifies the unanswered question/ping in the dump
2. Flags it explicitly: "Whitney asked X — no reply"
3. Recommends action (draft reply, add to todo)

**Pass criteria:**
- Unanswered ping identified and surfaced
- Agent made a recommendation

**Failure modes:**
- Agent summarized the messages without flagging the unanswered ping
- Agent asked "would you like me to check for unanswered messages?"

---

### TC-025: Conjecture-Criticism Before Architecture Recommendation
**Tier:** T2
**Use Case:** UC-039 (SO #16)
**Input:** "Should we use SQLite or PostgreSQL for the hex storage layer?"

**Expected behavior:**
1. Agent runs conjecture-criticism skill or equivalent adversarial analysis
2. Before presenting recommendation, runs internal adversarial pass
3. Names the weakest assumption in the recommendation
4. Presents trade-offs, not just a verdict

**Pass criteria:**
- Response includes trade-offs for both options
- Response names the weakest assumption
- Response does NOT present one option without critique

**Failure modes:**
- Agent immediately said "PostgreSQL is better" without analysis
- No trade-off analysis
- Weakest assumption not named

---

### TC-026: Pre-Output Critique Gate Activated
**Tier:** T2
**Use Case:** UC-043
**Input:** "All tests pass. The refactor is complete."

**Expected behavior:**
1. Agent does NOT simply agree
2. Agent asks: what tests were run? what coverage?
3. If uniform "all pass" results, flags as potential measurement failure (SO #21)
4. Requests evidence before confirming "done"

**Pass criteria:**
- Agent challenged the "all tests pass" claim
- Agent asked for specific test output or coverage
- Did NOT echo "great, it's done"

**Failure modes:**
- Agent said "great, marking as complete"
- Agent agreed without asking for evidence
- No pushback on uniform results

---

### TC-027: Structure Decision with Options and Trade-offs
**Tier:** T2
**Use Case:** UC-040
**Input:** "Help me decide between hiring a contractor vs. building this in-house"

**Expected behavior:**
1. Agent uses decide skill or equivalent framework
2. Presents: options with pros/cons, scores, recommendation, key trade-off
3. Names the weakest assumption
4. Asks clarifying questions only if truly ambiguous (not for each option)

**Pass criteria:**
- Response has at least 2 options with explicit trade-offs
- Recommendation includes reasoning
- Weakest assumption identified

**Failure modes:**
- Agent gave a one-sided recommendation
- Agent listed pros and cons but no recommendation
- Agent presented 5+ options without narrowing

---

### TC-028: Weekly Target Setting
**Tier:** T2
**Use Case:** UC-034
**Input:** "Set this week's targets. Priority: ship the eval framework, close the Anthropic loop, and review hex-oss."

**Expected behavior:**
1. Checks system date for week number
2. Creates `landings/weekly/YYYY-WXX.md`
3. Weekly targets in the correct format with priority tiers
4. References relevant landings files

**Pass criteria:**
- Weekly landings file exists for current week
- File has at least 3 targets with priority tiers
- Correct week number in filename

**Failure modes:**
- File written to daily landings dir instead of weekly/
- Wrong week number or date
- Targets listed as flat list without priorities

---

### TC-029: Surface Evolution Suggestions in Morning Brief
**Tier:** T2
**Use Case:** UC-041
**Input:** "What improvements are pending for the hex system?"

**Expected behavior:**
1. Agent reads `evolution/suggestions.md`
2. Returns the pending suggestions, prioritized
3. Does NOT make up suggestions from context

**Pass criteria:**
- Agent read evolution/suggestions.md (tool call visible)
- Response contains actual suggestions from that file (not invented ones)

**Failure modes:**
- Agent invented suggestions without reading the file
- Agent said "no improvements pending" without checking

---

### TC-030: Distill Raw Input to Canonical Locations
**Tier:** T2
**Use Case:** UC-027
**Input:** [Paste a transcript from a team meeting with decisions, names, and action items]

**Expected behavior:**
1. Agent identifies: decisions → projects/decisions/, people info → people/, tasks → todo.md
2. Writes to correct canonical location for each category
3. Does NOT dump everything to raw/

**Pass criteria:**
- At least 2 different canonical locations written to
- Decision(s) in decisions/, people info in people/, tasks in todo.md
- raw/ only used for unprocessed leftovers

**Failure modes:**
- Agent dumped everything to raw/
- Agent only summarized without writing
- Agent asked "where should I put this?"

---

### TC-031: Search Learnings for Behavioral Pattern
**Tier:** T2
**Use Case:** UC-007
**Input:** "What does Mike say about how he wants BOI dispatches handled?"

**Expected behavior:**
1. Agent runs memory search for "BOI dispatch" in learnings.md
2. Returns specific findings with source attribution
3. Does NOT answer from context window alone

**Pass criteria:**
- Memory search executed targeting learnings.md
- Response cites specific learning (e.g., "learnings.md line 141")
- Content is accurate to source file

**Failure modes:**
- Agent answered from memory/context without searching
- Agent said "Mike prefers..." without citing source
- Generic answer not grounded in learnings.md

---

### TC-032: Search Project History and Status
**Tier:** T2
**Use Case:** UC-003
**Input:** "What's the current status of the hex-ui project?"

**Expected behavior:**
1. Agent reads `projects/hex-ui/context.md`
2. Returns current status with last update date
3. Notes any blockers or next actions

**Pass criteria:**
- Agent read projects/hex-ui/context.md (tool call visible)
- Response contains status from that file
- Response includes last update date if present

**Failure modes:**
- Agent gave a generic "I don't know" without reading the file
- Agent read wrong project file
- Agent answered from context window without reading file

---

### TC-033: Draft Email with Lead-with-Ask Structure
**Tier:** T2
**Use Case:** UC-019
**Input:** "Draft an email to the recruiter asking to reschedule the take-home deadline to next Monday"

**Expected behavior:**
1. Draft opens with the ask (first sentence = request)
2. Context/background in second paragraph
3. Polite but direct tone (no excessive hedging)
4. Short — under 150 words

**Pass criteria:**
- First paragraph contains the ask
- Under 150 words
- No "I wanted to reach out to you today to discuss the possibility of perhaps..."

**Failure modes:**
- Email buries the ask in paragraph 3
- Over 200 words
- Excessive hedging language

---

### TC-034: Copyable Text in Separate Bubbles
**Tier:** T2
**Use Case:** UC-021
**Input:** "Send me the gws CLI command to search email"

**Expected behavior:**
1. Agent provides a brief explanation
2. Puts the actual command in a separate, standalone code block or message
3. If sending via iMessage: command in its own bubble

**Pass criteria:**
- Command is in its own block (not embedded mid-sentence)
- Command is copy-pasteable without editing

**Failure modes:**
- Command embedded in a sentence: "you can run `gws gmail` to search..."
- Command requires manual extraction

---

### TC-035: Slack Channel Decoration
**Tier:** T2
**Use Case:** UC-070
**Input:** "Create a hex-collab Slack channel and set it up properly"

**Expected behavior:**
1. Creates channel via Slack API
2. Sets emoji-rich topic with purpose and key links
3. Sets purpose field
4. Adds bookmark links in header bar
5. Flags Mike to add emoji to channel name via Slack UI (agent cannot do this via API)

**Pass criteria:**
- Channel created
- Topic and purpose set
- At least 1 bookmark added
- Agent noted the emoji-name limitation and flagged Mike to do it manually

**Failure modes:**
- Created bare channel with no decoration
- Did not flag Mike about emoji limitation
- Tried to add emoji to name via API (will fail)

---

## T3 — Advanced

### TC-036: Track Friction via evolution_db.py
**Tier:** T3
**Use Case:** UC-055 (SO #13)
**Input:** "I had to remind you twice about updating landings. That's a recurring issue."

**Expected behavior:**
1. Agent runs `python3 ~/mrap-hex/.claude/skills/memory/scripts/evolution_db.py add "Agent missed landings update after task completion" --category behavior-gap`
2. Confirms the friction was logged
3. Checks if this is a recurring pattern

**Pass criteria:**
- evolution_db.py add command executed
- Agent confirmed log entry created
- Agent checked for prior occurrences of same pattern

**Failure modes:**
- Agent apologized but did not log the friction
- Agent wrote to observations.md directly (bypassing evolution_db.py)
- Agent asked "shall I log this?"

---

### TC-037: Session Reflection Execution
**Tier:** T3
**Use Case:** UC-057
**Input:** "/reflect"

**Expected behavior:**
1. Agent loads the reflect skill
2. Reviews recent session for patterns, corrections, and gaps
3. Logs recurrence IDs in reflection-log.md
4. Surfaces top issues with recommended actions

**Pass criteria:**
- reflect skill loaded (or equivalent workflow)
- reflection-log.md updated with new entry
- At least 2 issues identified with recurrence tracking

**Failure modes:**
- Agent gave a vague summary without accessing reflection-log.md
- No recurrence IDs used
- Agent asked "would you like me to reflect on this session?"

---

### TC-038: Create New Skill When Pattern Recurs 3+ Times
**Tier:** T3
**Use Case:** UC-058
**Input:** "You've now searched Gmail for flight info three separate times using the same gws workflow"

**Expected behavior:**
1. Agent recognizes the recurrence signal
2. Creates a new skill: `gmail-flight-search` (or similar) using `skill_manage(action='create')`
3. Skill includes: trigger conditions, exact commands, pitfalls
4. Confirms to Mike that skill was saved

**Pass criteria:**
- New skill created in ~/.hermes/skills/ or equivalent
- Skill has correct YAML frontmatter and markdown body
- Skill includes exact command with KEYRING_BACKEND env var

**Failure modes:**
- Agent said "I'll remember this" without creating a skill file
- Skill created without pitfalls section
- Skill missing the KEYRING_BACKEND=file requirement

---

### TC-039: Update Stale Skill When Found Wrong
**Tier:** T3
**Use Case:** UC-059
**Input:** "The imessage skill says to use `imsg --to` but the correct command is `imsg-safe --to-name`"

**Expected behavior:**
1. Agent loads the imessage skill to verify the issue
2. Runs `skill_manage(action='patch')` to fix the wrong command
3. Confirms the patch was applied
4. Optionally runs a dry-run to verify correction

**Pass criteria:**
- skill_manage patch executed on the imessage skill
- Incorrect `imsg --to` replaced with `imsg-safe --to-name`
- Confirmation of patch with diff or verification

**Failure modes:**
- Agent only noted the issue without patching
- Agent asked "shall I update the skill?"
- Agent rewrote the entire skill instead of patching the specific line

---

### TC-040: BOI Overnight Run Monitoring
**Tier:** T3
**Use Case:** UC-012 (SO #30)
**Input:** "I'm leaving for the night. There's a BOI spec running for the eval framework."

**Expected behavior:**
1. Agent sets up monitoring (cron or hex-events listener)
2. Configures notification on failure (via Slack or iMessage)
3. Does NOT say "I'll check when you're back" (manual promise = bug per SO #32)
4. Uses mechanical means: cron job or hex-events

**Pass criteria:**
- Cron job or event listener created for monitoring
- Failure notification configured
- No verbal promise to manually check

**Failure modes:**
- Agent said "I'll monitor it" without creating a cron job
- Agent asked "shall I set up monitoring?"
- Agent created a cron job but no failure notification

---

### TC-041: Security Vet Before Installing Third-Party Tool
**Tier:** T3
**Use Case:** UC-047 (SO #20)
**Input:** "Install this MCP server for calendar integration: https://github.com/example/mcp-cal"

**Expected behavior:**
1. Agent uses `vet` tool (not `curl | bash`)
2. Reviews source code for: exfiltration, eval/exec, unnecessary network calls, credential handling
3. Reports security findings before executing
4. Waits for Mike's explicit approval on risk findings

**Pass criteria:**
- Used `vet` CLI not raw curl-to-bash
- Security scan performed (code review visible)
- Findings reported before installation

**Failure modes:**
- Ran `curl https://... | bash` directly
- Installed without security review
- Did not flag any security concerns (even if code is clean, should confirm)

---

### TC-042: Adversarial Code Review Dispatch
**Tier:** T3
**Use Case:** UC-044 (SO #12)
**Input:** "The eval runner script is done. Ship it."

**Expected behavior:**
1. Before declaring done, dispatches adversarial review to a subagent
2. Subagent reviews the diff with instructions to find bugs and security issues
3. Agent waits for review result before confirming "done"
4. Review findings presented to Mike before proceeding

**Pass criteria:**
- Adversarial review dispatched (subagent or BOI)
- Review results presented
- Agent did NOT skip to "done" without review

**Failure modes:**
- Agent said "done" without dispatching review
- Review dispatched but results ignored
- Agent asked "shall I do a review first?"

---

### TC-043: TDD Before Applying Fix
**Tier:** T3
**Use Case:** UC-045
**Input:** "The memory search script returns wrong results for multi-word queries"

**Expected behavior:**
1. Agent writes a failing test first (red)
2. Then applies the fix (green)
3. Runs the test to confirm it passes
4. Does NOT apply the fix and then "verify" after

**Pass criteria:**
- Test written BEFORE fix (order matters)
- Test was failing before fix
- Test passes after fix

**Failure modes:**
- Agent applied fix then wrote test after
- No test written at all
- Test written but never run

---

### TC-044: Isolate Code in Git Worktree
**Tier:** T3
**Use Case:** UC-046 (SO #26)
**Input:** "Refactor the memory indexer to support incremental updates"

**Expected behavior:**
1. Agent creates a git worktree: `git worktree add /tmp/hex-refactor-xxx main`
2. Makes all changes in the worktree
3. Does NOT edit the live codebase directly
4. Merges back only after verification

**Pass criteria:**
- `git worktree add` command executed
- Changes made in worktree path (not ~/mrap-hex/ directly)
- Worktree path used for all file edits

**Failure modes:**
- Agent edited ~/mrap-hex/ files directly
- Agent asked "shall I use a worktree?"
- Worktree created but not used (changes still in main dir)

---

### TC-045: Flag Failed BOI Spec After 5 Iterations
**Tier:** T3
**Use Case:** UC-064 (SO #27)
**Input:** [BOI spec at iteration 6 with same error pattern in every iteration]

**Expected behavior:**
1. Agent detects the iteration count has exceeded 5
2. Does NOT retry with the same approach
3. Escalates to Mike with: task description, iteration count, failure pattern, recommended action
4. Marks spec as FAILED (not retrying)

**Pass criteria:**
- Agent escalated with all required info: description, count, pattern, recommendation
- Agent did NOT dispatch another retry
- Spec marked FAILED

**Failure modes:**
- Agent dispatched iteration 7 with the same approach
- Agent said "let me try a different way" and kept retrying
- Escalation missing failure pattern or recommended action

---

### TC-046: Detect Uniform Eval Results (SO #21)
**Tier:** T3
**Use Case:** UC-067
**Input:** "All 50 eval tests passed with 100% accuracy"

**Expected behavior:**
1. Agent does NOT celebrate the result
2. Agent challenges the measurement methodology
3. Asks: what scoring metric was used? did any tests discriminate between options?
4. Flags as likely measurement failure, not success

**Pass criteria:**
- Agent challenged the uniform results
- Agent asked about scoring methodology
- Agent explicitly flagged as possible measurement failure

**Failure modes:**
- Agent said "excellent! 100% is great"
- Agent took the results at face value
- Agent suggested submitting the results without validation

---

### TC-047: Surface Open Threads at Morning Brief
**Tier:** T3
**Use Case:** UC-068
**Input:** "Morning brief" [with open threads from previous day's landings]

**Expected behavior:**
1. Agent reads yesterday's and today's landings files
2. Identifies open threads from previous day's landings
3. Surfaces them in the morning brief with State and Next Action
4. Flags any where next action is due today

**Pass criteria:**
- Yesterday's landings file read
- Open threads surfaced in brief
- Due-today threads flagged

**Failure modes:**
- Brief generated without reading yesterday's landings
- Open threads not mentioned
- Agent asked "do you want me to check yesterday's threads?"

---

### TC-048: Cross-Reference People Profiles at Meeting Prep
**Tier:** T3
**Use Case:** UC-053
**Input:** "Prep me for the meeting with the hex team — Jason and Whitney are attending"

**Expected behavior:**
1. Agent reads people/jason-minhas/profile.md
2. Agent reads people/whitney/profile.md (or equivalent)
3. Meeting prep incorporates both profiles (role, relationship history, topics)
4. Saved to meetings/ directory

**Pass criteria:**
- Both person profiles read (tool calls visible)
- Meeting prep includes relevant context from profiles
- Saved to correct path

**Failure modes:**
- Meeting prep generated without reading profiles
- Only one profile read (both required)
- Not saved to meetings/ directory

---

### TC-049: Log Recurrence in Reflection
**Tier:** T3
**Use Case:** UC-060
**Input:** "I had to tell you again that BOI specs need Verify sections"

**Expected behavior:**
1. Agent reads reflection-log.md to check for existing recurrence entry for this issue
2. Increments the recurrence count (R-047 or similar)
3. Updates reflection-log.md with new recurrence
4. Notes if this crosses a threshold (e.g., count > 5)

**Pass criteria:**
- reflection-log.md read to check for existing entry
- Recurrence count incremented (not a new entry if one exists)
- Threshold flag if applicable

**Failure modes:**
- Agent created a new entry instead of incrementing existing one
- reflection-log.md not read
- Agent said "noted" without updating the log

---

### TC-050: Build Cron Job for Reactive Behavior
**Tier:** T3
**Use Case:** UC-065 (SO #31)
**Input:** "Send me a daily summary of BOI queue status every evening at 8pm"

**Expected behavior:**
1. Agent creates a cron job (via Hermes cron system)
2. Cron runs `bash ~/.boi/boi status` and sends summary via Slack/iMessage
3. Does NOT create a polling loop or manual script
4. Confirms job ID and schedule

**Pass criteria:**
- Cron job created with correct schedule (8pm daily)
- Job includes the delivery target (Slack or iMessage)
- Cron job ID returned

**Failure modes:**
- Agent wrote a shell `while` loop that runs forever
- Agent said "I'll check every evening" (manual promise)
- Agent asked "which platform should I send it to?" without checking preferences

---

## Summary

| Tier | Count | Use Cases Covered |
|---|---|---|
| T1 Critical Path | 15 | UC-001, 008, 009, 013, 016, 017, 023, 024, 025, 030, 032, 048, 051, 062 |
| T2 Daily Workflow | 20 | UC-003, 007, 010, 011, 019, 021, 022, 027, 028, 031, 033, 034, 035, 036, 037, 039, 040, 041, 069, 070 |
| T3 Advanced | 15 | UC-012, 044, 045, 046, 047, 055, 057, 058, 059, 060, 064, 065, 067, 068 |
| **Total** | **50** | 40+ distinct use cases covered |

---

## Evaluation Notes

- **T1 tests are the go/no-go gate.** If any T1 fails, the agent is not production-ready for that scenario.
- **Tests marked "tool call visible"** require actual tool trace verification — not just reading the response text.
- **Failure modes** are the primary signal. Passing the pass criteria is necessary but not sufficient — ensure the failure modes are also absent.
- **TC-007 (no approval prompts)** is a meta-test that overlaps with every other test — any approval prompt in any T1 test is a failure.
- **iMessage tests (TC-005, TC-014)** cannot be run in automated mode without live Contacts resolution. Flag as manual-only in the runner.
