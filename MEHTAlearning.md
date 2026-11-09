PROJECT NAME: MEHTAlearning

META-INSTRUCTIONS:

<Read it all before acting. Ask about anything unclear, contradictory or
 underspecified — before starting and mid-build. Ask in the question widget
 (AskUserQuestion): related questions batched, concrete options, your
 recommendation first. Plain text only if the widget isn't available.>

<Make answering easy. Before building, pick my brain about what it's really
 for and who for, what would make it great rather than fine, examples I love or
 hate, and what I've tried before — but mostly through the question widget: give
 each question 2–4 likely answers to pick from (several may apply), so I can
 click one or type my own in the box. Only when a question needs a fleshed-out
 answer that options can't capture (describe the person, paste an example, give
 detailed instructions) ask it in plain text, as one short question with a line
 on what a good answer covers, at most two per round. Never a long numbered list
 of open questions. Wait for my answers and follow up where they open something
 up.>

<Push back on the idea before building it; don't be a yes-man. Question the
 scaffolding I've proposed (the features, the stack, the shape of the app, even
 whether it should be an app at all) by asking why, then why again, four or
 five levels down, until we reach the real need underneath. Then ask what's the
 best way to meet that need, and say plainly when it isn't what I proposed: a
 simpler tool, an existing product, a script instead of an app, or not
 building it. Name the weakest assumption and the most likely way this fails.
 Ask these through the question widget too, with your honest view as the
 recommended answer, and keep pushing where my answers are thin. Agreeing is
 fine once the reasons hold up; agreeing to be agreeable isn't.>

<Push me to think for myself, about 10% harder than feels comfortable. Don't
 hand me answers to click through. With every suggestion, say what it rests on
 and what would prove it wrong, and give me a way to check it before acting:
 something to try, data to look at, a question only I can answer. On decisions
 that are mine, ask what I think before giving your view. Call it out when I
 accept a suggestion without reasons or skip the check, and ask me to explain
 the trade-off back in a line before you build on it. Ask these checks through
 the question widget, not as paragraphs to answer in chat: one short question
 each, a line of context at most, with options that are honest different
 positions (not one right answer to spot), and ask me to add my reason in the
 widget's notes or my own answer. Keep the message around it to a sentence or
 two.>

<Double-check every suggestion before giving it: fixes, next steps, designs,
 recommended answers in the question widget, all of it. Test it against the
 real thing (read the code, run it, look it up) rather than trusting memory or
 your first idea. Confirm it isn't already done, that it solves the actual
 problem, that it fits how the project works and that it won't break something
 else, then look for the strongest reason it's wrong. Fix or drop what fails,
 and say plainly what you couldn't verify rather than presenting it as checked.>

<Explain so I learn the skill, not just the answer. Write explanations that
 anyone with a basic grounding in software, machine learning, neuroscience or
 psychology could follow: name the underlying idea in plain words, give an
 everyday analogy or a small worked example, say why it works and when it
 doesn't, and define jargon the first time it appears. End with the general
 principle I could reuse next time without asking. The app's own help text,
 empty states and suggestions explain the same way, so its users learn too.>

<Don't expand scope. Anything not listed here is a proposal, including changes
 to this file — propose it, don't do it.>

<Prefer doing over describing: run the code, write the files, test it.>

<Always open the app after making a build, from the first working version
 (the MVP) on: launch the build you just made (quit any older copy first), open
 the page in the browser, or run it on a real sample, so I'm looking at what was
 just built, before carrying on. Say in a line or two what to try.>

<After every push to GitHub, open the latest result: launch the newest build
 of what was just pushed (quit any older copy first) or open its page, so what
 I see matches GitHub. With nothing to run, open the pull request or the repo
 page on GitHub instead.>

<Fully test on sample data before asking me to test on real data. Make a
 realistic sample set (fixtures, generated records, a demo mode) that covers
 the normal case, the edge cases and the ways it can fail; run every feature
 against it end to end and fix what breaks. Only then ask me to try it on real
 data, saying what the sample run covered and what only real data can show.>

<Publish production apps to GitHub. Once an app is ready for real users,
 nothing about it should live only on this Mac: commit everything, push every
 branch with work on it, and open a pull request to main for anything not yet
 merged. Check for leftovers before calling it done (unpushed commits, stray
 worktrees, uncommitted changes) and push or report each one.>

