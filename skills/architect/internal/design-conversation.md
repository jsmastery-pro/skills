# Architect Main Flow: design conversation

### Scope validation (before Framing)

Run these two checks in order; Check B before Check A.

**Check B: "Already built" detection (runs first)**

Scan the topic for phrases signalling an existing decision: "I built", "we built", "we're using", "we use", "I use", "we chose", "I chose", "already using", "already built", "just document", "document the decision we made", "decided to use", "we went with", "we're on".

If found, before anything else present a decision panel (plain text options where the agent has no picker): "This sounds like an existing decision you want to *document* rather than explore from scratch.", options: **Document it (write the spec from what you tell me) (recommended)** · **Go through the full design process**.

If they pick Document it:
1. Capture the rationale behind the already made decision, as plain text (free text, not MCQ) questions generated for this specific decision. Cover at least these three angles, worded for what they built, and add any that this decision clearly raises: the **alternatives** they considered before choosing this (even a brief "we looked at X and Y but went with Z"), the **main reason** they chose it over those alternatives, and the **tradeoffs** the team is accepting (what it makes harder). Ask more if the decision has other load bearing rationale worth recording; the goal is a faithful account, not a fixed three.
2. Wait for their answers.
3. Take the documentation path: skip the staged conversation. Keep their answers as `DOCUMENTATION_CONTEXT` alongside the design topic, and treat the staged answers slot as `"skipped, documenting an already-made decision"`. Still infer the framing (MODE, platform, stack) from the topic + `AGENTS.md`.
4. Write the spec yourself as a documentation task: `DOCUMENTATION_CONTEXT` is the engineer's account. Read existing code if `SOURCE_FILE_COUNT` > 0 to verify and supplement (via a `scout` for a large repo). Document what was built, not another evaluation of options. Because this is **already shipped**, set `**Status**:` to **`Accepted`** at creation (not `Proposed`); same whenever the linked scope feature is already `existing` (shipped before this workflow existed).

If they pick the full process: proceed to Check A, then Framing and the staged conversation normally.

**Check A: Product vision vs. specific decision (runs second)**

Product scoped topic: describes what the product *is* rather than what to *decide* ("a B2B SaaS that manages teams", "a marketplace for freelancers"), names no specific technical component, feature, or technology, would need 5+ separate specs, and uses business/product language. Decision scoped: names a specific component, feature, or technical concern ("auth approach", "team invitations feature", "should we use PostgreSQL or MongoDB").

If product scoped, do not start the staged conversation yet:

1. Tell the engineer: "This describes a full product. /architect works one decision at a time. Let me help you pick the first foundational decision."
2. Generate 4 foundational first decision options tailored to the product type and present via your agent's interactive picker (`AskUserQuestion` on Claude Code), or the same options as plain text (question: "Which foundational decision should we design first?", header: "First decision"). For most products: tech stack/architecture, auth/identity, core domain data model, and the most important product specific concern, worded for what they described.
3. After selection: update the design topic to that decision and proceed to Framing.

---

### Framing: infer, don't interrogate (no fixed question round)

Infer the framing from the topic + `AGENTS.md` + codebase, don't ask it. State it back in a line or two so a wrong read is cheap to correct, then spend all questions on the feature:

