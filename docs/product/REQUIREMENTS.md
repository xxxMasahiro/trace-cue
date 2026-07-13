# REQUIREMENTS.md

## Purpose

TraceCue is the canonical product identity. The legacy Browser Debug CLI name and `browser-debug` commands remain compatibility aliases during the migration.

TraceCue should make visual evidence, browser debugging, and UI review reusable across repositories and AI agents. It should provide a local Playwright-based command surface that can observe a page, expose safe action candidates, run selected actions, and produce evidence for UI/UX and functional debugging.

## Users

- Developers who want fast browser-debug feedback during feature work.
- AI coding agents that need browser state without depending on Playwright MCP.
- Reviewers who want reproducible UI/UX findings with screenshots, traces, and notes.
- OSS users who want a repository-agnostic CLI they can add to different projects.

## Required Outcomes

- Provide a standalone CLI that can be used from any repository.
- Use Playwright as the browser automation layer.
- Provide a Node.js package layout with a stable local CLI binary before public release work starts.
- Support fast headless observation for routine debugging.
- Support headed browser and DevTools workflows for visual quality, animations, hover, focus, scroll, and final interaction checks.
- Support an opt-in process-scoped supervised browser run for ordered local actions when one-shot observation is too slow.
- Support an opt-in local background daemon for ephemeral browser supervision when a browser must stay open across CLI invocations.
- Support opt-in persistent browser sessions for cases where the current authenticated or multi-step page state must survive across CLI invocations, while keeping the retained context local, TTL/idle bounded, origin-allowlisted, receipt-backed, redacted, and independent of existing browser profiles.
- Support manual-login checkpoints where the human performs authentication in a headed browser and TraceCue records only completion evidence, checkpoint metadata, screenshots when requested, and redacted summaries.
- Support explicit storageState import/export only as an admin-only local opt-in under the configured artifact auth directory, with value-silent receipts and no cookie, token, password, or local-storage value printing.
- Return structured page observations suitable for AI decision making.
- Provide explicit action candidates instead of requiring raw DOM scraping.
- Record reproducible artifacts such as screenshots, traces, console messages, network summaries, and issue reports.
- Keep JSON output deterministic enough for agents, scripts, and regression tests to consume.
- Keep secrets, cookies, storage state, and existing browser profiles out of committed artifacts.
- Keep the design agent-independent: Codex, other agents, scripts, or humans should all be able to use the same CLI.
- Prepare for OSS distribution through local Git, GitHub publication with `gh`, CI, and npm packaging in later phases.
- Prepare a CLI-first review platform that exposes the same review core through MCP adapters without making MCP the required runtime.
- Preserve three usable integration paths: the CLI for any shell, human, or agent; MCP stdio for MCP clients; and a Codex plugin wrapper for skill/MCP discovery.
- Provide an explicit safe HTTP MCP endpoint for local MCP-compatible tooling that cannot use stdio, while keeping it loopback-only, bearer-token gated, and limited to safe no-browser/read-only tools.
- Provide machine-readable MCP client configuration output so humans, agents, and external repositories can connect through stdio or explicit safe HTTP without reverse-engineering package internals.
- Provide machine-readable MCP capability policy output so humans, agents, and external repositories can see which profiles, transports, admin-only agent execution tools, and remaining write/execute exclusions are currently in force without starting a server or inspecting source files.
- Provide a shared read-only operation registry and risk taxonomy so humans, dashboards, agents, MCP capability reports, and MCP execution gate reports can inspect risky operation families before any write, delete, provider, capture, translation, release, alias, artifact-root, or shell authority is implemented.
- Provide a read-only operation roadmap governance report so humans, dashboards, agents, and safe MCP clients can inspect draft phase A/B/C boundary contracts, phase order, group/risk classification, and approval-bound status without treating draft roadmap entries as product-plan commitments or live execution permission.
- Provide a read-only operation contracts report so humans, dashboards, agents, and safe MCP clients can inspect the shared Phase 61-64 risk taxonomy, gate schema, execute-token shape, and receipt shape before any token issuance, receipt writing, execution harness, or operation-specific live behavior exists.
- Provide a read-only operation policy report so humans, dashboards, agents, and safe MCP clients can inspect Phase 65-68 admin policy defaults, CLI plan readiness, disabled generic harness state, MCP readiness, and approved admin-only agent execution exposure without mutating policy or running live side effects from the report.
- Provide a read-only operation admin readiness report so humans, dashboards, agents, and safe MCP clients can inspect Phase 69-70 MCP admin execute-token flow readiness, generic harness bridge readiness, and approved admin-only agent execution bridge state without issuing tokens, storing tokens, or dispatching the generic harness.
- Provide a read-only operation provider readiness report so humans, dashboards, agents, and safe MCP clients can inspect Phase 71-78 provider MCP planning, bounded disclosure contracts, env credential guard names, admin-only fake/local/API execution exposure, and safe MCP status/list readiness without calling providers, executing local runners, reading credential values, or transferring evidence from the readiness report.
- Provide stdio `admin` MCP tools for the existing `agent execution plan` and `agent execution run --execute` flow, limited to deterministic fake providers, configured local runner callbacks, and env-only generic API providers with idempotency keys, workspace confinement, bounded disclosure, local receipts, safe/full exclusion, and HTTP exclusion.
- Keep future cleanup execution, capture execution, translation execution, npm publication, artifact-root migration, legacy alias removal, constrained shell execution, and release hardening represented as explicit registry/gate entries until each operation family has its own approved implementation slice.
- Provide a packaged external-repository usage guide so humans, shell-based agents, MCP-capable agents, and Codex users can choose CLI, MCP stdio, safe HTTP MCP, or plugin connection modes without source inspection.
- Provide TraceCue-local language settings that separate dashboard display locale from artifact output language, using the supported locale contract `ja|en|ko|zh-CN|zh-TW|es|pt-BR|fr|de|id|vi|th|hi|ar` without depending on the parent lesson repository.
- Provide read-only CLI/API/MCP inspection for those language settings so dashboards, humans, and agents can discover the active UI locale, output language mode, source-language behavior, and translation-execution boundary without writing files or running providers.
- Align Agentic Human Review `editorial_synthesis` language metadata with the local artifact output language settings across the supported 14-locale contract while preserving source advisory text when translation execution is disabled.
- Provide a read-only identity audit and rename-readiness check so humans and agents can distinguish canonical repository URL, legacy repository URL, checkout name, legacy aliases, and artifact-root migration boundaries before and after repository rename work.
- Document target runtime readiness for consumer repositories so frontend-only dev-server reviews, missing API/backend services, API base configuration gaps, and intentional degraded modes can be distinguished without adding app-specific runtime code.
- Support evidence-backed UI review findings for browser health, layout integrity, interaction quality, accessibility basics, and mock fidelity.
- Support generic target manifests so site review can cover local applications and dashboards without hard-coded product-specific branches.
- Treat manifest `expectedRoutes` as reviewable local targets so known app routes can be covered even when route discovery cannot find them from anchors or navigation candidates.
- Support optional manifest `pages` entries so named pages can define expected visible text, expected selectors, page-specific viewport coverage, and page-specific mock metrics without runtime product branches.
- Support manifest opt-in content UX advisory data so whole-application reviews can compare declared source facts with reviewed page text, selector-scoped UI state, and required user-question evidence without changing deterministic review findings or local gates.
- Provide separate content UX handoff outputs for advisory findings, next actions, and readiness so developers can act on content and information-architecture issues without mixing them into existing review findings, action plans, metrics, or release gates.
- Provide page-level content UX handoff and manifest-authoring suggestions so developers can see which page, route, selector, or target-manifest contract needs attention.
- Provide separate content UX review brief and rubric evaluation outputs so developers can compare reviewed page evidence with manifest-declared audience, page roles, user decision needs, and product communication criteria without changing existing review fields.
- Keep review findings developer-facing, reproducible, and tied to selectors, rectangles, routes, viewports, artifacts, confidence, severity, and reproduction steps.
- Produce a local review artifact index that groups review JSON, layout JSON, screenshots, mock metrics, coverage, reports, evidence classes, local boundaries, and rerun guidance for developer handoff.
- Detect generic rendered-state risks such as broken visible images, lingering loading indicators after the review wait, and empty data containers without visible empty-state messaging.
- Generate reusable target manifests so whole-application review can start from a URL without hand-writing the full manifest.
- Validate edited target manifests before browser review so developers can catch manifest shape, route, page expectation, content UX, and local boundary issues without launching Chromium.
- Provide a no-browser local resource status preflight so developers and agents can inspect memory, swap, cgroup, pressure, and process memory signals before browser-heavy review work.
- Integrate resource status into review as additive resource guard output with default advisory behavior, optional fail-critical stopping, route/viewport rechecks, and screenshot/trace pressure warnings.
- Provide optional daemon idle-timeout and max-lifetime guards so local background browsers do not remain alive indefinitely when users opt into lifecycle bounds.
- Provide local artifact usage planning and explicit `.browser-debug/`-scoped cleanup receipts so users on constrained machines can manage artifact growth without host cache or swap mutation.
- Provide local agent advisory handoff so a dashboard, local subscription agent, or future API provider boundary can use the same review package and normalized advisory-result schema.
- Provide local `agent package`, `agent ingest`, and `agent report` commands that create bounded evidence packages, import untrusted advisory JSON, and render separate advisory reports without changing deterministic review output.
- Provide local `agent requests list` and `agent requests show` output so dashboards and local automation can track and inspect advisory packages without running provider APIs or mutating review output.
- Provide local `agent workflow create`, `agent workflow status`, `agent workflow index`, and `agent workflow report` output so dashboards and local automation can track package, prompt, agent response, ingest, report-pending states, and local workflow summaries without running provider APIs or changing review output.
- Provide an agent execution layer so dashboards, local automation, subscription-style local agents, and API-style provider execution can share the same package, dry-run plan, run, status, result/report, and workflow experience without changing deterministic review output.
- Provide disabled-by-default Playwright Test regression evidence integration so users can import existing test results, optionally run Playwright Test locally only after explicit CLI confirmation, approve external-CI fetch settings, retrieve existing GitHub Actions artifacts through read-only `gh` commands, and project normalized E2E results into non-engineer review cards plus standard/deep/xhigh review inputs without changing TraceCue findings, Agentic Human Review proof, release gates, or deterministic product gates.
- Provide an Agentic Human Review layer for human-like UI/UX, visual perception, screen-text comprehension, copy/content review, subjective audience reaction, trust, risk, and improvement-advice review from existing local review artifact indexes. It must generate a plain-language plan, select reviewer roles by effort mode, require a matching plan hash plus explicit transfer flags before execution, write advisory-only results, and keep deterministic review output unchanged.
- Provide an Agentic Human Review editorial synthesis view that turns an existing normalized advisory result into a source-attributed, natural-language owner summary. The synthesis must be derived locally from existing normalized result sections only, must prioritize supplied bounded content summaries, excerpt units, observed claims, and limitations over generic run summaries when usable `content_evidence` is present, must compose bounded paragraphs without emitting empty template-only prose, must preserve provider-authored and source-evidence text when translation execution is disabled, must explain that preservation in localized report chrome, must reflect effort-dependent review stance without turning standard or deep into verification passes, must not be requested from providers, must not add new findings, claims, baseline proof, evidence coverage, or owner decisions, and must remain advisory-only with no gate effect.
- Provide optional Agentic Human Review content evidence intake so proposals and plans can reference workspace-confined, analyzer-neutral content evidence for videos, web pages, PDFs, meeting notes, documents, transcripts, and other textual artifacts. The intake must preserve existing `--video-evidence` compatibility by projecting video summaries into generic `content_evidence`, accept only bounded summaries, claims, limitations, and `content_units`, reject raw media, raw binaries, raw HTML/PDF bytes, full documents, and full transcripts, allow explicit false-valued privacy or boundary metadata to document that raw/full content is absent, strip local paths and source locators before provider payloads, expose source-type display labels, content-understanding diagnostics, bounded-evidence density, and content-review-strength diagnostics, verify the supported source-type matrix generically through plan and result/report generation, and keep the integration generic rather than tied to one content tool, site, repository, provider, model, URL, or file path.
- Provide optional Agentic Human Review source-text intake so proposals and plans can reference workspace-confined full source text for video transcripts, web-page text, PDF-extracted text, meeting notes, documents, transcripts, and other textual artifacts. TraceCue must read the full source text locally, derive a bounded `source_reading_review` with effort-dependent depth, source refs, narrative flow, key points, examples, cautions, and a natural review seed, and derive a bounded `source_understanding_review` with thesis, audience promise, narrative arc, turning points, must-not-miss points, tensions, limitations, reviewer implications, evidence claims, assistant-reference quality target, and coverage metrics. Editorial synthesis must use source understanding before summary-only material, compose the final review as owner-facing natural prose rather than a mechanical dump of structured records, and record an `editorial_integrator` handoff that cross-checks the full-source understanding against existing normalized TraceCue findings, reader-impact signals, role opinions, owner-baseline findings, quality signals, recommendations, video evidence, and content evidence through a target-independent editorial narrative plan. The source-understanding composer must be effort-profiled: `standard` should produce a practical source-grounded review, `deep` should add audience value, concrete examples, and prioritization, and complete `xhigh` should add verification, critique, counterpoint, evidence-limit, and conclusion-change-condition language without treating the prose as proof. The review body must not leak fake-provider scaffolding, internal `Step`/`role` markers, operational effort labels, assistant-reference target labels, duplicate source anchors, target-specific heuristics, or boundary boilerplate when those values are already represented as structured metadata. Full source text and chunk text must not be persisted in result JSON, Markdown reports, or provider payloads; raw media, raw binaries, base64/blob/data URI payloads, credentials, and raw/full structured fields must be rejected; provider transfer may include only bounded source-reading and source-understanding review data under the existing page-text transfer boundary, and source-understanding excerpt refs must be compacted to ids and hashes without excerpt text or source locators; deterministic findings, release gates, owner-baseline proof, benchmark proof, and human-equivalent or human-superior claim states must remain unchanged.
- Provide read-only Agentic Human Review source-text effort-matrix verification so standard, deep, and xhigh results generated with `--source-text` can be compared after execution without rerunning providers. The verification must read only workspace-confined advisory result artifacts, require all three efforts, report source-understanding completion, source type consistency, bounded same-source identity invariant status, source-reading/source-understanding source id consistency, source-reading/source-understanding counts, editorial synthesis hashes and scores, pairwise effort deltas, xhigh counterpoint/evidence-limit/conclusion-change readiness, optional reference-review score summaries, full-source/chunk-text non-persistence checks, direct raw source/chunk alias diagnostics, output-safety diagnostics, advisory-only diagnostics, and false human-equivalent or human-superior claim flags. It must not output full source text, chunk text, candidate full reviews, reference review prose, private source identity values, result paths, source locators, source titles, raw provider responses, credentials, proof claims, or release-gate state changes.
- Allow read-only Agentic Human Review source-text effort-matrix quality artifacts to be projected into downstream evidence-set, claim-readiness, longitudinal-quality, claim-standard-gate, and evidence-regeneration diagnostics as optional `owner_review_context.source_text_quality`. The context must be whitelist-only and non-proof: it may expose counts, statuses, booleans, effort names, pass-condition summaries, output-safety summaries, and stale or missing effort diagnostics, but must not expose full source text, chunk text, candidate or reference prose, result paths, source locators, source titles, private source identity values, raw hashes, provider responses, credentials, warning/blocker/condition changes, passed or claim-state changes, release-gate mutation, automatic rerun authority, or future claim-numerator effects. Downstream commands must treat prebuilt evidence-set owner context as untrusted, reconstruct the context from the allowed shape, neutralize provider/proof/claim/release/artifact-write/rerun authority flags, and keep the public owner-context schema synchronized with the emitted shape.
- Provide an explicit staged `xhigh` Agentic Human Review execution mode for approved real-provider dogfood runs that cannot reliably complete as one large provider request. Staged execution must remain generic across target URLs, repositories, providers, models, benchmark cases, and artifact layouts; it must preserve the same approved plan hash, exact transfer flags, owner-baseline requirement contract, benchmark coverage contract, env-only credential handling, raw-provider-response non-storage, advisory-only output, no MCP exposure, and false human-equivalent or human-superior claim state.
- Provide Agentic Human Review schema v2 so advisory results explicitly cover first impression, reader emotion, content comprehension, trust and credibility, visual UX, accessibility comprehension, improvement priority, mechanical-versus-human comparison, human-review coverage, and non-engineer-readable report output.
- Provide Agentic Human Review benchmark and calibration support so fake/injected provider output can be evaluated against page-type expectations for blogs, landing pages, commerce pages, dashboards, article pages, and images without requiring live provider credentials or mutating release gates.
- Provide structured Agentic Human Review benchmark requirement coverage so calibration readiness is based on explicit evidence-backed records for required mentions, required human-review dimensions, and forbidden claims rather than loose text matching. Forbidden-claim records must distinguish absence of a claim from coverage of the check.
- Provide read-only Agentic Human Review evidence-set, owner-labeled human baseline validation/comparison, batch comparison, evaluator policy, xhigh planning/simulation, longitudinal quality, claim policy/audit diagnostics, and a mechanical claim standard gate so standard/deep/xhigh dogfood results across multiple cases can be compared against explicit owner evidence before any human-equivalent or human-superior quality claim is considered. Evidence-set summaries must identify synthetic, fake, injected, local, and real-provider origins separately so local pipeline fixtures cannot be counted as future claim-numerator evidence, and they must accept supported TraceCue CLI and public API runtime-result wrappers for calibration, comparison, and human-baseline artifacts without weakening raw advisory-result validation.
- Provide read-only Agentic Human Review dogfood evidence-pack summarization and owner-facing review-pack projection so humans can inspect a longitudinal real-provider dogfood pack from a workspace-confined evidence-set manifest, evidence-set output, or dogfood pack manifest without replaying provider calls. The summary and review pack must reuse evidence-set, claim-readiness, longitudinal-quality, claim-standard-gate, and owner-review-context logic; report case-by-effort matrices, blocker categories, claim review state, advisory regeneration handoff, owner-facing ready/blocked/incomplete status, standard/deep/xhigh matrix badges, grouped blockers, top owner actions, trust/safety flags, and pathless advanced references; suppress detailed result paths, source paths, raw hash values in review packs, raw provider responses, credential values, full source text, chunk text, candidate/reference prose, and concrete rerun commands; perform no provider/API call, credential read, external transfer, artifact write, browser launch, MCP exposure, or automatic rerun; and keep human-equivalent and human-superior claim flags false.
- Require Agentic Human Review report-quality diagnostics to classify effort-dependent quality gaps mechanically. Missing dedicated critique or verification output is an informational expected gap for effort modes that do not plan those roles, but remains a policy warning for `xhigh` when the dedicated critic or verification contract is required and not satisfied. The classification must be machine-readable, advisory-only, gate-neutral, and consistent between embedded advisory results, standalone `agentic review report-quality`, Markdown report output, evaluator policy diagnostics, and maturity diagnostics.
- Require read-only Agentic Human Review editorial-quality comparison so a candidate advisory result can be compared with a workspace-confined assistant, owner, subscription, API, or other reference review. The comparison must score the candidate editorial synthesis against effort-aware targets, emit only hashes, scores, deltas, strengths, gaps, and diagnostics, reject raw media/binary/full-source/credential-bearing reference inputs, perform no provider calls or evidence transfer, expose no MCP execution, mutate no deterministic findings or gates, and keep human-equivalent and human-superior claim flags false.
- Require real-provider Agentic Human Review proof-readiness data to be case-aware and evidence-backed: the required benchmark case by effort matrix must be explicit, `direct-vs-tracecue` comparison readiness must be reported per benchmark case, calibration weakness must remain a claim-readiness blocker, missing result cells, mechanical-contract incomplete cells, failed calibration cells, and missing comparison cells must be classified separately, and adapter-produced advisory output must preserve structured benchmark records and local evidence-reference identifiers without fabricating owner baselines or quality claims.
- Provide reusable Agentic Human Review human-baseline registry, case-overlay, AI-draft, approval-packet, and claim-readiness diagnostics so humans approve only target-specific baseline differences, AI drafts never become proof by themselves, approved baselines require owner metadata, target-specific must-not-miss criteria are mechanically required and linked to evidence-backed owner labels before `owner_labeled` can verify, synthetic or fixture-only approval markers prevent owner-baseline verification, and claim flags stay false until separately approved evidence standards are met.
- Require `agentic review claim standard-gate` to consume a workspace-confined evidence set and optional claim policy, reuse evidence-set, claim-readiness, longitudinal-quality, comparison, owner-baseline, xhigh, and per-result claim-audit diagnostics, and fail closed with machine-readable blockers when evidence is incomplete, synthetic/local, mechanically incomplete, weakly calibrated, missing comparison coverage, regressed against direct/provider/benchmark comparisons, mismatched against owner-approved baselines, or supplied with a policy that attempts to authorize equality or superiority. The only passing state is owner claim-review readiness; human-equivalent and human-superior claim states must remain false until a separately approved claim standard changes the active policy.
- Require claim-audit forbidden-claim matching to distinguish asserted or ambiguous forbidden policy text from evidence-backed absence or coverage checks. Structured forbidden-claim absence rows, negated compliance findings, and claim text that proves a forbidden claim was not asserted may be diagnostic only when backed by catalog evidence references or matching structured absence coverage; ambiguous or affirmative forbidden text must remain a blocking claim-audit finding.
- Require proof-safe Agentic Human Review claim text before any result can contribute to future claim-numerator evidence. Normalized advisory results and adapter output may expose `review_claims` only when each claim is non-placeholder and supported by catalog-backed local evidence references or planned role output; unsupported, missing-evidence, placeholder, equality, and superiority claims must be isolated as diagnostics and excluded from strict claim eligibility.
- Require the Agentic Human Review Responses adapter to treat provider `review_claims` as optional proof candidates rather than as mandatory advisory output. Unsupported, placeholder, equality, or superiority claim candidates must be filtered mechanically before TraceCue result normalization, reported through non-secret claim-filtering diagnostics, and carried into `claim_integrity` so the run can complete as advisory output while remaining excluded from future claim-numerator evidence until only supported proof-safe claims remain. Staged final synthesis may use prior-stage role summaries as valid role support, but unknown roles, synthetic support, local paths, raw provider responses, credential values, and equality or superiority wording remain invalid.
- Require Agentic Human Review comparison diagnostics to make proof regressions visible by metric and by case. Direct-vs-TraceCue, batch, evidence-set, human-baseline, and claim-standard-gate outputs must surface critical metric regressions, missing owner labels, missing target-specific must-not-miss criteria, missing evidence-backed forbidden-claim absence, and owner-baseline mismatches without converting text-only or count-only matches into proof.
- Require `agentic review claim standard-gate` to emit a read-only minimal rerun plan when owner claim-review readiness does not pass. The rerun plan must identify the smallest result, calibration, comparison, owner-baseline, xhigh, or claim-audit targets needed to close blockers, provide command templates rather than executing them, and remain provider-free, artifact-write-free, gate-neutral, and configurable across future benchmark cases and target artifacts.
- Provide `agentic review evidence-set regenerate plan` so failed claim-standard-gate output can be converted into a reusable evidence regeneration dependency plan. The command must consume a workspace-confined evidence set, claim gate artifact, and optional target registry, derive provider-result repair, calibration, comparison, human-baseline comparison, and downstream summary/readiness/longitudinal/gate command templates from machine-readable blockers, include missing calibration cells as targets, and remain read-only, provider-free, artifact-write-free, browser-free, MCP-free, advisory-only, gate-neutral, and generic across future target URLs, benchmark cases, repositories, and artifact layouts.
- Require owner-baseline recovery planning to distinguish local comparison repair from provider result repair. When an owner-baseline comparison fails because the candidate result lacks or mismatches the approved owner-baseline requirement contract, the claim-standard gate must emit an approval-required provider result target, and the evidence regeneration planner must resolve it only from a matching owner-contract plan or explicit target registry entry.
- Require Agentic Human Review owner-baseline proof to remain canonical and comparison-visible. When an owner-baseline requirement contract is present, provider output must include evidence-backed canonical records in `owner_baseline_findings` for every required owner-label obligation, with a target-specific criterion fallback only when a target-specific criterion has no linked owner label; role-level findings, prose discussion, or generic advisory findings may support reviewer context but cannot satisfy the adapter owner-baseline proof contract by themselves. Normalized advisory results must retain `owner_baseline_findings`, merge those records into `agentic_human_review_findings` for downstream human-baseline comparison, preserve safe evidence-reference aliases such as `evidence_ref_ids`, and keep missing canonical proof records repairable rather than silently passing adapter validation.
- Allow approved Agentic Human Review human baselines to be attached to `agentic review propose` and `agentic review plan` through a workspace-confined JSON input, then convert only verified owner-labeled baselines into a hashed owner-baseline requirement contract. The contract must carry owner label ids, linked target-specific criterion ids, and summary metadata without local evidence paths, must be included in plan hashes and provider payloads, and must require structured provider findings with every required owner label id, matching criterion ids when linked, and catalog-backed evidence references before owner-baseline comparison can become ready. Adapter repair guidance must expose only redacted missing criterion ids, required fields, owner label ids, and allowed evidence-reference catalog ids, and repaired output must still pass fail-closed post-validation.
- Require the Agentic Human Review Responses adapter to expose owner-baseline output obligations as machine-readable required finding records derived from the approved baseline contract and request evidence catalog. Provider payloads and repair retries must identify the required `owner_label_id`, `owner_label_ids`, `must_not_miss_criterion_id`, `criteria_refs`, required fields, and recommended evidence-reference ids without copying long baseline text, local paths, credential values, or raw provider output. Provider-authored structured findings may be accepted from canonical `owner_baseline_findings` after normalization, but role-level findings, generic advisory findings, text-only baseline discussion, unknown owner labels, unknown evidence references, and synthetic findings remain insufficient.
- Require approved owner-baseline `required_mentions`, `required_dimensions`, and `forbidden_claims` to participate in the effective Agentic Human Review benchmark coverage contract whenever an owner-baseline requirement contract is attached. Provider payloads and repair retries must expose compact `required_benchmark_coverage` templates for the effective benchmark contract plus compact `required_owner_baseline_coverage` templates for owner-baseline provenance, adapter validation must require matching `benchmark_requirement_coverage` records with catalog-backed evidence references, forbidden owner-baseline claims must be represented as evidence-backed absence records, and normalization must not synthesize missing required-mention, required-dimension, owner-baseline finding, owner-label proof, or prose-derived coverage from target URLs, case-specific text, relaxed thresholds, or baseline prose. After a provider repair attempt, the Responses adapter may complete only missing forbidden-claim absence rows from canonical required coverage templates when the provider advisory does not assert that forbidden claim and a catalog-backed evidence reference is available; completed rows must be marked as adapter-derived and remain advisory-only. If full replacement repair is exhausted and the only remaining failure is missing benchmark coverage rows, the adapter may perform one bounded provider-authored coverage patch request, merge only exact missing rows with catalog-backed evidence references, and re-run the same fail-closed validation. Coverage patch repair must not infer rows from prose, owner-baseline findings, owner-label obligations, URLs, case text, target-specific branches, relaxed thresholds, or local artifacts.
- Provide provider capability snapshots, evidence plans, page-type rubric profiles, and privacy/disclosure audit output so live provider dogfood can be reviewed before execution and rejected when provider capability, endpoint policy, or transfer assumptions drift.
- Provide Agentic Human Review completion-readiness metadata for real-provider dogfood, benchmark corpus coverage, release-gate non-mutation, visible-text provenance, and `xhigh` multi-round role output so quality gaps are visible without changing deterministic release gates.
- Require `xhigh` Agentic Human Review to be enforced as a TraceCue mechanical effort contract, not only as provider prompt wording. Provider capability snapshots, approved plans, adapter payloads, advisory normalization, report-quality output, evidence-set summaries, human-baseline comparisons, claim-readiness diagnostics, and longitudinal quality rollups must expose native effort binding, strict output validation, placeholder rejection, required role/round coverage, synthesis coverage, structured local evidence-reference coverage, repair-readiness metadata, and claim-numerator exclusion when the mechanical contract is incomplete.
- Require staged adapter repair to identify placeholder role output mechanically even when the provider only signals the placeholder through role-output summary wording. Such output must not count as reported role/round coverage, while ordinary page-content statements such as unavailable pricing or missing target information must still count as provider-authored role output. Repair context must expose only safe stage, role, round, and reason metadata so a provider can replace the exact missing role output without receiving raw provider bodies, local paths, credentials, target-specific branches, or relaxed proof rules.
- Require explicit manual live-dogfood opt-in before a provider API can execute benchmark/dogfood Agentic Human Review runs, and reject those runs before any fetch or evidence transfer when the opt-in is absent.
- Ensure external Agentic Human Review provider payloads apply the same approved transfer flags to plan-level and package-level visual/text contracts so unapproved visible text or local references cannot bypass package filtering.
- Provide a loopback-only Agentic Human Review Responses adapter so the existing `generic-api-provider` contract can be connected to a Responses-compatible provider through a local HTTP boundary. The adapter must require a local bearer token, read provider credentials from environment variables only, build a bounded provider request with provider-side storage disabled, parse advisory JSON output, validate benchmark records against catalog-backed evidence references, and return normalized TraceCue advisory data without storing raw provider responses or credential values. Provider output parsing may recover a single unambiguous provider-authored advisory JSON object from formatting wrappers such as Markdown fences, leading or trailing prose, or JSON-string encoding, but it must not guess malformed JSON, synthesize advisory fields, store raw output text, or bypass fail-closed post-validation.
- Require live Agentic Human Review provider execution to resolve a concrete provider model before any fetch or evidence transfer. Abstract placeholder model ids used for provider-neutral planning must remain allowed in proposals and plans, but a provider API run must use either an explicit approved plan/run model or the provider runtime model environment variable. If neither produces a concrete model, TraceCue must fail before provider dispatch with non-secret model-resolution diagnostics instead of relying on an adapter or upstream API error.
- Keep Agentic Human Review live-provider adapter startup separate from MCP, safe HTTP MCP, generic `agent execution`, deterministic review, visual review preparation, and browser capture paths.
- Support subscription-style local agent execution through configured local runner callbacks, not through SaaS web UI automation or free-form shell input.
- Support API-style provider execution only through a dry-run execution plan, explicit `--execute`, env-only credentials, bounded disclosure policy, local receipts, and advisory-only result normalization.
- Provide local `agent execution plan`, `agent execution run`, `agent execution status`, and `agent execution list` contracts as an additive layer separate from existing `agent workflow` state.
- Suggest target manifest improvements when dogfood review evidence shows missing page expectations, unpinned discovered routes, exhausted route budgets, failed page checks, or rendered-state gaps.
- Provide action plans, implementation-focused fix candidates, and local heuristic advisory signals that help developers decide what to fix first.
- Provide structured local quality signals for visual hierarchy, rendered state, responsive layout, interaction affordance, accessibility structure, evidence completeness, local release readiness, and model-review boundaries.
- Provide local plugin metadata so Codex can discover the CLI/MCP review workflow without making remote services mandatory.
- Provide a shared visual evidence metadata contract for browser screenshots, standalone screenshots, generated mock images, screen captures, window captures, and desktop app captures without embedding raw pixels in JSON records.
- Provide a planning-only visual review provider policy inside `agent execution plan` so future AI-assisted visual review can disclose raw-pixel, provider, external-transfer, credential, and MCP boundaries before any execution path is expanded.
- Provide standalone image review for workspace-confined image files so existing screenshots, generated mock images, and manually captured UI images can enter the same local evidence workflow without browser launch or provider execution.
- Provide local visual review result preparation so existing review artifact indexes can become metadata-only future AI visual review contracts without provider execution, raw pixel transfer, external upload, MCP exposure, or deterministic review mutation.
- Provide explicit CLI visual review execution from preparation artifacts so AI or local-provider advisory output can be normalized as visual review results without raw pixel transfer, existing review mutation, release gate changes, raw provider response storage, or MCP exposure.
- Provide a read-only visual review dashboard so local control centers, humans, CLI users, and safe MCP clients can inspect visual review preparation, execution, and result status without writing artifacts, running providers, reading raw pixels, or changing gates.
- Provide a read-only MCP execution gate report so future MCP planning, provider execution, cleanup execution, and visual review execution can be reviewed against explicit safety gates before any write/execute tool is exposed.
- Provide a read-only capture planning report so screen, window, and desktop app capture can be reviewed against local privacy, artifact, raw-pixel, and MCP execution boundaries before any OS capture implementation is added.
- Provide a capture metadata handoff for existing workspace image files so they can be identified as screen, window, or desktop app evidence without OS capture, raw-pixel JSON embedding, provider calls, artifact writes, or MCP exposure.
- Provide a desktop review provider-preparation planning report from capture handoff metadata so future provider preparation can be reviewed without rereading image bytes, writing artifacts, calling providers, transferring evidence, exposing MCP tools, or mutating existing reviews.

