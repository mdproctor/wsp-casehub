# Decisions — #89 Redefine Briefing as Voice Card

## D1: Briefing field structure

**Choice:** Structured sub-fields in the eidos descriptor — a single `voice` field of type `AgentVoiceProfile` record (like `AgentDisposition` already is), not flat fields scattered on `AgentDescriptor`.
**Alternatives:**
- Single text field (rewrite content only) — simpler but the constraint is social (authoring convention) not structural; doesn't prevent behavioral instructions creeping back
- Hybrid (voice field + briefing) — half-measure, two fields but no full separation
- 8+ flat fields on AgentDescriptor — bloats the already 26-field record; rejected after decision review R1-02
**Rationale:** Pre-release platform — the right time to harden foundations. Structural separation enforces the voice/behavior boundary at the API level, not just by convention. Follows the same principle as the write-content skill's Form/Mode/Voice taxonomy: what the agent is, how it behaves, and how it sounds are different concerns that should be structurally distinct. The `AgentVoiceProfile` record pattern matches `AgentDisposition` — a nested structured type rather than flat fields.
**Trade-offs:** Requires eidos API changes (new record type, renderer updates, vocabulary support). Every consuming app's descriptor YAML needs updating.
**Sources:** write-content skill (Form/Mode/Voice taxonomy), mark-proctor-voice.md (voice fingerprint structure), descriptors-composite.yaml (current briefing content), AgentDisposition (pattern for nested structured type)
**Exploration:** quick
**Revision:** R1-02 — voice profile as nested record, not flat fields on AgentDescriptor
**Status:** revised

## D2: Voice profile fields — layered voice authoring

**Choice:** Layered voice authoring with a `description` field as the primary voice identity signal. `AgentVoiceProfile` record contains: `description` (natural language voice identity phrase), `register` (vocabulary-resolved), `accent` (vocabulary-resolved), `catchphrases` (list), `speech_patterns` (list), `vocabulary_uses` (list), `vocabulary_avoids` (list), `quirks` (list), `personas` (optional map of named voice variants). Layer 1 (`description`) lets the LLM draw from training data for well-known characters. Layer 2 (structured fields) provides optional fine-tuning where the LLM's default isn't quite right. Both layers render together — description first, structured fields as supplements.
**Alternatives:**
- Pure structured, no freeform (R1-03, original choice) — works for cartoon characters but doesn't generalise: clinical and AML agents don't have catchphrases or quirks. Enumerated fields over-constrain well-known characters and waste tokens restating what the LLM already knows.
- Prose-only (single text field) — simpler but no programmatic hooks for persona selection, vocabulary resolution, or tooling.
- Template-based voice (R1-02 alternative) — templates render to prose, not programmatically inspectable; can't support persona selection (D3).
**Rationale:** For well-known characters (e.g., Wacky Races), the LLM's training data IS the voice definition — a brief description is sufficient. For original characters, structured fields add information the LLM doesn't have. The enumerated fields (catchphrases, vocabulary) were domain-specific to cartoon characters and didn't generalise to clinical, AML, or other domains. Layered authoring gives the best of both: token-efficient for known characters, precise for original ones.
**Trade-offs:** Authors could put behavioral instructions in the description field. The separation relies on authoring discipline rather than structural enforcement. Mitigated by the cognitive system carrying behavior independently.
**Sources:** Analysis of 4 Wacky Races characters, domain generality testing against clinical/AML use cases. R2-01 — revised after implementation showed enumerated fields redundant for well-known characters.
**Exploration:** deep-analysis
**Revision:** R2-01 — layered voice authoring (description as Layer 1, structured fields as optional Layer 2)
**Status:** revised

## D3: Hooded Claw dual-voice — personas map with cognitive switching

**Choice:** Multi-voice characters use a `personas` map in the voice profile (e.g., `sneekly: {register: obsequious, ...}`, `claw: {register: grandiose, ...}`). The switching logic lives in the cognitive layer via existing HARD constraints and goals. System prompt contains ALL personas; observation signals which is active. This preserves system prompt caching.
**Alternatives:**
- Single voice with prose instructions for switching — conflates voice and behavior
- Separate descriptors per persona — over-engineers identity
- Cache key includes active persona — loses caching benefit for persona-switching characters
**Rationale:** The switching rule is cognitive behavior (driven by `never-break-cover` constraint and `maintain-disguise` goal). The two voices are independently structurable. All personas in the system prompt preserves caching; the observation layer signals the active persona.
**Trade-offs:** System prompt is slightly larger (contains all persona variants). LLM must honour the persona selection signal from the observation layer.
**Sources:** Hooded Claw briefing analysis, CognitionCore constraint handling
**Depends on:** D2 (voice profile fields)
**Exploration:** deep-analysis
**Revision:** R1-06 — resolved caching conflict by putting all personas in system prompt
**Status:** revised

## D4: Architecture — clean two-layer split with correct renderer ownership

