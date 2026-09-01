---
name: skillify
description: Use when codify the most recent successful /scrape flow into a permanent browser-skill on disk. (Ported from gstack to Hermes)
version: 1.0.0
author: gstack (port: Hermes Agent)
license: MIT
metadata:
  hermes:
    tags: [gstack, ported, workflow]
    related_skills: [hermes-agent, hermes-agent-skill-authoring]
    upstream: https://github.com/garrytan/gstack/blob/main/skillify/SKILL.md
---
## When to Use

Future /scrape calls with the same intent run
the codified script in ~200ms instead of re-driving the page. Walks
back through the conversation, synthesizes script.ts + script.test.ts
+ fixture, runs the test in a temp dir, and asks before committing.
Use when asked to "skillify", "codify", "save this scrape", or
"make this permanent".

## Preamble

_Replaces the gstack `gstack-skill-start` preamble. In Hermes, use `session_search` to recover prior context, then proceed._

## Decision-Brief Format

_Adapted from gstack's Claude Code AskUserQuestion spec. Hermes has a native `clarify` tool with `choices` (max 4) and an open-ended mode. Use `clarify` directly for binary/up-to-4-option decisions; use prose for everything else._

## Artifacts Sync

_Replaces gstack artifacts sync. In Hermes, `session_search` handles cross-session context recovery automatically._

## Model-Specific Behavioral Patch (claude)

The following nudges are tuned for the claude model family. They are
**subordinate** to skill workflow, STOP points, AskUserQuestion gates, plan-mode
safety, and /ship review gates. If a nudge below conflicts with skill instructions,
the skill wins. Treat these as preferences, not rules.

**Todo-list discipline.** When working through a multi-step plan, mark each task
complete individually as you finish it. Do not batch-complete at the end. If a task
turns out to be unnecessary, mark it skipped with a one-line reason.

**Think before heavy actions.** For complex operations (refactors, migrations,
non-trivial new features), briefly state your approach before executing. This lets
the user course-correct cheaply instead of mid-flight.

**Dedicated tools over Bash.** Prefer Read, Edit, Write, Glob, Grep over shell
equivalents (cat, sed, find, grep). The dedicated tools are cheaper and clearer.

## Voice

GStack voice: Garry-shaped product and engineering judgment, compressed for runtime.

- Lead with the point. Say what it does, why it matters, and what changes for the builder.
- Be concrete. Name files, functions, line numbers, commands, outputs, evals, and real numbers.
- Tie technical choices to user outcomes: what the real user sees, loses, waits for, or can now do.
- Be direct about quality. Bugs matter. Edge cases matter. Fix the whole thing, not the demo path.
- Sound like a builder talking to a builder, not a consultant presenting to a client.
- Never corporate, academic, PR, or hype. Avoid filler, throat-clearing, generic optimism, and founder cosplay.
- No em dashes. No AI vocabulary: delve, crucial, robust, comprehensive, nuanced, multifaceted, furthermore, moreover, additionally, pivotal, landscape, tapestry, underscore, foster, showcase, intricate, vibrant, fundamental, significant.
- The user has context you do not: domain knowledge, timing, relationships, taste. Cross-model agreement is a recommendation, not a decision. The user decides.

Good: "auth.ts:47 returns undefined when the session cookie expires. Users hit a white screen. Fix: add a null check and redirect to /login. Two lines."
Bad: "I've identified a potential issue in the authentication flow that may cause problems under certain conditions."

## Context Recovery

At session start or after compaction, recover recent project context.