## Non-Goals

- Do not clone Playwright MCP or require MCP as the runtime interface.
- Do not replace final visual review; the tool should help operate and capture evidence, while humans approve product-level decisions when needed.
- Do not bypass authentication or collect credentials.
- Do not upload artifacts to external services by default.
- Do not add runtime features that cross into authentication, profile reuse, external upload, credential handling, or external daemon control channels without explicit implementation approval and security documentation.
- Do not create public repositories, remotes, remote CI execution, or npm publication paths as part of package/runtime design.
- Do not reimplement Playwright or clone the full Playwright MCP tool surface.
- Do not claim subjective visual judgment as deterministic proof; subjective or model-assisted review findings must remain advisory unless backed by deterministic evidence and owner acceptance.
- Do not hard-code individual application names, localhost ports, route names, or product-specific UI labels into the generic runtime.
- Do not send screenshots, traces, raw DOM, source text, console logs, network evidence, or reports to a model or external service without explicit opt-in and security documentation.
- Do not treat content UX advisory as deterministic product approval, a replacement for owner judgment, or a release gate.
- Do not treat content UX review brief or rubric output as model judgment, aesthetic approval, deterministic product approval, or a release gate.
- Do not read arbitrary source-data files or remote source-data URLs from target manifests in the local content UX advisory layer.
- Do not mutate system memory cache, configure swap, delete artifacts automatically, kill arbitrary processes, or perform privileged host cleanup from the local resource status preflight or guard.
- Do not expose artifact cleanup execution through MCP; MCP may report local artifact usage but must not delete files.
- Do not expose HTTP `full` or `admin`, remote HTTP listeners, socket transports, shell tools, cleanup execution, package generation, ingest, report writing, workflow creation, execution planning outside the approved stdio `admin` agent execution plan path, `agent execution run` outside the approved stdio `admin` path, provider/API execution outside the approved stdio `admin` agent execution adapter path, persistent session tools outside stdio `admin`, storageState import/export outside explicit admin opt-in, or credential handling through MCP without a separate approved phase.
- Do not emit bearer token values, credentials, local secrets, raw environment values, or external upload configuration from MCP client configuration helpers.
- Do not treat an MCP capability policy report or the `admin` profile name as permission to expose write, delete, provider/API, shell, non-approved daemon/session, storageState, or credential-bearing tools.
- Do not hide consumer application API/backend startup failures through TraceCue runtime branches; document target runtime prerequisites in the consumer repository instead.
- Do not treat local agent advisory output as deterministic findings, release approval, or a replacement for owner judgment.
- Do not run provider APIs, upload evidence, store credentials, or expose agent/API execution through MCP as part of the local agent advisory handoff layer, except for the approved stdio `admin` agent execution plan/run adapter path that requires a prior local plan, explicit execute acknowledgement, bounded disclosure, and local receipts.
- Do not let agent execution mutate review `findings`, `metrics.finding_count`, existing `action_plan`, `quality_signals.release_readiness`, resource guard output, artifact cleanup behavior, or existing `agent_workflow` status meanings.
- Do not route Agentic Human Review packages through generic `agent execution`, expose Agentic Human Review through MCP, treat subjective agentic conclusions as deterministic findings or release gates, store raw provider responses, store credential values, or bypass plan-hash, `--execute`, and exact transfer-flag validation.
- Do not treat Agentic Human Review staged `standard`, `deep`, or `xhigh` stage output as final proof, calibration input, comparison evidence, claim-gate evidence, or owner claim-readiness evidence by itself. Only the final normalized advisory result produced after deterministic staged aggregation and existing contract validation can enter existing report-quality, calibration, comparison, evidence-set, longitudinal, or claim-standard-gate diagnostics.
- Do not run agent/API execution without a local dry-run execution plan, explicit `--execute`, local receipt, and advisory-only normalization path.
- Do not treat Playwright Test results or E2E result review-material projections as TraceCue review findings, proof of Agentic Human Review quality, release-gate approval, or permission to trigger/rerun/cancel remote CI. Local Playwright Test execution must remain CLI-only and explicit; external CI integration may resolve approved existing artifacts and fetch them, but must not start or mutate CI.
- Do not accept provider credentials through CLI arguments, committed files, package artifacts, workflow files, reports, receipts, `.env` auto-loading, or persistent local storage.
- Do not upload or send raw screenshots, trace contents, raw DOM, console payloads, network payloads, sourceData values, report bodies, cookies, storage state, existing browser profile data, or raw review artifacts as part of default agent execution.
- Do not store raw provider responses; only normalized advisory results and local receipts may be retained.
- Do not point Agentic Human Review `generic-api-provider` directly at an upstream Responses API when using the local adapter flow; the generic provider endpoint should target the loopback adapter, and the adapter should own the upstream conversion and provider credential boundary.
- Do not treat `generic-agentic-review-model`, fake-provider model ids, injected-runner model ids, or other provider-declared abstract model ids as executable upstream provider model names. They are planning placeholders only unless the provider descriptor explicitly declares them as concrete.
- Do not bind the Agentic Human Review Responses adapter to non-loopback hosts, accept query-string endpoints, accept browser-origin requests from non-loopback origins, forward the inbound adapter bearer token upstream, accept raw pixel bytes in JSON, send local plan/execution paths upstream, enable provider tools, enable provider-side storage, or expose the adapter through MCP.
- Do not expose `agent execution run` through MCP outside the approved stdio `admin` agent execution adapter path.
- Do not treat visual evidence metadata, visual review result preparation artifacts, visual review execution artifacts, or artifact references as permission to transfer raw pixels, upload raw evidence, expose MCP execution, or store raw provider responses.
- Do not treat visual review dashboard output as permission to run providers, write artifacts, mutate review state, transfer raw pixels, or change release gates.
- Do not treat MCP execution gate reports as permission to expose MCP write, delete, provider, credential, shell, daemon/session, or raw-pixel transfer tools.
- Do not treat operation registry entries as permission to execute, delete, publish, migrate artifact roots, remove aliases, call providers, translate evidence, capture pixels, or expose MCP write/execute tools.
- Do not treat operation roadmap entries as permission to promote draft phases into product-plan commitments, issue execution tokens, run live execution, trigger remote CI, execute, delete, publish, migrate artifact roots, remove aliases, call providers, translate evidence, capture pixels, or expose MCP write/execute tools.
- Do not treat operation contract entries as permission to issue execute tokens, enforce live gates, write receipts, run execution harnesses, execute, delete, publish, migrate artifact roots, remove aliases, call providers, translate evidence, capture pixels, or expose MCP write/execute tools.
- Do not treat operation policy entries as permission to enable admin execution tools, issue tokens, write receipts, enable harnesses, execute, delete, publish, migrate artifact roots, remove aliases, call providers, translate evidence, capture pixels, or expose MCP write/execute tools.
- Do not treat operation admin readiness entries as permission to issue execute tokens, store tokens, expand MCP admin execution beyond the approved agent execution bridge, dispatch generic harnesses, execute from the readiness report, delete, publish, migrate artifact roots, remove aliases, call providers from the readiness report, translate evidence, capture pixels, or expose unrelated MCP write/execute tools.
- Do not treat operation provider readiness entries, safe MCP status/list metadata, or capability-id aliases as permission to call providers, execute local runners, read credential values, transfer evidence, delete, publish, migrate artifact roots, remove aliases, translate evidence, capture pixels, or expose MCP write/execute tools beyond the approved stdio admin agent execution plan/run tools.
- Do not treat capture planning reports as permission to capture screens, enumerate windows or processes, write image artifacts, read raw pixels, call providers, transfer evidence, or expose capture execution through MCP.
- Do not treat capture metadata handoff as permission to capture screens, enumerate windows or processes, write artifacts, call providers, transfer evidence, expose MCP tools, or bypass workspace-confined image input checks.
- Do not treat language settings as permission to translate source evidence, repository documentation, raw page text, selectors, URLs, logs, screenshots, traces, or provider output through external services. Translation execution remains disabled until a separate approved implementation defines local templates, provider boundaries, disclosure, and tests.
- Do not treat Agentic Human Review `editorial_synthesis.language`, language settings, or artifact output language metadata as proof of translation, provider-authored output, owner-baseline or benchmark satisfaction, claim readiness, MCP exposure, owner approval, or release-gate authority.
- Do not treat Agentic Human Review content evidence intake as permission to call an analyzer, fetch remote content, transfer raw media or raw documents, embed frames, raw HTML/PDF bytes, full documents, or full transcripts, expand provider/API disclosure, expose MCP execution, weaken exact transfer flags, satisfy owner-baseline proof, repair benchmark coverage, authorize claim readiness, or change deterministic review gates.
- Do not register a plugin marketplace entry, change the package license, choose a public package name, or publish to npm without explicit release approval.