- **Mode**: `FEATURE` (new feature) · `ARCHITECTURE` (foundational stack) · `ENHANCEMENT` (changing something that exists) · `CROSS-CUTTING` (a project-wide standard). Infer from the topic and whether the thing exists in code; confirm only if genuinely ambiguous.
- **Platform**: web · mobile · API/backend · a mix. Infer from the stack in `AGENTS.md`, never assume web; it changes the questions (mobile auth, offline, push differ from web).
- **Workspace (monorepo)**: if a monorepo (workspaces config, or `apps/*`/`packages/*` manifests), identify which workspace this feature belongs to (topic, path, or the scope row's `Code area`; ask if unclear). Read that workspace's nested `AGENTS.md` for *its* stack (apps often differ; don't assume the root stack). Note the workspace in the spec's Context, and whether the decision is app-specific or repo-wide.
- **Stack & conventions**: language, framework, DB, community skills, from `AGENTS.md` (the target workspace's in a monorepo). Inferred, never asked.
- **Constraints**: team size, scale, compliance, from `AGENTS.md` / the product. Ask a per-feature compliance question only when *this* feature touches regulated data (payments, PII, health), never a generic deadline/team menu.

State it: *"Reading this as a new **FEATURE** on your existing stack (from `AGENTS.md`), web (correct me if not)."* Then begin the staged design conversation.

---

### Staged design conversation: gated, acceptance criteria first (main model)

An ordered sequence of stages walked one dimension at a time: one question per real choice, offering the current real options with your suggested pick marked (one line why); the engineer chooses. Never bundle a whole decision (the full acceptance criteria set, data model, stack, endpoint table, or authz model) into one accept or change panel; that applies to every stage. Assemble the spec from their per question answers; the engineer confirms the assembled result in the final spec review (the one place a whole artifact is shown for accept or change), and the data model additionally gets a light confirm at the end of its own walk, because a wrong one cascades. No vital dimension is silently decided or skipped. What you build becomes the spec's `## Requirements` and `## Build plan` (decision only spec: the `## Proposed stack`). Generate every question from *this* topic; an auth feature, a reviews feature, and a stack decision share none.

Mechanics (every question, no exceptions):
- **Offer the real options; exactly one is marked `(recommended)`** with a one line why (you make the call, they override). List every choice that genuinely applies, not a token two. Where the picker caps the count (Claude Code's `AskUserQuestion` allows four), present the strongest and let the custom slot carry the rest, or split across rounds; never drop real options to fit.
- **The last choice is always a free text custom input.** Claude Code's picker appends that "Other" slot automatically (don't add your own); in a plain text fallback, add it explicitly as the final option. This holds for design questions and confirm panels alike (the data model, accept the spec, References consent, an overlapping spec): one recommended option plus the custom slot.
- **Grill down to the smallest load bearing decision.** Work out every decision this specific project needs, from the big architectural calls to the smallest tool and setup choices, and ask each as its own question with a recommended pick and current, real options you generate at runtime. No choice is too small to route through the engineer; never silently decide one for them.
- Capability first, per the picker/custom slot mechanics above. Batch related questions up to 4 per call, run as many rounds as a stage needs, fold prior answers forward so it reads as one continuous interview.

Still infer the framing, but ASK the design inputs. Within each stage, sort every dimension INFER / ASK / RECOMMEND (see *Asks vs acts*): INFER silently from the prompt/codebase/`AGENTS.md`; ASK the engineer the design inputs (data model, stack, provider, methods, rules) one phase at a time with a suggested pick; RECOMMEND the small internal implementation details they don't want to weigh in on.

**Your mandate (senior+ role):** you are the Staff/Principal engineer accountable if this ships wrong. The spec is the complete build spec `/develop` implements from; any blank dimension becomes a question partway through the build, or a wrong guess. Leaving a gap is the failure mode; be exhaustive, cover everything a senior engineer would pin down before writing code.

**Before the stages, enumerate every load bearing dimension of this feature and assign each to the stage that owns it,** sorting each INFER / ASK / RECOMMEND. Checklist (not all apply; add feature specific ones):

- **Functional scope & boundaries**: what's in, what's explicitly out, key user flows with happy/unhappy paths
- **Data model & persistence**: entities, fields, types, nullability, relationships, indexes, uniqueness, retention/deletion
- **Lifecycle & state machine**: states, valid transitions, who/what triggers each
- **API / interface surface**: endpoints or actions, inputs, outputs, status codes, versioning
- **Authentication & authorization**: who may do what; ownership, roles, scoping across tenants
- **Validation & business rules**: limits, quotas, invariants that must always hold
- **External integrations**: providers, webhooks, idempotency, reconciliation
- **Library / provider & build vs buy**: central for any feature with a real implementation choice (auth, payments, search, storage, email, realtime); owned by Stage (c), whose rules apply (fresh current options, suggested pick, engineer chooses). For auth the mechanisms are: the project's existing platform/BaaS auth · a hosted auth provider · an auth library you host yourself · roll your own; pick the specific current products at runtime, never a frozen list.
- **Failure & edge cases**: concurrency, retries, timeouts, partial failure, empty/error/loading states
- **Performance & scale**: expected volume, pagination, async vs sync, caching
- **Security & compliance**: PII, encryption, audit logging, rate limiting, regulatory scope
- **Observability**: what to log, metrics, alerts
- **Configuration & secrets**: new env vars, feature flags, credentials
- **UX surface (if UI in scope)**: capture the requirements (what each screen must show/do, states, accessibility); leave pixel/layout detail to `/develop`
- **Discoverability & SEO (public facing features)**: for any publicly indexed page: metadata, structured data (JSON-LD), OG/social cards, canonical URLs, sitemap/robots, SSR/SSG vs client render. Skip for internal/auth walled surfaces.
- **UI design (when the topic IS a page/screen, e.g. "home page UI", "shop page UI")**: a real design decision; the spec is the page's build spec. Settle:
  - **Design source: ASK, never assume.** Never auto pick the source (not even "a Figma MCP is connected, so use it"). Ask *"How should I get the design for this?"* as a panel with no recommendation picked in advance: **From Figma** (use, or offer to connect, the Figma MCP to pull the real tokens, spacing, components, and frames) · **From a screenshot or images I'll give you** · **From the existing `design.md` / current UI** · **No design yet, suggest a direction** (only if picked do you propose a style). The picker adds its own Other. Record the chosen source in the spec (for Figma, which file and frames) so `/develop` uses the same one. If they pick Figma but no MCP is connected, point them to connect it (see *Tool skills & MCP*), then proceed.
  - **Design system**: a `design.md` (or a design tool MCP as above) is the source of truth if present. If not, decide the direction so `/develop` isn't inventing a look. A design system that doesn't exist yet is itself spec worthy (cross cutting; every page depends on it).
  - **Page composition**: what sections/blocks the page contains and in what order (e.g. home: hero → featured categories → product grid → social proof → footer); the "what goes on the page" the engineer alone knows.
  - **Component inventory**: the reusable components the page needs (cards, nav, filters, carousel), existing vs net new.
  - **Asset strategy**: when no screenshot/design was given and the repo has no images, decide the fallback (real assets the engineer will add, or an online placeholder source, e.g. a stock photo or avatar placeholder service), so `/develop` doesn't stall or invent broken paths.

Then walk the stages in order as one continuous, step by step interview. Ask each dimension as its own question with a suggested pick, take the answer, move on. Do NOT lead any stage with a proposed bundle for accept or change; assemble as you go.

**Stage (a): Requirements (ask step by step, then DERIVE the acceptance criteria).** Do not open with a finished acceptance criteria list. Ask the requirements one question at a time, seeding each from the scope row's intent + seeds when present and suggesting an answer: the core job, the main (happy path) flow, the key rules and limits, the important failure cases. From the answers, derive the acceptance criteria (`AC-1`, `AC-2`, …) as you go; they are the contract `/develop` builds to and `/check verify` checks, the spine every later stage and build task hangs off. The engineer reviews the assembled ACs in the final spec, not partway through.

**Stage (b): Data model (MANDATORY, ASK → assemble → SHOW → confirm → iterate).** Never skipped for a data backed feature. ASK, don't guess: elicit in batched questions, never open with a finished schema: first the **entities**, then per entity the **fields** (name, type, required or nullable), then the **relationships** (which relates to which, cardinality 1:1 / 1:N / N:M), then the **rules and constraints** (uniqueness, retention, invariants). Offer example options inside a question to make answering fast, but no complete ERD filled in advance to accept or reject. Then assemble the model from their answers and SHOW it as an ERD style table: entities, primary keys, foreign keys, cardinality. Gate (a confirm panel, one recommended option): *"This matches what I described (recommended)"* · *"Change/add/remove a field or entity"* · *"A relationship is wrong"*. ITERATE (revise and SHOW again) until Accept. On sign off, derive the migration as build task 1 (feeds `## Build plan`).

**Stage (c): Stack & tool walk (you suggest, the engineer picks).** Drive the walk automatically in a sensible dependency order, batching independent layers up to 4 per round (the mechanics above), which cuts round trips; the engineer never has to ask you to move on. Batching separate layers as their own questions is not bundling a finished stack. Which layers apply is your judgment from the platform and topic, not a fixed script (a web app, a mobile app, an API service, and a data pipeline share no layer list). A typical web app walk, illustration only: application type / architecture pattern → language → framework → database / persistence → auth approach → hosting / deployment → background jobs → email / notifications → file storage / search → observability → API shape. Per layer, present the current, real options, mark your suggested pick (one line why, prefer reuse of what the project runs), let the engineer choose. Illustration only: ask the layers and the finer tool or setup decisions THIS project actually needs, not just those named here. Generate the options FRESH and CURRENT at runtime, never a hardcoded/canned list (this category rots fastest); be honest about staleness (*"as of my knowledge; this space moves fast, verify current"*). Skip any layer the existing stack already settles (INFER from `AGENTS.md`; don't ask again about a decided layer). For an ENHANCEMENT most layers are inferred; for an ARCHITECTURE / greenfield stack decision this walk IS the whole conversation (see the ARCHITECTURE note below). For greenfield, the References consent below folds in a current landscape check (the web option runs it before the stack questions).

  **References consent (one panel, capability first).** ONE ask, not two (web assistance gate and references ask combined). Ask before the stack drill down for a greenfield decision (so current options can be checked); the write step reuses the answer, never asks again. Record the outcome as `REFERENCES_LEVEL`:
  - **question**: "Add a References section to the spec (where the recommendations come from, and optionally links)? The full reasoning (the Rationale) stays either way. For a greenfield stack decision the web option also checks the current tool landscape so the options are not stale. Web fetches cost some extra tokens."
  - **header**: "References"
  - **options** (each sets `REFERENCES_LEVEL`):
    - `No references, keep it clean (recommended)` → `none`
    - `Sources only (named project sources and practices, no web fetch)` → `sources`
    - `Sources plus web verified links (fetches pages to confirm the links, costs some extra tokens)` → `sources+links` (for a greenfield stack decision this also runs the current landscape check)

  For a greenfield/foundational ARCHITECTURE stack decision, make `Sources plus web verified links` the recommended pick instead (verify the landscape before presenting options). When `sources+links` is chosen for a greenfield stack decision and your agent has web tools, run ONE quick current landscape check before the stack panel; without web tools, proceed from your knowledge and flag the staleness.
  - **Cap/cache web research (runs once, in a subagent).** The landscape check is a web fetch, so it runs in a read only `researcher` subagent on the cheapest model (Claude Code: `haiku`, never inheriting the session model). It runs once here; the links it confirms are what you later write into References, and nothing fetches them again. Search undecided layers only. Max 5 searches / 8 pages, official docs/registry first; return top options, freshness notes, links. Reuse `docs/.agent-cache/research/<slug>.md` when under 30 days old unless asked for "latest today". Cap the reply at 40 lines, overflow to that cache file. No web capability → proceed from knowledge and flag the staleness.

  **Agent Skills & MCP servers.** When this stack walk settles one or more NEW tools not already installed or declined, read `internal/tool-discovery.md` and follow it. Its Step 1 asks the engineer whether to look for Agent Skills and MCP servers at all, and nothing is searched, fetched, or installed until they say yes. On yes, the search runs in the background (a read only, fast, low cost subagent) so it overlaps with the rest of this interview, and the found skills and servers are offered on the main thread. Asking is mandatory; searching is not. Skip the file entirely when no new tool is chosen (an ENHANCEMENT reusing the existing stack).

**Stage (d): API / interface surface (walk each endpoint).** First which surfaces the feature needs, then per endpoint its method, inputs, outputs, auth requirement, and key errors. Then **close the value sourcing loop**: for each acceptance criterion, take every value it needs an action to produce, compute, or display, and confirm the surface names a source for it (an input param, a DB column, derived from a named value, or a prior decision). A required value with no named source is an undecided input, not a build detail: ASK the engineer when only they know it, RECOMMEND otherwise, and add the resolution to the surface before moving on. Procedural, not a checklist: trace each value the ACs need, do not scan a fixed list of sources. Illustrations of the pattern only: an AC that reads "streak is 0 when the last read is before yesterday in the user's local day" needs "the user's local day", so name where the timezone comes from (a column, a client param, request headers); a displayed total names its rounding/currency source; a per tenant view names how the tenant is resolved. This is what fills the spec's **Value sourcing** table and stops `/develop` from inventing the missing source.

**Stage (e): Security & authorization (walk each rule).** Who may do what, rule by rule (ownership, roles, scoping across tenants and orgs), plus any compliance scope this feature triggers (payments/PII/health).

**Stage (f): Edge cases & failure modes (walk each case).** The handling one failure at a time (concurrency, retries, timeouts, partial failure, empty/error/loading states).

**(UI page features**, topic IS a page/screen: insert a page design stage between (a) and (d) that walks page composition/sections, design system direction, component inventory, and asset strategy (the UI design checklist bullet) one question at a time, suggesting a pick each. No upfront full layout to accept or reject.**)**

**(ARCHITECTURE stack decisions**, the topic IS choosing the stack/foundation (e.g. `/architect stack & architecture`): do NOT lead with Stage (a) acceptance criteria as a set to confirm. The conversation IS the Stage (c) stack walk: layer by layer (application type → framework → database → auth → hosting → API → observability, and so on, plus every finer tool and setup decision this project needs), batched per the mechanics, suggesting a pick and letting the engineer choose. Any light acceptance criteria and a data model sketch are derived from the chosen stack afterward, not gated up front. Stages (b), (d), (e), (f) collapse into "derived from the chosen stack"; the walk is the work. After the stack walk, ALWAYS run the Tool skills & MCP offer for the tools just chosen (a stack decision picks the most tools: framework, database, auth, ORM, hosting). Do not skip it or defer it to a `/audit` follow-up; run it before you write the spec.**)**

**Quality bar per stage:** every option maps to a real, feature specific decision (never a placeholder like "how complex is the data model?"), each with a one line tradeoff; allow several answers where they are not exclusive. One question per dimension, suggested pick marked with a one line why, and never add your own Other. No `(basis: …)` tag or source citation in option labels; the source and reasoning behind a recommendation belong in the written spec (its Rationale, which always stays, and its References section when opted in), not the live panel.

**Collect the RECOMMEND items** you will settle yourself when you write the spec (calls better made with full design context) as a list; decide each there, stating the pick + one line why + the runner up, and never echo one back as an open question.

**Completeness gate (before writing, do not skip).** Do not start writing the spec until every load bearing dimension above is accounted for: each is ASKED, or INFERRED with the inference stated back, or explicitly not applicable. Any still open → keep asking; an unasked dimension becomes a guess partway through the build. Depth is the goal: when in doubt, ask the extra question. Never fold two distinct dimensions into one option, never end with a dimension silently skipped. A short interview is a red flag; a real feature spans many dimensions and many batched rounds.

**After all stages are signed off** (buildable feature spec): the confirmed acceptance criteria seed the spec's `## Requirements`; the confirmed data model, API surface, and stack derive `## Build plan` (each task tagged with the AC it satisfies, the migration first). For a decision only spec (an ARCHITECTURE stack decision or a CROSS-CUTTING standard) there is no `## Requirements`/`## Build plan`: the spec is the decision itself (`## Proposed stack` / `## Standard definition`), and the feature that executes it (e.g. the scaffold sub task) derives its steps at `/develop` time. Order and slice the plan through your Staff/Principal lens on the feature's build approach (read in pre-flight: row override, else project default), reasoning about what it implies rather than a fixed recipe (e.g. Facade may move the data model migration later than task 1; Tracer Bullet stands up a working end to end slice before thickening). With no approach on record, default to end to end slices and note the assumption. Then write the spec (below).

**What good, feature specific staged grilling looks like** (illustrations of depth, not a script; generate the equivalent, and current options, for the feature at hand):
- `/architect auth` (no auth yet) → (a) ACs for sign in/session/reset · (b) identity/session data model · (c) which sign in methods (email+password · magic link · OAuth · passkeys · SSO)? then which auth approach, options fresh & current, aligned to the stack (a project platform with built in auth is the aligned recommended pick, vs a hosted provider, a library you host yourself, roll your own) → its config · (e) roles (customer/admin), ownership · (f) lockout, token refresh failure; mobile: token storage, biometric, deep link callback.
- `/architect home page UI` (no design/screenshot given) → which sections and in what order (hero · featured · how it works · testimonials · pricing · CTA · footer)? · what does each section show/contain (copy, data, imagery)? · build to an existing `design.md`, or pick a direction? · which components (existing vs net new)? · assets: real files the engineer will add, or a placeholder source? · responsive/mobile behavior. When the UI isn't specified, *you* extract the page's contents from the engineer; don't invent them.

**Too vague to generate from?** (rare; the topic should have been narrowed first) There are no canned questions to fall back to. Narrow instead: run Scope validation again or ask one clarifying question, then generate the stage questions from the dimension checklist above. Feature specific questions always, never a generic MCQ list.

**Skip the staged conversation** on the "documenting a made decision" path (Check B); proceed directly to writing the spec with the documentation context.

**Enhancement mode guard**: if the inferred mode is `ENHANCEMENT` AND `SOURCE_FILE_COUNT = 0`, stop before the staged conversation and tell the engineer:

"Enhancement mode reads existing code to understand what's being changed, but no source files were found. What's the situation?
- A) The code exists in a different directory. Tell me the path and I'll check again.
- B) There is no existing implementation. Then this is really a new **FEATURE** (or **ARCHITECTURE**)."

Wait for their answer. If (A): run the source file count for that path again. If (B): switch the inferred mode and continue.

---