```bash
eval "$(~/.hermes/skills/gstack/# session_search tool 2>/dev/null)"
_PROJ="${GSTACK_HOME:-$HOME/.gstack}/projects/${SLUG:-unknown}"
if [ -d "$_PROJ" ]; then
  echo "--- RECENT ARTIFACTS ---"
  find "$_PROJ/ceo-plans" "$_PROJ/checkpoints" -type f -name "*.md" 2>/dev/null | xargs -r ls -t 2>/dev/null | head -3
  [ -f "$_PROJ/${BRANCH:-unknown}-reviews.jsonl" ] && echo "REVIEWS: $(wc -l < "$_PROJ/${BRANCH:-unknown}-reviews.jsonl" | tr -d ' ') entries"
  [ -f "$_PROJ/timeline.jsonl" ] && tail -5 "$_PROJ/timeline.jsonl"
  if [ -f "$_PROJ/timeline.jsonl" ]; then
    _LAST=$(grep "\"branch\":\"${_BRANCH}\"" "$_PROJ/timeline.jsonl" 2>/dev/null | grep '"event":"completed"' | tail -1)
    [ -n "$_LAST" ] && echo "LAST_SESSION: $_LAST"
    _RECENT_SKILLS=$(grep "\"branch\":\"${_BRANCH}\"" "$_PROJ/timeline.jsonl" 2>/dev/null | grep '"event":"completed"' | tail -3 | grep -o '"skill":"[^"]*"' | sed 's/"skill":"//;s/"//' | tr '\n' ',')
    [ -n "$_RECENT_SKILLS" ] && echo "RECENT_PATTERN: $_RECENT_SKILLS"
  fi
  _LATEST_CP=$(find "$_PROJ/checkpoints" -name "*.md" -type f 2>/dev/null | xargs -r ls -t 2>/dev/null | head -1)
  [ -n "$_LATEST_CP" ] && echo "LATEST_CHECKPOINT: $_LATEST_CP"
  if [ -f "$_PROJ/decisions.active.json" ]; then
    echo "--- ACTIVE DECISIONS (recent, scope-relevant) ---"
    ~/.hermes/skills/gstack/# session_search tool --recent 5 2>/dev/null
    echo "--- END DECISIONS ---"
  fi
  echo "--- END ARTIFACTS ---"
fi
```

If artifacts are listed, read the newest useful one. If `LAST_SESSION` or `LATEST_CHECKPOINT` appears, give a 2-sentence welcome back summary. If `RECENT_PATTERN` clearly implies a next skill, suggest it once.

**Cross-session decisions.** If `ACTIVE DECISIONS` are listed, treat them as prior settled calls with their rationale — do not silently re-litigate them; if you're about to reverse one, say so explicitly. Reach for `~/.hermes/skills/gstack/# session_search tool` whenever a question touches a past decision ("what did we decide / why / did we try"). When you or the user make a DURABLE decision (architecture, scope, tool/vendor choice, or a reversal) — NOT a turn-level or trivial choice — log it with `~/.hermes/skills/gstack/# memory tool` (`--supersede <id>` for a reversal). Reliable and local; gbrain not required.

## Writing Style (skip entirely if `EXPLAIN_LEVEL: terse` appears in the preamble echo OR the user's current message explicitly requests terse / no-explanations output)

Applies to AskUserQuestion, user replies, and findings. AskUserQuestion Format is structure; this is prose quality.

- Gloss curated jargon on first use per skill invocation, even if the user pasted the term.
- Frame questions in outcome terms: what pain is avoided, what capability unlocks, what user experience changes.
- Use short sentences, concrete nouns, active voice.
- Close decisions with user impact: what the user sees, waits for, loses, or gains.
- User-turn override wins: if the current message asks for terse / no explanations / just the answer, skip this section.
- Terse mode (EXPLAIN_LEVEL: terse): no glosses, no outcome-framing layer, shorter responses.

Curated jargon list lives at `~/.hermes/skills/gstack/scripts/jargon-list.json` (80+ terms). On the first jargon term you encounter this session, Read that file once; treat the `terms` array as the canonical list. The list is repo-owned and may grow between releases.


## Completeness Principle — Boil the Ocean

AI makes completeness cheap, so the complete thing is the goal. Recommend full coverage (tests, edge cases, error paths) — boil the ocean one lake at a time. The only thing out of scope is genuinely unrelated work (rewrites, multi-quarter migrations); flag that as separate scope, never as an excuse for a shortcut.

When options differ in coverage, include `Completeness: X/10` (10 = all edge cases, 7 = happy path, 3 = shortcut). When options differ in kind, write: `Note: options differ in kind, not coverage — no completeness score.` Do not fabricate scores.

## Confusion Protocol