## Success Criteria

- The repository has the standard product scaffold expected by the lesson workflow.
- The initial five documents are synchronized and describe the same product direction.
- Product-local checks can validate structure, document sync, security, and design-system placeholders.
- Package/runtime design records the CLI shape, artifact boundaries, safety defaults, and focused verification plan before implementation begins.
- The first no-browser implementation slice provides local package metadata, the `browser-debug` executable, `doctor`, command parsing, deterministic JSON errors, and focused tests without launching a browser.
- The local MVP runtime provides Playwright-backed one-shot observation, local screenshots/traces/observation artifacts, session metadata, simple actions, report export, spec export, redaction tests, and browser smoke tests.

## Phase 2a Package and Runtime Design Criteria

- The working CLI binary is `browser-debug`.
- The package uses Node.js 20 or newer and ESM modules.
- The default runtime mode is local-first, headless, and artifact-safe.
- The first implementation slice is `doctor` plus a no-browser command parser and JSON output contract.
- The first Playwright slice is a one-shot `observe --url <url> --json` command using an ephemeral browser context.
- The default artifact root is `.browser-debug/`, which must stay ignored. It must not contain credentials or raw secrets, must not store cookies or storage state by default, and may contain storageState only under the explicit ignored auth artifact directory when the admin opt-in export/import flow is used.
- Long-running browser supervision is opt-in after the one-shot observation flow is working.

