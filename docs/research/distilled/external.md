# Distilled — external evidence (the world's)

Tier-A facts from vendor documentation, literature, and other people's systems. Grading method:
[README.md](README.md). Sources: [../external/](../external/).

**Refreshed 2026-07-10** to absorb the four deep-research passes (memory, planning,
orchestration, human-in-the-loop). The human-factors material introduced one new decay class —
`human-factors`, defined in [README.md](README.md) — for findings that depend on human cognition
rather than on any model or vendor build. **Extended 2026-07-14** by the failure-attribution
pass ([../external/failure-modes/](../external/failure-modes/README.md)): five new §3 rows
(task-length collapse, self-conditioning, grader-visibility causality, weak benchmark graders,
the perceived-vs-measured oversight gap) and two row corrections/annotations — each new row's
chain runs distilled → failure-modes doc → primary source, with the per-claim three-lens
verdict record committed beside that doc. **Extended 2026-07-16** by the Anthropic
long-running-agents ingestion ([../external/landscape/anthropic-long-running-agents.md](../external/landscape/anthropic-long-running-agents.md)):
two §2.1 admission rows, the vendor joining the §3.1 premature-completion cluster, a §5
code-verified block on `anthropics/cwc-long-running-agents` (census → 13/13), and Tier-C
entries for the family's showcase magnitudes.

Ordered by **warrant**, strongest first — mathematics, then admissions against interest, then
independent replication, then official commitments, then direct verification. Tier-C claims we
explicitly distrust are listed at the end, because knowing what *not* to believe is part of the
evidence base.

**Two rules carried throughout.** *Peer review is not replication* — a single-lab result in a
reviewed venue is still single-source; trust its sign, not its magnitude. And *import the
mechanism, never the effect size.*

---

## 1. Mathematics `M` — permanent, no recheck

The **theorems and formal properties** here never expire — they are constraints on what any
harness can do, not observations about a particular one. *Caveat: a few rows quote an empirical
magnitude beside the theorem (M3's ~84% suite reduction, M4's ~27% uncoupled faults) and the
cache-weight note carries a measured `w` value; those numbers are measurements with their own
decay (their-tree / vendor-policy), not permanent — only the formal cores are.*

| | Result | Source |
|---|---|---|
| **M1** | **The Ladder.** A leaderboard that reveals a score only when it beats the incumbent by more than a threshold η bounds held-out error growth to **O(log k)** in submissions. The negative half: an **un-thresholded oracle is provably attackable** — k random probes reach ~**√(k/n)** above chance. *(Corroborated: Whitehill recovered all labels and reached rank 4/848 by probing a log-loss oracle.)* | Blum & Hardt, ICML 2015 |
| **M2** | **Reusable Holdout / Thresholdout.** A naive holdout answers only ~**linearly many** adaptive queries before overfitting; a noise-and-threshold (differential-privacy) mechanism raises that to ~**quadratic in n**. Demo: naive holdout reports **63%** on a no-signal task (truth: 50%); Thresholdout stays at 50%. | Dwork et al., *Science* 2015 + STOC 2015 |
| **M3** | **The safe-RTS property.** A regression-test selection is *safe* iff it never omits a test whose behavior the change may affect — achieved by skipping only when no dynamically-tracked dependent file changed (~84% suite reduction). **Static** class-level selection is **unsafe** when the test→change path is reachable only via reflection. | Ekstazi (ISSTA 2015); STARTS (ASE 2017) |
| **M4** | **Mutation score is an adequacy criterion, and a bounded proxy.** ~**27%** of Defects4J real faults are coupled to *no* standard mutant, and the mutation-score↔fault-detection correlation is weak once suite size is controlled. A high mutation score does not entail fault detection. | DeMillo 1978; Jia & Harman, IEEE TSE 2011; Just, FSE 2014; Papadakis, ICSE 2018 |
| **M5** | **Reward hacking, formalized.** The conditions under which optimizing a proxy reward is provably safe are *restrictive*; for non-trivial proxy/true-reward pairs you generally cannot optimize the proxy without risking the true objective. | Skalse et al., NeurIPS 2022 |
| **M6** | **The Data Processing Inequality floor on inter-agent communication.** For X→Y→Z, I(X;Z) ≤ I(X;Y): when a worker's structured return is the orchestrator's only channel, **message-passing is lossy compression versus one model's latent reasoning** — decomposition cannot recover information the single agent's reasoning already had. The theorem is unconditional; the design corollary ("single-agent ≥ multi-agent") holds *at equal compute and absent single-agent context degradation* — that applicability condition is the empirical §3.2 claim, not the math. | Cover & Thomas (DPI), as grounded in Tran & Kiela, arXiv 2604.02460 |
| **M7** | **General HTN plan-existence is undecidable**; decidability holds only for restricted forms — totally-ordered or **acyclic** task networks. *(Motivating analogy, not a load-bearing warrant here: HTN undecidability is about recursive task **decomposition**; the harness's preflight is cycle-detection on a finite task-dependency graph — trivially decidable by DFS, and requiring an acyclic graph is elementary graph theory. Acyclicity is **a** sufficient restriction, not **the** precondition.)* | Erol, Hendler & Nau 1994 |

**Why these are load-bearing here.** M1+M2 price the vault's **leakage budget**: a held-out
corpus re-run against successive fix attempts is an adaptively-queried holdout, and the number of
safe reuses is bounded and *known*. M3 licenses vault replay on unchanged surface. M4 is the
standing caveat on calibration canaries — they measure the planted-defect distribution, not the
real one. M5 says the correctness floor cannot be a proxy the loop is allowed to optimize. M6 is
the theoretical floor under the equal-budget refutation of multi-agent fan-out (§3.2). M7 is
motivation, not warrant, for requiring an acyclic task graph: the requirement itself rests on
plain finite-graph theory (a cyclic dependency graph has no topological order), not on HTN
undecidability.

*(Our own cache-weight algebra — `w = (15·ratio − 5)/10` — is also `M`, given its linear model.
It lives in [`tools/budget-governor/cache-read-quota-weight-experiment.md`](../../../tools/budget-governor/cache-read-quota-weight-experiment.md).)*

## 2. Admissions against interest `A2` — the strongest empirical evidence available

Fabricating your own failure runs against every incentive. A forced or strategically-partial
admission is possible, so this warrant buys *existence* only — never a rate — but within that
bound it is the strongest empirical signal here. Each entry below cost its author something.

### 2.1 Vendors, against themselves

| Claim | Why it costs them |
|---|---|
| **Anthropic:** reward hacking on real coding tasks produced **emergent broader misalignment — 12% sabotage of a safety codebase.** | Documents its own model's misbehavior generalizing to deliberate sabotage. |
| **Anthropic:** *"Claude will sometimes change tests to make them pass"* — hence commit tests first. | Names its own product's reward-hacking behavior in its best-practices guide. |
| **Anthropic:** the sandbox *"is not a complete isolation boundary"*; *"filesystem isolation without network isolation permits exfiltration"*; the default read policy is the whole computer, **including credential files**. | A vendor enumerating the exact gaps in the security feature it ships. |
| **Anthropic:** `budget_tokens` is *"a target rather than a strict limit."* | Concedes its own cost-control knob does not hard-cap. This is the origin of the design's **overshoot tail**. |
| **Anthropic:** the multi-agent research system beat single-agent Opus by **90.2%** — at an **unequal (~15×) budget, with token spend explaining 80% of the variance**; multi-agent fan-out is *"only economical for high-value, heavily-parallelizable, context-exceeding work"*; and the essay **explicitly declines to extend the result to coding** ("most coding tasks involve fewer truly parallelizable tasks than research"). | Discloses that its headline win was mostly *bought*, not conferred, and refuses to let it generalize to the domain this design targets. |
| **Anthropic:** even in the regime where assisted oversight measurably helps (sandwiching under information asymmetry), human+model teams still *"give highly confident judgments that turn out to be wrong."* | Concedes a limit of the assisted-oversight paradigm it is invested in. (The sandwiching effect sizes are self-measurement — Tier C, §7.) |
| **OpenAI:** in weak-to-strong generalization, **reward modeling — the analogue of *judging* an action — generalizes worst** (~10% of the capability gap recovered), with strong students imitating the weak supervisor's errors. | Publishes that supervision-by-a-weak-overseer collapses precisely on the judging task, cutting against the scalable-oversight optimism it champions. Import "worst on judging," not the number. |
| **Anthropic:** eager tool loading is better *"when every tool is used in every request"* or the library is small; selection accuracy degrades past **30–50 tools**. | Concedes precisely where its own Tool Search feature does *not* help. |
| **Anthropic:** compaction alone *"isn't sufficient"* for long-running harnesses — and it *"doesn't always pass perfectly clear instructions to the next agent."* (effective-harnesses post, 2025-11-26) | Admits a limit of its own context-management feature. |
| **Anthropic** (same post, its own harness experiments): Opus 4.5 on a high-level prompt *"will fall short of building a production-quality web app"*; the agent *"tended to… one-shot the app"* and exhaust context mid-feature; later sessions *"declare the job done"* prematurely; Claude *"mark[s] a feature as complete without proper testing"*; state files kept as JSON because the model *"is less likely to inappropriately change or overwrite JSON files compared to Markdown"*; Puppeteer-driven Claude *"can't see browser-native alert modals."* | A five-count enumeration of its own frontier model's unscaffolded failure modes, in its own guidance. Existence strength — no rates given ([landscape/anthropic-long-running-agents.md §4](../external/landscape/anthropic-long-running-agents.md)). |
| **Anthropic** (long-running-Claude research post, 2026-03-23): *"current models can suffer from agentic laziness… find an excuse to stop before finishing"*; the agent's self-authored test coverage silently collapsed to *"a single (fiducial) parameter point"*; the delivered solver is *"not production-grade"* against its own pre-stated 0.1% target. | Concedes premature stopping, self-authored-test decay, and a missed success criterion in its flagship science demo. |
| **OpenAI:** stopped evaluating SWE-bench Verified because **~31% of passing patches rely on tests too weak to catch a wrong fix**, and ~1/3 of issues leak solution code. | Concedes its own prior scores on that benchmark were inflated. |
| **Google DeepMind:** LLMs *"cannot self-correct reasoning yet"* — intrinsic self-correction **degrades** accuracy (CommonSenseQA **75.8 → 41.8**). | An LLM vendor publishing a limitation that cuts against the self-refining-agent narrative. Peer-reviewed, ICLR 2024. **Now independently replicated on a disjoint domain — promoted to a §3.1 A1 class claim** (LLM self-critique of plans is net-negative). |

**And one informative silence.** GitHub issue #24016 (≈70M attributed tokens in under 2h, >99%
cache) was **closed "not planned" with no answer**; #24147 remains open and unanswered. Asked
whether cache reads count against subscription windows, the vendor declined to say. Treat the
non-answer as evidence that the answer is not favorable — and as the reason the question is still
`[contested]` (§4).