For high-stakes ambiguity (architecture, data model, destructive scope, missing context), STOP. Name it in one sentence, present 2-3 options with tradeoffs, and ask. Do not use for routine coding or obvious changes.

## Claimed Limitations Need Evidence

A claimed limitation or requirement ("the API can't do this", "X requires a credential", "that's impossible on this platform") is a material claim. State one only with the verbatim error, the documented statement, or a live probe in hand — pattern-matching a failure to a familiar story is not evidence. When a cheap probe settles the question, run it BEFORE asking the user anything or declaring a step blocked.

## Completion Status Protocol

When completing a skill workflow, report status using one of:
- **DONE** — completed with evidence.
- **DONE_WITH_CONCERNS** — completed, but list concerns.
- **BLOCKED** — cannot proceed; state blocker and what was tried.
- **NEEDS_CONTEXT** — missing info; state exactly what is needed.

Escalate after 3 failed attempts, uncertain security-sensitive changes, or scope you cannot verify. Format: `STATUS`, `REASON`, `ATTEMPTED`, `RECOMMENDATION`.

## Operational Self-Improvement

_Replaces gstack `gstack-learnings-log`. In Hermes, durable learnings are saved via the `memory` tool, and reusable workflows become `skill_manage` entries._

## Telemetry

_Replaces `gstack-skill-end`. In Hermes, log durable facts to `memory` and continue. The Hermes gateway handles cross-session metrics._

## Iron contract — never write a half-broken skill to disk

Skills are user-trust artifacts. A broken skill in `terminal skill list` makes
agents reach for the wrong tool and erodes confidence. This skill writes
to a temp dir, runs the auto-generated test there, and only renames into
the final tier path on (a) test pass + (b) explicit user approval. On
either failure, the temp dir is removed entirely. There is no "almost
shipped" state.

---

## Step 1 — Provenance guard (D1)

Walk back through the conversation, **at most 10 agent turns**, looking
for the most recent `/scrape` invocation that:

- Was bounded (you can identify the user's intent line and the trailing
  JSON the prototype produced)
- Produced a JSON result the user did not subsequently invalidate
  (e.g., did not say "that's wrong", did not ask you to retry)

If you cannot find one, refuse with exactly this message:

> "No recent /scrape result found in this conversation. Run /scrape
> <intent> first, then say /skillify."

Stop. Do not synthesize from chat fragments. Do not synthesize from a
match-path /scrape result (matched skills are already codified — there's
nothing to skillify).

If you find a candidate but the user is currently three turns past it
discussing something unrelated, ask once before proceeding:

> "The last successful /scrape was '<intent line>' a few turns back.
> Skillify that one?"

A "yes" lets you continue. Anything else: refuse with the message above.

## Step 2 — Propose name + triggers

From the prototype intent, extract:

- A short skill name: lowercase letters/digits/dashes, ≤32 chars,
  starts with a letter, no consecutive dashes. E.g.,
  `lobsters-frontpage`, `gh-issue-list`, `pypi-package-stats`.
- 3–5 trigger phrases the agent should match against in future `/scrape`
  calls. Mix the canonical phrase ("scrape lobsters frontpage") with
  paraphrases ("top posts on lobste.rs", "lobsters front page").
- The host (just the hostname, e.g. `lobste.rs`).

Then **AskUserQuestion** to confirm:

```
D<N> — Skill name + tier
Project/branch/task: codifying /scrape "<intent>" as a browser-skill.
ELI10: Pick a short name we'll use to find this skill next time you say
something similar. Pick a tier — global means every project on this
machine sees it, project means just this repo.
Stakes if we pick wrong: bad name buries the skill in terminal skill list;
wrong tier means future projects can't find it (or can find it when you
didn't want them to).
Recommendation: A — <proposed-name> at global tier — most scrape skills
generalize across projects.
Note: options differ in kind, not coverage — no completeness score.
A) Keep "<proposed-name>" at global tier — ~/.hermes/gstack/browser-skills/<proposed-name>/  (recommended)
B) Keep "<proposed-name>" but at project tier — <project>/.gstack/browser-skills/<proposed-name>/
C) Rename it (free-form — say the new name)
```