## Current Local MVP Criteria

- `doctor --json` verifies Node.js, ESM configuration, artifact ignore policy, and Playwright package availability.
- `observe --url <url> --json` launches an ephemeral Chromium context, captures structured page data, closes the browser context, and writes an observation artifact.
- `observe --screenshot` writes a local screenshot artifact without committing it.
- `observe --trace` writes a local Playwright trace artifact and warns that traces can contain page content.
- `session start`, `act`, `report`, and `spec export` operate on local `.browser-debug/` session metadata.
- `supervise --url <url> --actions <json-array>` keeps one ephemeral browser context alive for ordered local actions within a single CLI process and closes it before exit.
- `daemon start --url <url>`, `daemon status --daemon <id>`, and `daemon stop --daemon <id>` keep a local background ephemeral browser worker alive across CLI invocations and stop it through local process signaling.
- Page text, console messages, URLs, action data, and generated reports are treated as untrusted data and pass through basic secret redaction.
- Browser smoke tests verify local file observation, click actions, form controls, keyboard input, deterministic scroll, screenshots, reports, spec export, process-scoped supervision, and local daemon start/status/stop without using external services.
- Headed and DevTools mode regression tests verify Playwright launch-mode wiring without requiring a GUI display.
- Architecture regression tests check for generic runtime boundaries, shared page evidence helpers, and local Node CLI packaging.
- Local package dry-run verification confirms the npm package file set without publishing.
- Local CI manifest checks validate the GitHub Actions workflow definition without remote execution.
- Release readiness notes and `npm run release:check` track the unreleased status, public-release blockers, and no-publish boundaries.
- The review platform adds `review`, `schema list`, `schema get`, and local stdio MCP adapter surfaces while keeping existing commands compatible.
- Review artifacts are written under ignored `.browser-debug/` directories for reviews, layouts, diffs, and coverage.
- No-browser tests cover schema commands, review parsing, target manifest normalization, action risk classification, shell-safe action input, and MCP allowlisted tools.
- Browser smoke tests cover deterministic review findings, mock metrics, target manifest review, route discovery, viewport execution, and coverage artifacts.
- `target init --url <url> --json` writes a reusable local target manifest artifact for route and viewport review.
- `target validate --target <manifest> --json` validates edited target manifests without launching a browser, mutating the manifest, exposing sourceData values, uploading artifacts, or reusing profiles.
- `resource status --json` reports local memory, swap, cgroup, pressure, and process memory signals without launching a browser, writing artifacts, deleting caches, mutating swap, mutating system cache, uploading evidence, or reusing profiles.
- `review --resource-guard advisory|fail-critical|off` adds resource preflight and route/viewport recheck data to review output. Advisory mode is the default and does not change review findings, `metrics.finding_count`, existing action plans, or release readiness. Fail-critical mode can stop browser launch or remaining target work only when local resource status is critical.
- `daemon start --idle-timeout <duration>` and `daemon start --max-lifetime <duration>` add optional local lifecycle bounds to daemon metadata and worker shutdown behavior.
- `resource artifacts plan --json` reports local artifact usage and cleanup candidates without deleting files. `resource artifacts cleanup --execute --json` deletes only selected regular files under the configured artifact root and writes a local receipt.
- `agent surfaces list --json` reports local subscription-agent surfaces and a future API-provider boundary without contacting providers.
- `agent package --review-index <path> --json` creates a local bounded evidence package and prompt from an existing review artifact index without copying raw screenshots, traces, DOM, console payloads, network payloads, or source-data values.
- `agent requests list --json` reads local package/result artifacts and reports pending/imported advisory handoff status without launching a browser, contacting providers, uploading evidence, or writing review artifacts.
- `agent requests show --package <path> --json` returns one advisory handoff detail with package metadata, local artifact references, selected result summary, dashboard handoff hints, and unchanged gate boundary flags without writing artifacts.
- `agent workflow create --package <path> --json` writes a local workflow manifest and receipt under `.browser-debug/` for dashboard and automation handoff without launching a browser, contacting providers, uploading evidence, storing credentials, or mutating review artifacts.
- `agent workflow status --workflow <path> --json` and `agent workflow index --json` read local workflow/package/result metadata and report current handoff status without writing artifacts, launching a browser, contacting providers, uploading evidence, storing credentials, or changing deterministic review output.
- `agent workflow report --workflow <path> --json` writes a local Markdown workflow status summary without launching a browser, contacting providers, uploading evidence, storing credentials, mutating review artifacts, or changing deterministic review output.
- `agent execution plan --package <path> --surface <id> --json` creates a local no-network dry-run execution plan and receipt from a bounded agent package without launching a browser, contacting providers, uploading evidence, storing credentials, mutating review artifacts, changing deterministic gates, or exposing execution through MCP.
- `agent execution status --execution <path> --json` and `agent execution list --json` read local execution metadata for dashboards and automation without launching browsers, contacting providers, uploading evidence, storing credentials, writing review artifacts, or changing existing workflow status semantics.
- `agentic review propose --brief <request> --json` turns a conversational human-review request into a local non-executing Agentic Human Review proposal. The proposal explains the intended visual, UI/UX, content, comprehension, subjective-reaction, risk, and improvement scope, recommends effort and reviewer roles, previews transfer flags, and cannot authorize provider execution, evidence transfer, or plan hashes.
- `agentic review plan --review-index <path>|--proposal <path> --json` creates a local human-readable Agentic Human Review plan and metadata package from an existing review artifact index or verified proposal. The plan computes a fresh plan hash, selects reviewer roles by effort mode, records exact transfer permissions, and performs no provider execution.
- `agentic review provider-readiness --json` reports configured agentic review providers, environment-variable names, transfer policy, and required approval gates without reading credential values, calling providers, transferring evidence, writing artifacts, or changing MCP permissions.
- `agentic review run --plan <path> --plan-hash <hash> --execute --json` runs only a matching Agentic Human Review plan with the exact approved transfer flags. Results are written as `agentic_human_review_advisory`, include role execution records, claims, critique/rebuttal/integration metadata, dogfood metadata, report-quality metadata, and remain advisory-only without mutating deterministic review findings, metrics, release gates, existing review artifacts, or MCP permissions.
- `agentic review report-quality --result <path> --json` reads local advisory results and reports completeness, evidence coverage, verification coverage, effort-aware quality diagnostics, and warnings without calling providers, writing artifacts, or changing release gates.
- `agentic review report-quality --result <path> [--execution <path>] --json` validates that the result is an Agentic Human Review advisory, optionally verifies that it matches the execution record, reports human-review coverage, actionability, effort expectations, quality diagnostics, evaluator policy diagnostics, human-review maturity, longitudinal quality gaps, missing standard/deep/xhigh effort evidence, missing benchmark-case evidence, and explicit no-claim flags for human-equivalent or human-superior judgment, and rejects unrelated or mismatched artifacts.
- `agentic review benchmark list|show --json`, `agentic review calibrate --result <path> --case <id> --json`, `agentic review compare --baseline <path> --candidate <path> [--comparison-kind direct-vs-tracecue|editorial-quality] --json`, `agentic review compare batch --dataset <path> --json`, `agentic review evidence-set validate|summarize --input <path> --json`, `agentic review human-baseline validate --input <path> --json`, `agentic review human-baseline compare --baseline <path> --result <path> [--case <id>] --json`, `agentic review evaluator policy [--input <path>] --json`, `agentic review xhigh plan --plan <path> --json`, `agentic review xhigh simulate --plan <path> --round-input <path> --json`, `agentic review quality longitudinal --evidence-set <path> --json`, `agentic review claim policy [--input <path>] --json`, `agentic review claim standard-gate --evidence-set <path> [--policy <path>] --json`, `agentic review claim audit --result <path> [--policy <path>] --json`, `agentic review dogfood readiness --json`, and `agentic review dogfood plan --case <id> --json` provide read-only benchmark, calibration, comparison, evidence-set, owner-labeled human baseline, policy, xhigh, longitudinal, claim, manual dogfood, standard/deep/xhigh maturity-plan, and benchmark-case matrix diagnostics for Agentic Human Review advisory output without provider calls, credential-value reads, evidence transfer from readiness/planning, artifact writes, deterministic gate changes, or MCP execution. For `--comparison-kind editorial-quality`, the baseline is a workspace-confined reference review text or JSON artifact, and output includes only hashes, scores, deltas, and diagnostics rather than reference or candidate prose.
- `agentic review status --execution <path> --json` and `agentic review list --json` read local Agentic Human Review execution metadata for dashboards and automation without launching browsers, contacting providers from read commands, storing credentials, writing review artifacts, or changing existing workflow status semantics.
- `npm run ahr:responses-adapter -- --json` starts the optional loopback Agentic Human Review Responses adapter for manual live dogfood. It is not a replacement for `agentic review run`; execution still flows through the existing plan hash, exact transfer flags, explicit `--execute`, and generic provider path.
- `agent ingest --package <path> --input <json> --json` imports untrusted agent advisory JSON from inline input, stdin, or a workspace-relative `@file` into separate advisory fields and writes local receipts without changing deterministic review findings, metrics, existing action plans, or release readiness.
- `agent report --review-index <path> --agent-result <path> --json` renders a separate Markdown advisory report without mutating existing review JSON.
- Review outputs include `action_plan`, `review_advisory`, and `quality_signals` objects for developer handoff while keeping subjective or model-like judgment out of deterministic gates.
- Review outputs include local `evidence_summary` data and `artifact_index` metadata so agents can evaluate expected UI state and hand developers a bounded artifact bundle.
- Target review can emit `local_content_ux_advisory`, `content_ux_findings`, `content_ux_action_plan`, `content_ux_readiness`, `content_ux_page_handoff`, `content_ux_manifest_authoring`, and `quality_signals.content_ux` only when the target manifest explicitly enables `localContentUxAdvisory.enabled=true`.
- The repository includes local plugin metadata, local MCP configuration, and a plugin-facing skill without adding marketplace registration, npm publication, external upload, credential handling, or an HTTP default in the packaged MCP config.
- `browser-debug-mcp --transport http --profile safe --host 127.0.0.1 --port <port>` starts only a local safe HTTP MCP endpoint. It requires a bearer token, validates loopback Host and Origin headers, and does not expose browser-launching, write-producing, cleanup, provider/API, shell, `full`, or `admin` tools.
- `browser-debug mcp config --json` returns reusable client configuration for stdio MCP without launching a server, mutating files, or requiring repository-specific source inspection. It includes installed-bin metadata and local-checkout metadata for unpublished package use.
- `browser-debug mcp config --transport http --profile safe --port <port> --json` returns launch and client-connection metadata for the explicit safe HTTP MCP endpoint without printing token values. It includes a local-checkout launch block for the current package entrypoint when `browser-debug-mcp` is not on PATH.
- `browser-debug mcp capabilities --profile safe|full|admin|all --scope all|profiles|excluded --json` returns the current MCP profile, transport, and admin exclusion policy without launching a server, mutating files, reading credentials, or enabling write/execute tools.
- `trace-cue operation registry --json` returns the shared operation registry, 1-8 roadmap group mapping, risk taxonomy, required gates, current MCP exposure flags, and read-only boundary metadata without writing artifacts, deleting files, executing providers, capturing pixels, translating content, publishing packages, migrating artifact roots, removing legacy aliases, running shell commands, or changing MCP permissions.
- `trace-cue settings language --json` returns the current dashboard display locale and artifact output language settings from the TraceCue-local dashboard settings file or defaults, normalizes aliases such as `zh`, exposes direction and `Intl` locale metadata, and reports that translation execution is disabled.
- `trace-cue settings language policy --json` returns the supported locale contract, independent language-setting roles, output modes, reserved translation modes, and read-only local boundary flags without launching a browser, writing artifacts, reading credentials, calling providers, or contacting the parent lesson repository.
- Review JSON, target review JSON, visual review dashboard JSON, and Markdown review reports include bounded language-setting metadata so dashboards and consumers can see which UI and artifact-language policy was applied without changing existing findings, metrics, action plans, quality signals, or gates.
- `docs/workflow/CONSUMER_USAGE.md` is packaged with the local tarball and documents external-repository CLI, MCP stdio, safe HTTP MCP, Codex plugin connection flows, and target runtime readiness checks without requiring source-code inspection.