**Choice:** Clean the existing two-layer architecture. `CognitiveSystemPromptRenderer` (blocks-core) owns the system prompt for cognitive apps — it already exists and was designed as part of the directive-minimal architecture (#63). Eidos provides identity data via `AgentDescriptor`. Blocks/app owns the observation (cognitive state). Non-cognitive apps continue using `EidosSystemPromptRenderer`.
**Alternatives:**
- Eidos owns everything — inverts dependency direction
- New composition module — adds complexity for something existing classes already handle
- Pretend eidos owns the system prompt — contradicts the codebase; `CognitiveSystemPromptRenderer` already overrides eidos renderer via `@Alternative @Priority(1)` pattern
**Rationale:** The two-layer split maps to the LLM API contract. `CognitiveSystemPromptRenderer` was explicitly designed to take over system prompt rendering for cognitive apps, producing a minimal directive (identity + voice + HARD constraints + preamble) while all dynamic cognitive data flows through the observation layer. This is the established design from #63.
**Trade-offs:** Two renderer paths (cognitive vs eidos default). Cognitive renderer must be updated to handle new voice profile fields.
**Sources:** CognitiveSystemPromptRenderer.java, directive-minimal architecture spec (#63), Phase D spec §4
**Exploration:** deep-analysis
**Revision:** R1-04 — corrected renderer ownership from "eidos" to "CognitiveSystemPromptRenderer (blocks)"
**Status:** revised

## D5: Remove duplication between layers

**Choice:** Kill `PersonalityPromptSection` — raw DispositionValue codes are a workaround; personality belongs in the system prompt rendered with vocabulary resolution. Keep `ConstraintPromptSection` for SOFT constraints — the HARD/SOFT split is intentional (#63 directive-minimal spec): HARD → system prompt as "Prime Directives", SOFT → observation (because soft constraints can be superseded by cognitive state). Distinguish authored goals (eidos descriptor) from emergent goals (GoalPromptSection).
**Alternatives:**
- Kill both PersonalityPromptSection and ConstraintPromptSection — wrong; SOFT constraints are deliberately in the observation layer
- Keep both — perpetuates raw-codes duplication for personality
**Rationale:** Personality is identity (eidos concept, vocabulary-resolved). SOFT constraints are contextual guidance the cognitive system might override — they belong in the observation layer where other cognitive state lives. The HARD/SOFT split was an explicit design decision in #63.
**Trade-offs:** Personality rendering moves to the system prompt renderer. Apps without `CognitiveSystemPromptRenderer` lose cognitive-context personality rendering.
**Sources:** CognitionCore.promptSections() lines 383-389 (SOFT-only filtering), directive-minimal spec §4.3 (constraint severity split), PersonalityPromptSection (raw codes)
**Depends on:** D4 (renderer ownership)
**Exploration:** deep-analysis
**Revision:** R1-07 — kept ConstraintPromptSection for SOFT constraints
**Status:** revised

## D6: ~~Cognitive preamble bridge~~

**Choice:** WITHDRAWN. `CognitiveSystemPromptRenderer` already calls `CognitivePreambleGenerator.generate(config)` directly (line 46). No bridge needed. The preamble is already handled by the existing renderer.
**Previous choice:** Extension data bridge from CognitionCore to eidos
**Reason for withdrawal:** R1-05 identified that the bridge solves a non-problem. The decision was based on the incorrect assumption that eidos owned the system prompt (corrected in D4 revision).
**Status:** withdrawn

## D7: Implementation scope — validate with 3-4 characters

**Choice:** Validate the design with 3-4 contrasting characters (Hooded Claw for dual-persona, Penelope for straightforward voice, Ant Hill Mob for ensemble, one more). Remaining 13 characters as a mechanical follow-up issue.
**Alternatives:**
- All 17 characters in this issue — more work, delays validation feedback
- Design only, no rewrites — misses the concrete validation that proves the design works
**Rationale:** The design needs empirical validation before scaling. Contrasting characters test the edge cases (dual-persona, ensemble, straightforward). Once validated, the remaining rewrites are mechanical.
**Trade-offs:** Two issues instead of one. The follow-up issue is low-risk but still work.
**Sources:** descriptors-composite.yaml (17 characters with varying complexity)
**Exploration:** quick
**Status:** captured

## D8: Emergence verification — three-run experimental design

**Choice:** Extend the Phase D eval infrastructure with three runs: (a) voice-only WITHOUT cognitive config — null hypothesis (does the LLM generate interesting behavior spontaneously?), (b) voice-only WITH full cognitive config — test (does the cognitive system drive behavior?), (c) compare b vs a. Persist output to a durable location (not target/). The comparison answers "does the cognitive system produce emergent behavior?" cleanly because it isolates the cognitive system's contribution.
**Alternatives:**
- Two-run design (full-briefing baseline vs voice-only) — confounded; can't distinguish "loss of instruction" from "emergence"
- Manual verification only — no reproducibility
**Rationale:** The three-run design (R1-08) isolates the variable correctly. Run (a) establishes what the LLM does with just voice. Run (b) shows what cognitive systems add. The delta (b - a) is the emergence signal. Output persisted outside target/ for reproducibility without polluting git history.
**Trade-offs:** Three eval runs instead of two. Non-deterministic LLM output means qualitative analysis, not exact diff.
**Sources:** CognitiveEvalTest.java (existing infrastructure), Phase D spec §5, R1-08 (methodology improvement)
**Depends on:** D7 (implementation scope — uses the same 3-4 characters)
**Exploration:** quick
**Revision:** R1-08 — three-run design isolates emergence correctly
**Status:** revised