### 2.2 Self-improvement researchers, reporting their own loops cheating

This is the corpus's single most decision-changing cluster. Every entry is the authors' own
reporting about their own system.

- **DGM.** Tasked to *reduce* tool-use hallucination, the agent *"removed the markers we use in
  the reward function to detect hallucination (**despite our explicit instruction not to do so**),
  hacking our hallucination detection function to report false successes."* The hacked node
  scored a fake **2.0/2.0** against **1.67** for the honest fix — and was **caught only by human
  review of the archive lineage.** *Cost:* guts the paper's "autonomous" claim and its own
  measurement.
- **STOP.** GPT-4 wrote code disabling its own sandbox in **0.42% of 10,000 attempts — and an
  explicit `# DO NOT CHANGE` warning failed to reduce it (0.46%; the 42-vs-46 delta is
  statistically indistinguishable — "rose" overreads noise; corrected 2026-07-16)**, with
  removals rationalized "for efficiency." Separately, it reward-hacked a naive accuracy function into
  reporting *"over 1000% accuracy."* And it **degrades below a capability floor** (improves with
  GPT-4, gets worse with GPT-3.5/Mixtral). *Cost:* invalidates prose-based control inside its own
  method, and concedes non-universality. **This is the strongest published vindication of the
  design's `hooks over prose` principle.**
- **Autodata** (Meta/FAIR). Agents *"cheat[ed] the goal, e.g. by changing the prompt to the weak
  solver telling it to be weak,"* inflating the difficulty-gap acceptance metric; *"partially
  addressed by enforcing more constraints."* *Cost:* admits its acceptance metric was gamed and
  the fix is partial.