## Phase 37 External Repository Usage Criteria

- Add a packaged guide for using Browser Debug CLI from a consumer repository before npm publication.
- Document that the current working directory should be the consumer repository when review artifacts and target manifests belong there.
- Document CLI, MCP stdio, safe HTTP MCP, and Codex plugin as connection modes over the same core rather than unrelated products.
- Document the practical capability differences between CLI, MCP `safe`, MCP `full`, MCP `admin`, safe HTTP MCP, and the Codex plugin.
- Document that consumer reviews depend on the target app's full local runtime, and that missing API/backend services can correctly surface as browser-health findings or `needs_attention`.
- Keep the guide generic, local-first, token-free, credential-free, and free of consumer-specific paths or product names.
- Keep package smoke coverage proving the guide is included in the local tarball without publishing.

## Phase 39 Consumer Runtime Readiness Criteria

- Clarify that Browser Debug CLI can be connected correctly while the reviewed app is still missing its own backend/API runtime.
- Document that frontend-only dev servers may produce valid `needs_attention` or browser-health findings when required local API endpoints are absent.
- Keep app-specific startup commands, API base environment variables, degraded-mode expectations, and acceptance notes in the consumer repository.
- Keep Browser Debug CLI runtime generic; do not add product-specific branches for missing consumer backend state.
- Add no-browser architecture coverage proving the packaged consumer guide keeps runtime-readiness guidance generic and free of consumer-specific paths or product names.

## Phase 35 HTTP MCP Integration Hardening Criteria