**Tier-shadowing check.** Before showing the question, run `terminal skill list`
and check for an existing skill at the same name. If found, add to the
question:

> "Note: a <tier> skill named '<name>' already exists. Picking the same
> name at a higher tier (project > global > bundled) shadows it; picking
> the same tier collides and will be refused at write time. Pick a
> different name to coexist."

## Step 3 — Synthesize `script.ts` (D2)

**Use only the final-attempt `terminal` calls** that produced the JSON the
user accepted, plus the user's intent string. Drop:

- Failed selector attempts (the four selectors you tried before the
  working one)
- Unrelated `terminal` commands from earlier turns
- All conversation prose, summaries, your own reasoning

The script imports the SDK from `./_lib/browse-client` (a sibling copy,
written in step 6) and exports a parser function so `script.test.ts` can
exercise it against the bundled fixture without spinning up the daemon.

Mirror the bundled reference at `browser-skills/hackernews-frontpage/script.ts`:

```ts
import { browse } from './_lib/browse-client';

export interface Item { /* one row of the JSON output */ }
export interface Output { items: Item[]; count: number; }

const TARGET_URL = '<the URL the prototype used>';

export function parseFromHtml(html: string): Item[] {
  // Pure function: HTML in, parsed Item[] out. No terminal calls.
  // Future fixture-replay tests call this directly.
}

if (import.meta.main) { await main(); }

async function main(): Promise<void> {
  await browse.goto(TARGET_URL);
  const html = await browse.html();
  const items = parseFromHtml(html);
  const output: Output = { items, count: items.length };
  process.stdout.write(JSON.stringify(output) + '\n');
}
```

The parser MUST be a pure function. If your prototype used multiple `terminal`
calls (e.g., goto + click "Next" + html), keep all of them in `main()`
but extract the parsing into pure helpers. The fixture-replay tests in
step 5 only exercise the pure parts.

## Step 4 — Capture the fixture

```bash
terminal goto "<TARGET_URL>"
terminal html > /tmp/skillify-fixture-$$.html
```

The fixture filename inside the staged dir is
`fixtures/<host-with-dashes>-<YYYY-MM-DD>.html`, where the date is today.
E.g. `fixtures/lobste-rs-2026-04-27.html`.

Read the file you wrote, store its contents in a variable, and use it
when staging in step 7.

## Step 5 — Write `script.test.ts`

Mirror `browser-skills/hackernews-frontpage/script.test.ts`. The test
must include at least one ★★ assertion — parsed output has the expected
shape AND non-empty key fields — not a smoke ★ assertion. Smoke tests
that only check `parseFromHtml` doesn't throw are insufficient.

```ts
import { describe, it, expect } from 'bun:test';
import * as fs from 'fs';
import * as path from 'path';
import { parseFromHtml } from './script';

describe('<name> parser', () => {
  const fixturePath = path.join(import.meta.dir, 'fixtures', '<host>-<date>.html');
  const html = fs.readFileSync(fixturePath, 'utf-8');
  const items = parseFromHtml(html);

  it('returns at least one item from the bundled fixture', () => {
    expect(items.length).toBeGreaterThan(0);
  });

  it('every item has the required shape', () => {
    for (const item of items) {
      expect(typeof item.<keyfield>).toBe('<keytype>');
      // ... assert on every required field
    }
  });
});
```

## Step 6 — Resolve the canonical SDK path + read it

The canonical SDK lives at `<gstack-install>/browse/src/browse-client.ts`.
The bundled-skill loader walks the install tree to find it; mirror that.

Resolve the gstack install dir. Two reliable signals (in order):

1. The bundled `hackernews-frontpage` skill — look at its tier path from
   `terminal skill list` (the `bundled` row). The skill dir is
   `<gstack-install>/browser-skills/hackernews-frontpage/`, so the install
   dir is two `dirname` calls above its `_lib/browse-client.ts`.
2. The active gstack skills install at `~/.hermes/skills/gstack/`. Read
   the symlink target if it's a symlink, otherwise use the path directly.

Example (run as Bun, not bash, to avoid shell-redirect parsing issues):

