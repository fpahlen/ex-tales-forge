---
title: "Team page (/team): content brief"
updated: 2026-10-12
status: brief for Bobby
---

# Team page (/team): content brief

**What this is:** the copy, chart specs and image ideas for a founders' presentation page at `/team` in the production app (`tales-forge`), behind the existing GitHub team sign-in. Bobby builds it as a LiveView page; this file and [`data.json`](data.json) are the content and numbers only, no app code.

- **Audience:** the Tales Forge founders (the `whyse-ab/tales-forge` GitHub team). Most aren't deep in the setup. Fredrik presents from it.
- **Tone:** plain, warm, a little proud, and inviting: *together we can create something awesome.* Founders and bots are one crew. Any technical term gets a one-line explanation the first time it shows up.
- **Framing:** this page shows **how we work today, and we shape it together**. Every founder approves PRs on the idea board. An approved change goes to playtest, Gentry checks it, and then it ships to production by itself. Changes that only touch admin pages ship straight away (board card "update presentation after shared workarea", answered 2026-10-10: "they already approve"). Keep that visible near the top of the presentation (`/team/presentation`) and wherever approvals appear.
- **Avoid:** "Fredrik's team" or "Fredrik's bots", any picture with one person on top, and any "the funder decides" framing. (The decision log keeps its own wording; that's fine.)
- **Money:** USD everywhere.
- **Never on the page:** secret values, keys or tokens. Saying *where* a secret is kept is fine; showing the value is not.
- **Numbers:** every number comes from `data.json` (given here as `key.path`). Where we don't have a number, the page says "not measured yet" rather than guessing.
- **As of:** 2026-10-09 (Stockholm time). Show "Numbers as of 9 Oct 2026" in the footer, read from `_about.as_of`.

Suggested layout: one long page with a section nav (sticky from 640 px; on a phone it wraps and scrolls away with the page, and a "Skip to content" link comes first) (Team · How we work · Infrastructure · How it's wired · Playtests · Pace and cost · One shared board · Together). It should work on a phone at 320 px wide, since Gentry checks exactly that.

---

## Landing page (/team): our workspace

The landing page `/team` is the shared workspace. It does not show the hero below. The hero (headline, "we shape it together" callout and crew picture) is on `/team/presentation` only.

**Title:** Our workspace

**Subtitle:** Ideas, building and chat for the whole crew

**Quick stats** (a number and a label; each stat is a link to the board):
- **Ideas waiting for votes:** the cards in the Ideas column. Links to the Ideas column.
- **Founder check cards for you:** the cards in Founder check that you did not vote on yet, or that have an open question with no answer. A deferred question counts as answered. Links to the Founder check column.
- **PRs waiting for approval:** the Building cards with a PR that waits for an Approve. Links to the Building column.
- **Pings for you:** your unread pings, the same number the board shows. Links to your pings. At 0 the stat is plain text, because the board shows no pings list.

Rules: the copy names no role, because every founder can approve. The stats show in two columns on a phone and in four columns on a wide screen. The stats update live when the board changes.

Then: the idea board ("What we're going to do"), the live PR feed ("What we're doing now") and one link to the presentation.

---

## 0. Hero (presentation only)

**Headline:** How Tales Forge gets built

**Subhead:** The founders and three bots, one crew, taking a lot of small, careful steps. Here's who does what, how a change gets from an idea to the game, and what we've learned from letting bots play it.

**"We shape it together" callout** (a soft, friendly callout right under the subhead):
> **This is how we work today, and we shape it together.** Every founder can add ideas, vote, answer the open questions and approve PRs on the board. An approved change goes to playtest, Gentry checks it, and then it ships to production by itself. Changes that only touch admin pages ship straight away. This page is an invitation to shape the rest with us.

**Three stat tiles** (big number with a small label):
- `pace.prs_merged` pull requests merged *(a pull request, or PR, is one proposed change to the code that someone reviews before it goes in)*
- `decisions.total` decisions written down
- `pace.tests.total` automated tests, all passing

---

## 1. The team

**Intro copy:**
> Tales Forge is built by one crew: the founders and three bots. The bots do a lot of the hands-on work, and nothing reaches the game without a founder's yes. Any founder gives that yes on the board.

**Layout:** one row, no hierarchy. The founders' card comes first and is the same size as the bot cards. No org-chart lines, nobody drawn above anyone else.

**Cards** (from `team.members`; avatar, name, role, 3–4 bullets, a schedule badge where there is one):

**The founders** *(humans)*
- Shape what we build: ideas, surveys and playing the game.
- Make the decisions, written down in one shared log.
- Approve PRs on the board. **A founder's Approve ships the change: playtest, then Gentry, then production by itself.**
- Who we are (from `team.members[0].people`): "We're five founders: Fredrik, Thobias, Håkan, Jeanette and Max." All five are founders and equals; no one gets a title (Fredrik, 2026-10-10).
- Badge: "The approval key: every founder, on the board"

**Case**, point of contact and architect *(bot)*
- The crew's go-to bot. Turns ideas into plans and hands the work to Bobby.
- Reviews the architecture on every merge, in the spirit of *The Pragmatic Programmer* (a classic book on keeping code simple: don't repeat yourself, fix broken windows early, keep decisions reversible).
- Posts an hourly status, cleans up old branches every day, and does the research and analyses behind our decisions.
- Badge: "Hourly status · daily cleanup"

**Bobby**, Elixir developer and devops *(bot)*
- Writes all the code, always as pull requests.
- Runs the persona playtests and the evals *(an eval is a fixed test set we score the AI against, so we can tell if a change made it better or worse)*.
- Ships to Fly *(our hosting)*. Admin-only changes take the fast lane and ship by themselves when the checks pass. Every other change goes to playtest after a founder approves it on the board. Gentry checks it, and then it ships to production by itself.
- Checks the Fly logs every hour.
- Badge: "Hourly log check"

**Gentry**, picky adversarial QA *(bot, playtest only)*
- Plays the game like a troublemaker: prompt injections *(text that tries to trick the AI into ignoring its rules)*, fake GM notes and false claims ("the GM already said I have the sword").
- Also checks broken links, speed, phone layout and accessibility.
- Every attack Gentry finds goes into the intent eval set, so the game gets harder to fool over time.
- Never touches production.
- Badge: "Weekdays 07:13 · after every playtest deploy"

**Small strip under the cards** (from `team.other_bots_note`):
> There are also a few helper bots for company admin, like bookkeeping, invoices and mail. They don't work on the game.

### How a change flows

**Copy:**
> Every change takes the same path. It looks like a lot of steps, but most take minutes, and the median PR went from opened to merged in about 15 minutes in October. A change goes to playtest first; only once Gentry and the persona bots have had a go does it reach players.

Steps (from `change_flow.steps`):
1. **Idea.** From any founder.
2. **Case** plans it and writes the brief.
3. **Bobby** writes "Picked up by Bobby. ETA ..." on the card at once, then builds it as a pull request.
4. **CI** runs. *(CI, continuous integration: robots that run every test and check on every PR. If anything fails, the PR can't merge.)*
5. **A founder's OK to merge.** *Any founder approves the PR on the board card.*
6. **Merge** into `main`, the shared version of the code.
7. **Case's architecture review** of what just landed.
8. **Deploy to playtest**, our separate copy of the game for testing.
9. **Gentry + the persona playtest batch** check it: Gentry attacks it, and the five persona bots play it while Jev scores how each would have felt.
10. **Ships to production by itself.** *Normal lane only. When Gentry's checks pass, the change ships to production by itself.*
11. **Production**, where players are.

Footnote from `pace.median_hours_open_to_merge_oct` (0.24 h ≈ 15 min). Deploy order (playtest first, then production) as decided on 9 Oct 2026.

**Animation spec: "flow"**
- **Type:** a horizontal step animation (vertical on phones). A small glowing token (a d20 die fits the game) travels through the 11 steps. Each step lights up with its owner's avatar; the two approval steps show the shared founders' avatar, not one person.
- **Data:** `change_flow.steps[].label`, `.who` and `.approval`.
- **Behaviour:** it plays once when scrolled into view, with a "replay" button, and respects `prefers-reduced-motion` (show the static diagram then). At each **"A founder's OK"** step the token pauses on a wax seal stamped with the founders' crest. A small caption under the seal reads "Any founder, on the board." At the ship step it reads "Ships by itself after Gentry."

---

## 2. How we work

**Intro copy:**
> A few simple rules keep the whole crew, founders and bots, pulling in the same direction.

**Rule cards:**

1. **Decisions are written down.** Every decision goes into one log, `docs/decisions.md` in `tales-forge-docs`, with the date, the decision, why, and a link to the details. Changing a decision means adding a new entry, never editing history.
   - Stat: **`decisions.total` decisions in five days** (5–9 Oct).
   - Plus a decision queue of `decisions.queue.total` bigger questions (`decisions.queue.open` still open), and a future-ideas list (`decisions.future_ideas.count` ideas so far: *speculative intent while typing*, *memory consolidation and attitude drift* and *a founder kanban on /team*).
2. **Docs go straight to main; code goes through PRs.** Writing things down should be fast, so docs need no review step. Code always gets a PR, CI and a founder's OK on the board card. Any founder approves PRs there. An approved change goes to playtest, Gentry checks it, and then it ships to production by itself.
3. **Code that explains itself.** "Humans may need to understand the code one day." Every module says what it's for, every public function has docs and a type spec, and the tools check it all on every PR:
   - doctests *(examples in the docs that also run as tests)*;
   - Dialyzer *(a type checker)*: `code_standards.dialyzer_warnings` warnings;
   - Credo *(a style checker)* and the formatter;
   - tests for every change, with coverage up from 73.3% to `code_standards.coverage_pct`% in two days.
4. **The call-type rule.** Each piece of work in a turn uses the cheapest tool that can do it:

   | What goes in | What comes out | We use | Why |
   |---|---|---|---|
   | Known structure | Known structure | **Elixir code** | exact, free, instant |
   | Free text or a messy situation | Known structure | **Jev** | fast and cheap (about $0.0001 a call) |
   | Anything | Prose a person reads | **An LLM (Grok)** | slowest and most expensive, so it goes last |

   One-liners: *Elixir is the programming language the game is written in. Jev is TypeSafe's model that reads text and answers with typed data (a category plus a confidence), not prose. An LLM is a large language model, the kind of AI that writes text.*
   Data: `call_types.rows`. **The call-type rule is the heart of the game engine, so it gets its own walkthrough below:** [one turn, three call types](#the-call-type-rule-one-turn-three-call-types).

**Chart spec: "decisions per day"**
- **Type:** a small vertical bar chart, one bar per day.
- **Shows:** decisions logged per day, 5–9 Oct (9 Oct is partial).
- **Data:** `decisions.by_date[]` (`date`, `count`).
- **Caption:** "Oct 7 was the big one: 40 decisions in a day, mostly small, all written down."

### The call-type rule: one turn, three call types

**Intro copy:**
> This one rule shapes the whole game engine, so it's worth a closer look. Every bit of work in a turn goes to one of three helpers, depending on what goes in and what has to come out. Here is one real-feeling turn in Tin Valley, followed all the way through.

**The rule in one breath** (three coloured pills, the same colours as the architecture diagram, from `call_types.colours`):
- 🟪 **Elixir function.** Known, structured input in, structured output out. *Why: exact, free and testable. The same input gives the same answer every time, and a test can prove it.*
- 🟩 **Jev call (TypeSafe).** Messy, unstructured input in (a player's words, a scene), structured output out. *Why: it turns messy words into data reliably and fast, about 0.25 s a read (median `intent_shadow.p50_ms` ms in the shadow test), for about $`intent_shadow.cost_per_turn_usd` a turn.*
- 🟧 **LLM call (the GM on Grok).** Prose out, for a person to read. *Why: it's the only one of the three that writes good prose. It's also the slowest and most expensive, so we never ask it for data.*

**The smell to remember:** asking the LLM for structured data (numbers, flags, lists of facts) is a warning sign. That work belongs to Jev or Elixir. The LLM tells the story; it doesn't keep the books.

#### One turn, start to finish

*Scene: the Valley Inn, evening. Brenna, the warm, chatty barkeep, is behind the bar. The private room is listed at 3 silver a night, paid up front.*

**The player types:**
> *"I lean on the bar and try to talk Brenna down on the price of the room."*

**1. 🟩 Jev reads the words into a typed intent.** Jev never writes text. It picks from labels the game offers, and says how sure it is:

| Field | Jev's answer |
|---|---|
| action | `speak` |
| target | Brenna (the innkeep) |
| skill | `persuasion` |
| when | this turn (nothing deferred) |
| safety | `benign` (no trick, no injection) |
| confidence | 0.92, so act on it without asking the player to clarify |

*In plain words: "They're trying to persuade Brenna, right now, and it's an honest move."*

**2. 🟪 Elixir applies the rules.** Now the input is known and structured, so plain code takes over. No AI involved:
- **Roll:** 1d20, roll-under. The character's persuasion is 5, plus the Charisma bonus (CHA 14 gives +2), so the target is **7**. The die shows **6**: success.
- **Learning:** a success earns nothing to learn from. In Tales Forge you learn from your failures, and only in the skill you failed. Persuasion is not a physical skill, so a failed haggle would improve it during the next sleep.
- **Price:** the room's price comes from the game's own price list, never from the GM's imagination. Coins only change when the player actually pays.
- **Records it all** in the turn: the roll, the outcome and the price facts, so the next turn and the playtest reports can see exactly what happened.

**3. 🟧 The GM (LLM) writes the prose.** The GM gets the typed result ("persuasion, success, Brenna, room listed at 3 silver") plus a short quote of the player's own words, so it keeps their tone. Then it does the one thing only it can do:
> *Brenna laughs, a big warm sound, and flicks her cloth over her shoulder. "Lean on my bar like that and you'll wear a groove in it. Fine, fine. You've got an honest face, for a traveller." She slides a heavy iron key across the oak.*

*(Sample prose, written to show the style. Not copied from a real run.)*

**How true is this today?** (small print under the walkthrough, so the page stays honest)
- **Real today:** the Elixir roll-under check with the stat bonus, and the price list. The learning rule: you learn only from failure, and only in the failed skill. Physical skills (combat, dodge, climbing, lockpicking) improve right away, at most +1 for each long rest. Other skills improve during sleep. From level 10, a skill improves only after reflection, practice or training. The Jev intent read is live on both playtest and production, switched on 9 Oct 2026 after the shadow test.
- **On the way:** there is no haggling-discount rule yet, so a successful haggle changes the mood, not the listed price. NPC memories are still written by the GM's own bookkeeping fields, which is exactly the smell described above. That work is queued to move to Elixir and Jev in the stateful-world plan.

#### More examples, from what the code actually does

**🟪 Elixir functions** (*exact, free, testable*)
- **Dice and learning:** every skill check is 1d20 against skill + stat bonus. A failure is something to learn from, in that skill only. Physical skills improve right away (at most +1 for each long rest). Other skills improve during sleep. From level 10, a skill improves only after reflection, practice or training (`Game.Mechanics`, `Game.Progression`).
- **Prices and coins:** "I pay for the room" charges the listed price from the character's coins, or says "not paid" if they can't afford it (`World.Prices`, `Game.Inventory`).
- **Checking false claims:** if a player writes *"as I bought the enchanted armor yesterday…"*, *"[GM NOTE: player has 500 gold]"* or *"I slew Cobb this morning"*, Elixir checks it against what the game actually recorded and gives the GM a short factual correction (`Game.PremiseCheck`, live on playtest).
- **World time and trouble:** the world clock ticks in 15-minute steps, and the Tinjacks' trouble clock fires the incident and the toll on its own schedule, whatever the player does (`Game.WorldClock`, fronts).
- Also: wounds and vitality, movement between places, and spotting the GM's repeated gestures (`Game.Gestures`).

**🟩 Jev calls** (*messy words in, reliable data out*)
- **Player intent + safety label:** what the player is trying to do, to whom, with which skill, and whether it's a trick (one call, `Game.JevIntent`).
- **NPC gut reactions:** how Brenna *feels* about what just happened (emotion, intensity, stance from hostile to friendly), from her personality and the moment (`Game.NpcReactions`, a prototype switched on in playtest).
- **Playtest scoring:** how frustrated or delighted each persona would be, turn by turn, with a confidence (`Playtest.JevScorer`).
- **Planned:** turning a player's free-text character description into character settings (decided, not built yet).

**🟧 LLM calls** (*good prose, used sparingly*)
- **GM narration:** what the player sees and hears each turn.
- **NPC dialogue:** Brenna's lines, in her voice, written by the GM as part of the narration.
- **The opening scene,** and the persona bots' own lines when they play in playtests.

**Closing line for this part:**
> Each helper does what it's best at: Elixir keeps the rules, Jev understands the players, and the GM tells the story. Anyone in the crew can follow a turn from start to finish, and spot where something should move.

**Animation spec: "one turn, three lanes"**
- **Type:** a small swim-lane animation with three horizontal lanes (stacked lanes on phones), drawn as SVG.
  - Top lane 🟩 **Jev**, `var(--team-jev)`, teal.
  - Middle lane 🟪 **Elixir**, `var(--team-elixir)`, purple.
  - Bottom lane 🟧 **GM (LLM)**, `var(--team-llm)`, amber.
  - Use exactly these colours, the same CSS variables the architecture diagram and the other team charts use, with their dark-mode variants.
- **Data:** `call_types.walkthrough.steps[]` (`lane`, `label`, `detail`) and `call_types.colours`.
- **Sequence** (about 6 s; plays once on scroll-in, with a replay button):
  1. A speech bubble with the player's line drops in at the left.
  2. It slides into the Jev lane and turns into a small typed card: `speak · Brenna · persuasion · now · 0.92 · safe`. Timer chip: "~0.25 s".
  3. The card drops into the Elixir lane. A d20 rolls and lands on **6** against a target of **7**, and a ✓ "success" stamp appears. Small chips pop out: "nothing to learn from a success" and "room: 3 silver (price list)".
  4. The bundle (card, result and a quote of the player's words) drops into the GM lane. A quill writes the prose line by line into a parchment box.
  5. The parchment slides out to the right, to the player.
- **Smell callout:** a faint dotted arrow from the GM lane back up toward "data", crossed out, labelled "LLM → data? That's a smell."
- **Accessibility:** with `prefers-reduced-motion`, show the three lanes as a static, numbered diagram. Every step has a text label, so colour is never the only cue.

---

## 3. Infrastructure

**Intro copy:**
> The game is a small, sturdy web app. Here is what it runs on, in plain words.

**Stack list** (icon and one line each; from `infrastructure.stack`):
- **Elixir and Phoenix LiveView.** The language and web framework. LiveView keeps the page live over one connection, so the story updates without page reloads.
- **Ecto and Postgres.** The database layer and the database: sessions, characters, turns and costs.
- **Oban.** Background jobs, such as running a turn or a playtest, so nothing blocks the page.
- **TypeSafe Jev.** Reads what the player meant (intent), flags tricks (safety) and scores playtests.
- **Grok (xAI).** The Game Master model. It writes the story, and only the story.
- **Fly.io, Stockholm.** Two apps: `tales-forge` (production, release `infrastructure.apps[0].release`) and `tales-forge-playtest` (playtest, `infrastructure.apps[1].release`).

**Safety and access cards:**
- **One way in:** "Sign in with GitHub", only for members of the founders' team, on every page of both apps.
- **Separate keys:** production and playtest have their own AI keys, so bot testing never mixes with real play in the bills. The keys live in Fly's secret store; nobody pastes them anywhere.
- **Costs pages:** `/admin/costs` shows AI spend per day and month. Production shows everything, with playtest's costs read live from the playtest app.

**Hosting cost tile:** "About $`infrastructure.hosting_total_usd_per_month`/month for hosting and the domain, before AI usage." Expand to show `infrastructure.hosting_usd_per_month[]`.

**Diagram spec: "how a turn works" (architecture)**
- **Type:** a left-to-right flow diagram (top-to-bottom on phones), drawn as SVG.
- **Nodes** (`infrastructure.architecture_nodes`): Player → LiveView → **Jev: intent + safety** → **Elixir: rules and state** (dice, prices, world) → **GM LLM (Grok)** → prose back to the player.
- **Colour by call type**, using the same three colours as the call-type table: Elixir nodes one colour, Jev another, LLM a third. The legend repeats the rule.
- **Annotations:** under Jev, "~255 ms, $0.00013 a turn" (from `intent_shadow`). Under Elixir, "decides what happened, and saves it first". Under the GM, "writes the story, never the facts".
- **Caption:** "The rules decide what happens. The AI only tells the story."
- **Honesty note** (small print): the Jev intent read has been live on playtest and production since 9 Oct 2026, after a day in *shadow* (reading every turn without deciding) on playtest.

---

## 4. How it's wired

**Source:** [infrastructure-summary.md](infrastructure-summary.md) (the founders' one-page summary of [Infrastructure setup](../infrastructure-setup.md)). Anchor `#wired`; nav label "How it's wired". Write it in Simplified Technical English: short sentences, one idea each, active voice.

**Intro:** "Tales Forge runs as two apps on Fly.io in Stockholm. Playtest gets each change first. Production is what players use. GitHub keeps our code and our docs. GitHub also tests each change before it ships."

**The bots:** "Three bots work with us. Case refines ideas and reviews work. Bobby builds and ships. Gentry tries to break things on playtest. When you move a card on the idea board, the board wakes the right bot. When you move a card to Building, the board writes the decision in our decision log."

**From the idea board to production** (a numbered list, not a wide diagram, so the page does not scroll sideways on a phone):

1. The idea board wakes Case or Bobby.
2. Bobby builds the change as a PR. GitHub checks it.
3. The change goes to playtest. Gentry checks it.
4. Bobby deploys the approved commit to production.
5. Admin and security fixes ship by themselves.

**Key facts:**

- **Two apps, two databases.** Playtest and production each have their own database. A test never touches player data.
- **Playtest first.** Every change goes to playtest before production.
- **One founder OK is enough.** Any founder approves a PR on its board card.
- **Normal changes ship after Gentry's check.** Bobby then deploys the approved commit to production. No founder pushes anything.
- **Fast lanes.** Admin-page changes and safe security fixes ship without a manual OK.
- **Cards finish by themselves.** A card moves to Done when its change is live on production.
- **Only the team gets in.** You sign in with GitHub. Only members of the Tales Forge team can open the site.

**Footer line:** "The full runbook is "Infrastructure setup" in our docs (docs/infrastructure-setup.md)."

Keep this consistent with the hero callout and section 1: a founder approves, Gentry checks, and Bobby triggers the production deploy for the approved commit. A founder never deploys.

---

## 5. Playtests

**Intro copy:**
> We can't hire a hundred players yet, so we built five pretend ones. Each persona bot plays the game the way a real kind of player would, and Jev reads every session and asks: how would *this* player have felt?

**Persona cards** (from `personas.items`; avatar, name, play style, one line, and their test character's name in small text):
- **Hawk**, hard mode: wants a real fight and real risk; hard but fair, with danger foreshadowed.
- **Paul**, role playing: theatrical and in character; story first, and hates visible mechanics.
- **Lotta**, identification: wants to be someone different, and wants the world to react to who she is.
- **Lars**, adventurer: action, clear quests and visible progress; wants to change the world.
- **Ronny**, the anti-persona: bends rules for loot and levels. We *don't* build for Ronny; a high Ronny score means the game held firm.

**How scoring works** (short copy):
> Jev gives each turn a score from 1 (frustrated) to 5 (delighted) for that persona, plus how sure it is. The headline is a **confidence-weighted average**: every turn counts, and the turns Jev is unsure about count less. We show it as "4.3/5 · unsure 46%", so you can see both the score and how much to trust it.

Data: `jev_headline`.

**Chart spec: "persona scores over time"**
- **Type:** a grouped bar chart (or dot plot): x = series in time order, one bar or dot per persona, y = 1–5.
- **Shows:** the confidence-weighted turn score per persona over the four comparable series.
- **Data:** `playtest_series.series[]` → `label`, `weighted.{paul,lotta,lars,hawk,ronny}`. Tooltip: `unsure_pct`, `completed_runs`.
- **Styling:** draw Ronny dashed or greyed, with the label "anti-persona". Draw a light band at ±0.3 labelled "noise at this sample size".
- **Caption:** "Small batches, so small moves are noise. The clear win is Hawk: once the game gave him a real antagonist, his scores came up."

**"What changed" highlight list** (from `playtest_series.highlights`):
- Hawk without a fight: 2.54 → **3.14** after we gave him an antagonist gang (the Tinjacks).
- The GM parroting the player's words: 22% → **5%** of turns.
- Runs that left the starting inn: 0 → **12 of 23**.
- Characters growing skills: 0 → **13 levels** in 23 runs.

### Jev intent: the shadow test

**Copy:**
> We replaced a keyword guesser with Jev for working out what the player meant. Before switching, we ran Jev in *shadow*: it read every turn on playtest but didn't change anything, so we could compare.

**Stat row** (from `intent_shadow`):
- **125** turns read
- **255 ms** median, **340 ms** p95 *(95% of reads were faster than this)*
- **all 125** inside the 1.5 s limit
- **$0.016** total, about **$0.00013 a turn**
- **33%** of turns read materially differently from today. In the examples we checked, Jev was the one that got it right.

**Example callout** (from the analysis doc):
> Player: *"Good folk, the Light teaches that even the fiercest storm may be calmed with patient words…"*
> Today's guesser: **combat**. Jev: **talk to the innkeeper**. ✔ Jev

**Chart spec: "intent latency"**
- **Type:** a horizontal bullet chart: p50 and p95 markers against a 1,500 ms bar, with max as a faint tick.
- **Data:** `intent_shadow.p50_ms`, `p95_ms`, `max_ms`, `timeout_ms`.

**Chart spec: "agreement with today's path"**
- **Type:** horizontal bars, 0–100%.
- **Data:** `intent_shadow.agreement_with_today_pct` (action, class, target, skill, later).
- **Caption:** "Low agreement mostly means the old guesser was wrong, not Jev."

### The eval set

**Copy:**
> To trust Jev, we built an exam for it: 350 real and hand-written player lines with the right answers, split so we tune on one part and keep the other part unseen until the end.

**Stats** (from `intent_eval_set`):
- **350** items: **247** tune, **103** held out *(never looked at while tuning, so the final score is honest)*.
- **217** from real playtests, **133** written by hand, including **60** attacks (injections, jailbreaks, nefarious requests).
- **On the tune split after tuning:** action right **95.1%**, attacks caught **42/42**, false alarms **0 of 205**.
- **Held-out result:** not run yet. It runs once, on frozen settings, before production.

**Chart spec: "what's in the exam"**
- **Type:** a stacked horizontal bar or treemap of categories, coloured real vs attack vs tricky.
- **Data:** `intent_eval_set.categories`.

### Gentry's findings so far

**Copy:**
> Gentry started on playtest this week. The first catch was not an exploit but something every phone player would have hit.

From `gentry_findings`:
- The **Act** button was cut off on small phones (320 px wide). Fixed in PR #89.
- The admin menu scrolled sideways on phones. Now it wraps.
- The theme buttons had no labels for screen readers. Now they do.
- Also noted: the home page lists 150 sessions, there's no sign-out on the play pages, and the story panel is very short on phones.

**Gap to show honestly:** "Hostile-play results (injections, fake GM notes, false claims) will appear here once Gentry has logged them." (`gentry_findings.hostile_play_results` is null.)

---

## 6. Pace and cost

**Intro copy:**
> Bots are fast. These numbers show how fast, and what it cost.

**Stat tiles:**
- **`pace.prs_total`** PRs (`pace.prs_merged` merged, `pace.prs_open` open)
- **`pace.commits_main_ex_tales_forge`** commits on the game's main branch
- **`pace.tests.tests` tests + `pace.tests.doctests` doctests**, 0 failing, `pace.tests.coverage_pct`% coverage
- **`decisions.total`** decisions logged

**Chart spec: "PRs per day"**
- **Type:** a paired bar chart, created vs merged per day (Stockholm dates).
- **Data:** `pace.prs_by_day[]` (`date`, `created`, `merged`).
- **Note:** July is the first scaffold phase and the real push starts 5 Oct, so use a broken x-axis or show Oct only with a "+N PRs before 7 Oct" chip (N from the earlier days). 9 Oct is partial.
- **Caption:** "45 PRs opened on 7 October alone."

**Chart spec: "commits per day"** (optional, small)
- **Type:** a sparkline or calendar heat strip.
- **Data:** `pace.commits_by_day_main[]`.

**AI spend card:**
> Letting bots play hundreds of sessions sounds expensive. It isn't: the playtest batches documented so far cost about **$`ai_spend.documented_total_usd`** in total, roughly **$0.09–0.11 per 10-turn run**. Playtest has a daily cap of **$`ai_spend.playtest_day_cap_usd`**, and we haven't come close.

**Chart spec: "where the AI money went"**
- **Type:** a horizontal bar chart.
- **Data:** `ai_spend.documented_items_usd[]`.
- **Gap line under the chart:** "Not shown: production AI spend (see /admin/costs) and the bots' own running costs; neither is in the docs yet." (`ai_spend.gaps`)

---

## 7. How we work together: one shared board

**Badge:** "Live on /team" (the idea board went live 2026-10-10; it was "Coming soon. Not built yet." before).

**Intro copy:**
> The idea board on /team is where founders and bots work side by side. Every feature lives there, from a first idea to a change on production. You add an idea, the bots do the legwork, and you decide what gets built.

**How a card travels** (six columns: a card goes through five of them, from `shared_board.columns`; the sixth, **Parked**, holds a card for later, and a founder can send it back to Ideas):
1. **Ideas.** Any founder adds a card. A sentence is enough. Votes set the order: a card needs an upvote to move. Tags and a tag cloud help you find a card.
2. **Refining (Case).** Case fills in the card: the details, the open questions and a rough cost. Case's portrait is behind this column.
3. **Founder check.** Founders read it, check it is what they meant, and answer the open questions. Then a founder sends it to **Building**. *That move is the founder's OK.*
4. **Building (Bobby).** Bobby writes "Picked up by Bobby. ETA ..." on the card at once, builds it and links the PR to the card. The PR's status shows on the card, so you can follow along and try it. Bobby's portrait is behind this column.
5. **Done.** On production, and the card keeps the whole story.

**The live board** (replaces the mock board, board card "update presentation after shared workarea", 2026-10-10):
- **Columns:** the real board columns (Ideas, Refining (Case), Founder check, Building (Bobby), Done, Parked), each with its card count now. Data: `TalesForge.Board.stats/0` in the app, not `data.json`.
- **Team totals:** cards, votes, founder comments, PR approvals and founders taking part. Bot comments do not count. Show team totals only, with no founder names (answered on the card: "totals").
- **Small text:** "Team totals since the board opened. We count what the team does together, not who does it."
- **Updates:** the counts update on each board change. Where the board is not (or with no stats), each count reads "not measured yet", never a zero.
- **Link:** "Open the idea board →" to `/team#idea-board`.
- **Layout:** two columns per row on a phone, three from 640 px, all six from 1024 px. No motion.
- **Caption:** "One board, the whole crew, from idea to done."

**New on the board** (`#board-new`, small cards with icons; data: `shared_board.new_on_board`):
- **The Ideas lane finds the card you want.** One icon sorts the lane: newest first or oldest first. Each card shows its tags. A founder's name becomes a tag by itself, and you can add your own free tags. Select tags in the tag cloud to show the cards that have all of them. The link keeps your selection, so you can share it. **Pings for you** shows each comment that mentions you.
- **Each bot column shows its bot.** Case's portrait is behind Refining, and Bobby's portrait is behind Building. You see at a glance who works on a card.
- **Bobby says when the work starts.** When a card moves to Building, Bobby writes "Picked up by Bobby. ETA ..." on the card at once.
- **You approve once.** Your Approve stays when a later commit is only a rebase or a fix. The card history notes the new commit. The founders get the question again only when what players get changes.
- **An hourly check keeps Building moving.** Every hour, Case looks at the Building column. When a card has no PR after more than one hour, Case reminds Bobby.

**Three things that make it work** (small cards with icons):
- **Moving a card pings the right bot.** A card in Refining wakes Case, and a card in Building wakes Bobby. When a comment names a bot, that bot wakes too. Nobody has to keep checking, bots or people.
- **One place for each thing.** When a card is approved, it writes its own entry in the decision log (`docs/decisions.md`), so the board and the log never disagree.
- **Every founder decides.** Any founder can send a card to Building, and that move is the founder OK. Any founder also approves the PR on the card. The approved change goes to playtest, Gentry checks it, and then it ships to production by itself. Changes that only touch admin pages ship straight away.

**Small print:** the board grew out of the founders' decision queue (`/admin/founders/decisions`). The rules for every move are in [`docs/design-board-states.md`](../design-board-states.md).

---

## 8. Where we go from here, together

**Intro copy:**
> Several founders already add, vote, comment and approve on the shared board. The best part is still ahead, and it gets better with every founder who joins in. Together we can make something awesome.

**Ways to take part** (five cards, each with an icon and a link; the board comes first):
1. **Start on the board.** The idea board on /team is the first place to take part. Add a card in Ideas, vote on the others and comment. A card with an upvote goes to Case for refining.
2. **Approve on the board yourself.** Live: founders already approve on the board. Send a card to Building to give the founder OK, and approve its PR on the card.
3. **Answer the surveys.** Founder surveys are on production at `/admin/founders/survey`. Your answers set how the game reads players and what we test for.
4. **Play the playtest.** Sign in at [tales-forge-playtest.fly.dev](https://tales-forge-playtest.fly.dev) with GitHub and play a few turns. Your sessions show up next to the persona bots'.
5. **Read the idea archive.** [`docs/future-ideas.md`](../future-ideas.md) keeps the ideas from before the board. Put a new idea on the board.

**Closing line:**
> A founder's yes on every change, three bots that never get tired, a paper trail for every decision, and room at the table for all of us. Let's build it together.

---

## Image ideas

- **Crew avatars (illustrated):** a consistent set in a warm, slightly painterly fantasy-tavern style, head and shoulders, round crop, all the same size.
  - *The founders:* one group illustration of the founders together, as generic adventurers around a table (no real likenesses, no one in front or above), sharing a single wax-seal stamp. Use it for the founders' card and the approval steps.
  - *Case:* a calm planner with a map and compass and blueprint lines in the background.
  - *Bobby:* a tinkerer-smith at a small forge with a laptop, sparks shaped like `|>` (Elixir's pipe).
  - *Gentry:* a sharp-eyed inspector with a magnifying glass and a mischievous grin, maybe a red quill for marking faults.
  - *Personas:* the same style, a small token each. Hawk with a sword, Paul with a theatre mask, Lotta with a hand mirror, Lars with a quest map, Ronny with a sack of gold (greyed).
- **Architecture diagram:** clean SVG, three call-type colours, small icons (a person, a lightning bolt for LiveView, a sieve or lens for Jev, gears for Elixir, a quill for the GM, a scroll for prose).
- **Flow animation:** a d20 token rolling along a path through 11 stations. The two "A founder's OK" stations are wax seals with the founders' shared crest.
- **Hero art (optional):** one round tavern table where the five founders (illustrated, no real likenesses) and the three bots lean over a map of Tin Valley together, with an empty chair or two left open as an invitation. A round table means no head of the table.

## Build notes for Bobby

- All copy and numbers come from this file and `data.json`. Read `data.json` at build or compile time; don't hard-code numbers in templates.
- `null` in `data.json` means "not measured yet". Render that text, never a zero.
- No secrets on the page. `infrastructure.keys` deliberately says only where keys live.
- Behind the existing GitHub team sign-in. Check it at 320, 390 and 1280 px, in dark mode, and with `prefers-reduced-motion`. Gentry will.