- Add a no-side-effect MCP client configuration command that can be used from any repository after install or from this checkout.
- Keep generated stdio configuration compatible with normal MCP client `mcpServers` shapes while preserving the existing packaged `.mcp.json` compatibility behavior.
- Include a generated local-checkout `mcpServers` shape for stdio use when the package bin is not installed or not on PATH.
- Keep generated HTTP configuration safe-profile-only, loopback-only, bearer-token-env-based, and explicit about the single-request POST JSON response subset.
- Include a generated local-checkout launch shape for safe HTTP use when the package bin is not installed or not on PATH.
- Default generated HTTP examples to a fixed local port suitable for client configuration, while keeping the server runtime default port unchanged.
- Add packed-install smoke coverage that creates the safe HTTP MCP handler from the installed package API and completes an authenticated `initialize` request without binding a port.
- Keep all configuration output token-free, credential-free, local-first, reusable, and generic across external repositories.

## Phase 36 MCP Capability Policy Criteria

- Add a no-side-effect MCP capability policy command that can be used from any repository after install or from this checkout.
- Report safe/full/admin profile tool surfaces, stdio and safe HTTP transport support, and the current `admin` policy in a machine-readable JSON envelope.
- Report excluded MCP operations such as artifact cleanup execution, package/ingest/report writing, workflow creation/report writing, execution planning outside the approved stdio `admin` agent execution plan path, `agent execution run` outside the approved stdio `admin` path, provider/API execution outside the approved stdio `admin` agent execution adapter path, arbitrary shell, safe/full/HTTP persistent session control, unapproved daemon control, socket transport, remote HTTP listeners, and HTTP `full` or `admin`.
- Keep the report read-only, token-free, credential-free, local-first, reusable, and generic across external repositories.
- Expose the same report through the safe/full/admin MCP profiles because the report does not launch browsers, write artifacts, delete files, call providers, upload evidence, execute shell commands, or open listeners.
- Keep `admin` distinct from `full`; the capability report may identify approved stdio `admin` agent execution plan/run exposure and approved stdio `admin` persistent session exposure, but must not itself enable cleanup execution, unrelated provider/API execution, shell tools, non-admin persistent session control, credential handling, HTTP `full` or `admin`, socket transport, or remote listeners.

## Phase 29 Agent Execution Criteria

- Completed: `agent execution plan --package <path> --surface <id> --provider <id> --model <id> --json` creates a local no-network dry-run plan and receipt for subscription or API execution.
- Completed: `agent execution run --execution <path> --package <path> --surface <id> --provider <id> --model <id> --execute --json` requires a prior dry-run execution plan, rejects execution without explicit `--execute`, validates package/surface/provider/model plan consistency, and records local run receipts.
- Completed: `agent execution status --execution <path> --json` and `agent execution list --json` report local execution state, normalized advisory-result paths, dashboard status fields, and aggregate boundary flags without launching browsers, mutating review artifacts, or changing deterministic gates.
- Completed: subscription-style execution supports configured local runner callbacks through provider/model identifiers and rejects free-form shell input or SaaS web UI automation.
- Completed: deterministic fake-provider execution covers no-browser provider success paths and advisory-result normalization.
- Completed: API-style execution reads endpoint and credential values only from named environment variables, supports injected fetch transports for tests, records that an API call occurred, and never records credential values.
- Completed: execution plans and receipts record `api_call_performed`, `external_evidence_transfer`, `automatic_upload`, `credential_values_recorded`, `credential_storage`, `persistent_credential_storage`, `raw_response_stored`, `raw_provider_response_stored`, `existing_review_mutated`, `mcp_execution_exposed`, and `gate_effect`.
- Completed: execution output normalizes provider or runner responses into the existing untrusted advisory-result shape so dashboards get the same final experience for subscription and API modes.
- Execution output should not change review `findings`, `metrics.finding_count`, existing `action_plan`, `quality_signals.release_readiness`, resource guard behavior, artifact cleanup behavior, or existing workflow status semantics.
- MCP stdio `admin` may expose `agent execution plan/run` only for the approved Phase 74-76 provider execution path. Safe, full, and HTTP MCP profiles must not expose execution; additional MCP execution families require a separate allowlist decision and tests.

## Review Platform Criteria

- Completed: the review platform uses the existing Playwright runtime as the browser automation layer and adds a reusable review core above observation, action, artifact, and reporting primitives.
- Completed: `browser-debug review --url <url> --json` provides a single-URL review MVP with deterministic findings for browser health, horizontal overflow, clipped content, missing accessible names, empty renders, and local evidence completeness.
- Completed: `browser-debug review --target <manifest> --json` extends review to a generic target manifest with `baseUrl`, seed routes, scope rules, viewport matrix, action policy, artifact settings, and execution budgets.
- Completed: site review discovers routes from same-origin links and action candidates, then reports discovered, visited, skipped, failed, and expected-missing routes.
- Completed: site review visits manifest `expectedRoutes` as explicit review targets and records route-budget skips when `budgets.maxRoutes` prevents full coverage.
- Completed: site review checks optional manifest `pages` for expected visible text and selectors, records page expectation coverage, and emits findings when expected UI state is missing.
- Completed: page entries can add page-specific viewport coverage and page-specific mock metrics while reusing the existing target review and mock comparison paths.
- Completed: review runs a viewport matrix and records route, viewport, and action coverage without depending on a specific application stack.
- Completed: findings include `category`, `severity`, `confidence`, `selector`, `rect`, `evidence`, `artifacts`, and `repro` data.
- Completed: findings include developer-facing enrichment fields such as `priority`, `impact`, `recommendation`, `fix_candidates`, and `implementation_notes`.
- Completed: review results include `action_plan` and `review_advisory` to prioritize remediation and summarize local heuristic visual review signals.
- Completed: review results include `quality_signals` for heading hierarchy, rendered state, landmarks, image alt text, contrast, overlap, mobile target sizing, route coverage, evidence completeness, release readiness, developer handoff, and the disabled model-review boundary.
- Completed: target review results include `quality_signals.page_expectations` for expected page counts, checked pages, failed pages, skipped pages, and missing text or selector expectations.
- Completed: review results include local artifact indexes that summarize evidence classes and rerun guidance without uploading artifacts.
- Completed: local rendered-state review findings flag broken visible images, explicit or semantically marked lingering loading indicators, and empty data containers without visible empty-state messaging.
- Completed: loading indicator detection ignores normal ready/progress business-state text unless explicit loading semantics or loading-like attributes are present.
- Completed: target review output includes manifest suggestions for adding named page expectations, pinning expected routes, raising or splitting route budgets, and covering rendered-state gaps.
- Completed: target review supports opt-in `localContentUxAdvisory` with inline `sourceData` and page `expectations.dataBindings` for advisory source-to-screen checks.
- Completed: content UX advisory supports selector-scoped `text`, `attribute`, `data-state`, and `data-risk` bindings plus required user-question checks for information architecture and user-journey handoff.
- Completed: content UX advisory is additive, local-only, creates only separate `content_ux_findings`, does not create review findings, does not change `metrics.finding_count`, does not change `action_plan`, and does not change `quality_signals.release_readiness`.
- Completed: target review emits separate `content_ux_action_plan` and `content_ux_readiness` outputs so content-owner handoff can advance without changing existing release readiness or action-plan semantics.
- Completed: content UX advisory categorizes advisory findings for status clarity, action clarity, navigation clarity, information architecture, source alignment, content contracts, coverage contracts, and review scope while still accepting legacy manifest category aliases.
- Completed: target review emits separate `content_ux_page_handoff` and `content_ux_manifest_authoring` outputs for page-level triage and manifest authoring guidance.
- Completed: target review emits separate `content_ux_review_brief` and `content_ux_rubric_evaluation` outputs for manifest-declared audience, page roles, decision needs, and rubric criteria.
- Completed: mock comparison is optional and conservative; dimension mismatches, missing baselines, or unsupported images produce `inconclusive` review metrics rather than false pass/fail certainty.
- Completed: MCP support is implemented as thin adapters over the same core, not as a separate product runtime or default dependency. Stdio remains the compatibility default, and HTTP is explicit, loopback-only, token-gated, and safe-profile-only.
- Completed: model or vision review remains outside deterministic local review checks and has not been implemented.

## Plugin and Dogfood Readiness Criteria

- Completed: `target init` creates a manifest artifact that can be edited for applications with multiple routes.
- Completed: `target validate` checks edited manifests and reports normalized counts, local authoring suggestions, review next commands, and local-first boundaries before browser review.
- Completed: edited manifests can add unlinked `expectedRoutes`, and target review will visit them within scope and budget.
- Completed: edited manifests can add optional `pages` entries for expected page state and per-page mock metrics.
- Completed: edited manifests can opt into content UX advisory by declaring bounded inline `sourceData`, `localContentUxAdvisory`, and page `expectations.dataBindings`.
- Completed: edited manifests can add `localContentUxAdvisory.reviewBrief`, `localContentUxAdvisory.rubric`, and page `role` fields for advisory review-brief and rubric evaluation.
- Completed: reusable target manifest templates include a generic status-dashboard content UX advisory example without adding runtime product-specific branches.
- Completed: target review can emit a Markdown report with action plan and local advisory sections.
- Completed: Markdown reports include quality signal summaries so developers can triage local review output without reading raw JSON first.
- Completed: MCP tool allowlists include target manifest initialization, target manifest validation, and target review without adding shell, cleanup execution, socket transport, remote HTTP listener, external upload, or profile-reuse tools.
- Completed: MCP tool allowlists include local resource status preflight without adding shell, cleanup execution, socket transport, remote HTTP listener, external upload, profile-reuse, or privileged host mutation tools.
- Completed: MCP tool allowlists include local artifact usage planning without exposing artifact cleanup execution.
- Completed: MCP tool allowlists include read-only MCP capability policy inspection without exposing unrelated write/execute/admin operations.
- Completed: local agent advisory handoff commands create bounded task packages, list and inspect request state, import advisory results, and render separate reports without direct API calls, automatic upload, credential storage, MCP agent execution, or deterministic gate changes.
- Completed: `.codex-plugin/plugin.json`, `.mcp.json`, and `skills/browser-debug-review/SKILL.md` define a local plugin bundle over the existing CLI/MCP surface.
- Completed: `templates/review-target-manifest.json` provides a reusable manifest starting point for local route and viewport review.

## Closed Local Decisions

- JSON envelopes, artifact descriptors, and local metadata use schema version `0.1.0` for the local MVP. Additive fields may be added while existing fields keep their meaning and type. Renaming, removing, or changing the type of existing fields requires a schema version bump with updated docs and tests.
- Generated artifacts are retained manually under the ignored `.browser-debug/` artifact root. The CLI does not auto-delete artifacts. Explicit cleanup is available only under the configured artifact root with `resource artifacts cleanup --execute` and a local receipt.

## Open Decisions

- Final public npm package name and npm scope.
- Release license and contribution policy.

## Phase 41 Visual Evidence Core Criteria

- TraceCue must support local metadata records for visual evidence from browser screenshots, image files, future screen captures, future window captures, and future desktop app captures.
- Visual evidence metadata must remain local-first, artifact-root-confined, schema-versioned, and additive to existing review and agent workflows.
- The current default artifact root remains `.browser-debug/` for compatibility; `.trace-cue/` remains a future migration option only.
- Visual evidence metadata must not include raw image bytes, provider responses, credentials, cookies, storage state, or automatic external transfer.
- Existing CLI aliases, MCP tool names, artifact roots, schema fields, and browser review behavior must continue to work without tradeoffs.

## Phase 43 Standalone Image Review Criteria

- `review --image <workspace-file> --json` reviews workspace-confined image files without launching a browser.
- Standalone image review must reuse visual evidence metadata and write local review/index artifacts under the configured artifact root.
- Standalone image review must not embed raw pixels in JSON, copy source images into packages, call providers, upload evidence, read credentials, expose MCP execution, or change existing URL/target review behavior.