```ts
import * as fs from 'fs';
import * as os from 'os';
import * as path from 'path';

function resolveSdkPath(): string {
  const candidates = [
    path.join(os.homedir(), '.claude', 'skills', 'gstack', 'browse', 'src', 'browse-client.ts'),
    // Add other install-dir candidates if your environment differs.
  ];
  for (const c of candidates) {
    try {
      const real = fs.realpathSync(c);
      if (fs.existsSync(real)) return real;
    } catch {}
  }
  throw new Error('Could not resolve canonical browse-client.ts');
}

const sdkContents = fs.readFileSync(resolveSdkPath(), 'utf-8');
```

Read the SDK contents into a variable. The staging step writes it as
`_lib/browse-client.ts` byte-identical to the canonical. Phase 1 decision
#4 — each skill is fully self-contained, no version drift possible.

## Step 7 — Stage the skill (D3 atomic write)

Use the helper at `browse/src/browser-skill-write.ts`. Construct an inline
TypeScript snippet (or shell out to a small Bun one-liner) that calls:

```ts
import { stageSkill } from '<gstack-install>/browse/src/browser-skill-write';

const stagedDir = stageSkill({
  name: '<name>',
  files: new Map([
    ['SKILL.md', skillMd],
    ['script.ts', scriptTs],
    ['script.test.ts', scriptTestTs],
    ['_lib/browse-client.ts', sdkContents],
    ['fixtures/<host>-<date>.html', fixtureHtml],
  ]),
});
console.log(stagedDir);
```

The SKILL.md content for `<name>` follows the Phase 1 frontmatter
contract:

```yaml
---
name: <name>
description: <one-line, what data this returns>
host: <hostname>
trusted: false       # agent-authored skills are untrusted by default
source: agent
version: 1.0.0
args: []             # extend if your script accepts --arg key=value
triggers:
  - <phrase 1>
  - <phrase 2>
  - <phrase 3>
---

# <Name> scraper

<2-3 sentences on what the script does, what URL it hits, and what
shape of JSON it returns. NO conversation context. NO chat fragments.
This is a durable on-disk artifact — keep it tight.>

## Usage

\`\`\`
$ terminal skill run <name>
{ "items": [...], "count": N }
\`\`\`
```

Capture `stagedDir` (the path returned by `stageSkill`). You'll pass it
to `terminal skill test` next, then to `commitSkill` or `discardStaged`.

## Step 8 — Run `terminal skill test` against the staged dir

```bash
terminal skill test "<name>" --dir "<stagedDir>"
```

If `terminal skill test` does not yet accept `--dir`, fall back to invoking the
test runner directly against the staged path:

```bash
( cd "<stagedDir>" && bun test script.test.ts )
```

If the test fails:

1. Read the test output. If the failure is a fixable parser bug,
   rewrite `script.ts` and `script.test.ts` (still inside the staged
   dir) and retry — at most twice. Show the diff to the user before
   each retry.
2. If still failing after two retries, OR the failure is an
   environmental issue (SDK import, daemon connection):

   ```ts
   import { discardStaged } from '<gstack-install>/browse/src/browser-skill-write';
   discardStaged('<stagedDir>');
   ```

   Report the failure to the user, show them the staged `script.ts` for
   reference, and stop. No on-disk artifact.

## Step 9 — Approval gate

Tests passed. Now ask the user before committing:

```
D<N> — Commit skill "<name>" at <resolved-tier-path>?
Project/branch/task: codified /scrape "<intent>" — tests pass against fixture.
ELI10: The script ran clean against the snapshot we captured. Saying yes
moves the staged folder into ~/.hermes/gstack/browser-skills/ where /scrape
will find it next time. Saying no removes the staged folder and nothing
lands on disk.
Stakes if we pick wrong: yes commits an artifact you have to manually rm
later if you regret it (terminal skill rm <name> --global). No throws away
~30s of synthesis work.
Recommendation: A — tests passed, the script is self-contained, this is
the productivity payoff for the prototype.
Note: options differ in kind, not coverage — no completeness score.
A) Commit it (recommended)
B) Look at the script first (I'll print SKILL.md + script.ts and re-ask)
C) Discard — don't commit
```