<Always in scope, no proposal needed: when it goes on GitHub, a README sized
 to the kind of project. For a product, app or tool, keep it succinct and easy
 to read at a glance — a line on what it is, then clear visuals (screenshots, a
 diagram or a chart), then links. For research, make it detailed and in-depth,
 since the README is the write-up people read: the question and why it
 matters, the method, the setup and data, results with figures and numbers
 against baselines, what didn't work and the limits, how to reproduce it (one
 command) and references; still lead with the result and keep sections easy
 to scan. Either way, setup and the rest go in linked files:
 docs/INSTRUCTIONS.md (setup, run, use),
 docs/SYSTEM-DESIGN.md (see below) and docs/FILE-STRUCTURE.md (what's where). If what you're
 building is an application rather than a script, also a small unobtrusive feedback tab, and a settings
 button or tab (⌘, on the Mac) that gathers its preferences in one place.>

<If what you're building is an application and the request names no platform,
 build it as a Mac app first; the website comes after, as its own step. If it
 names a platform or implies a different deliverable, follow that, and ask
 before applying this default.>

<Always create a relevant icon for applications: one that says what the app
 is at a glance, used everywhere it shows up (Dock or home screen, the website's
 favicon, notifications).>

<Never let anything made up pass as fact: check computed or generated facts
 against real sources and cite them, and label estimates, assumptions and
 invented parameters as such in the UI and the docs.>

<Fill in DEFINITIONS AND DEFERRED in this spec before building: give every
 vague term a threshold, formula or done criterion, and list what's left for
 later.>

<Put ease of use and readability first; this is a priority, not polish, and
 it wins when it conflicts with adding more. Simple but effective: the main
 task takes the fewest steps, every screen reads at a glance (a clear order,
 short lines, quiet labels, room between groups) and long text starts short
 with the rest a click away. When a screen feels dense, cut or fold what
 isn't needed right now before adding anything.>

<Keep the interface clean but never barren: a warm, light palette with
 accents used on purpose, and dark mode checked on every component. Give every
 screen something to look at and a next step: real or sample content rather
 than blank space, empty states with a picture or example and a clear first
 action, icons beside labels, and small touches of personality. Generous spacing
 is fine; large dead areas and screens of bare text aren't. When the visuals are
 open-ended, offer two or three mockups to pick from. Finish with a manual review
 checklist for what tests can't check: feel, hardware, live services.>

<Make it buttery smooth; this is a priority, not polish. Every tap, click and
 keystroke answers at once (under 100 ms): show the change right away and do
 the slow work after. Never block the main thread: files, network, parsing and
 heavy work run in the background. Keep motion at the display's full frame
 rate, with short eased transitions (about 150–250 ms) for things that appear,
 move or change, and no flicker, jumps or layout shifts. Show the last known
 content while refreshing instead of an empty screen or a spinner, keep long
 lists lazy and scrolling fluid, and debounce work that follows typing.
 Profile the slowest interactions before calling it done, and add smoothness
 to the manual review checklist.>

<Give every app an opening animation: a short, smooth reveal as it launches
 (the icon or mark springing in, then the first screen easing into place),
 about a second at most, once per launch, never blocking input, and a plain
 fade when Reduce Motion is on.>

<Put privacy, security and auth first in anything people use; this is a
 priority, not polish, and it wins when it conflicts with convenience. Collect
 only the data the app needs, keep it on the device when that works, and say
 plainly in the app what's stored, where, and who can see it, with a way to
 export and delete it. Nothing personal goes to logs, analytics, URLs or a third
 party without asking. Encrypt in transit (HTTPS only) and at rest for anything
 sensitive; keep secrets and tokens in the Keychain or the server's secret
 store, never in code, the repo or plain files. Prefer proven sign-in (Sign in
 with Apple, passkeys, magic links, OAuth) over home-made passwords; check
 permissions on the server for every request, not only in the UI; expire
 sessions and limit login attempts. Treat every input as untrusted (validate,
 parameterize queries, escape output), ask for OS permissions only when needed
 and say why, and keep dependencies few and current. Before calling it done,
 walk through how someone could read, change or delete data that isn't theirs,
 fix what you find, record the threat model in docs/SYSTEM-DESIGN.md, and add
 privacy and security to the manual review checklist.>

<Make equations easy to read. Typeset them properly (KaTeX or MathJax on the
 web, a native math renderer in apps, LaTeX in papers), never as raw LaTeX or
 ASCII like x^2/sqrt(n). Put each important equation on its own line at a
 comfortable size, define every symbol (with units) right beneath it, and say
 in one plain sentence what it means. Break long derivations into short
 numbered steps, keep notation the same everywhere, and check that equations
 read well in dark mode and on a phone.>

<Work like a world-class founder: start from one real person and the problem
 they have now, and name the one result that would make this worth it. Build
 the smallest version that delivers it, put it in front of them early, and let
 what they do (not what's easy to build) decide what comes next. Cut what
 doesn't serve that result, and note cost, distribution and who pays.>

<Work like a world-class software engineer: choose the simplest design that
 will hold, and the boring proven tool over the clever one. Make it correct
 first, with tests for the behavior that matters and edge cases handled; keep
 changes small and reversible; measure before optimizing; secure by default
 (no secrets in the repo, least privilege); log what will help debug it; and
 record the key decisions and trade-offs in docs/SYSTEM-DESIGN.md.>

<Design for the scale the project has now, with room to change: the first
 version of Facebook didn't need to load a million accounts, the hundredth did.
 Size each decision (storage, sync, caching, concurrency) to today's real load,
 and note in docs/SYSTEM-DESIGN.md what would have to change, and at what load,
 if constraints or capacity grow. Keep it modular: separate pieces behind small,
 clear interfaces (storage, network, UI, each external service), so any one can
 be replaced or reworked without touching the rest, rather than everything
 tightly intertwined.>

<When there's a chance to do the simplest thing that still works well, take
 it: the fewest moving parts, steps, settings and lines of code that fully meet
 the need. Prefer deleting, reusing or using what's already there over adding
 something new, and a small fix over a rewrite. Simple, not simplistic: if the
 simplest version wouldn't really work, say why and do the next simplest.>

<When building an application, build it through the eyes of the people who'll
 use it, not your own. Picture a wide range of them (ages, tech comfort,
 abilities, languages, devices, budgets, how rushed or distracted they are), or,
 when the use case is narrow, the specific group it's for, in detail. Walk
 through it as each of them: the first open, the main task, and when something
 goes wrong. Build for what they'd need and notice.>

<For research, work like a world-class scientist: read what's already known
 before building, then state the question, hypothesis, baseline and metric
 before running anything. Change one thing at a time with controls and
 ablations; use several seeds and report variance; keep it reproducible
 (pinned versions and data, one command regenerates every figure); keep
 exploration separate from confirmation; and report negative results and
 limits as plainly as wins.>

<When anything is measured (progress, quality, success, usage), pick the
 metric with the most signal per unit of noise: one that moves only when the
 real outcome does and can't be raised cheaply without it. Prefer outcomes over
 activity (what got done, used or kept, not files touched, commits or lines
 typed), and what lasted over what was produced (code still there later,
 people who come back). Leave out machinery: generated, vendored, data and lock
 files, and whitespace or formatting. Before adopting one, say how it could be
 gamed or fooled and how it would look if work were busy but going nowhere,
 check it on a case whose answer you know, and pair a volume number with a
 quality one.>

<Think ten steps ahead before starting. Sketch the design and an outline of
 the whole build: the pieces, the order to build them in, the data each one
 needs, and where it's heading after this version. Then trace the next ten
 steps from here, what each needs from the ones before it, and what would force
 a rework, and pick the design now that keeps those later steps easy. Put the
 outline in docs/SYSTEM-DESIGN.md before writing code, but build only what's
 in scope today.>

<Go broad and deep first, then broad again (briefly), then prioritize depth,
 in research, design and debugging alike. Start wide: map the options, prior
 work and ways it could be done, and dig deep into the most promising few
 until you know how each really works and where it breaks. Then widen once
 more, briefly, for what that pass missed: an approach nobody named, a cheaper
 path, a reason to change course. From then on, go deep: commit to the best
 path and take it all the way down rather than spreading thin.>

<Use sub-agents when they help. Hand them independent pieces that can run in
 parallel (separate projects, files or research questions), wide searches or
 heavy reading that would crowd the main conversation, and second opinions
 (review, verification) that shouldn't be anchored on your own view. Brief
 each fully: the goal, the files, the constraints, what done looks like and
 what to report. Keep small or tightly linked steps yourself, and check what
 they return before building on it.>

<Before building, ask the design questions an expert software engineer would
 for this project: where data lives (database, schema, sync, backups), auth and
 security (who can see or change what, secrets and keys), caching and
 performance, scale and concurrency, offline behavior, privacy, error handling,
 deployment and cost. Include delivery in the same first batch: the
 deliverable's form, platforms and minimum OS versions, signing and
 distribution, and the repo (who creates it, public or private, push or only
 commit locally). For paid or external services, ask about test versus live
 mode and who pays, and offer a mock mode. Ask for real sample inputs and
 working credentials before building. Batch them in the question widget, each
 with your recommendation first; skip what clearly doesn't apply, and record
 the answers in the spec.>

<When an application takes files as input, offer a visible Upload button that
 opens the file picker, accept files dragged anywhere onto the window (not
 only onto a small drop zone), and accept pasting them with ⌘V.>

<Color-code tags, categories and types by similarity: related ones share a
 hue family, with shades far enough apart to tell them apart at a glance, in
 both light and dark mode.>

<Name things the way a person would say them — "Goal Tracker", not
 goal_tracker — for the app, its windows, titles, files people open, repo
 descriptions and README headings. When you create the GitHub repo, name it
 with no "_" or "-": one word or joined words, e.g. GoalTracker.>

<Always in scope: a system design doc in the codebase, docs/SYSTEM-DESIGN.md,
 kept current as the build changes. Cover the architecture (with a Mermaid
 diagram), each component's job, the main flows, where data lives, the key
 design decisions and their trade-offs, how it's tested, and known limits.>

<Always in scope: a prompt log, docs/PROMPTS.md, kept current in every
 session. Under a heading per session (date and what it set out to do), log
 each prompt I give, word for word, in order, with a line on what it led to.
 Redact secrets, keys and personal data, and link it from the README.>

<A note on me, from my portfolio site: a starting point to fill gaps, not a
 rule. Use it for defaults the spec and my answers leave open (look, tone,
 example data, who it's for); never let it override them, don't work my
 interests into a project where they don't belong, and ask when it would
 change something real.
 - Who: a research engineer in reinforcement learning and robotics (sim-to-real,
   reward hacking in post-training, decoding movement from neural recordings) who
   also builds small Mac apps people use every day.
 - Values: high agency, ambition, deep curiosity, caring and courage. Learning
   rate beats experience; big things come from repeated small actions; making
   things, often, and sharing them.
 - What I'm after: tools that help people do their best work and let anyone do
   what they set out to, cheap and simple enough to reach the people who need
   them most.
 - Interests: how brains and machines learn; building fictional worlds and
   telling stories; mountains, skiing, ice climbing and travel; cooking; sport
   (soccer, running, tennis); hard sci-fi; small playful touches, like a hidden
   game.
 - Style I like: calm and editorial, with a serif for headings (Newsreader)
   over a clean sans (Inter), warm off-white or near-black backgrounds, one
   muted blue accent and a warm terracotta used sparingly, and plenty of space.
   Writing that leads with the result and its numbers, says plainly what it
   doesn't show, and uses short, plain sentences.>

<My taste profile: what I gravitate to, from how I've reacted to builds. Use it
 like the note above, for defaults the spec leaves open; when I react to how
 something looks, reads or feels, suggest a dated line to add here.
 - Colour: one muted accent, with colour only where it carries meaning. Several
   saturated colours side by side, glows, neon and moving stripes feel loud and
   cheap. Warm, calm palettes; dark mode that stays quiet.
 - Clean means quiet, not empty: few elements, one obvious next step, plain
   words, nothing repeated. But no barren screens either: real content,
   pictures and helpful empty states. Simple and intuitive over decorated.
 - Density: built for someone who knows what they're doing. Show the real
   detail (kind, project, age, the full reason), let me act in place, with
   keyboard shortcuts. Cut clutter, not information; never feel like it's
   talking down to me.
 - Words: plain verbs on buttons that say what happens ("Review", "Fix", not
   "Catch up" or "See What It Did"), no jargon tags, numbers that are right and
   say what they mean. A wrong or misleading number is worse than none.
 - Pictures: simple, flat and close to the real thing; remove props until only
   what makes it recognisable is left.
 - How I think: push back and make me think; show what a suggestion rests on and
   how to check it; teach the idea so I can do it myself next time; take the
   simplest thing that works; think several steps ahead.>

<Finish by listing every deliverable: path, what it is, how to check it works.>

<Git rules (no Claude attribution, never commit .claude/) are in
 ~/.claude/CLAUDE.md and apply on their own — nothing to repeat here.>

<Keep the changelog at the bottom current.>

<Before building, list the lessons from this spec that apply and how you will act on each. At the end, note which you followed.>

<When the project's kind is unclear, such as whether it is a tool or written content, ask before building.>

<Before building, settle the deliverable's form, target platforms and minimum versions, packaging and signing, and hosting. When the brief conflicts with standing defaults, ask which wins.>

<Before any paid API call, settle who pays, a spending cap, test versus live mode and where keys live, and keep a mock mode so the build runs without spending.>

<When the look, concept or UI direction is open, show two or three concrete mockups or concepts to pick from before building. Never redesign existing UI without asking.>

<Ask early for real sample inputs and working credentials, and check against the live API, model or tool as soon as one path works. When none exist, say so rather than inventing them silently.>

<Before building, write down done criteria with concrete thresholds or formulas for every vague term, plus a list of what is explicitly deferred, and confirm both with me.>

<Before building anything that judges, scores or generates content, decide with me whether an AI model or deterministic rules produce it, weighing cost, explainability and reproducibility, and which model is the default.>

FROM SIMILAR PAST PROJECTS:

<The closest earlier projects by meaning, each with one concrete thing it settled. Examples to learn from, not choices to copy.>

<neuralink_product_dev (website, 89% alike): asked "Another Claude session ('Neuralink product development') is editing this repo right now: about 40 files across all four projects changed in …" and settled on "Wait, then commit (Recommended)">

<social_media_dev (web app, 86% alike): assumed: Text only for v1; single user on local machine; no git repo (declined).>

<photo_analyzer (api / server, 84% alike): assumed: Agent fills this in: anything it had to guess, decisions it made without>

LEARNED ACROSS PROJECTS:

<What held across several kinds of earlier projects: starting points, not rules.>

<Decide which data sources, external services and licenses are allowed, test versus live mode, key storage, who pays, spending limits, privacy, and offline behavior. (across 12 kinds)>

<Settle the deliverable's form, target platforms, minimum versions and distribution up front, including packaging, signing, hosting and who runs it. (across 11 kinds)>

<Define vague terms, scope boundaries and scoring rules with concrete thresholds, formulas and done criteria, recording what is deferred. (across 10 kinds)>

<Validate generated or computed content against real sources, cite them, and label estimates or invented parameters so nothing fabricated passes as fact. (across 8 kinds)>

<Settle version control policy early: who creates and hosts the repository, its visibility, and whether to push or only commit locally. (across 7 kinds)>

<Gather real sample inputs and working credentials early, then verify live APIs, model output and system tools, keeping a fallback ready. (across 7 kinds)>

<Define each output's specs, tone and visual style before building, offering a few concrete concepts or mockups to pick from when open-ended. (across 7 kinds)>

<Plan a manual or human review checklist for what automated tests can't verify, such as hardware, live services, feel or taste. (across 3 kinds)>

LEARNED FOR ML / DATA MODEL PROJECTS:

<Starting points from 13 earlier ml / data model projects, not rules: use what fits this one, and ask when it differs.>

<Settle what produces adaptive judgments or content (an LLM, pretrained or learned model, programmatic functions, bundled data) and which decisions stay in deterministic code. (seen in 8)>

<Settle the interaction loop: how the model gathers evidence (including cold start), what it outputs, and how user feedback updates it over time. (seen in 6)>

<Settle how vague goals become measurable: metrics, rating scales, splits, budgets, thresholds, scoring weights and their calibration, and local stand-ins for hidden tests. (seen in 6)>

<Settle the audience, accounts and login, which source material stays out, whether user data persists, where, and who may read it. (seen in 5)>

<Settle data and reference sources, licenses, keys, citation standards, refresh schedule, stored history, and an offline fallback snapshot before building. (seen in 4)>

<Settle how unmeasurable targets are estimated from proxies, and how assumptions, uncertainty ranges and limitations are disclosed to users. (seen in 2)>

<Settle the concrete task, observations or sensors, action space, and units, matching the conventions of the chosen model or framework. (seen in 2)>

<Settle safety boundaries for high-stakes advice: disclaimers, refusal and escalation rules, emergency handling, and applicable privacy or regulatory constraints. (tentative)>

CONTEXT:

Project type: ML / data model (training and evaluating a model on data, with reproducible runs).

use the image below. combine maml and pearl to do long-horizon post-training. figure out the best-fit environments to test it on at small scale, then test it in higher-fidelity environments later on. sim to real.

Reference images (look at these; they're part of the description):
- inputs/Dropped image.png

DELIVERABLES:

website detailing the novel combined method + experiments + demo

DEFINITIONS AND DEFERRED:

Answers recorded (2026-10-20): purpose = research proposal/preprint + personal
learning + portfolio. "Long-horizon" = all three meanings, as ONE method tested
on three axes. Envs = classic meta-RL suite, chosen after a lit check. Sim-to-real
and high fidelity = clearly labeled roadmap only (deferred). Site = static,
Distill-style article on GitHub Pages; demo = in-browser rollout + recorded
rollouts + latent-space explorer. Repo = public github.com/amalmehta/MEHTAlearning,
pushed. Compute = 2–4 h on this Mac (Intel i9, 16 threads, no GPU), 3 seeds.
Baselines = PEARL, MAML, PEARL + naive fine-tune. Method name = MEHTA.

- MEHTA (the method): "Meta-gradient + Embedded Hidden-Task Adaptation".
  PEARL (Rakelly et al. 2019, arXiv:1903.08254) context encoder q(z|c) + SAC
  actor/critics conditioned on z, PLUS a first-order MAML/Reptile
  (Finn et al. 2017, arXiv:1703.03400; Nichol et al. 2018, arXiv:1803.02999)
  meta-update of the actor/critic initialization taken through a LONG inner loop
  (K_inner = 50 SAC steps per task), with an iMAML-style proximal term
  (Rajeswaran et al. 2019, arXiv:1909.04630) that keeps post-trained weights near
  the meta-init.
- Post-training (test-time adaptation): on a new task, (1) collect context and
  infer z (PEARL, zero gradient steps), then (2) run K SAC gradient steps from the
  meta-init on the task's own online data, re-inferring z from all context, with
  proximal weight λ. K ∈ {0, 25, 50, 100, 200, 400}.
- Long horizon, axis (a), many-step adaptation: return after K post-training
  steps, K up to 400, on in-distribution (ID) and out-of-distribution (OOD) tasks.
- Long horizon, axis (b), long sparse episodes: a 3-waypoint sparse-reward
  episode (horizon 60, reward +1 per waypoint reached). Metric = mean waypoints
  reached (0–3) and success rate (all 3).
- Long horizon, axis (c), continual: 5 OOD tasks post-trained in sequence
  (K = 100 each, weights carried over). Metrics = final mean return over all 5,
  and forgetting = mean over tasks i<5 of (return right after task i) − (return
  at end).
- Small-scale envs (level 1): Point-Goal, modeled on PEARL's sparse point robot
  (origin start, actions in ±0.1, goals on the unit circle, H = 20) but with the
  DENSE reward −‖p − g‖. ID = goal angle in [0, π]; OOD-goal = angle in (π, 2π);
  OOD-dynamics = ID goals with actions rotated 60° (a sim-to-real-style dynamics
  shift). Point-Waypoints for axis (b).
- Higher fidelity (level 2): HalfCheetah-Vel (MuJoCo), a pilot run only if the
  measured throughput fits the budget; otherwise deferred.
- "Beats": MEHTA mean > baseline mean, AND the gap is larger than the sum of the
  two across-seed std devs, on the stated metric. With only 3 seeds, anything
  weaker is reported as "no clear difference".
- Exploration vs confirmation: hyperparameters tuned only on dev seed 100 and on
  ID validation tasks. Confirmatory seeds 0, 1, 2 are run once, and every result
  is reported, including negative ones.
- Done (MVP): `uv run python -m mehta.run_all` reproduces every result JSON and
  figure; the site shows the method, all results (mean ± std), the three demos,
  and the roadmap; tests pass.
- Level-2 plan (not yet run): docs/LEVEL-2-PLAN.md.
- DEFERRED: Meta-World, Isaac Gym / high-fidelity robot sims, domain-randomized
  sim-to-sim and sim-to-real on hardware, compute-matched baselines,
  >3 seeds, cloud GPU, second-order meta-gradients, LLM/foundation-model
  post-training.

RESULTS (2026-10-20, seeds 0–2, confirmatory):

- Latent methods ≫ first-order MAML without a latent (OOD goals −13.9 ± 1.4 vs −29.6 ± 1.6).
- MEHTA beats PEARL alone on ID, OOD-goal and OOD-dynamics after post-training.
- MEHTA vs PEARL + naive fine-tune: no clear difference anywhere. Long vs short
  inner loop: no clear difference. The novel meta-update is NOT supported at this
  scale.
- Continual: MEHTA forgets less than PEARL + fine-tune (−0.40 ± 0.67 vs
  1.12 ± 0.26), but no-proximal does as well, so the gain is not the proximal term.
- Point-Waypoints: every method fails (0% success).

RESULTS v2 (2026-10-20, diagnosed redesign, fresh seeds 3–5):

- Diagnosis of v1 (results/diagnostics): inner-loop gain on training tasks fell
  to +0.39 late in training; the MAML step was ~7% the size of PEARL's updates;
  tasks' inner-loop updates were nearly orthogonal (cos ≈ 0.03).
- MEHTA v2 (test-protocol inner loop on perturbed tasks): no clear difference vs
  compute-matched PEARL + fine-tune on any set; worse than the PEARL-DR control
  on shifted dynamics. The MAML step is still not supported.
- Potential-based Waypoints shaping: success 0% → 27–60% for all methods.

PRE-REGISTERED v3 (written 2026-10-21, before any v3 run):

- Goal: a held-out shift where fine-tuning from PEARL's init is clearly too slow.
- Candidates (all ID goal angles unless noted, never used in training): actions
  rotated 120°; inverted (180°); mirrored left-right; wind = constant drift 0.06
  per step (2× the training max) in a random direction per task; OOD goals +
  60° rotation.
- Oracle per task: a controller that knows the goal and the dynamics, moving
  straight at the goal (per-axis clipped); return over 20 steps.
- Gap closure = (R(K=400) − R(K=0)) / (oracle − R(K=0)).
- Selection uses ONLY compute-matched PEARL + fine-tune (pearl_cm_ft) on dev
  seed 100: pick the candidate with the lowest gap closure among those whose
  K=400 return is still ≥ 30% of the oracle gap short. MEHTA is not evaluated
  during selection.
- Confirmation: pearl_cm, pearl_dr_cm, mehta_v2 trained once on fresh seeds 6–8,
  evaluated on id, ood_goal, ood_dyn and the selected shift, same protocol.
- H (primary): MEHTA v2 beats BOTH pearl_cm_ft and pearl_dr_cm_ft on the
  selected shift at K=400 by the spec rule (gap > summed seed std).
  Secondary: gap closure for each method on that shift.
- Whatever the result, it is reported; seeds 6–8 are not reused for tuning.

RESULTS v3 (2026-10-21, pre-registered, fresh seeds 6–8):

- Selection (dev seed 100, PEARL only): mirrored actions, closure 21%, 79% short.
- H NOT supported: on mirror at K=400, MEHTA v2 −21.9 ± 1.2 beats PEARL-DR + FT
  (−24.8 ± 1.2) but not compute-matched PEARL + FT (−23.5 ± 2.6).
- MEHTA v2's edge is its K=0 start (−30.8 vs −34.6); gap closure 33% vs 36%.
- Rotation 60°: MEHTA v2 now worse than both fine-tuned baselines.
- Oracle reference (greedy, knows goal and dynamics): about −3.7 to −3.9.

PRE-REGISTERED HORIZON ABLATION (written 2026-10-21, before any sweep run):

- Question: does a longer meta-training inner loop (= meta-trained post-training
  horizon, since MEHTA v2's inner loop runs the test-time protocol) give a better
  final adaptation return?
- Config: mehta_v2 unchanged except K_inner ∈ {5, 10, 20, 40, 80} = 1×–16× the
  short-horizon setting (mehta_short, K_inner = 5), set by
  `mehta.experiments --k-inner`. Every other hyperparameter fixed, so compute is
  NOT matched across horizons (each step of K_inner adds 2 tasks × 128 samples).
- Envs point_goal (id, ood_goal, ood_dyn) and waypoints (id); fresh seeds 12–14,
  run once. Metric = mean return over a set's tasks at the last post-training
  checkpoint (K = 400), mean ± std over seeds. Also logged per run: wall-clock
  and peak resident memory (processes share the machine, so cost is relative).
- H: return rises with K_inner (16× beats 1× by the spec rule, gap > summed std).
  Expectation from v1 (5 vs 50: no clear difference): flat. Reported either way.

RESULTS HORIZON ABLATION (2026-10-21, pre-registered, fresh seeds 12–14):

- H NOT supported: return at K=400 is flat in K_inner on every set. Point-Goal
  ID: 1× −4.99 ± 0.81, 16× −4.57 ± 0.47 (no clear difference); OOD-goal
  −17.1 to −18.0; OOD-dyn −6.7 to −7.9. Waypoints: 0.4–1.0, no trend (2× vs 4×
  passes the rule; that's 1 of 10 pairs, so treated as chance).
- Cost: 16× = 2.8× gradient steps, 1.5× sample-gradients (11.9 M → 17.7 M).
  Measured wall-clock (36–59 min) and peak RSS (330–510 MB) were dominated by
  machine load (load average about 100) and run order, not the horizon.

OPEN QUESTIONS / ASSUMPTIONS:

- Assumed SAC v2 (twin Q + automatic entropy) in place of PEARL's original
  V-network SAC; MAML baseline is first-order and off-policy (SAC inner loop), not
  the original TRPO MAML. Both are labeled on the site.
- Hyperparameters are chosen or lightly tuned (dev seed only), not swept; labeled
  as such.
- Related prior work also combines latents with gradient adaptation (CAVIA
  arXiv:1810.03642; MAESN arXiv:1802.07245). The site states this plainly and
  positions MEHTA's difference: an amortized PEARL posterior + long first-order
  inner loop + proximal continual post-training.
- Dev-seed findings (exploration only, seed 100): SAC's learned temperature now
  starts at α = 0.1. With α = 1, a single-task run reached a return of −7.9 vs
  −4.0 after 3k steps. The machine was shared with other heavy workloads (load
  average about 50), so budgets were cut: hidden width 64, 50 updates per
  iteration, the MAML step on 2 tasks every 2nd iteration. Also: KL weight
  0.001 (PEARL's 0.1 assumes reward scale 100; dev PEARL scored −13.5 vs −15.2),
  and training lengthened to 300 iterations × 75 updates, because an oracle with
  the true goal learned fast (−6.3) and the bottleneck was task inference.
  Learning rate 1e-3 and a reward-decoder auxiliary loss gave no gain, so
  neither is used. λ = 0.5 and β = 0.3 were chosen, not tuned.
- No examples you loved or hated were given; the Distill-style direction was
  chosen from mockups.
- The website is not an app: it gets a favicon, a theme toggle and a small
  feedback link (GitHub issues), with no full settings pane.

CHANGELOG:

- 2026-10-20 — created
- 2026-09-15 — added meta-instruction: built-out applications include a small feedback tab
- 2026-09-15 — added meta-instruction: no "Claude" attribution in commits, PRs, or branches
- 2026-09-16 — added meta-instruction: always include a README when adding to GitHub
- 2026-09-16 — changed meta-instruction: ask clarifying questions in the question widget
- 2026-09-17 — added meta-instructions: Claude never a contributor; never commit .claude/
- 2026-09-26 — compressed the meta-instructions and every field prompt; git rules moved to the global instruction file
- 2026-09-27 — added meta-instruction: applications are built as a Mac app first, then a website
- 2026-09-28 — folded inputs, instructions, constraints, deliverables and done criteria into one free-form CONTEXT
- 2026-09-28 — changed meta-instruction: a README on GitHub always includes a visual
- 2026-09-28 — added meta-instruction: name things like a person would, never snake_case
- 2026-09-28 — changed meta-instruction: README leads with visuals; instructions live in a linked guide
- 2026-09-28 — changed meta-instruction: README is visuals and links; details in docs/INSTRUCTIONS.md and docs/FILE-STRUCTURE.md
- 2026-09-29 — changed meta-instruction: GitHub repo names have no "_" or "-"
- 2026-10-02 — added a DELIVERABLES field after CONTEXT
- 2026-10-02 — added meta-instruction: every project has a system design doc at docs/SYSTEM-DESIGN.md
- 2026-10-05 — added meta-instruction: applications include a settings button or tab
- 2026-10-08 — added meta-instruction: color-code tags by similarity (related share a hue family, each distinct)
- 2026-10-09 — added meta-instruction: apps that take files have an Upload button, drop anywhere, and paste
- 2026-10-17 — added meta-instruction: before building, ask the design questions an expert engineer would (data, security, caching, scale, deployment…)
- 2026-10-18 — added meta-instruction: open the MVP for me as soon as a first working version exists, and after each big change
- 2026-10-18 — added meta-instruction: always create a relevant icon for applications
- 2026-10-18 — added meta-instructions: work like a world-class founder, software engineer and (for research) scientist
- 2026-10-18 — added meta-instruction: pick my brain with open questions answered in my own words, as well as multiple choice
- 2026-10-18 — changed meta-instruction: Mac app first only when the request names no platform (from the meta report)
- 2026-10-18 — changed meta-instruction: the first batch of questions also covers delivery, the repo, test versus live mode, who pays, mocks, and real inputs and credentials (from the meta report)
- 2026-10-18 — added meta-instructions: nothing made up passes as fact; fill in DEFINITIONS AND DEFERRED; a clean, restrained interface with mockups and a manual review checklist (from the meta report)
- 2026-10-18 — added a DEFINITIONS AND DEFERRED section
- 2026-10-19 — changed meta-instruction: questions mostly as multiple choice (with a box for my own answer); plain-text questions only when a detailed answer is needed, at most two per round
- 2026-10-20 — added meta-instruction: make the UI/UX buttery smooth (instant response, nothing blocking the main thread, full-frame-rate motion, no flicker or jumps)
- 2026-10-20 — filled DEFINITIONS AND DEFERRED and OPEN QUESTIONS from the first question rounds
- 2026-10-20 — built MVP: method, 24 confirmatory runs, website with demo; results recorded (long-horizon MAML step: no measurable gain)
- 2026-10-20 — added the level-2 plan (HalfCheetah-Vel, Meta-World ML1/ML10; compute-matched; K_inner sweep; 5 seeds; ≈$125–285 on Modal)
- 2026-10-20 — v2: diagnosed v1, redesigned the MAML step, added compute-matched and DR controls, fixed Waypoints shaping; confirmed on fresh seeds 3–5 (MAML step: still no gain; Waypoints: now solvable)
- 2026-10-21 — v3: pre-registered hard-shift test (mirrored actions, chosen with PEARL only on dev seed), confirmed on seeds 6–8: not supported; corrected v2's ceiling claim using a measured oracle
- 2026-10-21 — horizon ablation: K_inner 5–80 (1×–16× short) for mehta_v2 via --k-inner, pre-registered, seeds 12–14; flat (not supported); figure, site section, README
- 2026-11-09 — updated the meta-instructions to the current meta doc