## Phase 51 Desktop Image Review Criteria

- `review --image <workspace-file> --capture-handoff <workspace-json|-> --json` must accept existing screen, window, and desktop app screenshot handoff metadata.
- The image review must verify that the handoff source path and SHA-256 media hash match the reviewed workspace image before propagating desktop provenance.
- The output must keep source provenance caller-declared and must not claim TraceCue captured or verified the actual OS screen, window, or desktop app identity.
- Desktop image review must remain no-browser, no-provider, no-raw-pixel JSON, no external transfer, no MCP execution, and additive to existing standalone image review.

## Phase 53-55 Multi-Agent Visual Review Aggregation Criteria

- `visual review aggregate --preparation <workspace-json> --json` must read existing local visual review result metadata for one preparation and aggregate advisory findings across reviewer outputs.
- Aggregation must keep every advisory finding source-attributed to result, provider, model, and finding identifiers.
- Aggregation must report corroborated findings, conflicts, owner decision requests, source effects, and read-only boundary flags.
- Aggregation must treat provider output as untrusted advisory data, bound text and result counts, skip malformed or unsafe local artifacts with warnings, and avoid release gate changes.
- Aggregation must not run providers, read raw pixels, write artifacts, mutate existing reviews, expose MCP tools, read credentials, or store raw provider responses.

## Agentic Human Review Responses Adapter Contract Recovery Criteria

- TraceCue must treat external provider effort settings as advisory execution controls and enforce `standard`, `deep`, and `xhigh` review quality through TraceCue-owned mechanical contracts after provider output is returned.
- Responses adapter validation must aggregate benchmark, owner-baseline, optional claim, and effort-aware staged-role contract failures into one repairable diagnostic instead of stopping at the first failure family.
- Repair prompts must be compact and reusable: they should include only missing or invalid checklist items, approved criterion ids, owner label ids, required fields, role/round gaps, and recommended local evidence-reference ids while relying on the original request as the canonical full contract.
- Explicit staged provider calls for `standard`, `deep`, and `xhigh` must validate the required stage roles and round for each stage, and the final staged call must still require synthesis integration. Intermediate stage output remains non-final evidence and cannot enter proof, calibration, comparison, evidence-set, claim-readiness, longitudinal, or claim-standard-gate diagnostics by itself.
- Provider failure diagnostics written to execution records and receipts must preserve safe loopback adapter error codes, missing-condition summaries, size/timeout metadata, and stage identifiers while excluding raw provider responses, provider request bodies, credential values, endpoint strings, local paths, and raw payloads.
- Adapter startup output and help must expose request-size and provider-response-size limits so long real-page dogfood runs can be configured deliberately without source inspection.
- Provider output JSON recovery must remain local, bounded, and fail-closed. The adapter may extract exactly one advisory JSON object from a direct JSON body, a JSON string, a single JSON Markdown fence, or prose wrapped around one balanced JSON object, then must continue through the same unwrap, evidence-reference, benchmark, owner-baseline, staged-effort, claim-filtering, and advisory-only normalization contracts. Multiple JSON candidates, non-JSON fences, malformed JSON, arrays, primitives, or non-advisory objects must not become accepted proof.
- This recovery layer must stay target-agnostic. It must not add branches for a specific page, benchmark case, repository name, product name, URL, local path, provider model, or one-off dogfood artifact.

## Control Center Browser Surface Criteria

- TraceCue must provide a local browser surface for non-engineers that can run the dedicated page-review and approved Agentic Human Review workflow without becoming a generic provider console, shell, cleanup surface, MCP write/execute surface, or gate-affecting execution surface.
- The surface must answer only the practical owner questions: whether review can proceed, what is missing, what to inspect next, what evidence supports the status, and what actions remain prohibited.
- The browser surface must be implemented with React + Vite under `control-center/`, and its visual styling must be driven by `docs/design-system/tokens.json` and `docs/design-system/components.json`.
- The read model must reuse existing TraceCue APIs such as visual review dashboard, agent request/workflow/execution status, resource status, artifact-root status, language settings, and optional owner-review evidence-pack projection instead of reading raw artifacts directly.
- The server must be loopback-only, Host/Origin validated, cache-disabled with `Cache-Control: no-store`, and keep `/api/dashboard` GET-only.
- The server may expose only approved bounded local POST actions for Control Center workflows. The existing eight action endpoint paths remain unchanged. Separate namespaced endpoints may persist ordinary Control Center preferences and prepare, confirm, start, decide, or repeat one dedicated page review. External AI execution requires a fresh one-time confirmation bound to the prepared disclosure and plan.
- Source intake must create only local non-executing proposal artifacts from workspace-confined source text; it must not run providers, call APIs, use shell commands, expose MCP execution, transfer evidence externally, store full source text, store chunk text, mutate review gates, or execute plans.
- Display-language settings must write only the ignored TraceCue-local user override and must not mutate tracked shared defaults, translate source evidence, provider output, generated review text, or artifact output language.
- The UI must stay minimal and follow the accepted prototype typography, spacing, and narrow settings layout. The ordinary Settings page contains display language, default review screen size, a plain-language automated-check choice, AI suggestions, immutable send-before-confirmation, and one save action. Implementation names such as Playwright or CI, technical locale state, providers, models, credentials, storage paths, diagnostics, regression import forms, and boundary badges must not appear there.

### Purpose-Led Production Navigation Criteria

- The ordinary Control Center must organize the product around three top-level destinations: `確認` (`confirm`), `進行中` (`running`), and `設定` (`settings`). Detailed Regression, Evidence, Findings, and Advanced data and actions remain compatible through backend, CLI, API, and read-model contracts, but must not add technical disclosures to the ordinary Settings page.
- The ordinary workflow must use five user stages: `準備` (`prepare`), `確認` (`review`), `判断` (`decide`), `再確認` (`recheck`), and `完了` (`complete`). These stages summarize current local evidence and available navigation only; they must not fabricate timers, percentages, findings, decisions, recheck outcomes, or completion.
- The default ordinary screen must lead with the user's current goal, current truthful status, one primary safe action, and a result or empty state that explains the next available step. Status-only panels without a decision or navigation purpose must not become ordinary destinations.
- Review effort must be selected through purpose-led labels while preserving the exact existing `standard`, `deep`, and `xhigh` values in the proposal request. The selection titles are `大切な改善点を知りたい` for `standard`, `改善点を詳しく洗い出したい` for `deep`, and `重要な判断の前に念入りに確かめたい` for `xhigh`; their short action labels are `大切な改善点を確認`, `詳しく確認`, and `念入りに確認` respectively.
- Purpose-led effort selection must prepare a real TraceCue browser review and, when AI suggestions are enabled, the existing Agentic Human Review proposal and plan. It must not call the external AI service until the user sees the concrete service name and transferable evidence classes and explicitly starts that prepared revision.
- The purpose-led slice must preserve the exact existing eight Control Center action endpoint paths and must not add a generic action endpoint. Its additional namespaced endpoints are limited to Control Center preferences and agentic review prepare, confirmation, start, status, decision, repeat, and list.
- A completion label must be withheld whenever the current read model lacks completion evidence, has unresolved blockers, or reports only proposal readiness. Proposal creation, advisory readiness, and `gate_effect=none` are not review completion.

### Control Center Agentic Review Execution Criteria

- Review state must persist under the local artifact root so closing the page does not lose prepared, running, completed, failed, or decision state. Public projections must omit local paths, hashes, provider/model identifiers, credentials, request bodies, and raw provider responses.
- Browser input may choose only URL, purpose, purpose-led effort, viewport, and whether AI suggestions are used. Provider, model, endpoint, token, plan, hash, transfer flags, artifact root, and execute authority must be rejected if supplied by the browser.
- External service credentials stay in environment/provider configuration. The browser must never accept, read back, or persist credential values.
- Confirmation must name the configured external service and enumerate what evidence will be sent. Its nonce is one-time, time-bounded, stored only as a hash, and invalidated when the disclosure or prepared plan changes.
- After dispatch begins, TraceCue must never retry automatically. If a restart makes completion uncertain, status becomes `dispatch_unknown`; the UI must explain the uncertainty and avoid a duplicate provider call.
- Findings are advisory. Each finding may receive `fix`, `later`, or `ask`; these choices and AI output must not mutate deterministic findings, proof contracts, owner authority, or release gates.
- `recheck` and `deeper` create new operations and new browser evidence. `deeper` advances `standard` to `deep` and `deep` to `xhigh`; it is unavailable after `xhigh`.

## Document Synchronization Enforcement

- TraceCue must reject integration ranges that change classified product,
  workflow, CI, Agentic Human Review, provider/external-send, MCP, persistent
  browser-session, evidence, evaluation, or claim authorities without the
  required product, workflow, verification, security, and manifest updates.
- Synchronization must be evaluated over the complete pull-request or push
  range, not each commit. Renames and deletions must remain visible to the
  classifier, and missing comparison commits must fail closed.
- The policy must be repository-local, JSON-based, schema-versioned,
  dependency-free on Node 20, reusable by local checks, an optional safe
  pre-push hook, and CI without duplicating product or browser tests.
- Temporary memory, ignored local dashboard overrides, ignored/generated browser
  evidence, dependencies, builds, coverage, and test reports must neither
  trigger synchronization nor count as synchronized authority.
- Mechanical synchronization is an omission guard only. It must not replace
  semantic review, focused tests, security inspection, or existing gates.

## Development Workflow Enforcement

- `docs/workflow/INSTRUCTION_MEMORY.md` remains the English human authority for
  durable development instructions. Stable `workflow-rule:*` identifiers map
  its enforceable subset to `ops/DEVELOPMENT_WORKFLOW_POLICY.json`.
- The policy must be strict, schema-versioned, repository-local, and free of
  fixed model or reasoning-effort selections. Non-trivial proposal and plan
  reviews inherit the active user session selection when the runtime exposes or
  verifiably inherits it.
- When the runtime does not expose or attest effective subagent settings, the
  workflow must disclose that limitation and must not claim a specific model or
  effort. Product Agentic Human Review `standard`, `deep`, and `xhigh` effort
  contracts remain separate and unchanged.
- The dependency-free checker must reject unknown policy fields, duplicate rule
  ids or anchors, missing instruction anchors, unregistered test ids, missing
  required files, missing package scripts, and fixed selection overrides.
- Machine enforcement is limited to objective structure, registration,
  synchronization, and executed checks. It must not claim to prove semantic
  design quality, approval authenticity, complete no-regression, useful
  parallelism, or unavailable runtime attestation.
- The existing `repository-contracts`, Node, and browser jobs retain separate
  responsibilities. Workflow policy checks must not duplicate product or
  browser execution and must not change Control Center, CLI, provider, MCP,
  browser-session, evidence, or release-gate behavior.

## Local Dashboard Settings Persistence

- `ops/DASHBOARD_SETTINGS.json` is the tracked shared-default authority. Ordinary
  Control Center and Playwright Test setting changes must never write it.
- User choices are stored in ignored `ops/DASHBOARD_SETTINGS.local.json` and
  layered over shared defaults through one allowlisted settings store.
- The ordinary Settings page must validate display language, default viewport,
  AI suggestions, and Playwright Test mode before one atomic save. A failed save
  must not leave a partially applied combination.
- Local settings must not disable external-send confirmation or enable provider,
  credential, browser, shell, MCP, translation, destructive, or release-gate
  authority. Malformed, oversized, non-regular, symlinked, or workspace-escaping
  settings must fail closed.