If the user picks B, print the staged `SKILL.md` and `script.ts` (NOT
the fixture or _lib/), then re-ask the same A/B/C question (without B
this time — they already saw it).

## Step 10 — Commit (atomic) or discard

If the user approved:

```ts
import { commitSkill } from '<gstack-install>/browse/src/browser-skill-write';
const dest = commitSkill({
  name: '<name>',
  tier: '<global|project>',  // from step 2 answer
  stagedDir: '<stagedDir>',
});
console.log(`Committed: ${dest}`);
```

If `commitSkill` throws "already exists" (tier-shadowing collision the
user dismissed in step 2), report and ask whether to:

- Pick a different name (back to step 2)
- `terminal skill rm <name>` then retry
- Discard

If the user rejected in step 9:

```ts
import { discardStaged } from '<gstack-install>/browse/src/browser-skill-write';
discardStaged('<stagedDir>');
```

Report: "Discarded. No skill was written to disk."

## Step 11 — Confirm + verify

After a successful commit, run one verification:

```bash
terminal skill list | grep <name>
terminal skill run <name>    # should match the JSON the prototype produced
```

If the post-commit run does not match the prototype output, something
in synthesis drifted. Surface this to the user — they may want to
`terminal skill rm <name>` and retry. Do NOT silently roll back; the user
deserves to see the discrepancy.

End the skill with one line: "Skill '<name>' committed at <tier>. Future
/scrape calls matching '<canonical-trigger>' will run in ~200ms."

---

## Limits (be honest)

- **Bun runtime required.** The codified skill runs as a Bun process
  (`bun run script.ts`). Phase 1 design carry-over (Codex finding #7).
  Real fix lands in Phase 4 (self-contained binary or Node fallback).
  For now: the skill works on any machine that has gstack installed,
  which means it has Bun.
- **Fixture-replay tests are point-in-time.** When the target site
  rotates HTML, the fixture goes stale and the test passes against an
  outdated snapshot. Phase 4 will add fixture-staleness detection.
- **Synthesis is best-effort.** You're writing a script from your own
  conversation memory. If the prototype was complex (multi-page, JS
  hydration, lazy load) the codified script may need a hand-edit before
  it's reliable. The post-commit verify step catches obvious drift.
- **Single-target only.** One `terminal goto` URL per skill. Multi-page
  crawls are out of scope — write a separate skill per target, or
  parameterize via `args:` if the URL pattern is regular.

## What this skill does NOT do

- Codify match-path /scrape results (matched skills are already codified)
- Codify mutating flows (those are /automate's job — Phase 2 P0)
- Run skills (that's `terminal skill run` — codified skills are run via /scrape's
  match path or directly)
- Edit existing skills ($EDITOR + the skill dir is the surface — `terminal skill
  show <name>` finds the path)
- Tombstone or remove (terminal skill rm)

## Capture Learnings

If you discovered a non-obvious pattern, pitfall, or architectural insight during
this session, log it for future sessions:

```bash
~/.hermes/skills/gstack/# memory tool '{"skill":"skillify","type":"TYPE","key":"SHORT_KEY","insight":"DESCRIPTION","confidence":N,"source":"SOURCE","files":["path/to/relevant/file"]}'
```

**Types:** `pattern` (reusable approach), `pitfall` (what NOT to do), `preference`
(user stated), `architecture` (structural decision), `tool` (library/framework insight),
`operational` (project environment/CLI/workflow knowledge).

**Sources:** `observed` (you found this in the code), `user-stated` (user told you),
`inferred` (AI deduction), `cross-model` (both Claude and Codex agree).

**Confidence:** 1-10. Be honest. An observed pattern you verified in the code is 8-9.
An inference you're not sure about is 4-5. A user preference they explicitly stated is 10.

**files:** Include the specific file paths this learning references. This enables
staleness detection: if those files are later deleted, the learning can be flagged.

**Only log genuine discoveries.** Don't log obvious things. Don't log things the user
already knows. A good test: would this insight save time in a future session? If yes, log it.
