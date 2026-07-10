# SESSION.md — Algolia-Central-Spectrum (ACS)

## ═══ STATUS (2026-07-10, post-midnight, CLOSED): real offer-caching-race bug fixed, shipped, deployed, verified live. Pure-orchestrator design built out then deliberately killed as redundant. 3 more real bugs caught by live usage after deploy, all fixed. Production stable. ═══

**Status (one line):** The real bug (Generic's deep-dive offer sometimes silently missing) is fixed in production — a new dedicated `ACS-classifier-neural` agent replaces Agent Studio's racy async `config.suggestions` job. 3 more real bugs, all caught by Arijit actually using the live site (none caught by the test suite), found and fixed same session. Everything below is verified live, not claimed.

**Session closed (2026-07-10, re-persisted at close):** no new work happened between the first persist and this close-out — re-verified state is unchanged, all fixes above remain shipped, deployed, and live.

**Handoff complete.** Next session: read this file top to bottom, then `.development-loop/run-2026-07-09-002/` if touching the classifier/orchestrator work further. Nothing is mid-flight.

**Resume action (do FIRST next session):**
1. Nothing is currently broken or blocked. Read this block + the "What has NOT been done" section before starting anything new.
2. If touching the UI: Arijit raised a suggestion — lean on the existing sample-question chips more, add a "click a sample question to get started" hint. Not scoped yet — ask him what exactly he wants before building.
3. ~~`docs/plans/2026-07-09-revert-to-tool-call-and-port-to-ac2.md` is now fully stale~~ ✅ DONE (2026-07-10 later): moved to `docs/plans/archive/`, superseded-by note added at top pointing to the shipped classifier architecture.
4. `mandate-guard.sh` vs. Claude Code's auto-mode classifier — confirmed WORSE than previously known this session (see decisions below). Still needs Arijit's decision on a real fix; every push/deploy in the meantime needs him to run it manually.

**Where we stopped (exact):** Deployed `c3ad2b9` (the real numbered-list rendering fix), verified live via a direct DOM query on `algolia-central-spectrum.vercel.app` (`document.querySelector('ol')` → real `<ol>`, 3 `<li>`, 12px `margin-top` between items — not a screenshot). `git status` clean, `main` matches `origin/main`. No further code changes pending.

**Decisions locked (this session):**
- The offer-detection signal is now a dedicated classifier agent (`ACS-classifier-neural`) called synchronously by the client — NOT Agent Studio's native `config.suggestions` (too racy) and NOT the pure-orchestrator design (built, validated 10/10 on real data, then deliberately killed as redundant once the classifier existed).
- The pure-orchestrator architecture is shelved, not discarded — `.development-loop/run-2026-07-09-002/04-spec-track-b.md` has the full corrected spec (query-provenance fix, `scopeTools` fix) for whoever revisits it for Algolia-Central2's port.
- `MessageMarkdown.tsx`'s block-rendering model changed: lines within a text block are grouped into same-kind consecutive runs (prose/bullet/ordered) instead of classifying an entire block as one unit. This is the correct model going forward for any future markdown feature added to this renderer.
- One shell-call-per-git-action discipline confirmed necessary: never bundle a `git commit` with a following `git push`/`vercel --prod` in the same Bash call — the guard hook blocks the whole thing, including the harmless commit.

**Remaining work:** Arijit's sample-questions UI suggestion (unscoped). `docs/plans/2026-07-09-revert-to-tool-call-and-port-to-ac2.md` needs archiving/rewriting. AC2 port (Phase 1) not started. `mandate-guard.sh` real fix not applied — every push/deploy needs manual intervention. Full 100-question eval never run. Judge calibration (P2b) never run. T6 (real browser click-through of the shelved orchestrator design) never run — low priority now that the orchestrator isn't shipping for ACS.

**Reference files:** `.development-loop/run-2026-07-09-002/` (full build record: intake, risk, architecture review, spec, plan — Track A only, Track B shelved), `docs/spikes/2026-07-10-classifier-empirical-findings.md`, `docs/spikes/2026-07-10-track-a-repeated-query-acceptance.md` (includes the follow-up precision-bug fix + re-verification), `scripts/agents/instructions_classifier.md` (the classifier's prompt, includes the over-triggering fix), `web/src/lib/classifier.ts`, `web/src/hooks/useChat.ts` (`resolveOfferPatch`), `web/src/components/MessageMarkdown.tsx` (the run-grouping fix). Vault: `Projects/Algolia-Central/spectrum/index.md`, `wiki/dev-log.md`, `tasks.md`.

**What has NOT been done (read before claiming anything is finished):** the sample-questions UI suggestion — zero scoping, zero code. The stale plan doc — not archived or corrected. AC2 port — not started, zero code. `mandate-guard.sh` — diagnosed further (confirmed the classifier blocks its own sanctioned self-unlock too), not fixed. 100-question eval and judge calibration — never run. T6 (orchestrator browser click-through) — never run, and now low-priority since Track B isn't shipping for ACS.

**Files written this session:** `scripts/agents/agentConfig.mjs`, `scripts/agents/build_acs_agents.mjs`, `scripts/agents/instructions_classifier.md` (new), `scripts/agents/agentConfig.test.mjs`, `web/src/lib/classifier.ts` (new), `web/src/lib/classifier.test.ts` (new), `web/src/lib/agentStudio.ts`, `web/src/hooks/useChat.ts`, `web/src/hooks/useChat.test.ts`, `web/src/types.ts`, `web/src/components/DiscoveryCard.tsx`, `web/src/components/MessageMarkdown.tsx`, `web/src/config/instance.ts`, `web/src/config/active.ts`, `web/src/config/active.test.ts` (new), `web/src/config/instances/spectrum.ts`, `web/.env.local.example`, `.development-loop/run-2026-07-09-002/*` (full run record), `docs/spikes/2026-07-10-classifier-*` (3 files), `docs/spikes/2026-07-10-track-a-repeated-query-acceptance.md`, `scripts/spikes/track-a-classifier/repeated-query-acceptance-probe.mjs`, `docs/plans/2026-07-10-reconciled-handoff-architecture-build.md`. Commits: `860ed3e` (classifier fix), `be576e7` (empty-answer fix), `ca19f83` (list-fix attempt 1), `c3ad2b9` (list-fix, real).

---

## ═══ PRIOR STATUS (2026-07-10, very early — HOLD, awaiting Arijit review): real E2E test on the NEXT handoff architecture passed 10/10 on real data. Zero Build code written. Production (below) is untouched and still live. ═══

**Status (one line):** Arijit halted further building on a proposed next handoff architecture (a "pure-orchestrator" design tested the night before with hand-faked data) and ordered a real end-to-end test on real data before touching any code. Built and ran that test. It passed. Nothing has been built yet — the next step needs Arijit's explicit go-ahead.

**Resume action (do FIRST next session):**
1. Fix a bug in `scripts/spikes/agent-tool-handoff/e2e-orchestrator-validation.mjs`: `const chainedToSpecialist = turn2.tc2 && turn2.tc2.toolName === 'call_specialist'` evaluates to `null` (not `false`) when no tool call happened, so the later `chainedToSpecialist === r.gotOffer` check reads `null === false` → `false` under JS strict equality. This made the script report the chaining test as "5/10" when the real behavior was correct on all 10 trials (verified by hand from the raw output — every design-question row correctly did not chain, every impl-question row correctly did). Wrap in `!!(...)` and re-run to get a clean report.
2. Run T6 — the one test case not covered by the script: a real browser, network tab, live click-through of the full 3-agent chain (user question → orchestrator → real generalist answer streamed to UI → offer → accept → real specialist answer streamed to UI).
3. Reconcile `docs/plans/2026-07-09-revert-to-tool-call-and-port-to-ac2.md` — it still describes Options A/B (a single generalist agent, no orchestrator), not the pure-orchestrator design that was actually tested and validated tonight. Rewrite or addend it before any Build task starts.
4. **Do not start any Build task (Phase 0 tasks 0.1–0.12, Phase 0.5, or Phase 1 of the revert plan) without a fresh explicit yes from Arijit on the reconciled design.** This is a repeat of the exact mistake he flagged tonight — don't let momentum from a passing test substitute for his sign-off.

**Where we stopped (exact):** E2E test run complete, results reported to Arijit inline in-session (not yet reviewed/approved by him in a follow-up turn). No git changes staged for the test script or its outputs — `scripts/spikes/agent-tool-handoff/e2e-orchestrator-validation.mjs` and `docs/spikes/2026-07-10-e2e-orchestrator-results.json` are untracked, uncommitted. `SESSION.md` itself had a pre-existing unstaged diff from an earlier persist (still present, see the block below — not part of tonight's work, not yet committed).

**Decisions locked (from tonight only):** pure-orchestrator is the design being validated (Arijit's explicit answer when asked); live Agent Studio API via disposable `-dev` copies is an acceptable test method (established pattern, reconfirmed); the full T1–T6 suite runs together, not staged one test at a time (Arijit's explicit choice).

**Remaining work (tonight's thread):** fix the test script's counting bug; run T6; reconcile the plan doc; get explicit go-ahead; only then start Build. Everything else queued from prior sessions is unchanged — see `tasks.md` in the vault project folder (`Projects/Algolia-Central/spectrum/tasks.md`) for the full list (mandate-guard/classifier conflict, `<Chat>` widget swap, 100-Q eval, judge calibration).

**Reference files (tonight):** `scripts/spikes/agent-tool-handoff/e2e-orchestrator-validation.mjs` (the test), `docs/spikes/2026-07-10-e2e-orchestrator-results.json` (raw per-question results), `docs/spikes/2026-07-09-pure-orchestrator-VERDICT.md` (the earlier faked-data spike this test was built to re-verify with real data), `docs/plans/2026-07-09-revert-to-tool-call-and-port-to-ac2.md` (the plan doc that needs reconciling), vault `Projects/Algolia-Central/spectrum/wiki/dev-log.md` + `wiki/open-questions.md` (#13-15, new) + `tasks.md` (new file).

**What has NOT been done (read before claiming anything is finished):** no Build code written; T6 not run; the plan doc not reconciled; the test script's own bug not fixed (its 5/10 chaining number is wrong, the true number is 10/10, but the script itself still prints the wrong one until fixed); no commit made for any file touched tonight; Arijit has not yet given a go-ahead to build anything.

**Files written this session:** `scripts/spikes/agent-tool-handoff/e2e-orchestrator-validation.mjs` (new), `docs/spikes/2026-07-10-e2e-orchestrator-results.json` (new, generated by the script) — both untracked/uncommitted. Vault: `index.md`, `wiki/dev-log.md`, `wiki/open-questions.md`, `tasks.md` (new), `log.md`, vault-root `wiki/hot.md` + `wiki/log.md`, `Projects/AI-OS/My-Projects.md`. Memory: `session_pointer.md`, `project-tracker-status.md`, `MEMORY.md`, two new feedback files (`feedback-null-vs-false-strict-equality-test-scoring.md`, `feedback-validate-architecture-with-real-e2e-before-build.md`).

---

## ═══ PRIOR STATUS (2026-07-09 evening, CLOSED): suggestions migration shipped + live incident fully resolved. Everything below is verified live and is the CURRENT PRODUCTION architecture — tonight's work above did not change any of it. ═══

**Status (one line):** The Generic→Technical deep-dive handoff moved off `consult_technical_specialist` onto Agent Studio's native `config.suggestions`, shipped to `main`+prod (`111c8fd`), survived a live model-deprecation incident (`225b04b`) plus 3 more real bugs found while re-verifying (`0958e32`, `64c48fc`, `d7a999c`) — all fixed and confirmed live in a real browser tonight. The site is stable as of this write.

### ▶▶ RESUME ACTION (do FIRST next session):
1. **Resolve the `mandate-guard.sh` vs. Claude Code auto-mode-classifier conflict** before doing anything else that needs a push/deploy. Every `git push`/`vercel --prod` tonight was blocked for the assistant and had to be run manually by Arijit, even with explicit repeated in-session yes. Two fixes proposed, neither applied: add a Bash allow-rule in `~/.claude/settings.json`, or redesign the hook to use a real permission-prompt instead of a file-write unlock signal. Full detail: memory `feedback-mandate-guard-vs-auto-mode-classifier-conflict.md`.
2. **Check whether `gemini-2.5-flash-lite` is deprecated elsewhere too** — any OTHER project/agent pinned to that exact model ID will have the same failure. Not checked this session outside ACS.
3. Then the older, still-open jobs: the react-instantsearch `<Chat>` widget swap (top deferred architecture item, needs a `frontend-builder` design pass — not started), the full 100-question eval (never run), judge calibration (P2b, never run).

### ▷ What actually happened tonight, in order, with evidence:

**1. Shipped the suggestions migration (9-task dev-loop B0-B9, TDD throughout).** Native `config.suggestions` on both agents replacing the `consult_technical_specialist` client-side tool; R12 removed the tool from Generic; R11 multi-turn history summarization (segment-aware — a code-health review caught that a naive flatten-then-truncate approach silently deleted Technical's content). Code health + security review both clean, 0 Critical/High findings. 25 vitest + 8 node:test passing. Squash-merged to `main`, deployed to Vercel prod. Two real bugs caught and fixed BEFORE this deploy: `generation.max_words` round-trips clean on write but 500s the completions endpoint at runtime; the naive history summarizer (fixed before shipping, see above).

**2. Production broke: `gemini-2.5-flash-lite` deprecated by Google, mid-session.** User report: "No response came back this time" / hung "Writing the answer..." / an `ERR_HTTP2_PROTOCOL_ERROR` visible in real browser network inspection (curl alone gave a false-healthy signal — it never reproduces this error because it doesn't request gzip/HTTP2 the way a browser does). Root cause found via direct curl to the live agent: a literal 404 from the provider, `"This model models/gemini-2.5-flash-lite is no longer available."` Fixed: switched every agent + the suggestions config to `gemini-2.5-flash` (~4x cheaper than `-pro`: $0.30/$2.50 vs $1.25/$10.00 per 1M tokens, confirmed via live web search). Also fixed a latent design flaw: the main agent's model was self-cloning from whatever the live agent record already had, so a future deprecation would have silently perpetuated the dead model forever — added an explicit `MAIN_MODEL` constant in `agentConfig.mjs`. Commit `225b04b`.

**3. Re-verifying after the model fix surfaced 2 more real regressions, from the SAME day's earlier build, unrelated to the model swap:**
- Generic had silently lost its brevity constraint. The old HANDOFF section (deleted when the tool-call mechanism was retired in step 1) contained the ONLY instruction telling Generic not to write full implementation code itself — deleting that "dead" prose deleted a working constraint by accident. Restored explicitly in `instructions_generic.md`'s Role/DEPTH DOCTRINE, without reintroducing the tool. Commit `0958e32`.
- Both agents were recapping the PREVIOUS turn's topic before answering a new question (e.g. asked about Slider, got a full ComboBox recap first) — traced to "the user must never repeat themselves" plus full conversation history now in context, read by the model as license to proactively re-cover old ground. Fixed with an explicit "answer only the current turn" constraint in `_shared_grounding_acs.md`. Commit `64c48fc`. Verified live: same ComboBox→Slider reproduction, no recap.

**4. A built-in sample-question chip got cache-poisoned — 2nd time this exact bug class has hit this project (1st: 2026-07-03).** Agent Studio caches completions by exact literal query text; a fixed sample-question chip sends the same literal string every click, so any transient failure on its first hit gets replayed to every visitor after, forever, regardless of whether the underlying system is later fixed. Today's heavy repeat-testing (mine and Arijit's) re-poisoned the exact ComboBox sample question. Reworded (`web/src/config/instances/spectrum.ts`). Commit `d7a999c`.

**Every one of these 4 fixes was verified live in a real Chrome browser session (navigate, type, click, read network requests) — not just curl, and not just claimed.** Each was tested on a disposable `ACS_AGENT_SUFFIX=-dev` copy first, then confirmed on production after push.

### ▷ Deploy mechanics note (for whoever hits this next):
`git push` to `main` and `vercel --prod` were both blocked for the assistant all night by `~/.claude/hooks/aios/mandate-guard.sh` colliding with Claude Code's auto-mode classifier (see Resume Action #1). Arijit ran every push/deploy manually. Vercel IS wired to auto-deploy from a `main` push — confirmed multiple times tonight — but the canonical domain alias sometimes needs a manual `vercel alias set <new-deployment-url> algolia-central-spectrum.vercel.app` nudge afterward if it doesn't auto-point.

### Where we stopped (exact)
Session ended after confirming `d7a999c` (the reworded sample question) was live in the deployed JS bundle (`index-C5H-mUf3.js`), verified by fetching the bundle directly and grepping for the new wording. No further code changes pending. `git log --oneline -1 main` = `d7a999c`. `origin/main` matches local `main` (push confirmed by the user, then re-verified by `git fetch` + `git status --short --branch`).

### Decisions locked
- Model: `gemini-2.5-flash` for every ACS agent + the suggestions config (not `-pro` — cost, ~4x cheaper, sufficient for this use case).
- The tool-call handoff design (2026-07-08) stays retired — native `config.suggestions` is the permanent mechanism, not a stopgap.
- Generic's brevity constraint and the no-recap constraint are both now explicit, standalone instructions — not bundled inside any other mechanism's prose, specifically so a future cleanup pass can't accidentally delete them again.
- `mandate-guard.sh`'s fix is NOT decided yet — Arijit was given both options (settings.json allow-rule vs. hook redesign) but hasn't picked one.

### Remaining work
- Fix the `mandate-guard.sh`/classifier conflict (blocking, affects every future push/deploy on this machine, not just ACS).
- react-instantsearch `<Chat>` widget swap — not started.
- Full 100-question eval — never run to completion.
- Judge calibration (P2b) — never run, all eval scores directional only.
- Check other projects for `gemini-2.5-flash-lite` pins that would hit the same deprecation.
- Consider whether Agent Studio has a cache-bypass mechanism to prevent a 3rd sample-question poisoning incident (vault open-questions #10).

### Reference files
- Vault: `Projects/Algolia-Central/spectrum/index.md` (compiled-truth zone fully rewritten tonight), `wiki/dev-log.md`, `wiki/open-questions.md` (#10-#12 new).
- Memory: `acs-live-incident-model-deprecation-2026-07-09.md`, `feedback-mandate-guard-vs-auto-mode-classifier-conflict.md`, `feedback-agent-studio-fixed-sample-question-cache-poisoning.md`.
- Dev-loop run artifacts: `.development-loop/run-2026-07-08-001/` (intake through validate, all stages).
- Commits: `111c8fd` (suggestions migration), `225b04b` (model fix), `0958e32` (brevity+retry), `64c48fc` (no-recap), `d7a999c` (sample question).

### What has NOT been done (read before claiming anything is finished)
- The mandate-guard/classifier conflict is diagnosed, not fixed.
- The `<Chat>` swap: zero code written, still just researched.
- The full 100-question eval: never run.
- Judge calibration: never run.
- No check was done for whether `gemini-2.5-flash-lite` is pinned anywhere outside ACS.
- Code health/security review/validate stages in this session's dev-loop pipeline covered the ORIGINAL suggestions migration build — the 4 incident-response fixes made AFTER that (model swap, brevity, recap, sample question) were verified live but did NOT go through a separate formal code-health/security pass. Low risk (small, targeted prompt/config changes) but stated explicitly, not assumed clean.

### Files written this session (code + prompts, not counting vault/memory)
`scripts/agents/agentConfig.mjs`, `scripts/agents/agentConfig.test.mjs`, `scripts/agents/build_acs_agents.mjs`, `scripts/agents/instructions.test.mjs`, `scripts/agents/suggestions_generic.md`, `scripts/agents/suggestions_technical.md`, `scripts/agents/instructions_generic.md`, `scripts/agents/instructions_technical.md`, `scripts/agents/_shared_grounding_acs.md`, `web/src/lib/agentStudio.ts` + `.test.ts`, `web/src/hooks/useChat.ts` + `.test.ts`, `web/src/types.ts`, `web/src/lib/agents.ts`, `web/src/components/DiscoveryCard.tsx`, `web/src/config/instances/spectrum.ts`, `web/package.json`, `web/vite.config.ts`, `.gitignore`, `CLAUDE.md` (repo root).

---

## ═══ STATUS (2026-07-08): Real tool-call handoff shipped + live-tested. Bug fixed. Engagement redesigned. NEXT = react-instantsearch <Chat> swap + full 100-Q eval. ═══

**Status (one line):** Generic→Technical handoff moved from a `[[HANDOFF:technical]]` text sentinel to a real, live-tested Agent Studio `client_side` tool call; deployed, bug-fixed, and the follow-up-question engagement layer was redesigned — but the entire chat client is still hand-built (zero `react-instantsearch`/`algoliasearch` usage) and that's the next real job.

### ▶▶ RESUME ACTION (do FIRST next session):
1. Read this block, then `docs/spikes/2026-07-08-agent-to-agent-tool-VERDICT.md` for the tool-call architecture proof.
2. **Job 1 — scope + execute the `react-instantsearch` `<Chat>` swap.** Packages are already installed (`web/package.json`: `algoliasearch`, `react-instantsearch`). `<Chat>` takes one `agentId` (no native multi-agent routing — confirmed via WebFetch of the real API, not assumed). Its `tools` prop (`{inputSchema, onToolCall, layoutComponent}`) maps closely onto today's hand-built tool-call mechanism — plan: Technical stops being a separate UI "agent identity" and becomes the tool's `layoutComponent` result. This needs a `frontend-builder` design pass per this repo's own CLAUDE.md (design-thinking before any UI build) — don't just start hacking.
3. **Job 2 — run the full 100-question eval.** `lab/eval/src/orchestratorRunner.ts <limit>` (default 100) against the 120-question bank (`lab/eval/src/questions-orchestrator.json`). Only 20-question pilots ran this session (mean 8.02→8.61/10 after 3 bug fixes). Judge is UNCALIBRATED (P2b never run, standing CLAUDE.md gate) — every score is directional, not authoritative; Arijit's explicit call was to proceed anyway.
4. **Job 3 — verify the auto-retry actually helps.** Added a one-shot silent retry in `useChat.ts` for the known empty-completion flake (SESSION.md-documented since 2026-07-03). Not yet observed in real multi-turn browser use, only unit-tested logically.
5. Current live agent IDs (churn every redeploy — `build_acs_agents.mjs` deletes+recreates by name): generic `95826da6-d1b6-4b81-b061-bfb52b881356`, technical `ae127977-c728-4b7c-bc15-6502a77873d1`. Source of truth: `web/src/config/instances/spectrum.ts`.

### What has NOT been done (read before claiming anything is finished):
- The `<Chat>` swap: only researched + deps installed, zero code written.
- The full 100-question eval: never run to completion. Only 20-Q pilots.
- The auto-retry fix: not yet observed catching a real empty-completion in live browser use.
- Generic's minor prose quirk (sometimes asks a redundant question in its own text before the FOLLOWUP token) — noticed, not fixed.
- Judge calibration (P2b): still never run. All eval scores in this session are directional only.

### ▷ SESSION 2026-07-08 — Real tool-call architecture, live bug fix, engagement redesign
Full detail in commits `8b65334`..`fac01d5` on `origin/spike/agent-to-agent-tool` (NOT merged to main — main is untouched, zero deploy risk).

1. **Agent-to-agent client-tool spike, run for real.** An earlier pass in this same session leaned on 2026-06-27 vault research and stopped short of empirical proof; Arijit caught this and had it re-run live. Found the real live-API tool schema empirically (Algolia's own docs shape — `{type:"function"}` — is rejected by the live API; the real shape is flat: `{name, type:"client_side", description, inputSchema}`). Confirmed deterministic pause/resume across 5+2 independent live cycles. Zero production drift. Full writeup: `docs/spikes/2026-07-08-agent-to-agent-tool-VERDICT.md` + `-findings.md`.
2. **Implemented + deployed.** Replaced `[[HANDOFF:technical]]` sentinel-scanning with real tool-call interception in `useChat.ts`/`agents.ts`; updated `build_acs_agents.mjs` to register the tool on Generic only; rewrote `instructions_generic.md`'s handoff section. `npm run build` clean throughout.
3. **Eval loop, 3 real bugs found and fixed** (not just harness noise — verified with live judge transcripts each time): (a) test harness fed the judge YAML frontmatter instead of real `SpectrumDesignDocs` body content; (b) Generic genuinely under-searched on "X vs Y" comparison questions (searched one side, answered the other from general knowledge) — fixed via a new hard rule in `_shared_grounding_acs.md`; (c) harness used `res.text()` on the streaming endpoint — the EXACT bug this same SESSION.md already documented on 2026-07-03, missed because it wasn't checked before writing new code (logged as a standing lesson in memory: `recheck-known-lessons-before-new-harness`).
4. **Arijit's own first live test caught a real bug**: "No response came back this time" on Technical's leg. Root-caused as the pre-existing ~1-in-8 empty-completion flake (not a new defect from the architecture change — reproduced fresh, worked fine). Fixed with a silent one-shot auto-retry on both legs.
5. **Arijit re-flagged the UI architecture, hard**: the entire chat client is hand-built (fetch + manual SSE parsing), zero Algolia frontend library usage. Installed `algoliasearch` + `react-instantsearch`; researched `<Chat>`'s real API rather than assuming (see Resume Action above for findings).
6. **Engagement/discovery redesigned.** The `[[FOLLOWUP:...]]` mechanism was a rigid ~12-word generic template ("How do I make it accessible?" — could follow any answer about anything); Technical never had one at all. Rewrote both agents' instructions to require naming a real, specific prop/component from the actual retrieved hits, dropped the word cap, added the mechanism to Technical. Verified live: Technical's follow-up on a ComboBox question correctly asked about the real `defaultItems`/`items` prop distinction visible in its own code example.

### Reference files
- `docs/spikes/2026-07-08-agent-to-agent-tool-VERDICT.md` / `-findings.md` — the tool-call architecture proof.
- `lab/eval/src/orchestratorRunner.ts` + `questions-orchestrator.json` — the eval harness + bank.
- `scripts/agents/_shared_grounding_acs.md`, `instructions_generic.md`, `instructions_technical.md` — current agent prompts.
- Vault: `Projects/Algolia-Central/spectrum/index.md` (compiled truth + timeline).

---

## ═══ STATUS (2026-07-03 late-night): ✅ JUDGE LIVE IN CHAT + GATE FIXED AT SOURCE + everything shipped. NEXT = optional polish only. ═══
**The grounding judge is now surfaced per-answer and the false-cap bug is fixed at the backend source.** Every answer shows a **Confidence chip** (composite score) bottom-right of its sources; clicking opens a **JudgeDrawer** (3-judge accordions Skeptic/Referee/Advocate + dynamic dimension bars + synthesis rationale). Judge runs on the **hosted VPS** (`ac2-lab-backend` container → `https://judge.contentengagement.info`, Caddy 443, `x-lab-key` auth). **Browser-verified live**: the ComboBox answer that used to read `3.0 UNSUPPORTED` now reads **8.9 GROUNDED** (= panel mean); a fabricated answer still caps to 0 with the fake claims listed. Public app: `https://algolia-central-spectrum.vercel.app`. GitHub `main` @ **`fabbd07`** (v0.3.0). Design system unchanged (Algolia LIGHT: Sora, Nebula Blue `#003DFF`, cobrand Adobe × Algolia). Corpus `ACS_SPECTRUM_MULTI` = 358 recs. Front agent = gemini-2.5-flash-lite.

### ▶▶ RESUME ACTION (do FIRST next session):
1. Read this STATUS block. The judge feature + gate fix + all docs/deploy are DONE and verified live. No open bug.
2. Run app locally: `cd web && npm run dev` (:5173). Judge needs no local server anymore — it's hosted (VPS). Env in `web/.env.local`: `VITE_JUDGE_URL=https://judge.contentengagement.info`, `VITE_LAB_API_KEY=<lab key>` (both also set on Vercel prod). Hard-refresh browser (Cmd+Shift+R).
3. **Vercel CORS risk is CLEARED** — Agent Studio answers + the hosted judge both work from the `vercel.app` origin (browser-verified this session).
4. Only OPTIONAL polish remains: dead `OR "ReactAria"` filter clause on Technical agent; own Adobe Fonts kit; `lab/eval` offline scoring-map bug (live path unaffected); Part 3 operator screen (spec-only). The SourcePills expand + all judge fixes are shipped.

### ▷ SESSION 2026-07-03 (late-night) — Judge surfaced in chat + grounding-gate false-cap FIXED at source
Long session, all closed & verified live:
- **Judge was invisible in the chat** — the engine (3-judge panel) ran on the VPS but the ACS UI never showed it (passive right-rail `JudgePanel` pointed at `localhost:8788`, no auth). Built the AC2 pattern into ACS: `ConfidenceChip` (inline composite) + `JudgeDrawer` (click → full breakdown); retired `JudgePanel`/`RightPanel`. Wired `judgeClient` to send `x-lab-key` from `VITE_LAB_API_KEY`; `VITE_JUDGE_URL` → hosted judge. Env vars set on Vercel via CLI (key pulled from the container, never printed).
- **`JudgeDims` was hardcoded 4-dim** (coverage/depth/relevance) but the deployed service returns the **3-dim** rubric (grounding/confidence/breadthDepth) → would crash. Changed to `Record<string,number>`, drawer renders dims dynamically.
- **THE BIG FIX — grounding hard-gate false-capping to 3.0:** judges scored 7-9 but composite showed 3.0 UNSUPPORTED with no flagged claim. Root cause: the gate caps via **claim recurrence across rounds** (≥60%), but live runs **1 round** → recurrence 1/1 = 100% → ANY single Skeptic flag caps, incl. harmless `unverifiable` flags (hidden from display). **Fixed at the source on the VPS** (`/home/chowmesadmin/lab-judge/lab/server/src/liveJudge.ts` `toVerdict`): cap only on a real, shown contradiction (`violations.some(v=>v.confidence>=0.7)`), else `composite = preGate mean`; `gateTripped` from same. Rebuilt `ac2-lab-backend` image + restarted (backup `liveJudge.ts.bak-judgegate`). Verified: honest answer → mean; fabrication → capped 0 with claims. **This container also serves the AC2 demo (contentengagement.info) — same fix helps both.**
- **UI polish:** SourcePills count badge + "+N release notes" now clickable → expand to show every source as a verify-link. Confidence chip moved bottom-right beside sources. 3 judges folded into accordions; synthesis expanded. Drawer reads `confidence` field (was reading `certainty` → blank %).
- **Base package patched (turnkey):** copied the fixed judge pieces (judgeClient, vite-env, ConfidenceChip, JudgeDrawer, SourcePills) + wired App/ChatMessage/ChatPanel into `Algolia-Central-Artifacts/UI/template`. Rewrote `judge/README-artifact.md` as the turnkey guide; logged both fixes into `AUTONOMOUS-LAUNCH-PLAYBOOK.md` §7 + `BUILD-STATUS.md`. Bumped web to v0.3.0, updated GH description/topics + README diagram.

### ▷ SESSION 2026-07-03 (night) — Docs shipped + Vercel 404 fixed + live-verified
Two-part session, both closed:
- **Docs (Arijit's repeated ask, previously ignored across sessions):** wrote `README.md` (what/quickstart/env-vars-table/run-app+judge/project-layout/corpus-table/deploy, with 2 inline Mermaid diagrams that render natively on the GitHub page) + `docs/ARCHITECTURE.md` (file-level dir-by-dir code map: `web/src/{components,hooks,lib,config,themes,styles}`, `lab/{judge,server,eval}`, `scripts/{crawler,agents,neural}`) + `docs/diagrams/{system-architecture,turn-flow}.excalidraw`+`.png` via `diagram-builder` (render-validated, embedded in ARCHITECTURE.md). Set GitHub repo description + 10 topics via `gh repo edit` (repo previously had zero metadata). Committed + pushed as `973add9`.
- **Vercel 404 → root cause + fix + live verification:** diagnosed via file listing — no `vercel.json`, no root `package.json`, app lives in `web/` → Vercel built repo root (nothing there) → `404 NOT_FOUND`. Added root `vercel.json` (`installCommand`/`buildCommand` = `cd web && npm install`/`build`, `outputDirectory: web/dist`, SPA rewrite). Pushed. User then demanded the env-var step be done via CLI, not handed off — did it: extracted the already-inlined search key straight from `web/dist/assets/*.js` (`0EXRPAXB56` / `b5807cba5eaa2030b6095cd202e4b708`), validated it live against the index via curl (72 hits), `vercel link`'d the repo to project `algolia-central-spectrum`, set `VITE_ALGOLIA_APP_ID` + `VITE_ALGOLIA_SEARCH_API_KEY` for Production via `vercel env add`, ran `vercel --prod` to rebuild with the vars, then verified the live URL: HTTP 200, correct `<title>`, both values confirmed present in the served JS bundle. **Preview env vars were NOT set** — Vercel CLI 50.37.0 has a bug requiring an explicit git-branch arg for "all preview branches" even with `--yes`/`--value`; skipped since the public URL is the Production target, which is fully configured. Lesson captured to memory: `feedback-vercel-monorepo-subdir-404.md`.
- **Still unverified:** whether Agent Studio's completions API accepts the `vercel.app` origin (CORS) — only provable by an actual browser query against the live site, not yet done.

### ▷ SESSION 2026-07-03 (evening) — UI/UX overhaul + discovery + git (all in the PLAYBOOK fix-log)
Big design/UX session. What shipped (all browser-verified, all on the LIGHT Algolia design system):
- **Design system:** rebuilt skin `web/src/themes/algolia-adobe.css` = Algolia DS (Sora via Google Fonts — the old Adobe Clean Typekit was referrer-locked off localhost → looked broken). Cobrand header (Adobe logo left, "Search by Algolia" white/blue wordmark right). **Removed the "Powered by Algolia" footer** (header cobrand covers it — overrides the old UI/README "invariant"). ⚠️ **I once wrongly flipped it to a DARK theme (unapproved) — Arijit rejected it; reverted to light.** Lesson logged: "draw inspiration ≠ copy the reference's theme; never change a fundamental (bg/theme) without approval."
- **Polish:** de-boxed answer cards (no hard border, radius-xl 24px, soft float shadow) + **titled heading band** per card ("ASSISTANT"/"CODE SPECIALIST" accent bar); ambient blue wash bg; rounder composer + pill Send; prettier empty state (eyebrow + big Sora heading). Hero moved up so the sample popover clears it.
- **Human-gated deep-dive** (earlier this session): one answer + a consent "go deeper?" card; specialist runs only on click. `DeepDivePrompt.tsx`, `useChat` runDeepDive/declineDeepDive.
- **Discovery follow-up (REAL, agent-generated):** generic agent emits `[[FOLLOWUP: <question>]]`; `useChat.parseAgentText` strips it; `DiscoveryCard.tsx` renders "YOU MIGHT ALSO ASK →"; click asks it. Verified.
- **Sample questions:** grouped/sectioned config (`sampleQuestions` is now `{section,questions}[]`, 4 sections ×3, grounded, bait dropped); `SampleQuestions.tsx` popover above composer (2-col titled sections); EmptyState shows 1 chip/section.
- **Sources:** grouped by facet w/ **count badges**, clean names, release-notes collapsed to "+N".
- **Robustness:** empty-answer fallback ("No response came back — Try again", never a blank card); `ThinkingIndicator.tsx` phased status animation during the ~5s pre-text dead-air (Agent Studio delivers text bunched at end — no true token streaming); logo-click = reset session.
- **KEY DEBUG LESSON (cost 3 wrong diagnoses):** "empty answers" were NOT flash-lite instability — they were **node `fetch`+`await res.text()` truncating the streaming SSE response**, and those empties got **cached by Agent Studio** (poisoning the exact query). Proof: `curl`+grep = 0/8 empty. Test completions with curl or a streaming reader, NEVER node `res.text()`; never hammer one query (poisons cache). Fully in the playbook.
- **Corpus + agent:** V3 topped up 95→144 via free `scripts/crawler/crawl_html.mjs` (v3 pages are server-rendered — Scout not needed). New reusable `scripts/agents/update_agent_model.mjs` + refreshed `update_generic_prompt.mjs` (adds HANDOFF + FOLLOWUP rules).

### ▷ UX REWORK (2026-07-03) — auto-handoff KILLED → human-gated deep-dive (RC2 alignment)
Arijit flagged the build diverged from RC2: it auto-fired a Generic→Technical two-agent relay on every answer, exposed "Generic/Technical" chips, and put the judge front-and-centre. Dispatched a read of `RAG/AlgoliaRAG-Google/rc2-algolia`+`rc3-phoenix`: RC2 = ONE streaming answer + a **human-gated** specialist deep-dive (user clicks "Proceed to Deep Dive"), NO visible judge, front agent on gemini-2.5-flash-lite. **Fixed in `web/` + browser-verified:**
- `useChat.ts`: no more auto-run. On the handoff sentinel it sets `deepDiveOffered`; new `runDeepDive()`/`declineDeepDive()`. Specialist runs ONLY on user click.
- New `DeepDivePrompt.tsx` consent card (Arijit's copy): "For this topic, our code specialist can go deeper… Want me to bring them in?" [Yes, go deeper]/[No thanks].
- `ChatMessage.tsx`: dropped the `AgentBadge` chips — one assistant answer; `HandoffMarker` relabelled "<specialist> deep dive" for the opted-in leg. Instance labels → `Assistant`/`code specialist`.
- `RightPanel.tsx`: judge `collapsed` defaults **true** (async, on-demand — never blocks/dominates; the answer never awaited the judge anyway).
- **Verified live** (chrome): code Q → one grounded streaming answer → offer card (NO auto-2nd-answer) → click Yes → "code specialist deep dive" divider + real `@react-spectrum/s2/ComboBox` code. Build clean (tsc+vite, 51 modules).
- **DONE since:** (a) front agent `ACS-generic-neural` → **gemini-2.5-flash-lite** (via new `scripts/agents/update_agent_model.mjs`; live, fast, grounds+refuses). (b) **Logo click = reset session** (`useChat.reset()` + `AppHeader` button; verified). (c) **FINAL corrected root cause of the "empty answer" (I was wrong twice — it was ME, not flash-lite):** a node `fetch`+`await res.text()` on the STREAMING completions response intermittently truncated the body to empty. Proof: same fresh queries via **curl+grep** = 0/8 empty on flash-lite; my node harness ~1/8. Those false empties then got **cached** by Agent Studio (identical `messageId` on repeats) and poisoned the browser sample button. **flash-lite is stable — keep it.** Full write-up + testing rules in `AUTONOMOUS-LAUNCH-PLAYBOOK.md` §7 (test completions with curl or a streaming reader, never node `res.text()`; never hammer one query). (d) **Deep-dive sentinel fix:** front agent wasn't emitting `[[HANDOFF:technical]]` on flash-lite (judgment-heavy rule); rewrote `instructions_generic.md` HANDOFF SIGNAL to a hard trigger + pushed → 3/3 fresh impl queries now emit it (offer fires). (e) reworded the ComboBox sample question to escape the poisoned cache entry.
- **Still deferred (Agent Studio prompt edits):** reword front-agent instruction that says "the Technical agent can…"; drop dead `OR "ReactAria"` filter clause; consider strengthening flash-lite's synthesis+sentinel instructions. All in `Algolia-Central-Artifacts/AUTONOMOUS-LAUNCH-PLAYBOOK.md` §7.

### ▷ V3 CORPUS TOPPED UP (2026-07-03 04:16 UTC) — 95→144, the "deepen V3" polish item CLOSED
Completed the pending V3 crawl. **Scout was NOT needed** — react-spectrum.adobe.com/v3/*.html is server-rendered, so plain `curl` gets full `<main>` content. Ran the existing free tool: `node scripts/crawler/crawl_html.mjs --seed https://react-spectrum.adobe.com/v3/index.html --scope /v3/ --source ReactSpectrumV3 --index ACS_SPECTRUM_MULTI --max 300`. BFS reached exactly 144 pages (median 15k ch, 0 empty) — matches the historical full crawl. Added deeper pages: theming, testing, ssr, routing, releases/*.
- **objectID gotcha (why I deleted-then-repushed):** the old 95 V3 records had auto-generated **hash objectIDs** (Scout re-ingest let Algolia assign them), but `crawl_html.mjs` uses **path objectIDs** (`ReactSpectrumV3/v3/X.html`). Same URL, different ID → would DUPLICATE. So: backed up 95 (`scratchpad/v3-old-95-backup.json`, in the throwaway session scratchpad) → `deleteByQuery filters=source:ReactSpectrumV3` → pushed 144 fresh. Verified: 144 records, 144 unique urls, **0 dupes**. Keyword smoke passed (ssr/theming/testing return the new pages top-ranked with real bodies).
- ⚠️ **Neural re-embed:** the ~49 new records are keyword-live NOW but need Algolia to re-embed for neuralSearch — semantic hits on the new deep pages lag ~a bit. Keyword unaffected.

### ▷ SCOUT KEY FIXED (2026-07-03) — root cause was REVOCATION, not credits
SESSION.md previously said "reactivate the Scout tenant to deepen V3." **That diagnosis was wrong.** Real cause: the ACS Scout key (`arijit-internal-apps@chowmes.internal`, "Arijit internal apps key") was **REVOKED** server-side (`hosted_api_keys.status='revoked'` on the VPS), likely swept up in the Jul-3 launch/load-test key rotation — despite **1477 std credits still on it**. That's why Scout returned `403 "API key is not active"` (matches `account_service.py:235-238`). Provisioned a **fresh** hosted key via `Scout/scripts/scout-hosted-admin generate-api-key --email acs-adobe-demo@chowmes.internal --name "ACS Adobe Demo" --key-name "ACS Spectrum crawl key" --plan hosted_beta_pass` → 100 std credits, `/v1/hosted/me` returns 200 active. **ACTION FOR ARIJIT:** the new `scout_live_…` key is NOT yet written to `web/.env.local`/`.env.local` (env-file writes are permission-blocked for me) — paste it as `SCOUT_HOSTED_API_KEY` to replace the revoked one. The 1477 credits stay stranded on the revoked key unless you run one SQL `UPDATE hosted_api_keys SET status='active'` on the VPS.

**RESUME FIRST (next session):** 1) read this file top-to-bottom + `Algolia-Central-Artifacts/BUILD-STATUS.md`. 2) Run app: `cd web && npm run dev` (:5173) + `cd lab/server && npm run judge:serve` (:8788). Search key already in `web/.env.local`. 3) Only OPTIONAL polish remains (below).

**NOT done (explicit — no false completion):** Part 3 operator screen (spec-only, not built); ~~V3 depth~~ ✅ DONE (95→144, 2026-07-03); new Scout key not yet pasted into `.env.local` (see SCOUT KEY FIXED above); Technical agent's live source-filter still has a dead `OR "ReactAria"` clause (cosmetic; needs Agent Studio edit); own Adobe Fonts kit for public deploy (font hotlinks Adobe CDN now); `lab/eval` offline judge scoring-map bug (live path unaffected); nothing git-committed yet (web/, lab/, docs, Artifacts all untracked).

**Sections below = full session history (append-only, newest first).**

_Created 2026-07-01 (session 1). Fork of Algolia-Central2 for Adobe as prospect. Agent namespace `ACS-`._

## WHAT THIS IS
AC2 architecture (strictly-grounded neural agent panel) rebuilt on an **Adobe Spectrum** corpus. See `CLAUDE.md`. Base repo to port from: `~/Dropbox/AI-Development/RAG/Algolia-Central2`.

## STATUS (session 1)
**Corpus INGESTED — Adobe-Spectrum sources in ONE federated index `ACS_SPECTRUM_MULTI`** (app `0EXRPAXB56`). **357 recs**, facet `source`:
- `SpectrumDesignDocs` = 103 — GitHub `adobe/spectrum-design-data/docs/s2-docs` (design guidance; median 4,740ch). `ingest_git_docs.mjs`.
- `ReactSpectrumS2` = 104 — `react-spectrum.adobe.com` S2 (code/API; median 4,866ch) via `llms.txt` + `.md` twins. `ingest_site.mjs`.
- `ReactAria` = 150 — `react-aria.adobe.com` (React Aria headless + internationalized + blog; median 10,025ch) via `llms.txt` + `.md`. `ingest_site.mjs` (body capped 90KB — Algolia 100KB record limit; batch chunk 50).
- **REMAINING (not yet in):** React Spectrum **v3** (~96 pages, `/v3/*.html`) — no `.md` twins → needs an HTML self-fetch path (not built). It's the legacy version; decide if worth adding (overlaps S2).

## KEY LEARNING (drove the whole session)
**Native Algolia Crawler CANNOT crawl a domain you don't own** — `internet.custom.domainAllowed` 400, no API to add a domain (dashboard-only ownership verify). So prospect corpora (adobe.com, github.com) MUST be **self-fetched + pushed via the indexing API** (no domain gate on indexing). This forked the tooling into 3 engines. [[feedback-crawler-domain-allowlist-gate]] · AC2 RUNBOOK #17.

## SKILL BUILT (this session)
`~/.claude/skills/algolia-content-fetch/` — SKILL.md + 3 bundled engines + `crawler-runbook.md`:
- `provision.mjs` — one-click NATIVE crawler for OWNED domains (auto-detects JS-render + sitemap; pre-checks domain allow-list).
- `ingest_git_docs.mjs` — git markdown docs → index.
- `ingest_site.mjs` — un-owned docs site self-fetch (prefers `llms.txt` + `.md` twins).
Tested live on both Spectrum sources. Registered + discoverable.

## AGENTS — GENERIC + TECHNICAL, BUILT + VERIFIED (session 1)
Decision (Arijit): 2 agents = **Generic** (front door, all sources) + **Technical** (React code). NOT designer/developer (that earlier split retired). Live on app `0EXRPAXB56` (gemini-2.5-pro):
- `ACS-generic-neural` — NO source filter (sees all 502). Fronts, synthesizes design+code, routes deep code → Technical.
- `ACS-technical-neural` — `source:"ReactSpectrumS2" OR "ReactSpectrumV3" OR "ReactAria"` (React code, version-aware S2 vs v3).
Smoke PASSED: Generic synthesizes design+availability, routes to Technical; Technical gives real S2 code (controlled ComboBox, `@react-spectrum/s2/ComboBox`). Neural cross-source grounding verified. Artifacts: `scripts/agents/{_shared_grounding_acs,instructions_generic,instructions_technical}.md` + `build_acs_agents.mjs` (clone-base self-hosted = ACS-generic-neural).
**Cleanup:** retired ACS-designer/developer + 4 AC2 leftovers (allsource/bruno/elena/maverick). AC2's live 3-panel (general/developer/marketer3) left intact.

## HTML CRAWLER added
`scripts/crawler/crawl_html.mjs` — BFS HTML self-fetch for un-owned sections with no `.md` twins (used for /v3/ + /releases/). Extracts `<main>`/`<article>`, caps 90KB, chunks 50.

## NEURAL — LIVE ✅
`ACS_SPECTRUM_MULTI` `mode: neuralSearch` (enabled via dashboard Train after `seed_and_enable.mjs` pushed 1,099 events; aggregation took ~1 session to land). NL queries that returned 0 on keyword now work semantically: "let users pick a date"→DatePicker, "show a loading indicator"→Progress bar. Panel auto-upgraded (same index/tool). Verified end-to-end: Developer answers "date range in React"→`DateRangePicker` + real code + `@internationalized/date` (cross-source neural grounding).

## JUDGE HARNESS — PORTED, runs e2e; scoring bug open (session 1)
`lab/judge` (@lab/judge, unchanged from AC2) + `lab/eval` (ACS runner). Uses AC2's Gemini key (`GOOGLE_API_KEY`, copied). Runs end-to-end (askAgent captures retrieved body from tool frames → judge panel → gate → summary). **BUT scores uniformly ~1/10 = a scoring/parse-mapping BUG (not the agents): correct refusal scores 0.00; real-body vs title barely moved mean 1.15→1.04.** Next: debug pass (dump `judgments[].dimensions[].score` + raw judge output; probe must be ESM inside lab/eval w/ absolute env path). P2b calibration gates trust regardless. See `lab/eval/README.md`.

## UI — ALREADY BUILT (prior session, in `web/`, untracked/uncommitted)
Correction to earlier note: the chat UI is NOT a to-do — it EXISTS and is TS-clean + self-reviewed. Full 2-agent chat in `web/` (Vite + React + TS): wire-protocol client `src/lib/agentStudio.ts` (ported from AC2), `lib/agents.ts` config, **handoff via sentinel `[[HANDOFF:technical]]`** that Generic appends → UI fires Technical (Generic agent redeployed w/ sentinel, live-verified). Components: Thread/Composer/Message/SourcePills/HandoffDivider/AgentChip/ToolTrace/EmptyState/ErrorCard + `useChat`. tokens.css (CSS vars, light+dark), aesthetic = theme-dashboard (dark-first). Its own workspace: `web/docs/workspace/acs-chat-ui/`.
Still blocked (both sessions): browser smoke test needs the search-only key (below).

## ✅✅ BROWSER SMOKE PASSED (2026-07-02) — Phase 1.6 done, full pipeline verified live
Search key found in `.env.local` (`ALGOLIA_SEARCH_API_KEY=b5807cba…`, search-only confirmed: search 200 / write 403). Wrote `web/.env.local` (VITE_ALGOLIA_APP_ID/SEARCH_API_KEY/JUDGE_URL). Started judge service (`lab/server` :8788) + dev server (`web` :5173); drove the real app via chrome. Query "controlled ComboBox in React Spectrum" → **Generic answered + grounded V3/S2 source cards → sentinel handoff to Technical → Technical returned real `@react-spectrum/s2/ComboBox` code → live judge: Confidence 9.7/10 GROUNDED (Grounding 10 / Coverage 10 / Depth 9 / Relevance 10, 3-judge + rationale).** Everything works: streaming, grounding-from-`a:`-frames, handoff, live judge, Adobe skin, powered-by-Algolia footer. THE BUILD IS DONE. (Dev server + judge service may still be running in background — app at localhost:5173.)

## ✅ VISUALS FIXED (2026-07-02): real Adobe logo + real Adobe font
- Logo: `web/public/brand/adobe-logo.svg` = the Adobe red-A mark (Arijit's reference). Earlier "broken" = a `--` double-hyphen inside the placeholder's XML comment broke SVG parsing (naturalWidth 0). [[feedback-svg-xml-comment-double-hyphen]]
- Font: **real Adobe Clean Spectrum** now loads. Adobe uses `adobe-clean-spectrum-vf` (variable 100–900) from the Adobe Fonts CDN (`use.typekit.net`) on react-spectrum.adobe.com. Mirrored those exact `@font-face` rules into `web/src/themes/spectrum.css` + put it first in `--ac-font-sans`. Loads cross-origin onto localhost. ⚠️ hotlinks Adobe's licensed kit CDN — fine for internal demo; production needs own Adobe Fonts web project. Falls back to Source Sans 3 if referrer-locked.

## ⚠️ CORPUS RE-INGESTED via SCOUT (2026-07-02) — index changed 502→309
Arijit corrected the sources: the old index had WRONG sources (react-aria, v3-from-old-crawl). Re-ingested `ACS_SPECTRUM_MULTI` **natively via hosted Scout** from the 2 authoritative roots. Now **309 records**, facet `source`:
- `SpectrumDesignDocs` 103 — GitHub `adobe/spectrum-design-data/docs/s2-docs` (recursive `.md`, scraped via Scout).
- `ReactSpectrumS2` 111 — react-spectrum.adobe.com (llms.txt list).
- `ReactSpectrumV3` 95 — react-spectrum.adobe.com/v3 (nav-link discovery; ~48 deep sub-pages NOT captured, old had 144; 1 page `workflow-icons` failed).
- **react-aria (150) + releases (1) REMOVED.**
Push method: backup→clear(keeps settings: neural+facet)→batch 309→verify. **No dupes** (309 = source sum). Old 502 backed up: `scratchpad/index-backup-502.json`.
**Scout hosted:** `https://scout.chowmes.com`, `Authorization: Bearer $SCOUT_HOSTED_API_KEY` (in `.env.local`), endpoints `/v1/hosted/{scrape,crawl,me}`; scrape 1 std-credit/page, `use_js:false` works. ⚠️ **Scout key went INACTIVE mid-run** (403 "API key is not active") — reactivate the Scout tenant to deepen V3 / re-scrape. Neural may need a moment to re-embed the new records.
Re-ingest driver = `scratchpad/push_corrected.py` (needs `ssl._create_unverified_context()` — proxy self-signed cert blocks Python's default verify; curl tolerates it).

## ✅ BUILD DONE (2026-07-02) — Parts 1–2 built + verified; one hold
Status record: `Algolia-Central-Artifacts/BUILD-STATUS.md`. Built via /goal from PLAN.md.
- Part 1: chat (`web/`, Adobe-Spectrum skin, ported client + sentinel handoff) + live judge (service `lab/server/`, UI RightPanel/JudgePanel). Build clean; judge live-tested end-to-end (minus browser).
- Part 2: `Algolia-Central-Artifacts/` = `UI/` template + `new-instance.mjs` (swap proven via throwaway Acme build), `skill/` crawler (extended), `judge/` artifact (package+service).
- **HOLD = browser smoke (1.6):** needs a search-only key for `ACS_SPECTRUM_MULTI` → `web/.env.local` `VITE_ALGOLIA_SEARCH_API_KEY`. Can't read AC2 env (perm); ACS admin key can't mint. Arijit pastes a key, then run dev + `lab/server` judge:serve.
- Old plain-CSS chat archived at `web/_legacy_plaincss/`.

## ▶ AUTHORITATIVE BUILD PLAN (2026-07-02)
`~/Dropbox/AI-Development/RAG/Algolia-Central-Artifacts/PLAN.md` — the `/goal`-ready plan for the whole framework (Part 1 ACS screen chat+judge Algolia-skinned · Part 2 template + crawler skill in `Algolia-Central-Artifacts/` · Part 3 operator launcher, future). Grounded on 3 parallel readers (RC3 screen map, Algolia design-token extraction, crawler skill audit). Key facts: RC3 = `RAG/AlgoliaRAG-Google/rc3-phoenix` (two-column chat + resizable right panel; **NO live judge — we build it**); Algolia tokens = ready CSS-var file in the design-system zip (Sora, `#003DFF`); stack = Vite+React+TS+Tailwind+shadcn. Execute Parts 1–2 via `/goal` against that PLAN.

## ▶ RESUME ACTION — REFACTOR the working app into a DESIGN SYSTEM (Arijit, 2026-07-02)
New direction: ACS UX = **templatizable Algolia-Central framework**. TWO-LAYER: structure (ours, fixed) + skin (client's design system, swappable). Every future `Algolia-Central-[company]` re-applies the same structure with a new skin. Plan (see `docs/workspace/ac-chat-ux/`):
1. Generalize `tokens.css` → frozen `--ac-*` token contract (= the API to any client skin).
2. `src/themes/` — `framework.css` (house default) + `spectrum.css` (Adobe skin: overrides token VALUES only). Load skin per instance.
3. `src/config/` — extract every Spectrum string (title, source-facets, sample Qs, agent labels) into a typed `InstanceConfig`. New company = new config + theme.css, zero structural edits.
4. Components read `var(--ac-*)` + `useInstance()` only.
5. `themes/theme.template.css` + README = the "apply Adobe Spectrum (zip)" contract.
6. Consolidate the two workspaces (`ac-chat-ux` root ↔ `web/.../acs-chat-ui`).

## OPEN DECISIONS (asked Arijit; he stepped away — re-ask)
1. **Search-only key source** (blocks browser test only): (a) mint in dashboard + paste [recommended], (b) give true admin key w/ key-mgmt ACL (the `ALGOLIA_ADMIN_API_KEY` in `.env.local` reads fine but CANNOT create keys — 403), (c) reuse AC2's existing browser key. Add result as `VITE_ALGOLIA_SEARCH_API_KEY` in `web/.env.local`.
2. **Spectrum skin look:** (a) authentic Adobe light — Adobe Clean font, Spectrum blue `#1473E6`, tight radii [recommended, best proves the client-skin thesis], (b) keep dark dashboard, (c) both — dark = framework default, light Adobe = the skin.

Agent IDs: Generic `13809d4b-6b6d-4297-b95c-a934bceef0b4` · Technical `63ab0c86-3493-416b-a771-a820ab25d83d`.
Also open (non-blocking): judge scoring-bug debug pass; snapshot refresh cadence; app/index isolation.

## PROTOCOL READ-RECEIPT (Agent Studio streaming) — locked
`docs/workspace/ac-chat-ux/00-protocol-read-receipt.md`. Endpoint `POST https://{APP}.algolia.net/agent-studio/1/agents/{AGENT_ID}/completions?compatibilityMode=ai-sdk-4`; browser cred = search-only key; SSE frames `0:`text `9:`toolcall `a:`hits(=grounding) `3:`error. Source cards render ONLY from `a:` frames.

## CONCERNS (logged)
- Design-docs = point-in-time offline archive (drifts); citation URL = GitHub blob not a live doc page.
- react-spectrum overlaps design-docs on component names → argues for the 2-persona split.
- Third-party ToS: internal demo/eval only, don't republish.

## FILES
- `scripts/crawler/{provision,ingest_git_docs,ingest_site}.mjs` · `.env.local` (4 creds from AC2, gitignored) · `data/` (cloned repo, gitignored)
- Vault: `Projects/algolia-central-spectrum/` (index, overview, open-questions, log)