- Existing display-language, preference, Playwright mode, and approved external-CI
  compatibility endpoints must use the same local store and preserve unrelated
  settings branches. Saving user preferences must not make Git dirty.

## Verification Orchestration Requirements

- TraceCue must provide one repository-local, versioned verification authority
  for task argv, profiles, dependencies, execution kinds, resource locks,
  bounded limits, changed-path selection, CI execution instances, cache
  boundaries, and the proof-only final owner.
- Commands must be spawned as argv without shell evaluation. Unknown tasks,
  profiles, fields, dependencies, owners, cache states, or proof inputs must fail
  closed. A deterministic one-worker path must remain available.
- Verification CLI arguments must be command-specific and strict. Unknown,
  repeated, valueless, conflicting, or inapplicable options must fail before a
  task runs. The configured release profile, remote name, workflow path, and
  allowed GitHub hosts must come from policy rather than command literals.
- Independent local checks may run with bounded rolling parallelism. Package,
  browser, build, settings, and evidence mutation must be isolated or locked;
  timeout, output limit, cancellation, or cleanup failure must fail the gate.
- A verification request that is already cancelled must not start a child task.
  Cancellation observed before or during orchestration must cancel active and
  pending work, remain non-passing, and preserve the repository snapshot.
- Dependency scheduling must be independent of task declaration order. A
  serial consumer waiting on a later-declared producer must not block that
  producer from running, and unresolved dependencies must never be reported as
  a successful or skipped check.
- `focused` is a partial local result. It must explain why checks were selected,
  use a conservative full-core fallback for unknown paths, and must never claim
  release readiness. CI and complete release verification must execute every
  required owner regardless of changed-path selection.
- The no-browser suite must remain compatible through `npm test` while its large
  CLI regression surface is split by product responsibility into independently
  runnable files. Test names, assertions, and pre-split coverage must remain.
- Node 20 and Node 22 runtime compatibility must remain separate execution
  instances. Package production must occur once per CI run, and every configured
  consumer must verify and test the same revision-bound tarball without repacking.
- Package manifest inspection must work in non-interactive CI with piped parent
  output. Empty, incomplete, oversized, or invalid npm JSON output must fail
  closed from a run-isolated private file rather than being inferred as PASS.
- Both dry-run inspection and the real package producer must capture npm JSON
  through the same bounded, mode-0600, same-descriptor file helper. Neither
  path may accumulate unbounded child stdout in memory.
- Cross-run Playwright caching may contain exact-version browser binaries only.
  A cache hit cannot satisfy a test and must not contain results, receipts,
  profiles, storage state, traces, screenshots, or reports.
- Authoritative local evidence must come from an executed clean result and bind
  full HEAD, tree, worktree, inputs, policy, command, and result. Manual PASS,
  dirty success, expired or mismatched receipts, and raw secret-bearing evidence
  cannot satisfy readiness.
- Remote readiness must be represented by one proof-only final job bound to the
  same workflow run, attempt, full HEAD, policy, and exact owner graph. It must
  not rerun provider suites or reuse local or prior-run PASS results.
- CI ownership must be validated from parsed YAML structure. Required jobs and
  steps may not use conditions, failure-ignoring controls, shell masking, matrix
  include/exclude changes, alternate shells, or working-directory overrides to
  bypass a policy-owned command or execution instance.

## Parent Authority Evidence Projection

- The Dashboard-facing evidence index must remain a derived current-state view,
  not an append-only history. Historical and superseded evidence must remain
  locally inspectable without participating in the current readiness decision.
- The active receipt and release-batch stores must enforce policy-owned count,
  byte, lock, stale-owner, and ingress limits. Superseded immutable records must
  move atomically to a marker-owned inactive archive rather than be deleted.
  The inactive archive is non-authoritative local history and is not claimed to
  have an automatic total-size bound; export or compaction requires a separate
  explicit design.
- The projection must use the parent's fixed 13-column contract, a full product
  HEAD, and UTC timestamps at whole-second precision. An invalid row must fail
  closed rather than being normalized into a successful result.
- A source with one active workflow context must have a matching safe v2 detail
  projection. A source with multiple active contexts must use a context-neutral
  detail so Dashboard never attributes one context's event to another.
- Pre-v2 short-HEAD rows must be archived with an integrity digest before they
  are removed from the active projection. They must never be promoted to current
  authority, silently deleted, or re-imported on later rebuilds.
- Readiness aggregation must consider current required evidence only. Missing,
  failed, blocked, advisory, stale, dirty, or tampered required evidence must
  remain non-ready; optional historical evidence must not make a current
  required result stale.
- Required-source completeness must come from the evidence detail manifest.
  Required sources without a current receipt must be projected as `not_run`;
  contextual sources are not required until a separate operation-specific
  applicability decision exists.
- Evidence storage must reject symlinked evidence directories and altered
  integrity-bound receipt fields before writing or projecting authority.
- Concurrent receipt writers may coalesce a derived-view rebuild only after the
  locked, bounded ledger proves that the exact new event is already projected.
  Coalescing must not drop receipts or weaken deterministic rebuilds.
- A complete release batch must reserve bounded temporary receipt admission for
  all policy-owned sources before sequential publication. Interim retention
  must not discard an earlier batch receipt while an older authoritative failure
  remains the semantic winner before commit; the committed batch must fit the
  configured active count and byte capacities.
- Parent compatibility is verified read-only. TraceCue must not modify the
  parent repository or weaken the parent's missing-evidence, freshness, HEAD,
  authority, or malformed-index rejection behavior.

## Control Center Goal Completion

- A non-engineer must be able to start the installed Control Center without
  building the React application or entering an implementation command. The
  launcher must use package-relative assets, keep the selected workspace as a
  separate data boundary, reuse a healthy existing loopback instance, and
  present the local URL when the operating system cannot open it. Reuse must
  also match the runtime protocol, package version, and packaged asset identity.
- `New review` must provide one purpose-led entry for a website URL, a local
  image, a UTF-8 text document, or a Playwright JSON/JUnit result. File input
  must use the browser picker or drag and drop; arbitrary local path entry is
  forbidden.
- The destination for each input must remain truthful: URL runs the existing
  browser review; image runs the existing metadata/evidence review; text
  prepares a local review proposal; Playwright imports and summarizes test
  evidence. Raw PDF/DOCX, OCR, browser execution, and remote CI execution are
  not supported by this entry point.
- Uploaded input must be streamed to a workspace-confined private intake store
  under an unpredictable opaque id. Per-file, per-operation, total-capacity,
  type, signature, dimension, UTF-8, retention, and cleanup limits must fail
  closed. Public state must not expose storage paths or original filenames.
- Intake quota checks and completion must be cross-process transactions. One
  source can execute at most once, abandoned reservations and orphaned files
  must be cleaned safely, and completed safe results must remain listable and
  openable after navigation, reload, or restart.
- Active Control Center history may be count bounded for predictable listing,
  but completed operation and intake-result records must not be automatically
  deleted. Older records must move to a private sharded inactive history and
  remain directly readable by opaque id until the user explicitly cleans the
  configured artifact root. History movement must acquire the same per-record
  lock as publication or update and revalidate the selected revision before the
  active copy moves. History maintenance must run outside the committed primary
  transaction: lock contention or archival failure must not delay external
  dispatch, turn a saved decision or completed intake into an error response, or
  overwrite the primary operation result. Time-based cleanup may remove expired
  unfinished intake state and released source bytes, but it must not remove a
  completed receipt before explicit artifact-root cleanup.
- A private store may create its ownership marker only when it atomically
  creates the store root. A pre-existing markerless root must fail closed and
  its contents must remain untouched. Read-only requests must not create the
  store, marker, result directory, or any other artifact state.
- Quota accounting must include every unexpired staged source, live processing
  source, and active reservation so concurrent completion cannot free capacity
  before its private source is actually released.
- Active intake-result publication must have a configurable hard count bound.
  Admission must reserve one opaque id under a cross-process lock, bind that
  reservation to exactly one completion owner, renew its lease during long
  processing, and permit non-owners only to wait for or read the same result.
  A second request must never run the intake engine for an id already owned by
  another request, and a different id must remain blocked while the bound is
  full.
- Reading an already completed active or archived result must not require a new
  publication slot. A completed same-id retry must remain available while the
  active result store is full or history maintenance is temporarily busy.
- Intake publication must remain private until the result digest, completed
  receipt, and source-release marker are durably consistent. A valid pending
  pair may be finalized once after interruption. Processing state without a
  valid pending pair must become a non-retryable interrupted or invalid result,
  release its reservation and safe result file, and allow later intake and
  result admission to recover without running the engine again.
- A private-store lock owner must not leave its logical lock permanently held
  when the coordinated release window expires. A nonce- and process-identity-
  matched owner may remove only its own unchanged lock; changed ownership or
  unsafe state must fail closed.
- Ordinary AI state must say only whether suggestions are available, need
  setup, or are unavailable, together with a user-facing service name and a
  safe next step. Provider, model, endpoint, credential name/value, destination
  fingerprint, and configuration hash are not ordinary UI content.
- External AI execution continues to require a fresh concrete disclosure and
  one-time confirmation. Input identity, evidence classes, service identity,
  and a non-secret destination configuration fingerprint must remain unchanged
  through dispatch.
- Interrupted work must expose only truthful recovery actions. Local preparing
  may restart explicitly, expired confirmation requires a new disclosure,
  dispatch uncertainty must never retry automatically, validation may resume
  only from verified persisted execution evidence, and cancellation may be
  claimed only before external dispatch or for a genuinely abortable local
  task.
- A same-server operation whose background task is no longer active must be
  recoverable even when its persisted owner process is still alive. Another
  live process remains authoritative while it owns the work. Active operation
  admission must be bounded and may retire only revision-revalidated terminal
  records to inactive history.
- Read-only status, list, dashboard, and saved-result GET requests must not
  recover or otherwise mutate state. Recovery must be an explicit protected
  action. A known no-send failure must remain retryable as failed, while a
  possible transmission remains dispatch-unknown and cannot auto-retry.
- A failure is known to be pre-send only when the runner returns an explicit
  structured boundary attesting false for provider call, API call, and external
  evidence transfer. A thrown runner or a missing/partial boundary is uncertain
  and must remain `dispatch_unknown`.
- The UI must show purpose and standard/deep/xhigh only when the selected engine
  uses them. It must follow the approved production mock and design tokens,
  preserve visible keyboard focus, show safe actionable errors, translate the
  representative RTL flow, and avoid overlap or horizontal overflow at the
  verified mobile, tablet, and desktop widths.
- Saved image, document, and test results must show the safe source-specific
  facts needed for a decision. Prepared evidence or a proposal must never be
  counted or presented as a completed review. Failed, timed-out, empty, missing,
  blocked, stale, or unreadable automated checks must never use a passing state;
  timeout, skipped, and failure counts must survive the safe projection.
  Agentic and intake items must share one newest-first order, dates must use the
  selected locale, and a result-list read failure must retain already displayed
  results with a clear retry action.
- After one file intake succeeds, the same form must not submit that file again.
  The user must explicitly choose to prepare another item or open the saved
  result. Intake-only results must not show the website-review five-stage
  completion sequence.
- Status meaning must remain visible as text on mobile instead of relying on
  color alone. Current workflow stages and selected finding decisions must
  expose standard accessibility state, and directional symbols must follow the
  active text direction.
- A complete local release verification may refresh product authority only as
  one exact-HEAD evidence batch. All projected source receipts must reference
  the same batch. Verified remote CI proof remains a distinct exact-run
  authority and cannot replace local release evidence.