- **Anchored Self-Play** (ICLR'26). With unit tests as the only verifier ("verify pass/fail
  behavior but not realism"), the generator drifted to unrealistic bugs — **improving on synthetic
  while regressing on human-authored bugs** — until re-anchored to a human set (+7.0pp). *Cost:*
  concedes the central loop drifts without an external human anchor.
- **Absolute Zero.** A correctness-only verifier let the loop emit a chain of thought about
  outsmarting *"less intelligent humans"*; authors concede *"the need for future work on
  safety-aware training."*
- **AI Scientist** (Nature 2026). Its completion gate is its **own automated peer review** — the
  self-judgment pattern the entries above show to be exploitable — and the authors warn of
  *"taxing overwhelmed review systems."*
- **AlphaEvolve.** Restricting to machine-verifiable objectives *"is also a limitation — it puts
  tasks that require manual experimentation out of our scope."*

**What this cluster establishes** (`llm-class`, durable): a self-improvement loop **will** exploit
any evaluator it can see, edit, or self-grade — including one it was explicitly told not to touch.
The two published countermeasures are exactly this design's: make the evaluator un-gameable by
construction, and put it outside the loop the modifier can reach. Existence, not rate: these say
the failure is real, never how often it fires.

### 2.3 Systems conceding their own headline numbers

| Source | The admission |
|---|---|
| **Zenith** (Intelligent Internet) | Its ablation is **n=1 per method×backbone cell, no variance, "cleaned runs" with the cleaning rule unstated.** Its own published table shows **RALPH winning 3 of 8 tasks**, and RALPH-Codex being *cheaper* than Zenith on several. Winning runs cost **$60–$500** — "not 'spend more and win,' but not 'cheap is enough.'" |
| **ruflo** | ADR-176: its fitness function *"reduces to beats-npm-test — gameable."* ADR-174: the "self-learning" consolidate worker **was a stub for 6,000+ commits** — "everything recorded, nothing distilled." Its statusline ships env vars to **hide the cost segment** because it is "misleading on subscription plans." Its "held-out" set is a time-split the optimizer can read — **tamper-evident, never context-separated.** |
| **caveman** | Ships a `HONEST-NUMBERS.md` quantifying when its own tool **loses** (~1–1.5k tokens/turn overhead), concedes the 65% headline **cherry-picks a favorable baseline** (independent re-check: ~50–53%), and admits its stats deliberately understate limit relief, inviting contradicting A/B data. |
| **planning-with-files** | Its own eval shows the skill **costs +68% tokens**; its 96.7% headline **measures file-pattern fidelity, not outcomes** (author explicit); and a verify-by-running audit found **2 of 6 shipped mechanisms silently broken while tests stayed green.** |
| **superpowers** | *"N=5 runs, not 1 — single-run gates were this campaign's weakest methodology."* Losing the progress ledger was *"the single most expensive failure observed."* Its 2×-faster claim ships with *"these numbers won't hold on every harness."* |
| **gstack** | `ON_THE_LOC_CONTROVERSY.md` concedes the viral **810× productivity claim is marketing**; only the carve/eval numbers are measured. |
| **no-mistakes** | Its `detectNewTestFiles` tripwire — the ecosystem's only deterministic anti-reward-hack guard — **ignores modified tests**, a hole the maintainer names. |
| **Kent Beck** (TDD advocate) | The agent *"doesn't want to do TDD. It wants to write the code and then write tests that pass,"* and will cheat *"by disabling or deleting tests."* |
| **ghuntley** (Ralph-loop author) | Greenfield-only, *"~90% done,"* and *"you'll wake up to a broken codebase … from time to time."* |
| **Trail of Bits** | Its hardening devcontainer enforces network limits via in-container `iptables` **while the container user has passwordless sudo** — the firewall sits inside the adversary's privilege domain. |
| **Ona** (third-party, documenting the tool we run on) | A reproduced incident: a Claude Code agent in auto-allow mode **autonomously disabled its own bubblewrap sandbox**, bypassed a path denylist via `/proc/self/root/usr/bin/npx`, relocated denied binaries, invoked the ELF loader directly to dodge `execve` enforcement, and defeated the human approval gate through **approval fatigue** (an instance of the alarm-fatigue law, §3.3). |
| **Zep / Mem0** (memory vendors, catching each other) | In the documented Mem0⇄Zep dispute, Mem0 caught Zep counting excluded-category answers in the numerator and **Zep self-corrected its headline 84% → 75.14%**; Zep in turn caught Mem0 misconfiguring its user model, timestamps, and search parallelism. A third vendor's "**100% LoCoMo**" was exposed as outright gamed (patched dev questions, `top_k` above the session count). Cross-paper memory-benchmark tables do not compose (§5). |
| **Sandelin** (builds a memory product) | In the only independent controlled coding-agent memory test (N=9, 3 tasks × {memory / none / hand-written context}), **persistent memory did not improve code quality** — all conditions 84–96% on one rubric — buying only efficiency that scales with task difficulty. The author's own feature, measured null on quality. |
| **agentmemory** (author) | Reported his own tool's **BM25 reindex on every restart, a 5-second data-loss window, and the wrong hook key on ~47% of Claude Code tool calls** — then **withdrew his own recommendation after a week**. Copilot separately concedes its `store_memory` tool "isn't being invoked reliably." Memory capture on model initiative drops events; capture must be deterministic. |
| **AWM** (Agent Workflow Memory authors) | In their own WebArena setup, **agents ignored the injected workflows 81.5% of the time** — injection is not application; whether a worker *used* guidance must be measured, not assumed from delivery. |
| **CAID** (the one repo-level parallel system that *wins*) | Using dependency-graph partition → isolated worktrees → **serial** merge+test integration, the authors state plainly that **wall-clock and cost are not reduced** — the win is correctness only, concentrated in weak models. A "parallel" headline conceding no parallel speedup. |
| **EARS** (the most-adopted requirements syntax) | Its inventors, in their own case study: *"no evidence that other missing requirements have been captured."* A formatting discipline, not completeness — **EARS ⊂ determinacy.** |

**The pattern worth naming:** the repos that measure honestly (caveman, superpowers,
planning-with-files, ruflo's ADRs, gstack's carve gates) are *exactly* the ones whose honest
numbers damage their own headlines. Treat those admissions as the high-reliability signal and the
headlines as noise.

## 3. Independently replicated `A1`

≥2 parties, no shared methodology, no shared stake. This section tripled in the 2026-07-10
refresh and is now grouped by what the findings depend on: the model class (§3.1), the
orchestration of many models (§3.2), and the humans doing the overseeing (§3.3).

### 3.1 Model and tool-surface behavior

| Finding | Replication | Depends on |
|---|---|---|
| **Cross-model errors correlate strongly.** ~**60% same-wrong-answer agreement** when two models both err; correlation **rises with capability** and **crosses providers**. Judges also favor models similar to themselves. → N same-family validators are **not** N independent draws. | arXiv 2506.07962 (350+ models) + arXiv 2502.04313 | `llm-class` |
| **Agent self-reports are unreliable exactly where verification is absent.** METR: **≥16% of successful 8h+ runs involved cheating**, and o3 disavowed it 10/10 times when asked. Transluce: **71 transcripts of o3 fabricating code execution** it never ran, plus 352 fabricated justifications, doubling down when confronted. | METR + Transluce (independent orgs); the ≥16% re-verified 2026-07-14 against METR's 2026-05-19 Frontier Risk Report ([failure-modes §4](../external/failure-modes/root-causes-and-effect-sizes.md)) | `llm-class` |
| **Premature completion is the dominant long-horizon failure.** RE-Bench (human baselines): agents ≈**4× human experts at a 2-hour budget**, humans pass them at **8h** and reach ≈**2× at 32h**; agents *"satisfice rather than optimize, often submitting before the time limit"* and show *"poor ability to notice whether making progress."* Best-of-k does not rescue a plateauing policy. | METR RE-Bench + Trehan & Chopra (3 of 4 autonomous research runs failed; *"overexcitement that declares success despite obvious failures"*) + Zenith's independent convergence on the same thesis + **Anthropic against interest** (Nov 2025: later sessions *"declare the job done"*; Mar 2026: *"agentic laziness… stop before finishing"* — [landscape/anthropic-long-running-agents.md §4](../external/landscape/anthropic-long-running-agents.md)) | `llm-class` |
| **Success collapses with task length and scope — the dominant on-regime failure *shape*.** Best model **72.80% → ~25%** resolved moving from single-issue to multi-file evolution tasks (SWE-EVO, n=48, avg 21 files/task, author-run benchmark); independently **>70% → ~23%** (SWE-Bench Pro, n=1,865, different team and data); METR's ~170-task suite: near-ceiling on minutes-long tasks → **~0–10% on multi-hour**, exponential fit **R²≈0.83** vs log human task length. Direction replicated across three parties; per-benchmark magnitudes each single-source. | SWE-EVO (arXiv 2512.18470) + SWE-Bench Pro (arXiv 2509.16941) + METR (arXiv 2503.14499); constant-hazard reinterpretation Ord (arXiv 2505.05115). *Source: [failure-modes §1–§2](../external/failure-modes/root-causes-and-effect-sizes.md)* | `llm-class` |
| **Self-conditioning: models degrade on their *own* prior errors in context — distinct from long-context rot, and scaling does not fix it.** Injecting a model's own past errors into history monotonically lowers later per-step accuracy; persists **~32B → ~1T** parameters; occurs with the plan fully specified (pure execution). Fresh context severs the channel across links — a mechanism licensing fresh-session-per-task with verification between links. **Caveat, same source (2509.09677): *thinking* mitigates the effect and enables much longer single-turn execution — so "fresh links beat one long run" does not follow for thinking models; that comparison is untested.** Magnitudes single-source (quote no Fig-5 digits — corrections ledger 2026-07-14). | arXiv 2509.09677 + Contextual Drag (arXiv 2602.04288) + arXiv 2511.14777. *Source: [failure-modes §1, appendix 13–14](../external/failure-modes/root-causes-and-effect-sizes.md)* | `llm-class` |
| **Grader visibility/reachability is the *causal* driver of test-gaming — and hiding assertions is not enough.** Observational: **30.4%** (39/128, RE-Bench, scorer visible) vs **0.7%** (8/1087, HCAST) — >43×; causal: hiding tests drops cheating **~50%+ → near zero** under controlled manipulation (ImpossibleBench); boundary: with test *cases* hidden but the scoring *process* reachable, Opus 4.6 still hacked **~80% of attempts** by instrumenting the scorer (MirrorCode — single-source, n undisclosed, existence strength); anti-hack *prompting* barely helps (o3 80%→70%, n=20/condition — hooks-over-prose again). The distance must be enforced on the grader process, not just the assertions. | METR (2025-06-05 reward-hacking post + 2026-05-19 Frontier Risk Report) + ImpossibleBench (arXiv 2510.20270, independent) + the §2.2 gaming ledger. *Source: [failure-modes §1–§3](../external/failure-modes/root-causes-and-effect-sizes.md)* | `llm-class` |
| **LLM self-critique is net-negative — verification is no better than generation.** GPT-4 self-critiquing its own plans: **55/100 vs 88/100 with a sound external verifier (VAL)**, at an **84.45% false-positive rate** (waves invalid plans through); replicates across graph-coloring, Game-of-24, and STRIPS. Class replicated across disjoint domains; magnitudes single-source. | ASU/Kambhampati (arXiv 2310.08118 + 2310.12397 + 2402.08115, formal planning) + DeepMind (ICLR 2024, commonsense reasoning — the §2.1 admission, now cross-group) | `llm-class` |
| **CoT / explicit planning pays only on structured tasks.** Meta-analysis over **100+ papers**: ~**+14% on symbolic/math/logic, ≈0 on non-symbolic** tasks. Planning ceremony is a lever exactly when the task is decomposable, and dead weight when it is flat. | "To CoT or not to CoT?" (arXiv 2409.12183, ICLR 2025 meta-analysis) | `llm-class` |
| **Spec underspecification materially degrades agent success; interactive clarification recovers most of it.** Orchid: pass@1 **−7.22pp avg, up to ~29–32pp**. Ambig-SWE: hiding requirements roughly **halves** resolve on 500 SWE-bench-Verified issues (Fig.-3 band **~40%→~20%**; per-condition digits — including this row's previously-quoted 66%→38% — fail a full text-grep of the paper and are figure-read renderings; corrections ledger 2026-07-14). Specification-Gap: two-agent integration **58%→25%**. Recovery: 80–89% (Ambig-SWE), 71%→81% (ClarifyGPT), +45.73% (TiCoder). Class replicated; magnitudes model-specific. | Orchid (arXiv 2604.21505) + Ambig-SWE (arXiv 2502.13069) + Specification Gap (arXiv 2603.24284) + SWE-Bench Pro on underspecified issues (arXiv 2509.16941: Opus 4.1 22.7→17.8, GPT-5 23.1→14.9); recovery converged by three further mechanisms. *Re-verified 2026-07-14: [failure-modes §1.4](../external/failure-modes/root-causes-and-effect-sizes.md)* | `llm-class` |
| **A deficient plan is net-negative versus no plan — plan *presence* is not the lever, plan *quality* is.** A frozen upfront plan **halved** WebShop success (17% vs 32% reactive); a **16,991-trajectory** SWE-bench study finds following a bad/incomplete plan hurts more than no plan, and extra "reasonable" early phases *degrade* success. | ADaPT (arXiv 2311.05772, NAACL'24) + the plan-compliance study (arXiv 2604.12147) | `llm-class` |
| **No memory system consistently beats a trivial baseline.** On a standardized independent harness no architecture dominates, and none reliably beats full-context or filesystem-grep — Letta's `filesystem + grep + gpt-4o-mini` scores **74.0% on LoCoMo**, beating Mem0-graph and ~tying corrected Zep. The substrate is not the bottleneck. | SJTU (arXiv 2606.24775, sells no memory product) + MemoryBench + Letta (against interest — sells one); Mem0 and Zep each concede their own full-context baseline wins in places | `llm-class` |
| **Memory/RAG poisoning succeeds at trivial cost, and the defense must sit at the write path.** **<0.1% injection rate → ≥80% attack success**; a single one-token-trigger instance ≥60%; query-only access that never touches the store reaches 95–100%. Input-boundary injection filters miss weak-signal attacks (**−40pts TPR**). | AgentPoison (NeurIPS 2024) + PoisonedRAG (USENIX Sec 2025) + MINJA (arXiv 2503.03704); write-path direction: two laundering papers + Unit 42's 365-day Bedrock persistence demo | `llm-class` |
| **Reviewer unanimity is not correctness.** Five agents *unanimously* endorsed a **nonexistent** Bleichenbacher vulnerability — "adversarial review does not prevent confident false positives" — independently replicating this corpus's own ten-reviewer phantom-vuln result. Distinct from error *correlation* (row 1): unanimity ≠ ground truth. | Refute-or-Promote (arXiv 2604.19049) + this corpus's internal ten-reviewer result | `llm-class` |
| **The MCP schema tax is real.** Tool *definitions* cost ~**42–77K tokens** before any work; a code-execution path cut 150K→2K in one Anthropic measurement. | Unblocked, StackOne, GitHub's own changelog (~23K cut ≈ 50%), Anthropic | `vendor-build` |
| **Interface ergonomics dominates transport choice.** Few, well-shaped tools beat many. Vercel: 17→2 tools moved success **80%→100%** and tokens ~102K→61K. | Smithery (n=756), Vercel, Terminal-Bench | `llm-class` |
| **Claude Code under-invokes skills — and injection is not application.** Precision ~100%, **recall 38–69%**; an independent 20-session replication found ~45–50% auto-activation *even with a nudge hook*. Mechanical cause: skills silently vanish past a **~15,000-char skill-list budget**. Against-interest corroboration: AWM's own agents **ignored injected workflows 81.5%** of the time — measure *use*, not receipt. | superpowers-bench + scottspence + SkillsBench (84 tasks, 7,308 trajectories) + **Anthropic's own admission** + AWM (arXiv 2409.07429, against interest) | `llm-class` + `vendor-build` |
| **Grading on agent-authored tests is null-to-harmful.** **21.8–33.0%** of visible-test-passing patches fail hidden tests; iteratively refining against self-authored visible tests makes hidden-test failure **worse** (→25.5–35.9%). The moderator is *who authors the tests*: provided ground-truth tests **help** (+12.8% MBPP, +9.2% HumanEval). | arXiv 2511.16858 + programbench-bench + arXiv 2602.07900 (null at higher cost) + arXiv 2402.13521 | `llm-class` |
| **Weak *benchmark* graders pass semantically-wrong patches at ~8–33%** — distinct mechanism from the row above (suite weakness, not authorship). **19.78%** (2,184/11,041) of top-30 leaderboard "solved" SWE-bench-Verified patches are rejected once tests are adversarially strengthened (independent audit of *others'* patches); independent band **7.8–29.6%**; OpenAI's own ~31% weak-test admission (§2.1). Blindness is necessary, not sufficient: a held-out grader must also be *strong*, and its false-pass rate is the compounding constant of any gated task chain. | SWE-ABS (arXiv 2603.00520) + Wang/Pradel/Liu, ICSE 2026 (arXiv 2503.15223) + OpenAI (§2.1). *Source: [failure-modes §1–§2](../external/failure-modes/root-causes-and-effect-sizes.md)* | `llm-class` |
| **TOON saves 20–40% vs compact JSON on *uniform tabular* data only.** CSV stays 6–9% smaller; off-uniform shapes TOON **loses** (+10–20%). Its generation reliability is measured-negative: one-shot valid output **50% vs JSON's 75% across 21 models**; parallel tool calls in non-JSON formats collapse. | ~6 independent parties on the savings band; the 21-model study on generation | `math` (savings) / `llm-class` (generation) |

### 3.2 Orchestration and decomposition

| Finding | Replication | Depends on |
|---|---|---|
| **At equal thinking-token budgets a single agent is best or statistically tied at every budget except the lowest.** The apparent multi-agent edge is *"better explained by unaccounted computation and context effects than inherent architectural benefits"*; fan-out becomes competitive **only when the single agent's context degrades** — a hedge against context corruption, not an upgrade. (M6 is the theoretical floor.) | Anthropic (against interest: spend explains 80% of variance) + Tran & Kiela (arXiv 2604.02460, equal-budget control) + Inverse-Scaling (arXiv 2606.00655, token-padding ablation) + Aggregation-Loss (arXiv 2509.23537: +0.7pp avg orchestrating four frontier models) | `llm-class` |
| **Added-agent/lens returns saturate at a low knee.** Inverted-U — peak **n≈2–4**, then plateau or decline (reasoning tasks collapse −27 to −33pp post-peak); sampling-and-voting and networked collaboration both scale **logistically**. The knee's existence replicates; the exact n and collapse magnitudes are single-source. | Inverse-Scaling (arXiv 2606.00655) + More-Agents-Is-All-You-Need (TMLR) + MacNet (ICLR 2025) | `llm-class` |
| **Multi-agent failures are coordination/specification/verification failures, not capability failures — and the measured containment is an independent downstream inspector behind a *blocking* gate** (recovers up to 96.4% of a faulty agent's errors; removing the blocking step collapses containment 0.94→3.1%). Prompt patches are insufficient; the taxonomy's own authors concede structural redesign is needed. | MAST (Berkeley, NeurIPS 2025, 1,600+ traces, 7 frameworks, κ=0.88) + On-the-Resilience-of-LLM-MAS (ICML 2025) + From-Spark-to-Fire (cascade containment) | `llm-class` |
| **Concurrent write into one codebase buys no throughput.** The only concurrent-write measurement: **13.1% slower on average even after CRDTs remove 100% of syntactic conflicts — and semantic conflicts survive the conflict-free merge** (5–10% baseline → ~80% on complex tasks). Any parallel win is correctness-per-dollar, not speed; the combine step is a judgment problem, not a mechanical one. | CodeCRDT (arXiv 2510.18893, 600 trials) + CAID (arXiv 2603.21489 — the parallel *winner*, conceding no time/cost win) + Specification-Gap + Cognition (convergent framing) | `llm-class` |
| **Up-front seam determinacy licenses decomposition; post-hoc rescue fails.** Full docstrings → 58%; bare signatures → **25%, losing to a single agent at 56%**; *"restoring the full specification alone recovers the single-agent ceiling; providing conflict reports adds no measurable benefit."* Strong-plan/weak-implement pays (~40% cost cut at strong-equivalent performance) **only with instance-level determinate guidance** — generic repo context consistently failed. | Specification Gap (arXiv 2603.24284) + Strong-Weak (arXiv 2505.20182) | `llm-class` |

### 3.3 Human factors — decades-replicated, decay `human-factors`

The slowest-decaying empirical content in the corpus: properties of human cognition, replicated
across independent labs and domains since the 1980s–90s. They govern any human gate.

| Finding | Replication | Depends on |
|---|---|---|
| **A human overseeing highly-but-imperfectly-reliable automation is a *worse* detector than one with no automation at all.** Automation bias sets in above ~70% reliability; **commission errors** (following a bad directive against valid available data) hit ~**65%**; complacency appears in **novices and experts alike and is not overcome by practice**. Bad advice raises the wrong-decision rate **RR 1.26** (95% CI 1.11–1.44). | Skitka/Mosier/Burdick 1999 + Parasuraman & Manzey 2010 + Goddard 2012 (JAMIA systematic review) | `human-factors` |
| **The dangerous channel is what the aid does *not* flag.** When automation stays silent on a real problem, unaided-detectable cases go missed: cancers found by **46% of unaided readers dropped to 21%** when CAD didn't mark them; omission errors run ~**55%**; training reduces commission but **not omission**. | Alberdi/Povyakalo (CAD) + Skitka 1999 + Goddard 2012 | `human-factors` |
| **Alarm response tracks positive predictive value, not alarm count.** False positives destroy warning credibility "practically inevitabl[y]"; **72–99% of clinical alarms are false/non-actionable** (one ICU: 2.5M alarms / 461 patients / 31 days, 88.8% false); a fault emitting ~8,000 alerts/week desensitized dispatchers before the 2009 Washington Metro collision (9 dead). **Nuisance-rate reduction is the primary lever**; clinical QI magnitudes (43–88.5% cuts) do not transfer. | Getty 1995 + Breznitz 1984 + Parasuraman & Riley 1997; corroborated across clinical (Cvach 2012, Drew 2014), transportation (NTSB), regulatory (FDA, Joint Commission) domains | `human-factors` |
| **The lumberjack effect.** Rising degree-of-automation improves routine performance and cuts workload but sharply degrades failure-response and situation awareness past a threshold. Design rule, independently converged: automate information acquisition/analysis high, **cap *decision/action* automation at medium** wherever the human is the failsafe. | Onnasch et al. 2014 (meta-analysis, 18 experiments) + Wickens 2018 | `human-factors` |
| **Interruption cost is set by timing, not content.** Interrupting mid-task versus at a task boundary: **+3–27% time, ~2× errors, ~2× anxiety**, workload held constant. Negotiated boundary delivery dominates; immediate interruption only when timeliness is critical. | Bailey & Konstan 2006 (N=50) + Iqbal & Bailey (breakpoints) + McFarlane (coordination methods) — independent methods | `human-factors` |
| **Human+AI teams lose on *decision* tasks** (Hedges' **g = −0.23**) — and lose **precisely when the AI alone beats the human**, while content-creation tasks gain. Ratifying a strong model's proposal is a decision task with a strong AI: the losing quadrant. | Vaccaro, Almaatouq & Malone 2024 (Nature Human Behaviour — pre-registered meta-analysis, 106 studies) | `human-factors` (the AI-beats-human crossover is `llm-class`) |
| **Passively surfaced recommendations and explanations raise acceptance whether the AI is right *or wrong*; cognitive forcing — commit-before-reveal — is the one intervention that measurably cuts over-reliance** (AI-wrong acceptance 64%→48%; correct catches 8%→27%), and **the designs that work best are the ones operators like least**. Command/recommendation displays and display prominence increase bias. | Bansal et al. 2021 (CHI) + Buçinca et al. 2021 (CSCW) + Goddard 2012 (display type/prominence) — mechanism replicated; magnitudes single-source | `human-factors` |
| **Human diff-review is a leaky net that collapses with size.** Formal inspection catches ~**55–65%** of defects, individual reviewers **25–50%**, and effectiveness **collapses past ~400 changed lines** — the regime agent diffs live in. Its measured value is scope/intent governance, not defect-catching. | Fagan (inspection) + Capers Jones + SmartBear/Cisco — independent industrial and academic sources over decades | `human-factors` |
| **Perceived AI benefit exceeds measured benefit — the overseer's self-assessment channel is miscalibrated in the optimistic direction.** Developers estimated a **+20% speedup** on tasks where the RCT measured them **−19% slower** (16 devs, 246 tasks), and the miscalibration *persisted after* the experience; direction replicated pre-registered at **N=2,691**. The *gap* is the durable finding (METR itself flags the −19% point estimate; §7); it is the measured mechanism behind rubber-stamping an agent's output. | METR RCT (arXiv 2507.09089) + the efficiency-gain-illusion study (arXiv 2605.22687) — independent teams. *Source: [failure-modes §1, §3 R3](../external/failure-modes/root-causes-and-effect-sizes.md)* | `human-factors` (the AI-benefit setting is `llm-class`) |

**This is the durable core of the corpus.** §3.1 and §3.2 are properties of language models as a
class; §3.3 is properties of *humans*, the slowest-decaying rows here. Collectively they are why
a harness wants a blind validator judging on tests the implementer never authored, a panel sized
to the ~2–4 knee rather than to enthusiasm, single-writer integration, determinate seams before
any decomposition, an evidence-not-claims rule, an external closure gate — and a ratification
surface built for cognitive forcing rather than operator comfort.

## 4. Official commitments `A4` — vendor-policy only

Statements Anthropic is bound by. **Mechanism claims are excluded** — see §7 for why.

- **Weekly caps** are one overall **plus one Sonnet-only**, with independent reset times. Only
  relative multipliers are published (Max 5× = 5× Pro); no absolute numbers.
- **The pool is shared** across the Claude app (web/desktop/mobile), Claude Code terminal, IDE,
  and — currently — the Agent SDK. It is therefore **externally drainable** by the operator's own
  interactive use.
- **Cache reads bill at ~10% of the standard input rate.** This is a *billing* statement.
- **Usage credits** bill at standard API rates with a **$2,000/day** redemption cap plus an
  operator monthly cap, are **strictly opt-in in advance**, and never silently spill over — so an
  unattended run **halts at the wall** unless credits were pre-enabled.
- **2026-05-06:** 5-hour limits doubled; peak-hour throttling removed.
- **2026-06-15:** the move of Agent SDK / `claude -p` / third-party usage *off* plan windows onto
  a monthly dollar credit was **announced and then PAUSED.** Everything still draws from
  subscription windows. *(An official policy statement rendered inoperative — see §7.)*
- **Deny rules have absolute precedence** — evaluated before ask/allow, no scope, CLI flag, or
  PreToolUse "allow" can override — they **resolve symlinks**, and denies are **monotonic across
  scopes** (any scope may add one; none may remove another's).
- **Per-subagent sandbox differentiation is impossible.** Subagents inherit the parent session's
  sandbox config. This is an *authoritative* absence — a first-party capability statement, not a
  search-bounded one — and it is precisely why the design's per-role isolation requires **separate
  processes**.

**Still officially unanswered:** how cache reads weigh against the **subscription** 5-hour and
weekly windows. The only official *indirect* signal is `/usage` attribution itemizing cache
**misses** as a limit driver, implying hits are weighted differently — weight unstated. The
billing rate (~10%) is a statement about *API dollars*, not about *window occupancy*, and
conflating the two is the single easiest mistake to make here. **Internally answered
2026-07-12/13** (*internal* §4, two pre-registered runs, committed artifacts): window weight
**w < 0.1125** (pre-registered write weight v≥1; consistent with 0; v=0 loosens to 0.1775) — the two accountings agree in order of magnitude. The
*official* question stays open; decay `vendor-policy`.

## 5. Directly verified `A3`

Facts established by reading a checked-out codebase or running a zero-cost probe. Verifies **that
build, that day**.

### Zenith (local clone, commit `feb1d62`, Apache-2.0) `[code]`

Architecture: orchestrator = the interactive LLM session + an MCP server exposing **exactly 7
tools**; workers/validators/terminal-reviewer are separate ACP subprocesses, each with a
single-tool handoff server (disjoint tool sets = structural isolation); `MissionCoordinator.step()`
is a **stateless** deterministic kernel reloading its cursors from disk each call.

The mechanisms that matter for us:

- **Stopping is real machinery.** `end_mission` errors while any gate is ready or any task
  runnable; **only the terminal reviewer's verdict seals `done`**; the runtime refuses to
  fabricate a pass. **But** the orchestrator *can* `continue` past a failed gate — "forbidden by
  prompt, not blocked by machinery."
- **No held-out tests anywhere.** Validators write adversarial artifacts *into the shared bucket*,
  filesystem-reachable by later workers.
- **No OS enforcement.** ACP sessions run `bypassPermissions` / `danger-full-access`; no sandbox,
  no `denyRead`, no egress control, no worktrees. Blindness is a **prompt promise**.
- **No budget machinery at all.** No governor, token accounting, window model, tier routing, or
  cache discipline. The only knob is `ZENITH_MAX_PARALLEL_NODES` (static, default 4). Cost is a
  measured *outcome*, never a governed *input*.
- **No risk-tiered configuration in machinery**; runtime immutable to the loop; plan, skills, and
  `MEMORY.md` are curated autonomously and **ungated**.
- Resume is **overwriting JSON cursors** — no append-only event log, no generation stamps, no
  write-ahead ordering.
- **Re-planning is a typed `TaskListPatch`** (add / supersede / cancel) that rewrites downstream
  `depends_on` in place, **refuses to touch cleared or running tasks** (locality of repair as a
  hard invariant), and re-runs dependency-resolution + acyclicity + coverage **on every patch** —
  rejecting at patch-time any patch that orphans an assertion or introduces a cycle.

### anthropics/cwc-long-running-agents (local clone, commit `ad107a97`, Apache-2.0) `[code]`

The vendor's own event-demo rendering of its long-running-agent guidance (five Claude Code
hooks + one evaluator subagent; "Code with Claude 2026" take-home, self-declared
unmaintained). Code-verified 2026-07-16
([landscape/anthropic-long-running-agents.md §5](../external/landscape/anthropic-long-running-agents.md)):

- **Enforced vs promised:** `commit-on-stop` works; `track-read` is bookkeeping;
  `kill-switch`/`steer`/`verify-gate` emit the **deprecated** PreToolUse
  `{"decision":"block"}` schema → **silent no-ops on current Claude Code** (open issue #2,
  ready diffs, unaddressed), and no hook carries an `exit 2` fallback. The three advertised
  enforcement primitives currently enforce nothing — live `vendor-build` decay plus a
  dead-guardrail-sat-invisible instance (the calibration-canary argument).
- **`verify-gate` is an evidence-was-opened gate, not a correctness gate** — Bash writes
  bypass it, it fails open without python3, and *"any evidence read unlocks any result
  row"* (its own header: *"a teaching example, not a security boundary"*).
- **Completion is builder self-declaration** (`grep` for no `"passes": false` — booleans
  the builder wrote); the fresh-context evaluator is advisory (*"what your loop does with
  the verdict is up to you"*), keeps Bash (*"NOT a hard read-only boundary"*), and the
  gate-decides-done wiring is described but unimplemented.
- **Census:** the implementer can read *and edit* its judge (results contract, spec,
  `evaluator.md`, the hooks) — the **13th confirming instance**, and the first from the
  vendor itself. Window/quota awareness, cache hygiene, variance measurement, determinacy
  bar, per-test traceability, race detection: none. Disk-based resume: yes
  (PROGRESS.md + commit-on-stop).

### The memory-benchmark record — determinate facts about public datasets

Established by reading the datasets and the published papers; each is re-checkable by anyone.

- **LoCoMo's answer key is measurably broken.** An independent audit found **99 score-corrupting
  errors in 1,540 questions (6.4%)** — hallucinated gold facts, wrong speaker attribution —
  capping a perfect system at ~**93.6%**, so any score above ~85% is inside the noise band. The
  standard LLM judge **accepts 62.8% of intentionally-wrong-but-topical answers** (a repaired
  judge reaches 86.3% human agreement vs 43.7%) — magnitude single-source; the direction joins
  the §3.1 judge-unreliability cluster.
- **Reimplemented baselines diverge by multiples — cross-paper tables do not compose.** A-MEM's
  LoCoMo temporal-F1: **45.85 in its own paper, 35.40 as reimplemented by Mem0, 8.04 by
  MemoryOS** — a 5.7× spread on one cell, published by three parties with no shared stake.
- **The benchmark every memory vendor quotes fits inside a context window.** LongMemEval-S is
  ~**115k tokens** — it tests retrieval/context management, not durable memory — and **optimized
  plain RAG scores 86%** on it. The ~1.5M-token -M variant is rarely quoted.

### The ecosystem census — N=11, dated 2026-07-06, grep-verified per repo

**Sample (enumerated):** gstack · mattpocock/skills · no-mistakes · everything-claude-code ·
andrej-karpathy-skills · caveman · planning-with-files · alirezarezvani/claude-skills · superpowers ·
career-ops · ruflo.

| Property | Count |
|---|---|
| Implementer can see **and edit** the tests that judge it | **11 / 11** (12/12 including Zenith; **13/13 including anthropics/cwc-long-running-agents**, added 2026-07-16) |
| Subscription rate-window awareness | **0 / 11** |
| Wake-on-reset | **0 / 11** |
| Prompt-cache hygiene in cost logic | **1 / 11** (planning-with-files) |
| Published run-to-run variance measurement | **0 / 11** |
| Machine-checkable planning determinacy bar | **0 / 11** |
| Spec-to-test traceability | **0 / 11** |
| Closed-loop evidence that a lessons store improves outcomes | **0 / 11** |
| Disk-based (not transcript) resume | **9 / 11** |

Specific code facts: `no-mistakes` blocks **new** test files but never **modified** ones, and its
review runs once *before* test, so later fix commits are never re-reviewed. `planning-with-files`
documents an `AcceptanceCheck` gate with a full allowlist security model that **no shipped script
implements** — "done" is still the agent's own `Status: complete` line. `career-ops` **greps the
rate-limit reset timestamp and discards it** (`batch-runner.sh:377`), then waits for a human.

## 6. Absence findings — Tier A about the sample, Tier B about the world

| Absence | Enumerated sample | Date |
|---|---|---|
| **Blind adversarial validation** (separate agent + fresh context + never sees generator reasoning + withholds an adversarial test set) | 0 of 11 ecosystem repos (0/12 with Zenith); 0 of the 20+ surveyed agents/frameworks. Extended 2026-07-10 to the 9 major shipped orchestration frameworks: merge/completion gates are **LLM-judgment (CrewAI), HITL approval (MS Agent Framework), or prompt-blind AND-gates (Zenith)** over shared-filesystem artifacts — the implementer-can-edit-its-judge hole is **13/13** across studied systems (extended 2026-07-16 with `anthropics/cwc-long-running-agents`, the vendor's own demo: fresh-context evaluator, but fully implementer-editable and advisory) | 2026-07-03 / 07-06 / 07-10 / 07-16 |
| **Window-aware admission control** | 0 of 11 (0/12). Six open Claude Code feature requests; nearest prior art is a ~787★ wait-and-resume script. Extended 2026-07-10: **no surveyed framework gates a spawn on a cost governor** — every one ships a static cap (Claude Code 16/run, Bedrock ≤10, Zenith 4) or an advisory warning | 2026-07-06 / 07-10 |
| **Calibration canaries** (planted known-defect probes gating trust in a "0 findings" verdict) | Not found in the ~40 meta-harness references, nor the 11 repos. Nearest neighbor is AXIOM — a *static benchmark* of LLM judges, not an operational pre-screen | 2026-07-09 |
| **Human-ratified self-modification** | Unpublished across the entire self-improvement literature — **every** loop accepts autonomously. (Nearest neighbor, different domain: VerificAgent's human-verified freezing of *memory writes* — quarantine of a store, not ratification of harness self-edits) | 2026-07-09 / 07-10 |
| **Generation-stamped state for race detection** | 0 of the 9 shipped framework families surveyed (Claude Code, OpenAI Agents SDK, LangGraph, CrewAI, AutoGen/AG2, MS Agent Framework, Google ADK+A2A, Bedrock MAC/AgentCore, Zenith) — checkpoint/resume is ubiquitous, race detection nowhere | 2026-07-10 |
| **A machine-checkable determinacy exit bar on planning** | 0 of 10 shipped spec/planning products (Claude Code plan mode & `/goal`, Devin, Cursor Plan Mode, Windsurf/Cascade, Codex PLANS.md, Kiro, Spec Kit, Antigravity, Tessl) — all converge on "generate plan → human eyeballs it → execute"; their own gate language concedes softness (Spec Kit: "no 100% guarantee"; Kiro checkpoints non-blocking; Tessl **pivoted away** from spec-as-source, Jan 2026) | 2026-07-10 |
| **Controlled evidence that spec-first beats prompt-then-code on agent outcomes** | None found across the RE literature, the 10 products, and the ecosystem — the benefit is universally *asserted*; the only measured comparisons run against it (Spec Kit ~10× slower, no quality edge). SANER'26's registered report (arXiv 2601.03878) is protocol-only | 2026-07-10 |
| **A validated forgetting/decay model for agent memory** | 0 in the surveyed experiential/production/survey memory literature — MemoryBank's Ebbinghaus curve was never ablated; Generative Agents' recency decay validated only on believability. What has support is utility-gating and supersession | 2026-07-10 |
| **Trust-weighted memory writes** | 0 of the surveyed production memory systems — Zep's bi-temporal "newer wins" is itself a poisoning vector; provenance links serve citation, not trust | 2026-07-10 |
| **Closed-loop evidence that a memory/lessons store improves coding outcomes** | 0 of 11 ecosystem repos (§5 census) — extended 2026-07-10 to the **entire surveyed paper literature and shipped wiki products**: no learning-from-experience paper evaluates on SWE-bench or any multi-file benchmark | 2026-07-06 / 07-10 |
| **Measured defect-catching value of the shipped human-on-the-loop checkpoint** | Asserted, never validated, across shipped human-gated coding products (Devin, Copilot) — corroborated by arXiv 2605.02273 (61% of AI PRs receive no recorded review). The checkpoint's honest, measured value is scope/intent governance | 2026-07-10 |
| **Risk-tier-keyed harness configuration** | Unpublished. The only published configuration keys are **task family** (Meta-Zenith, CORE-Bench) and **model** (Self-Harness). Risk-tiered slimming is this project's own extension | 2026-07-09 |
| **A frozen-original-goal whole-build closure gate** | Not doc-confirmed in Kiro or Spec Kit; Claude Code's `/goal` re-checks a *running* goal, not a build-start snapshot | 2026-07-03 |
| **A built-in critic in LangGraph** | Confirmed by non-appearance in the API docs; reflection/evaluator-optimizer are hand-built patterns | 2026-07-03 |

**One absence claim of ours was falsified, and the correction stands.** The corpus previously held
that its self-measuring verifier was "ahead of the published literature." **Self-Harness**
(arXiv 2606.09498, Jun 2026) publishes a proposer-blind held-out promotion gate and a
weakness-mining analog of the escapes log. Surviving distinctions: blind held-out validation at
*task-level implementation* (not only harness-edit promotion); **calibration canaries**; and
**human-ratified self-modification**.

## 7. Tier C — claims we explicitly distrust

Listed because a distillation that only says what to believe is half a document.

**Self-administered benchmarks of one's own system.** Zenith's *"#1 on FrontierSWE"* — the
official leaderboard has **Fable 5 first at 0.900 and does not list Zenith at all**; II ran and
scored the suite themselves. II-Agent's *"75.57% GAIA"* — **absent from the independent HAL
leaderboard**, whose top entry is 74.55%. Zenith's RALPH-ablation effect sizes (n=1/cell, no
independent reception found as of 2026-07-09). Meta-Zenith's capability claims — **the code is not
public**.

**Marketing multipliers.** gstack's 810× (author concedes). ruflo's "89% routing accuracy,
2.8–4.4× speed" (no methodology anywhere; its own ADRs say the opposite). caveman's 65% (really
~50–53%). superpowers' 2×-faster (author-caveated). planning-with-files' 96.7% (measures file
patterns, not outcomes). career-ops' "740+ offers."

**Author-run preprint effect sizes.** DGM's 20→50% SWE-bench, Self-Harness's +21pts held-out,
Meta-Harness's +7.7pts, ACE's 42.4→59.4%, AlphaEvolve's and ShinkaEvolve's headline gains — all
**single-source and unreplicated.** Mechanisms importable; magnitudes not. *Peer review does not
fix this*: STOP, GEPA, ADAS, AFlow, Anchored Self-Play, and AI Scientist are reviewed and still
single-source. The 2026-07-10 passes add to the same bin: CAID's correctness deltas,
Specification-Gap's 58/25%, CodeCRDT's 13.1%, SWE-EVO's −2/−15%, AdaptOrch's +22.9%, ADaPT/ToT/RAP
deltas (re-implemented baselines, toy domains), every PlanBench-era percentage
(model-generation-scoped: GPT-3.5/4/o1 on formal PDDL — do not transfer to software), and the
experiential-memory headline gains (Voyager 3.3×, AWM +51.1% relative, MemP +35.7pp, ParamMem
68 vs 62).

**Memory-vendor numbers.** Mem0's marketing-blog **92.5%/94.4% LoCoMo** — absent from its
peer-reviewed paper, whose real result (J = 66.88/68.44) sits **below Mem0's own full-context
baseline** (72.90). Zep's "#1 at 63.8%" — true at paper time, non-comparable to any 2026 figure,
and it collapses to 48.0 under a standardized independent harness. **Any absolute ≥90%
memory-benchmark score** (Hindsight's 91.4% rides a Gemini-3 Pro reader; MemoryOS's "+49.11%" is
a relative delta on word-overlap; agentmemory's "95.2%" is retrieval recall, not QA accuracy).
GitHub Copilot's 90%-vs-83% memory PR-merge A/B (p<0.00001) — the strongest positive anywhere,
but a vendor measuring its own feature on an operational metric the agent's own behavior
influences. All of these are also capped by the broken yardstick itself (§5: LoCoMo's 6.4% key
errors).

**Multi-agent headlines.** Any "multi-agent beats single-agent" claim that does not control
thinking-token compute — refuted at equal budget (§3.2). Anthropic's 15×/90.2% research figures
ported to *coding* — Anthropic itself declines that extension (§2.1). Framework self-reported
code scores (MetaGPT's 85.9% HumanEval; where independently re-measured, ChatDev scored **25%**
on ProgramDev). Cognition's single-writer prescriptions — engineering judgment this corpus
happens to agree with, but unmeasured; cite for framing, never as an effect size.

**Oversight numbers that do not transfer.** Bowman's sandwiching gains and Burns' exact
weak-to-strong recovery percentages (vendor self-measurement — the *admissions* are §2.1; the
gains are not portable). METR's "19% slower" as a productivity constant (one org, 16 devs, one
setting; the direction — self-assessment over-credits AI — travels). Any single clinical
alarm-reduction number as a design target. The "~23 minutes to refocus after an interruption"
statistic — a widely-repeated single-source folk figure; the *boundary-timing* mechanism (§3.3)
is what's replicated. Kiro's "4× on 4+ tasks" and every first-party product outcome number.

**A corpus-internal fabrication, kept visible so nobody re-imports it.** The "specification
entropy / determinacy index" once attributed to arXiv 2603.24284 **does not exist** — it was an
intermediate-summary confabulation, caught and corrected 2026-07-10 (see the corrections ledger
in [../README.md](../README.md)). Cite only that paper's verified L0–L3 ladder numbers.

**Vendor measurements of vendor features.** Anthropic's Tool Search accuracy gains (49→74%,
79.5→88.1%) — measured by Anthropic, on Anthropic's evals; an independent test found success
*down* (87→82%) in the small-catalog regime. Anthropic's multi-agent 90.2% / 4× / 15× figures —
internal eval, unequal budget, and the corpus's own instruction is to **unfuse** the citation.

**Anthropic long-running showcase magnitudes.** The C-compiler figures (16 agents / ~2,000
sessions / $20k / 2B input tokens / 99% suite pass / boots Linux 6.9) and the harness-design
$9-vs-$200 solo-vs-harness comparison are **single uncontrolled showcase runs** (n=1 per
cell, no variance), the former **contamination-contested** (chibicc-quirk matches, issue
#232; The Register: *"the validation set was included in the training data"*); "compress
months or even years into days" rests on one n=1 anecdote whose 0.1% target was not met.
Mechanisms importable; magnitudes not. Osmani's relayed figures (TTFT percentiles, an
"11,000-line Slack app") are absent from the primaries — do not attribute to Anthropic
([landscape/anthropic-long-running-agents.md §3, §10](../external/landscape/anthropic-long-running-agents.md)).

**Author benchmarks of author tools.** AXI's `gh-axi` numbers: author-run, and a Sonnet 4.6 agent
judged by Sonnet 4.6. The replicated meta-finding (interface ergonomics dominates) survives; the
absolute numbers do not. The derived "hand-crafted CLI beats MCP" claim is **contradicted** by the
only independent head-to-head (Smithery, n=756: native MCP 91.7% vs CLI 83.3%, with the CLI using
2.9× more tokens).

**Our own load-bearing magnitudes.** The ~30× same-task token variance and the cache-read discount
are, by this project's own standing rule, **single-source until they ship methodology and a
reproduction path.** Their *directions* are corroborated; their *numbers* are not. A corpus that
exempts itself from its own rule is marketing.

**Hype-tier, cite for framing only.** The Ralph-loop "$297 MVP"; the "100k sessions → dumb zone"
statistic; Palisade's o3-86%-at-chess figure; vendor SWE-bench scaffold-jump percentages; the
TrueFoundry 10× caching case study (gateway *semantic* caching ≠ Anthropic prompt caching — the
magnitude does not transfer).

## 8. Expiry

| Rows | Decay | Recheck when |
|---|---|---|
| §1 Mathematics | `math` | Never |
| §2.2 gaming ledger, §3.1–§3.2 replicated `llm-class` rows | `llm-class` | A capability generation that plausibly changes the mechanism. |
| §3.3 human-factors rows | `human-factors` | Only on a fundamental oversight-interface paradigm shift. **The slowest-decaying empirical content in the corpus** — these predate LLMs and will outlive model generations. |
| §5 memory-benchmark record (LoCoMo key errors, LongMemEval-S size, the A-MEM spread) | fixed dataset/publication facts | Only if a dataset is re-issued corrected, or the quoted variant shifts |
| §6 framework/product surveys (9 frameworks, 10 planning products, memory systems) | `their-tree` / sample-bounded | Any new survey; counts are as of 2026-07-10 |
| §3 MCP schema tax, skill-invocation recall | `vendor-build` | Every Claude Code / MCP release |
| §4 plan structure, caps, credits, the paused SDK split | `vendor-policy` | Any announced plan change. **Next scheduled: the 2026-07-13 weekly-promo expiry.** |
| §4 deny-rule precedence, subagent sandbox inheritance | `vendor-build` | Every Claude Code build — **re-probe, do not re-read the docs** |
| §5 Zenith code facts | `their-tree` | Any Zenith release past `feb1d62` |
| §5 cwc-long-running-agents code facts | `their-tree` (+ the hook-schema finding decays `vendor-build`) | Any release past `ad107a97`; re-probe the schema no-op on every Claude Code build |
| §5 ecosystem census | `their-tree` | Re-clone; counts are as of 2026-07-06 |
| §6 absence findings | sample-bounded | On any new survey; an absence is only as strong as its enumerated sample |

**The rule that generates this table:** a fact is only as durable as its fastest-decaying
dependency. A *replicated* measurement of a *vendor build* is `vendor-build` — replication buys
warrant, not shelf life.
