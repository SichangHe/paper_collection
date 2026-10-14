                                             Formal Conjectures: An Open and Evolving
                                                Benchmark for Verified Discovery in
                                                           Mathematics


                                          Moritz Firsching1∗ Paul Lezeau2∗ Salvatore Mercuri2∗ Miklós Z. Horváth1∗
                                                   Yaël Dillies3 Calle Sönne1 Eric Wieser1 Fred Zhang1
                                                 Thomas Hubert1 Blaise Agüera y Arcas4 Pushmeet Kohli1
arXiv:2605.13171v1 [cs.AI] 13 May 2026




                                             1                         2                                3                            4
                                                 Google DeepMind           Imperial College London          Stockholms universitet       Google



                                                                                        Abstract
                                                     As automated reasoning systems advance rapidly, there is a growing need
                                                     for research-level formal mathematical problems to accurately evaluate their
                                                     capabilities. To address this, we present Formal Conjectures,2 an evolving
                                                     benchmark of currently 2615 mathematical problem statements formalized
                                                     in Lean 4. Sourced from areas of active mathematical research, the dataset
                                                     features 1029 open research conjectures providing a zero-contamination
                                                     benchmark for mathematical proof discovery, and 836 solved problems for
                                                     proof auto-formalization. Notably, the repository provides a structured
                                                     interface connecting mathematicians who formalize and clarify problems
                                                     with the AI systems and humans attempting to solve them. Demonstrating
                                                     its immediate utility, the benchmark has already been leveraged to make
                                                     new mathematical discoveries, including the resolution of open research
                                                     conjectures. We describe our approach to ensuring the correctness of these
                                                     formalizations in a collaborative open-source project where contributions
                                                     stem from an active community. In this framework, AI-generated proofs
                                                     and disproofs serve as a valuable auditing mechanism to iteratively improve
                                                     the fidelity of the benchmark. Finally, we provide a standardized evalua-
                                                     tion setup and report baseline results on frozen evaluation subsets, demon-
                                                     strating a climbable signal that measures the current frontier of automated
                                                     reasoning on research-level mathematics.


                                         1       Introduction
                                         As automated reasoning systems, including large language models (LLMs), continue im-
                                         proving their capabilities, the benchmarks used to measure their progress face significant
                                         challenges. In the domain of (formal) mathematics, many existing evaluation frameworks
                                         suffer from: (i) Data leakage: As solutions to benchmark problems appear online, it is
                                         diﬀicult to distinguish genuine reasoning from memorization. This is a challenge for bench-
                                         marks like Zheng et al. [2021], Tsoukalas et al. [2024], Jiang et al. [2025], Yu et al. [2025];
                                         (ii) Secretive evaluation: To combat leakage, some benchmarks require that the evalua-
                                         tion set be kept private, which hinders open and reproducible research [Chollet et al., 2025,
                                         Glazer et al., 2024, Center for AI Safety et al., 2026]; (iii) Oversimplified success cri-
                                         teria: Many benchmarks rely on verifying a simple, machine-checkable final answer (such
                                         as a number), which fails to capture the complex, multi-step reasoning inherent in a full
                                             ∗ Equal contribution. Correspondence to: firsching@google.com
                                             2 https://github.com/google-deepmind/formal-conjectures



                                         Preprint.
mathematical proof [Hendrycks et al., 2021, Glazer et al., 2024]; and (iv) Saturation: As
models improve, some benchmarks become saturated. For instance, MiniF2F [Zheng et al.,
2021] is now routinely solved with over 99%; see Hubert et al. [2025], Chen et al. [2025b],
Lin et al. [2025].
To address these limitations, we introduce Formal Conjectures, an open-source and grow-
ing collection of mathematical problems formalized in Lean 4 [Moura and Ullrich, 2021] using
Mathlib [The mathlib Community, 2020]. The benchmark focuses on open conjectures as the
primary challenge, providing a zero-contamination testbed where solutions cannot be found
in existing training data. The secondary challenge consists of (informally) solved problems
for auto-formalization, which do not share the same zero-contamination guarantees. We
formalize all problems in a formal language to allow for objective, rigorous, and automated
evaluation: a proposed solution is definitively correct if and only if its corresponding proof
is accepted by the kernel without relying on forbidden axioms like sorry. Our choice of
Lean 4 is pragmatic: Mathlib, the largest formal mathematics library available, is essential
for stating a wide variety of advanced conjectures. While we focus on Lean 4, the core
principles of our benchmark are language-agnostic and extendable to other formal systems.
This paper details the construction and methodology of the Formal Conjectures bench-
mark. The benchmark is publicly available under the Apache 2.0 license and has already
been utilized for real-world mathematical discovery [Alexeev and Mixon, 2025, DeepMind,
2026]. In summary, our main contributions are:
     • The Formal Conjectures Benchmark: A large-scale, evolving dataset of 2615
       mathematical statements in Lean 4, including 1029 open conjectures for zero-
       contamination proof discovery and 836 solved problems for auto-formalization.
     • A Unified API for Mathematical Reasoning: A repository interface connect-
       ing mathematicians with an ecosystem of automated solvers to facilitate simultane-
       ous statement auditing and rapid dissemination of problems to AI systems.
     • Methodology for Statement Formalization: We introduce a collaborative
       pipeline and a three-level taxonomy of misformalizations (Translation, Underspeci-
       fied, and Source) to ensure formalization fidelity. This includes the answer(sorry)
       mechanism, which decouples the mathematical value discovery from proof verifica-
       tion. We provide insights from 291 fixed cases of research-level formalization.
     • A Standardized Evaluation Framework: We provide a rigorous evaluation
       setup using the Lean 4 kernel to verify multi-step reasoning without relying on
       oversimplified numerical answers. We establish frozen subsets, FC100SolvedSet1 and
       FC100OpenSet1, to enable stable, reproducible model comparisons.


2   Related Work
Our work intersects mathematical reasoning benchmarks and formal theorem proving.

General mathematical reasoning benchmarks. Several benchmarks evaluate AI sys-
tems on advanced problem-solving without requiring formal proofs. FrontierMath [Glazer
et al., 2024] uses expert-crafted problems verified by numerical answers, which, while
machine-checkable, do not fully capture the multi-step reasoning process. In January 2026,
Epoch AI launched FrontierMath: Open Problems, a website-only pilot of a small collection
of unsolved research-level informal problems with evaluation offered as a service. Human-
ity’s Last Exam [Center for AI Safety et al., 2026] crowdsources expert questions but relies
on answer-checking rather than proof verification. MathArena [Balunović et al., 2025] evalu-
ates LLMs on fresh competition problems to reduce contamination risk and assesses informal
proof-writing. The ARC Prize [Chollet et al., 2025, 2026] targets abstract reasoning, sharing
our focus on measuring genuine reasoning over pattern matching. Formal benchmarks, by
contrast, allow automatic verification of full reasoning or proof.

Formal mathematics benchmarks and automated theorem proving. Interest in
automated theorem proving has accelerated AI reasoning, leading to the rapid saturation
of existing formal benchmarks. MiniF2F [Zheng et al., 2021] pioneered high-school-level


                                              2
               Informal Source Problems                                               Formal Conjectures Benchmark

    Erdős Problems                1318                                          Research Open (1029)
    Wikipedia                      476                                          ,→ Primary Goal: New Proof Discovery
    Green’s Open Problems          175                                          Zero-contamination testbed for genuine reasoning.
    Papers                         131
    Open Quantum Problems          125
    Written on the Wall II         110                                          Research Solved (836)
    OEIS                           105                                          ,→ Secondary Goal: Auto-formalization.
    arXiv                           56
    MathOverflow                    53
    Other sources                   66                                          All Other Statements (750)
    A mix of established archives, research collections, and open prob-         • Test (467)        • API (155)   • Textbook (128)
    lem lists.                                                                  ,→ Purpose: Sanity & Definition Testing.



                                                               Formalization Pipeline

Figure 1: Left: informal source distribution. Right: formal category distribution, including
open (1029) and solved (836) problems.


evaluation but became increasingly saturated as models improved. This shift was defined
by AlphaProof [Hubert et al., 2025] and AlphaGeometry 2 [Chervonyi et al., 2025] reaching
silver-medal performance at the 2024 IMO, where AlphaProof solved Lean problems and
introduced the Formal-IMO [Hubert et al., 2025] dataset. Systems like Aristotle [Achim
et al., 2025] and Seed-Prover [Chen et al., 2025b] achieved gold-medal equivalents at the
2025 IMO. This capability leap cascaded to undergraduate math, where benchmarks like
PutnamBench [Tsoukalas et al., 2024] and Putnam 2025 are being saturated by models such
as Seed-Prover 1.5 [Chen et al., 2025a] and Numina [Liu et al., 2026], and other industry
systems. While SorryDB [Letson et al., 2026] evaluates AI on practical theorem completion
and FATE [Jiang et al., 2025] targets varying diﬀiculties of frontier algebra, the saturation
of earlier benchmarks highlights an acute need for research-level evaluation: benchmarking
reasoning on unsolved research-level mathematics.

Adoption of Formal Conjectures. Since its open-source release in May 2025, the repos-
itory has been adopted by both mathematicians and tool builders. Boris Alexeev used a
repository formalization to prove Erdős Problem 124 [Bloom, 2025] with Aristotle [Achim
et al., 2025]. Although the statement was initially misformalized and included an unintended
extra hypothesis, Aristotle’s proof succeeded without relying on it. Numerous subsequent
successes such as [Alexeev and Mixon, 2025] highlight the repository’s value for discovery
and demonstrate how AI-generated proofs serve as a vital auditing mechanism to improve
formalization fidelity. A DeepMind prover agent [DeepMind, 2026] conducted a systematic
evaluation of the full repository, solving several open problems. To facilitate standardized,
reproducible evaluation, this paper introduces named, versioned snapshots (Section 4.1),
moving beyond individual tests to systematic benchmarking across diverse methods.

3     Formal Conjectures
3.1     Problem Selection and Composition

The benchmark’s problems are sourced from diverse            600
                                                                                       Lean files




mathematical literature for broad coverage. Key              400
sources include the collection of problems posed by
                                                             200
Paul Erdős, as catalogued on erdosproblems.com
[Bloom, 2023]; the Kourovka Notebook of unsolved                0
                                                             May 2025            Apr 2026
problems in group theory [Khukhro and Mazurov,
2026]; the IQOQI Vienna list of open quantum prob-
lems [IQOQI Vienna and Werner, 2017]; well-known Figure 2: Repository growth over
Wikipedia conjectures; conjectures from recent pub- time.
lications in academic journals and on arXiv; and questions asked on MathOverflow. The
number of problems per informal source is in Figure 1. Furthermore, the repository has
grown steadily since its initial open-source release, as visualized in Figure 2.


                                                                          3
/--
There are no indecomposable vector bundles of rank 2 on $\mathbb{P}^n$ for $n \ge 7$.
-/
@[category research open, AMS 14]
theorem hartshorne_conjecture (n : ℕ) (hn : 7 ≤ n)
    (F : VectorBundles (ProjectiveSpace (Fin (n + 1)) (Spec (.of ℂ))))
    (hF : F.rank = 2) : Nonempty (F.Splitting (Fin 2)) := by
  sorry

Figure 3: A statement in Formal Conjectures, an open conjecture from [Hartshorne, 1974].
It includes an informal statement as a comment, tags, and a Lean statement.


The collection is divided into two primary categories: Unsolved Conjectures, open re-
search problems where a formal or informal proof would represent a new mathematical
discovery; and Solved Problems, established theorems with known informal proofs that
benchmark an AI’s ability to formalize existing arguments, though only a fraction currently
have a formal proof available. We include both categories not only because they indepen-
dently serve as benchmarks for different tasks (proof generation and auto-formalization),
but also because they are often intertwined. When formalizing an open conjecture, it is
natural to also state and prove simpler, solved variations. For instance, a general conjecture
about the existence of Hadamard matrices of size 4k for all valid k ∈ N can be presented
alongside the solved cases (e.g., for all k ≤ 166) and the first open case (k = 167).
Other sources of solved problems are collections of conjectures that include both open and
solved questions. In those cases, we also formalize the statements of the solved cases. They
are often related in subject to the open conjectures, and hence the formalization of their
statements and the auto-formalization of their proofs support the open conjectures.
The collection of solved problems also includes simpler statements, ranging from trivial to
textbook level, which help validate the correctness of the underlying formalizations. Includ-
ing such simpler problems helps detect incorrect formalizations of open problems: a disproof
of an easy special case or known variant might indicate that some of the definitions used
have been stated incorrectly. See below for examples of how those initial misformalizations
can lead to improved formal and informal problem statements. We strive to always state
the simplest open variant of a conjecture, as well as the conjecture in greater generality.

The @[category] attribute. To help navigate this collection, each statement is labeled with
one of the following category tags: research open (an open research-level problem), research
solved (a solved research-level problem), textbook (a textbook-level math problem ranging
from high school to graduate level), API (statements developing foundational theory for a
new definition intended for general reuse), and test (a statement serving as a sanity check).
The distribution of all categories is in Figure 1 on the right.

The @[subject] attribute. Statements are also labeled with subject tags following the
AMS Mathematics Subject Classification [Editors of Mathematical Reviews and zbMATH,
2020]. The distribution by source collection and AMS subject classification is shown in
Tables 3 and 4 (Appendix A.1). While number theory and combinatorics account for over
half of all statements, the benchmark already spans over 10 AMS subjects (e.g., also quantum
theory, or algebraic geometry), which we aim to broaden further.

3.2   Formalization Methodology

All problems are presented as Lean theorems with informal statements. While our core goal
is providing open statements with sorry placeholders for AI solvers to replace, we also include
solved variants of conjectures and items from problem lists. For open problems, no proofs
are provided. For solved items, we appreciate very short proofs or counterexamples (under
25–50 lines) that test the definitions. Longer proofs are excluded to keep the repository
lightweight; instead, contributors are encouraged to host proofs in their own repositories
and link to them using the @[formal_proof] mechanism described below.


                                              4
We provide an example statement in Figure 3.

The answer(sorry) mechanism. Many mathematical problems ask not just for a proof
but for a specific answer: a number, a function, or a set. To handle this, we introduce
an answer(sorry) construct, implemented as a custom Lean term elaborator, that separates
the task of discovering a computable answer from proving it correct. For example, “What
is the smallest n such that P (n)?” is formalized with answer(sorry) as a placeholder that
a solver must replace with a concrete value, reducing the problem to a verifiable proof
obligation. The construct also handles unknown truth values: when answer(sorry) appears
in a biconditional, a solver replaces it with True or False to conjecture or refute a proposition.
See Appendix A.2 for detailed examples and the full elaboration semantics.

The “for Mathlib” pattern. The project maintains a FormalConjecturesForMathlib di-
rectory containing 88 files of auxiliary definitions and lemmas not yet in Mathlib but needed
for conjectures. These results are asynchronously contributed upstream to Mathlib. See Ap-
pendix A.3 for details on the rationale and contents of this directory.

The @[formal_proof] attribute. To keep the repository lightweight, the @[formal_proof]
attribute decouples problem statements from their solutions. It supports three modes:
(1) formal_conjectures for proofs solving exactly the type of the statement given here; it
should point to a commit on top of a commit in the main branch of our repo, filling in the
sorry; (2) lean4 for equivalent problems solved in Lean 4 elsewhere (e.g., in Mathlib or ex-
ternal repos); and (3) other_system for problems solved in other systems like Lean 3, Isabelle,
or Rocq. This design links to external verification sources while keeping the repository
maintainable. The attribute applies to any solved category, though usage on a research open
problem triggers a linter warning. Table 1 summarizes proof coverage recorded via this
attribute.

3.3   Misformalizations

It is notoriously diﬀicult to formalize a mathematical problem correctly without providing
a formal proof. A misformalization is a formal statement that is incorrect. To provide a
rigorous foundation for benchmark quality, we introduce a taxonomy of misformalizations.
It includes the following levels, where in all cases the formal statement is incorrect.

      1. Translation: the informal statement is accurate and explicitly phrased.
      2. Underspecified: the informal statement is accurate but lacks detail.
      3. Source: the informal statement is not as intended.

These levels are ordered with respect to the degree of contribution from the formalizer. Level
1 misformalizations arise from the formalization only, while level 3 misformalizations arise
from the informal text only. Moreover, for a Lean expert who does not necessarily have
domain expertise in the informal statements, levels are ordered with respect to diﬀiculty
to fix. Note that level 2 and 3 misformalizations have been useful in clarifying informal
statements in the literature. An illustrative example is Erdős Problem 978: multiple at-
tempts to formalize the statement led to a refinement of the original informal problem3 .
The original statement, “Are there infinitely many n for which f (n) is (k − 2)-power-free?”,
was found to require multiple additional hypotheses and became: “If k > 3, and for all
primes p there exists n such that pk−2 ∤ f (n), then are there infinitely many n for which
f (n) is (k − 2)-power-free?” More broadly, informal texts may exclude trivial cases without
explicitly describing them, while formalization requires these to be explicit.
Misformalizations can further be categorized into six types across the three levels: syntactic,
semantic, and misrepresentation errors at the translation level; implicit conventions at the
underspecified level; and reporting and mathematical errors at the source level. The full
taxonomy with definitions and representative pull requests is given in Appendix A.4. Across
the repository a total of 291 misformalizations have been fixed, with misrepresentation (48%)
  3 https://www.erdosproblems.com/forum/thread/978




                                                     5
       Informal Source                            Human Formalization                        Merge to Repository
          Erdős, arXiv, etc.                       Draft Lean 4 code & tests                    formal-conjectures
                                  So
                                    urc
                                         eE             Misformalization
                                           rro
                                              r
       Status Updated                  Valid      Verification & Triage          Proofs &     Automated Runs
      In repo & informal source        Result     Manual inspection of results   Disproofs   AI systems attempt proofs


Figure 4: Iterative pipeline for Formal Conjectures. Formalized statements are tested by
periodic AI runs, solving problems or triggering a revision loop.




and semantic (35%) errors being the most common (Table 5). Detailed code diffs illustrating
these misformalization examples can be found in Appendix A.5.




3.4     Avoiding Misformalizations


In Formal Conjectures, every contribution undergoes mandatory code review by humans
with both Lean expertise and relevant mathematical domain knowledge. While early
contributions to the repository were written entirely by hand, the authoring process has
evolved: most recent submissions use AI tooling, including agentic coding assistants and
auto-formalization systems. To facilitate high-quality AI-assisted contributions, the repos-
itory provides an AGENTS.md file with structured guidance for these tools. Similarly, the
review process increasingly leverages AI: reviewers use language models to cross-check for-
malizations against informal sources, and AlphaProof runs on submissions to catch potential
misformalizations before merging.
Beyond this review process, we employ a number of additional strategies to mitigate the
risk of misformalizations across the dataset. Firstly, we employ and encourage a test-based
design for definitions. Any new definitions introduced should be accompanied by a suite
of proven test lemmas and API statements that are designed to establish expected behav-
ior of the definition and mitigate the risk of edge-case errors. Lean and Mathlib’s tooling
(for example decide) can be employed to prove many of these test statements. As of the
bench-v1-lean4.27.0 release, the repository contains 467 test statements and 155 API state-
ments, amounting to 23.8% of the repository statements.
Secondly, automated theorem provers like AlphaProof regularly attempt proofs and dis-
proofs across the repository (Figure 4); manually inspecting these results primarily reveals
misformalizations. In contrast to test-based design, which proactively reduces the risk of
edge-case errors, this retroactive approach is capable of unearthing misformalizations across
all categories as described in Section 3.3. In addition, we use Gemini, AlphaProof, and
other tools to automatically cross-check formalizations against their informal source texts,
flagging potential discrepancies for human review. Future work involves further automating
these processes in GitHub CI in order to reduce the overhead of manual post-hoc fixes from
the maintainers.
Thirdly, custom Lean linters built on Mathlib’s framework enforce metadata and documen-
tation standards across contributions. These cover AMS classification tags, answer(sorry)
usage, problem category annotations, and module docstrings.
Finally, as Formal Conjectures has grown in stature, community engagement and proof/dis-
proof attempts from external automated theorem provers have been increasingly valu-
able. Furthermore, insights and corrections discovered through this process are actively
upstreamed to the original sources, e.g., prompting the maintainer of the Erdős problems
website to regularly clarify and adjust the informal problem statements.


                                                               6
4     Benchmark Evaluation
4.1    Evaluation Framework

Evaluation Paradigms. Formal Conjectures provides a dynamic, rigorous benchmark
for advanced automated reasoning premised on novel mathematical insight as the ultimate
intellectual hurdle for complex problems. We define two distinct setups:

       1. Primary Goal: New Formal Proof Discovery. Measuring AI’s ability to
          discover formal proofs for open problems, these unsolved conjectures form a zero-
          contamination testbed for genuine mathematical discovery. Since no solutions exist
          in any training corpus, success provides a definitive signal of reasoning capabilities,
          removing the need for secretive evaluation sets common in other benchmarks.
       2. Secondary Goal: Proof Auto-formalization. This track provides a climbable
          benchmark treating the non-trivial translation of established mathematics into for-
          mal code as a distinct, rigorous challenge. It measures a model’s ability to work
          with Lean 4 and Mathlib to formalize known arguments.

Evaluating Open Problems. Evaluating open problems is definitive: as no formal so-
lutions exist at release time, the first kernel-accepted proof provides a zero-contamination
success signal. However, since a proof may settle a misformalized statement rather than the
intended problem, any result for an open conjecture triggers manual inspection for fidelity.

Fixed Benchmark Subsets. To enable stable model comparisons, we provide two
frozen subsets of 100 problems each: FC100OpenSet1 (100 research open statements) and
FC100SolvedSet1 (100 research solved statements). These subsets are defined in the repos-
itory files FC100OpenSet1.lean and FC100SolvedSet1.lean, which import exactly the corre-
sponding theorem statements. Because these files are compiled as part of the repository
across all supported Lean versions, the problem sets remain fixed and comparable even
as the repository evolves. Further details on the construction of these subsets are in Ap-
pendix B.1.

Correctness. Following established formal math benchmark methodologies [Zheng et al.,
2021, Tsoukalas et al., 2024], our evaluation leverages the Lean 4 kernel for an objective,
rigorous, and automatable success criterion. A proposed solution is a Lean proof term re-
placing the sorry placeholder. Solutions are correct if and only if accepted by the kernel
without relying on forbidden axioms, such as sorry. This binary criterion eliminates human
grading ambiguity and provides an indisputable ground truth. While theoretically suscepti-
ble to foundational bugs in the Lean kernel or unintended axioms (e.g., a Lean Zulip thread4 ,
which mentions a now-fixed exploit), in practice, kernel-level verification provides the high-
est mathematical rigor. Consequently, all evaluations are automatically verifiable, allowing
results and proof terms to be shared publicly for transparent, reproducible research.

Versioning and Reproducibility. Evaluating on a living repository is challenging: de-
pendency updates can alter statement semantics, and new Mathlib theorems may simplify
problems. To enable reproducible comparisons, we tag frozen benchmark snapshots using
a two-part naming scheme: bench-vN -lean4.X .Y . The bench version vN identifies a fixed
problem set; the Lean version suﬀix pins the Mathlib tag (and hence Lean toolchain) against
which statements compile and are evaluated. Releases are issued every few months; when
Lean versions bump, companion tags allow evaluating the same problem set against interme-
diate toolchains, e.g. bench-v3-lean4.27.0. To preserve baselines, snapshots are immutable;
misformalization fixes are never patched into existing versions but incorporated into the
next (e.g., bench-v(N+1)).

A Living Benchmark and Unified API. Outside the frozen subsets, the repository
operates as a dynamic benchmark that exhibits useful evaluation dynamics over time. As
    4 https://leanprover.zulipchat.com/#narrow/channel/270676-lean4/topic/Soundness.20bug.3A.

20hasLooseBVars.20is.20not.20conservative/with/520153084



                                                     7
Table 1: Proof coverage across all statement categories. Proved in repo: the statement has
a sorry-free proof in the repository; Linked proof : a proof is recorded via the @[formal_proof]
attribute but is not present in the repository itself; With proof : either of the above.

          Category            Total                    Proof Status
                                      Proved in repo     Linked proof     With proof
          research_solved      836         44 (5.3%)     101 (12.1%)     145 (17.3%)
          textbook             128        45 (35.2%)        3 (2.3%)      48 (37.5%)
          test                 467       390 (83.5%)        3 (0.6%)     393 (84.2%)
          API                  155       140 (90.3%)               0     140 (90.3%)
          Total               1586       619 (39.0%)       107 (6.7%)    726 (45.8%)


new conjectures are added, solved, or corrected by the community, it naturally self-adjusts its
diﬀiculty, expands, and improves. The hardest problems remain open, pushing the frontier
of automated reasoning. Crucially, the repository acts as a unified API: researchers can
submit formalized conjectures to a single centralized hub for simultaneous exposure to all
evaluating AI systems. This obviates the need to manually engage with individual provers,
ensuring broad and concurrent attempts at mathematical discovery.

Open Problems Baseline. For the primary proof-discovery task on open problems, the
baseline for the first tagged release bench-v1-lean4.27 is 0% for all systems: by definition,
no formal proof exists for any research open statement at the time of tagging (problems
with known solutions are reclassified as research solved). Over time, these open statements
may receive formal or informal proofs. Proofs that expose a misformalization (Section 3.3)
rather than settling the intended problem trigger revisions incorporated into the next version.
In subsequent releases, interim-solved problems are reclassified to research solved, with
formal solutions receiving the @[formal_proof] attribute. The new research open set combines
remaining unsolved problems with new additions; thus, successive versions start with a
baseline of ≥ 0% solved statements and become increasingly more diﬀicult.

Proof Auto-Formalization Baseline. For auto-formalization, the baseline is system-
agnostic: we track all formal proofs contributed to the repository, regardless of origin. These
are tracked using the @[formal_proof] attribute (Section 3.2), which records the proof system
(formal_conjectures for proofs within the repository, lean4 for proofs in external Lean 4
projects such as Mathlib, or other_system for proofs in Isabelle, Rocq, etc.) and links
to the source. Table 1 summarizes the current state. Notably, 17.3% of research_solved
statements have a known formal proof (5.3% internal, 12.1% linked externally).

4.2   Illustrative Evaluation
We provide illustrative evaluations, with setup and cost details in Appendix B.2.

Frozen Evaluation Subsets. To ensure sta-
                                                   Table 2:      Results on the frozen
ble comparisons despite repository fluidity, we
                                                   FC100SolvedSet1.
provide two frozen evaluation subsets, each con-
taining 100 problems randomly sampled from            Method                  Proved (%)
the bench-v1-lean4.27.0 tag: FC100SolvedSet1          AlphaProof (1k sims)         45.0%
(proof auto-formalization) and FC100OpenSet1          AlphaProof (16k sims)        50.0%
(proof discovery; 0% baseline). By definition,        DM prover agent (dev)        66.0%
FC100OpenSet1 currently remains at a definitive
0% baseline across these evaluated methods, which highlights its status as a rigorous fron-
tier for new discovery. Results on FC100SolvedSet1 (Table 2) demonstrate a clear, climbable
signal across both compute and model capabilities. To provide a diverse evaluation, we
evaluate both a slightly improved version of the AlphaProof system used in the 2024 IMO
[Hubert et al., 2025] and a development version of a DeepMind prover agent [DeepMind,
2026]. These are different systems rather than incremental versions of the same architecture.
Utilizing a constrained tree-search-only inference setup on v6e TPUs, AlphaProof achieves


                                               8
a solve rate of 45% on FC100SolvedSet1 with a low compute configuration of 1,000 simula-
tions per problem. By increasing the compute budget to 16,000 simulations, the solve rate
improves to 50%, demonstrating a clear scaling signal. We emphasize that these evaluations
are conducted using tree-search inference only and do not utilize AlphaProof’s test-time rein-
forcement learning (TTRL) mechanism, which generates a curriculum to learn from during
the proof finding process through weight updates. Furthermore, utilizing a newer, devel-
opment version of the DeepMind prover agent, the solve rate increases to 66%, illustrating
that the benchmark effectively measures advancements across improved model architectures
and methodologies. Because running automated reasoning methods within Lean involves
significant infrastructure overhead, we provide these specific systems as illustrative baselines
to validate the benchmark’s signal. We encourage the community to report results against
these subsets as well as the evolving main repository.

5   Discussion
Broader Benefits. Beyond its primary role, Formal Conjectures provides precise math-
ematics by enforcing a level of formal precision that clarifies the exact meaning of state-
ments. This creates a library of conjectures referenced unambiguously via unique file names
and commit hashes, ensuring fixed and verifiable mathematical intent; unlike standard cita-
tions where generality or precision is often left to interpretation. Furthermore, the bench-
mark serves as a compass for Mathlib development, as formalizing advanced conjectures
reveals gaps in the existing library. We address these via FormalConjecturesForMathlib,
a directory of results continuously upstreamed to Mathlib. By identifying hard-to-state
concepts, the repository both benchmarks reasoning and expands formalized mathematics.

Limitations. Problem selection faces a scope bias constrained by Mathlib’s current cov-
erage, which we mitigate somewhat via our ForMathlib directory. While some concepts
remain hard to formalize, this limitation will diminish as Mathlib expands. There is also
a selection bias toward famous conjectures and Erdős problems, resulting in a concentra-
tion of number theory and combinatorics; we plan to mitigate this by sourcing diverse arXiv
preprints in areas like computer science and physics. Focusing on open problems introduces
a misformalization risk from subtle statement or source errors. While mitigated via
new methods in Section 3.4, these risks remain until a full proof is provided; fixing newly
discovered errors may require revisions impacting historical comparisons. The benchmark
also faces contamination challenges: for solved problems, models may retrieve known
arguments rather than reasoning from scratch; for open problems, zero-contamination is not
permanent as future solutions enter training data. Our living repository tracks these devel-
opments and reclassifies problems accordingly. Finally, verification and reproducibility
rely on the Lean 4 kernel’s integrity; while the theoretical exploitability of foundational
bugs or unintended axioms is a general challenge for formal systems, it remains the highest
standard for rigor. To ensure stable results despite the repository’s evolution, we provide
frozen, versioned subsets for standardized evaluation.

Future Work. As an active open-source project, we are committed to maintaining and ex-
tending Formal Conjectures with new problems, improved problems, and platform features;
this ongoing commitment is reflected in the repository’s steady growth since its initial release
(see Figure 2). See Appendix C for details on planned extensions, metadata improvements,
and community features.

6   Conclusion
We present Formal Conjectures, an evolving collection of mathematical problem state-
ments formalized in Lean 4, including open conjectures. Sourced from a diverse range of
mathematical literature and areas, the benchmark provides broad coverage as an evaluation
framework for AI systems’ capabilities in formal math. By providing a zero-contamination
testbed of research-level problems alongside a substantial set for proof auto-formalization,
we establish a rigorous environment for evaluating AI for formal mathematical research.
Crucially, to ensure stable and reproducible model comparisons as the repository evolves,


                                               9
we complement this dynamic dataset with versioned, frozen evaluation subsets. We hope
the work can drive the expansion of formalized math: both through its living repository and
the continuous upstreaming of new definitions to Mathlib, as well as serve as a high-fidelity
benchmark that bridges the gap between human mathematical expertise and automated for-
mal reasoning. Ultimately, we believe this resource will not only measure current progress
but also help accelerate the frontier of formal mathematical discovery.

Acknowledgments and Disclosure of Funding
We thank all contributors who have contributed to the repository since it was released
as open source, among them Abel Doñate, Aditya Ramabadran, Amogh Parab, Anirudh
Rao, Anthony Wang, Ayush Debnath, Bhavik Mehta, Bolton Bailey, Cong Lu, Daniel
Chin, Felix Pernegger, Franz Huschenbeth, James Jordan, Jean-Guillaume Durand, Jofre
Costa, Junseok Lee, Junyan Xu, Madhu Shree Aravindan, Mario Krenn, Martin Bruse,
Michael Rothgang, Mirek Olšák, Ralf Stephan, Reklle, Seewoo Lee, The bbchallenge Col-
laboration (bbchallenge.org), Wojciech Nawrocki, Yan Yablonovskiy, Yoh Tanimoto, Yongxi
Lin, Zeyu Zheng, and Zhen Ning David Liu. A full list of contributors is available at
https://github.com/google-deepmind/formal-conjectures/graphs/contributors. Addition-
ally, we thank Swarat Chaudhuri, George Tsoukalas, Anton Kovsharov, Henryk Michalewski,
Edward Lockhart, and Goran Žužić for helpful discussions and support running experiments.

References
Tudor Achim, Alex Best, Alberto Bietti, Kevin Der, Mathïs Fédérico, Sergei Gukov, Daniel
  Halpern-Leistner, Kirsten Henningsgard, Yury Kudryashov, Alexander Meiburg, et al.
  Aristotle: Imo-level automated theorem proving. arXiv preprint arXiv:2510.01346, 2025.

Boris Alexeev and Dustin G. Mixon. Forbidden Sidon subsets of perfect difference sets,
  featuring a human-assisted proof, 2025. URL https://arxiv.org/abs/2510.19804.

Mislav Balunović, Jasper Dekoninck, Ivo Petrov, Nikola Jovanović, and Martin T. Vechev.
 MathArena: Evaluating LLMs on Uncontaminated Math Competitions, 2025. URL https:
 //arxiv.org/abs/2505.23281.

Thomas Bloom. Erdős Problems, 2023. URL https://www.erdosproblems.com/. Accessed:
 2026-03-24.

Thomas Bloom. Erdős Problem #124, 2025. URL https://www.erdosproblems.com/124. See
  comment section. Accessed: 2026-04-20.

Center for AI Safety, Scale AI, and HLE Contributors Consortium. A benchmark of expert-
  level academic questions to assess AI capabilities. Nature, 649:1139–1146, 2026. doi:
  10.1038/s41586-025-09962-4. URL https://arxiv.org/abs/2501.14249.

Jiangjie Chen, Wenxiang Chen, Jiacheng Du, Jinyi Hu, Zhicheng Jiang, Allan Jie, Xiaoran
  Jin, Xing Jin, Chenggang Li, Wenlei Shi, et al. Seed-prover 1.5: Mastering undergraduate-
  level theorem proving via learning from experience. arXiv preprint arXiv:2512.17260,
  2025a.

Luoxin Chen, Jinming Gu, Liankai Huang, Wenhao Huang, Zhicheng Jiang, Allan Jie, Xi-
  aoran Jin, Xing Jin, Chenggang Li, Kaijing Ma, et al. Seed-prover: Deep and broad
  reasoning for automated theorem proving. arXiv preprint arXiv:2507.23726, 2025b.

Yuri Chervonyi, Trieu H Trinh, Miroslav Olšák, Xiaomeng Yang, Hoang H Nguyen, Marcelo
  Menegali, Junehyuk Jung, Junsu Kim, Vikas Verma, Quoc V Le, et al. Gold-medalist
  performance in solving olympiad geometry with alphageometry2. Journal of Machine
 Learning Research, 26(241):1–39, 2025.

Francois Chollet, Mike Knoop, Gregory Kamradt, and Bryan Landers. ARC Prize 2024:
  Technical Report, 2025. URL https://arxiv.org/abs/2412.04604.


                                             10
François Chollet, Mike Knoop, Gregory Kamradt, and Bryan Landers. ARC Prize 2025:
  Technical Report, 2026. URL https://arxiv.org/abs/2601.10904.
Google DeepMind. DeepMind prover agent. In preparation, 2026.
Editors of Mathematical Reviews and zbMATH.         MSC2020-Mathematics Subject
  Classification System, 2020. URL https://mathscinet.ams.org/mathscinet/msc/pdfs/
  classifications2020.pdf.

P Erdős. Problems and results in chromatic graph theory. Proof techniques in graph theory,
  pages 27–35, 1969.
P. Erdős and A. Hajnal. On chromatic number of infinite graphs. Theory of Graphs (Proc.
  Colloq., Tihany, 1966), pages 83––98, 1968.
Paul Erdős. Some of my favorite solved and unsolved problems in graph theory. Quaestiones
  Mathematicae, 16(3):333–350, 1993. doi: 10.1080/16073606.1993.9631741. URL https:
  //doi.org/10.1080/16073606.1993.9631741.

Elliot Glazer, Ege Erdil, Tamay Besiroglu, Diego Chicharro, Evan Chen, Alex Gunning,
  Caroline Falkman Olsson, Jean-Stanislas Denain, Anson Ho, Emily de Oliveira Santos,
  Olli Järviniemi, Matthew Barnett, Robert Sandler, Matej Vrzala, Jaime Sevilla, Qiuyu
  Ren, Elizabeth Pratt, Lionel Levine, Grant Barkley, Natalie Stewart, Bogdan Grechuk,
  Tetiana Grechuk, Shreepranav Varma Enugandla, and Mark Wildon. FrontierMath: A
  Benchmark for Evaluating Advanced Mathematical Reasoning in AI, 2024. URL https:
  //arxiv.org/abs/2411.04872.

Robin Hartshorne. Varieties of small codimension in projective space. Bulletin of the
 American Mathematical Society, 80(6):1017–1032, November 1974.
Dan Hendrycks, Collin Burns, Saurav Kadavath, Akul Arora, Steven Basart, Eric Tang,
 Dawn Song, and Jacob Steinhardt. Measuring mathematical problem solving with the
 math dataset. In Thirty-fifth Conference on Neural Information Processing Systems
 Datasets and Benchmarks Track, 2021.
Thomas Hubert, Rishi Mehta, Laurent Sartran, Miklós Z. Horváth, Goran Žužić, Eric
 Wieser, Aja Huang, Julian Schrittwieser, Yannick Schroecker, Hussain Masoom, Ot-
  tavia Bertolli, Tom Zahavy, Amol Mandhane, Jessica Yung, Iuliya Beloshapka, Borja
  Ibarz, Vivek Veeriah, Lei Yu, Oliver Nash, Paul Lezeau, Salvatore Mercuri, Calle Sönne,
  Bhavik Mehta, Alex Davies, Daniel Zheng, Fabian Pedregosa, Yin Li, Ingrid von Glehn,
  Mark Rowland, Samuel Albanie, Ameya Velingker, Simon Schmitt, Edward Lockhart,
  Edward Hughes, Henryk Michalewski, Nicolas Sonnerat, Demis Hassabis, Pushmeet
  Kohli, and David Silver. Olympiad-level formal mathematical reasoning with reinforce-
  ment learning. Nature, 651:607–613, 2025. doi: 10.1038/s41586-025-09833-y. URL
  https://doi.org/10.1038/s41586-025-09833-y.

IQOQI Vienna and Reinhard Werner. Open Quantum Problems, 2017. URL https://
  oqp.iqoqi.oeaw.ac.at/open-quantum-problems. Maintained by IQOQI Vienna since 2017.
  Accessed: 2026-03-24.
Jiedong Jiang, Wanyi He, Yuefeng Wang, Guoxiong Gao, Yongle Hu, Jingting Wang, Nailin
  Guan, Peihao Wu, Chunbo Dai, Liang Xiao, et al. Fate: A formal benchmark series for
  frontier algebra of multiple diﬀiculty levels. arXiv preprint arXiv:2511.02872, 2025.
E. I. Khukhro and V. D. Mazurov. Unsolved Problems in Group Theory. The Kourovka
  Notebook, 2026. URL https://arxiv.org/abs/1401.0300v41. 21st edition. First published
  in 1965; continuously updated on arXiv since 2014.
Austin Letson, Leopoldo Sarra, Auguste Poiroux, Oliver Dressler, Paul Lezeau, Dhyan
 Aranha, Frederick Pu, Aaron Hill, Miguel Corredera Hidalgo, Julian Berman, George
 Tsoukalas, and Lenny Taelman. SorryDB: Can AI Provers Complete Real-World Lean
 Theorems?, 2026. URL https://arxiv.org/abs/2603.02668.


                                           11
Yong Lin, Shange Tang, Bohan Lyu, Ziran Yang, Jui-Hui Chung, Haoyu Zhao, Lai Jiang, Yi-
  han Geng, Jiawei Ge, Jingruo Sun, et al. Goedel-prover-v2: Scaling formal theorem prov-
  ing with scaffolded data synthesis and self-correction. arXiv preprint arXiv:2508.03613,
  2025.
Junqi Liu, Zihao Zhou, Zekai Zhu, Marco Dos Santos, Weikun He, Jiawei Liu, Ran Wang,
  Yunzhou Xie, Junqiao Zhao, Qiufeng Wang, et al. Numina-lean-agent: An open and gen-
  eral agentic reasoning system for formal mathematics. arXiv preprint arXiv:2601.14027,
  2026.
Leonardo de Moura and Sebastian Ullrich. The lean 4 theorem prover and programming
  language. In International Conference on Automated Deduction, pages 625–635. Springer,
  2021.
The mathlib Community. The Lean Mathematical Library. In Proceedings of the 9th ACM
 SIGPLAN International Conference on Certified Programs and Proofs, CPP 2020, New
  Orleans, LA, USA, January 2020. ACM. doi: 10.1145/3372885.3373824. URL https:
 //doi.org/10.1145/3372885.3373824.

George Tsoukalas, Jasper Lee, John Jennings, Jimmy Xin, Michelle Ding, Michael Jennings,
 Amitayush Thakur, and Swarat Chaudhuri. PutnamBench: Evaluating Neural Theorem-
 Provers on the Putnam Mathematical Competition, 2024. URL https://arxiv.org/abs/
 2407.11214.

Zhouliang Yu, Ruotian Peng, Keyi Ding, Yizhe Li, Zhongyuan Peng, Minghao Liu, Yifan
  Zhang, Zheng Yuan, Huajian Xin, Wenhao Huang, et al. Formalmath: Benchmarking
  formal mathematical reasoning of large language models. arXiv preprint arXiv:2505.02735,
  2025.
Kunhao Zheng, Jesse Michael Han, and Stanislas Polu. MiniF2F: a cross-system benchmark
 for formal Olympiad-level mathematics. arXiv preprint arXiv:2109.00110, 2021.




                                           12
Supplementary Material

Here, we include various supplementary details.


A     Formal Conjectures Details

A.1   Source and AMS Classification Tables

Note that a single source problem typically gives rise to multiple formal statements due
to variants (e.g., special cases, generalizations, solved sub-problems, and test lemmas). We
explicitly allow and encourage the inclusion of multiple alternative formalizations for a single
informal claim to capture different mathematical perspectives or resolutions of ambiguity;
thus, the counts in this table reflect formal statements, not distinct source problems.

Table 3: Number of formal statements by source collection, split by category. A single
source problem may yield multiple statements (variants, special cases, tests).

 Source Collection             Total    Research Open        Research Solved        All Other
 Erdős Problems                 1318                   551                   551            216
 Wikipedia                       476                   208                   113            155
 Green’s Open Problems           175                    83                    73             19
 Papers                          131                    65                    25             41
 Open Quantum Problems           125                    35                    13             77
 Written on the Wall II          110                    13                    12             85
 OEIS                            105                    22                     6             77
 arXiv                            56                    13                    13             30
 MathOverflow                     53                    12                     9             32
 All other sources                66                    27                    21             18
 Total                          2615                 1029                    836           750

Table 4 shows the distribution of statements across AMS subject classifications. Other
notable areas beyond number theory and combinatorics include quantum theory, linear
algebra, and algebraic geometry.

Table 4: Top 10 AMS subject classifications by number of statements in Formal Conjectures.

               AMS Subject Classification                         Statements
               Number theory                                               1545
               Combinatorics                                                923
               Quantum theory                                               174
               Linear and multilinear algebra; matrix theory                140
               Information and communication, circuits                       96
               Convex and discrete geometry                                  93
               Algebraic geometry                                            80
               Geometry                                                      56
               Field theory and polynomials                                  53
               Group theory and generalizations                              42


A.2   The answer(sorry) Mechanism in Detail

Problems requiring a solution are formalized using answer( ), a custom Lean term elaborator.
Concretely, a problem like “What is the smallest n such that P (n)?” is formalized as:

theorem smallest_n : IsLeast {n : ℕ | P n} answer(sorry) := by
  sorry


                                              13
As usual, sorry is a placeholder which must be filled in order to claim that a problem
is solved, but now there are two of them. If the solution is known, then answer(sorry)
is replaced in the statement with answer(42). This mechanism allows our statements to
include computational conjectures where discovering the answer is the primary challenge
and verification is routine.
Crucially, while providing a proof simply requires finding any way to replace := sorry with
a valid term, providing an answer is a fundamentally different task: it requires evaluating
mathematical meaning to determine the correct value. Lean’s type checker can verify that
a proposed answer leads to a valid proof, but it cannot judge whether the answer itself is
mathematically meaningful—that remains a job for human mathematicians or AI systems
with genuine mathematical reasoning capabilities.
There are a number of advantages to using the answer( ) wrapper over directly writing a
solution or a bare sorry placeholder:

      • It makes clear which part of the formalization corresponds to the solution; this allows
        the solution to be masked from research solved statements in order to evaluate
        agents. This can either be done by inspecting the metadata inserted in the Lean
        term, or more pragmatically, by a simple regex replacement.
      • It provides some protection against Lean’s flexible elaboration; a problem stated as
        1 / 2 * 2 = sorry could be solved by replacing the sorry with either (0 : ℕ) or (1
        : ℚ), as by default, Lean only infers the type of an equality after analyzing both
        sides. This is clearly undesirable; we do not want the meaning of our questions to
        change depending on the answer provided! Stating the problem instead as 1 / 2 *
        2 = answer(sorry) protects against this, as the answer elaborator postpones analysis
        which forces Lean to decide the type of the equality before seeing the solution.
      • It forces the statement to be written in such a way that does not pre-assume what
        the solution is.

A.2.1 Propositional Solutions
A particularly common use case arises when the truth value of a proposition P is itself
unknown, i.e. when the problem can be phrased as a question: ”Is it true that...”. In this
case, answer(sorry) serves as a propositional placeholder that should be replaced with either
True or False:

theorem is_P_true : answer(sorry) ↔ P := by
  sorry

Replacing answer(sorry) with True amounts to conjecturing that P holds (and the solver
must prove P ), while replacing it with False amounts to conjecturing that P fails (and the
solver must disprove P ). This pattern is widely used throughout the repository for open
problems where even the expected truth value is uncertain.
For the convenience of evaluating solver systems that are capable of filling proofs only, when
answer(sorry) is detected to be used propositionally in this way, it elaborates to True under
its default settings. This permits these systems to decide the proposition by either proving
or disproving the statement, rather than by filling the placeholder.

A.3    The “for Mathlib” Pattern

It is typical when undertaking formalization projects to discover missing (and often trivial)
results that seem suitable for Mathlib. Contributing these results to Mathlib is of course
the natural resolution, but this has a number of downsides:

      • New conjectures that depend on these results find themselves at the end of a long
        dependency chain; the missing results must undergo Mathlib review, the merged
        change must land in a monthly Mathlib release, and the Formal Conjectures repos-
        itory must be upgraded to that release


                                              14
      • Some results may be too specialized for Mathlib, and a Mathlib contribution would
        require generalizing these immediately.
      • When the results entail a whole new mathematical development, it may take time for
        the Mathlib community to find the right abstractions and evolve said development
        into the right shape. Bypassing the dependency chain mentioned above allows much
        of this evolution to happen more rapidly outside of Mathlib.
The Lean community has widely adopted the pattern of creating a ForMathlib direc-
tory as a staging ground for such results, the oldest example of which being the
for_mathlib directory in the “liquid tensor experiment”5 . The formal-conjectures project’s
FormalConjecturesForMathlib directory follows this pattern, and contains 88 files with re-
sults such as natural and logarithmic density of sets of natural numbers (with proofs of basic
properties like monotonicity and the density of even numbers), arithmetic progressions and
AP-free sets, hypergraph Ramsey numbers, Turing machines and busy beaver halting num-
bers, perfect powers with a decidability instance, VC dimension in abelian groups, Latin
squares and transversals, and a library of graph invariants including the Wiener and Szeged
indices, the Lovász theta function, and the Havel–Hakimi residue. Over time, these results
are asynchronously contributed upstream to Mathlib.

A.4    Misformalization Taxonomy
Misformalizations can be categorized roughly as follows, with the level shown in parenthe-
ses.6
      • Syntactic (1): where the formalizer misses a subtlety in the way Lean parses a
        piece of syntax. For example, this could be missing brackets changing the meaning
        of an expression in unexpected ways; see PR #1338.
      • Semantic (1): where the formalizer misses a subtlety in the way that Lean repre-
        sents types or operators. For example, the natural numbers in Lean contain 0 and
        have truncated subtraction; see PRs #349, #1259, #1262.
      • Misrepresentation (1): where the formalizer formally misrepresents aspects of
        the informal statement during translation. For example, the use of incorrect quan-
        tifiers, the use of incorrect logical connectives, or the failure to include hypotheses
        which are present in the source text; see PRs #1164, #1156.
      • Implicit conventions (2): where the source text assumes domain expertise and
        does not explicitly include certain hypotheses or conventions. For example, in ana-
        lytic number theory, questions about the magnitude of a set of numbers are often
        implicitly asymptotic; see PRs #2136, #1151.
      • Reporting (3): where the statement changes in the literature through repetition,
        usually as the result of typos; see Erdős Problem 918 discussion.
      • Mathematical (3): where the source text is clearly not as intended or contains
        genuine mathematical errors; see Erdős Problem 728 discussion.

           Table 5: Number and proportion of misformalizations across categories.
           Level              Category                     Number of misformalizations
                              Syntactic                            9 (3.09%)
           Translation        Semantic                                     103 (35.40%)
                              Misrepresentation                            140 (48.11%)
           Underspecified     Implicit conventions                          23 (7.90%)
                              Reporting                                     15 (5.15%)
           Source
                              Mathematical                                  1 (0.34%)
  5 https://github.com/leanprover-community/lean-liquid
  6 Pull   request   (PR)   numbers   refer   to   the   repository   at    https://github.com/google-deepmind/
formal-conjectures; Erdős Problem discussions are at https://www.erdosproblems.com.



                                                     15
A.5   Misformalization Examples
This section contains the misformalization examples, mentioned in Section 3.3.

A.5.1 Syntactical Errors
An example of a syntactical error involving the correction of misplaced parentheses is shown
in Figure 5.

  /-- Let $f(n)$ be the minimal integer $m$ such that $n$ is the sum of the
  $k$ smallest divisors of $m$ for some $k\geq 1$. Is it true that
  $\limsup f(n)/n=\infty$? -/
  @[category research open, AMS 11]
  theorem erdos_1054.parts.iii : (∃ (A : Set ℕ), A.HasDensity 1 ∧
-       atTop.limsup (fun n ↦ (f n : EReal) / n) = ⊤) ↔ answer(sorry) := by
+       atTop.limsup (fun n ↦ (f n : EReal) / n = ⊤)) ↔ answer(sorry) := by
  sorry

Figure 5: Code diff showing an example of a syntactical error, and the correction of paren-
theses.

A.5.2 Semantic Errors
Figures 6, 7 and 8 illustrate various semantic errors encountered during formalization.

  /-- `Polynomial.HasOddCoeffs f` means that all coefficients of
  `f : Polynomial ℤ` are odd. -/
  def Polynomial.HasOddCoeffs (f : Polynomial ℤ) : Prop :=
-   ∀ i : ℕ, Odd (f.coeff i)
+   ∀ i ∈ f.support, Odd (f.coeff i)

Figure 6: Code diff showing an example of a semantic error, with the fix requiring quantifi-
cation over the support of the polynomial.

  /-- A group `HasPolynomialGrowth` if there exists a finite generating set
    such that the growth function is bounded above by a polynomial. -/
  def HasPolynomialGrowth (G : Type*) [Group G] : Prop :=
    ∃ (S : Set G), Set.Finite S ∧ Subgroup.closure S = ⊤ ∧
      ∃ (C : ℝ) (d : ℕ), C > 0 ∧
-     ∀ n : ℕ, (GrowthFunction S n : ℝ) ≤ C * (n : ℝ) ^ d
+     ∀ n > 0, (GrowthFunction S n : ℝ) ≤ C * (n : ℝ) ^ d

Figure 7: Code diff showing an example of a semantic error, where the formalization had
failed to account for behavior at the natural number 0.




                                            16
+ /-- An exact covering of a group `G` is a finite collection of subgroups
+ `{H_1, ..., H_k}` and representative `{g_1, ..., g_k}` such that the
+ cosets `g_iH_i` are pairwise disjoint and their union covers `G`.
+
+ Note that this differs from `Partition (α := Subgroup G)` because the
+ covering condition there invokes `Subgroup.sup` which is subgroup generation
+ and thus stronger than union. This definition is easier to use in this
+ context than the alternative `Partition (α := Set G)`, which lacks
+ subgroup definitions such as `Subgroup.index`. -/
+ structure Group.ExactCovering (G : Type*) [Group G] (ι : Type*) [Fintype ι] where
+   parts : ι → Subgroup G
+   reps : ι → G
+   nonempty (i : ι) : (parts i : Set G).Nonempty
+   disjoint : (Set.univ (α := ι)).PairwiseDisjoint
+     fun (i : ι) ↦ reps i • (parts i : Set G)
+   covers : ⋃ i, reps i • (parts i : Set G) = Set.univ

  /--
  If `G` is a group then can there exist an exact covering of `G` by more than
  one cosets of different sizes? (i.e. each element is contained in exactly
  one of the cosets.)
  -/
  @[category research open, AMS 20]
  theorem erdos_274 (G : Type*) [Group G] (hG : 1 < ENat.card G) :
-     (∃ (P : Partition (⊤ : Subgroup G)),
-       1 < P.parts.ncard ∧
-       (∀ A ∈ P.parts, ∃ᵉ (s : G) (H : Subgroup G), s • (H : Set G) = A) ∧
-       P.parts.Pairwise fun A B ↦ #A ≠ #B) ↔ answer(sorry) := by
+     (∃ (ι : Type*) (_ : Fintype ι) (P : Group.ExactCovering G ι),
+       1 < Fintype.card ι ∧ (Set.range P.parts).Pairwise fun A B ↦ #A ≠ #B) ↔
+         answer(sorry) := by
  sorry

Figure 8: Code diff showing an example of a semantic error, where the formalization missed
the subtlety that Partition invokes sup for the covering condition, which means something
different for subgroups than for sets.




                                           17
A.5.3 Misrepresentation Errors
Figure 9 provides an example of a misrepresentation error where a hypothesis from the
informal text was omitted, and Figure 10 shows an error involving incorrect quantification.

  /--
- A (weak) Giuga number is a number $n$ such that
+ A (weak) Giuga number is a composite number $n$ such that
  $$\sum_{i=1}^{n - 1}i^{\varphi(n)} \equiv -1\pmod{n}$$.
  -/
  def IsWeakGiuga (n : ℕ) : Prop :=
-     2 ≤ n ∧ ¬ n.Prime ∧ n ∣ 1 + ∑ i ∈ Finset.Ioo 0 n, i ^ φ n
+     n.Composite ∧ n ∣ 1 + ∑ i ∈ Finset.Ioo 0 n, i ^ φ n

Figure 9: Code diff showing an example of a misrepresentation error, where the formalization
was missing a hypothesis that was present in the informal text.

  @[category research open, AMS 11]
  theorem erdos_944 :
-     (∀ k ≥ 4, ∀ r ≥ 1, ∃ (G : SimpleGraph V), G.IsErdos944 k r) ↔
-       answer(sorry) := by
+     (∀ k ≥ 4, ∀ r ≥ 1, ∃ (V : Type u) (G : SimpleGraph V), G.IsErdos944 k r) ↔
+       answer(sorry) := by
  sorry

Figure 10: Code diff showing an example of a misrepresentation error, where the vertex type
V was incorrectly quantified. In the old version V was a section variable and thus appeared
out of the scope of the existential quantifier.

A.5.4 Implicit Conventions
Examples of errors stemming from implicit conventions in the source material can be seen
in Figures 11 and 12.

  @[category research open, AMS 11]
  theorem erdos_510 :
      answer(sorry) ↔ ∃ (c : ℝ) (hc : 0 < c),
-       ∀ N > 0, ∀ (A : Finset ℕ), 0 ∉ A → #A = N →
+       ∀ᶠ N in atTop, ∀ (A : Finset ℕ), 0 ∉ A → #A = N →
        ∃ θ, ∑ n ∈ A, cos (n * θ) < -c * sqrt N := by
    sorry

Figure 11: Code diff showing an example of an implicit convention, where the source8
implicitly assumes that the inequality holds for suﬀiciently large N . This is a common
implicit convention across analytic number theory where one is typically interested in the
asymptotic behavior of functions or sequences of natural numbers.




  8 https://www.erdosproblems.com/510




                                              18
  @[category research open, AMS 5]
  theorem erdos_128 :
-     ((∀ (G' : G.Subgraph) [Fintype G'.verts] [Fintype G'.edgeSet],
-         letI n := Fintype.card V;
-         2 * G'.verts.toFinset.card ≥ n →
-         50 * G'.edgeSet.toFinset.card > n^2) → ¬ (G.CliqueFree 3))
+     ((∀ (V' : Set V),
+       2 * V'.ncard ≥ Fintype.card V →
+         50 * (G.induce V').edgeSet.ncard > Fintype.card V ^ 2) → ¬(G.CliqueFree 3))
    ↔ answer(sorry) := by
  sorry

Figure 12: Code diff showing an example of an implicit convention, where the source11
wrote “subgraph” rather than “induced subgraph”. The comments12 demonstrate that the
problem is trivial if one does not restrict to induced subgraphs, which is why we class this
as implicit convention. It might also be considered to be a reporting error since the original
paper explicitly writes “induced subgraph”, [Erdős, 1993, p. 344].


A.5.5 Reporting Errors
Figure 13 demonstrates a reporting error caused by ambiguities in the historical source
material regarding induced subgraphs.

  /-- Is there a graph with $\aleph_2$ vertices and chromatic number $\aleph_2$ such that every
  subgraph on $\aleph_1$ vertices has chromatic number $\leq\aleph_0$? -/
  -- Formalisation note: source material [ErHa68b] uses only induced subgraphs
  @[category research open, AMS 5]
  theorem erdos_918.parts.i :
      (∃ (V : Type u) (G : SimpleGraph V), #V = ℵ_ 2 ∧ G.chromaticCardinal = ℵ_ 2 ∧
-       ∀ (W : Set V) (_ : #W = ℵ₁), (G.induce W).chromaticCardinal = ℵ₀) ↔
+       ∀ (W : Set V) (_ : #W = ℵ₁), (G.induce W).chromaticCardinal ≤ ℵ₀) ↔
      answer(sorry) := by
    sorry

Figure 13: Code diff showing an example of a reporting error between an internal draft
formalization of the problem. This problem appears in Erdős and Hajnal [1968] and Erdős
[1969]. In the former citation the explicit use of ≤ ℵ0 is used, while this does not appear
in the latter citation. This ambiguity was only clarified post draft formalization with the
discovery of trivial solutions – in the (non-induced) subgraph case by the website comments14
and by AlphaProof in the induced subgraph case. Note also that Erdős and Hajnal [1968]
explicitly writes induced subgraph while Erdős [1969] and the website do not.



B     Experimental Evaluation Details

B.1   Frozen Subsets

The frozen subsets FC100SolvedSet1 and FC100OpenSet1 consist of 100 problems each, sampled
uniformly at random from statements in the research solved and research open categories,
respectively. They are defined by the files FormalConjectures/Subsets/FC100OpenSet1.lean
and FormalConjectures/Subsets/FC100SolvedSet1.lean in the repository, which import ex-
actly the corresponding theorem statements. These files are compiled as part of every
tagged release, ensuring that the problem sets remain well-defined and their statements
compile correctly across all supported Lean versions.
 11 https://www.erdosproblems.com/history/128
 12 https://www.erdosproblems.com/forum/thread/128
 14 https://www.erdosproblems.com/forum/thread/918




                                                     19
The subset names (e.g., FC100OpenSet1) are orthogonal to the repository’s release tags
(bench-vN -lean4.X .Y , see Section 4.1). When the bench version N stays the same and
only the Lean version changes (e.g., from bench-v1-lean4.27.0 to bench-v1-lean4.29.0),
the problem set is guaranteed to contain the same statements; the new tag only ensures
compilation against the updated Lean toolchain and Mathlib. When the bench version in-
crements (e.g., from bench-v1 to bench-v2), statements in an existing set may receive fixes
(e.g., corrected misformalizations) or category updates (e.g., an open problem reclassified as
solved), but the membership of the set remains stable: no problems are added or removed.
For full reproducibility, results should specify both the set name and the release tag, e.g.,
FC100SolvedSet1@bench-v1-lean4.27.0.

In the future, we plan to release additional sets (e.g., FC100SolvedSet2, FC500OpenSet1) that
may contain entirely different problems, enabling targeted evaluations at different scales or
diﬀiculty levels while preserving earlier sets.

B.2   Illustrative Evaluation Details

As noted in Section 4.2, our evaluations focus on demonstrating the benchmark’s utility
and its sensitivity to scaling. For all systems, a solution is correct if and only if the Lean 4
kernel accepts the proof term without relying on forbidden axioms.

AlphaProof Setup. We evaluated a slightly updated version of AlphaProof [Hubert et al.,
2025], with tree-search inference, without the test-time reinforcement learning loop. As
reported in Table 2, we distinguish between two compute configurations for AlphaProof to
demonstrate the benchmark’s sensitivity to search budget: 1k sims utilizes 1,000 simulations
and 2 attempts per problem (approximately 0.1 TPUh on v6e TPUs); and 16k sims and 2
attempts (approximately 1.6 TPUh on v6e TPUs).

DeepMind Prover Agent Setup. The DeepMind prover agent [DeepMind, 2026] results
were obtained using a development version of the method under active experimentation.
Based on current API pricing, this evaluation costs up to $100 per problem.

C     Extended Discussion
C.1   Future Work

We plan to continuously extend Formal Conjectures with new problems unblocked by newly
added Mathlib definitions or from community contributions. While our implementation
uses Lean 4, the methodology is language-agnostic and portable to systems like Isabelle
or Rocq should they develop comparable library support. We will also track future Lean
updates to maintain ecosystem compatibility. To better evaluate the diﬀiculty and impact
of conjectures, we plan to extend the metadata by recording when a conjecture was first
proposed. This objective metric will enable users to filter for long-standing open problems
versus contemporary questions. However, since diﬀiculty and importance are often subjec-
tive, we also propose an interactive interface where the community can share insights. Users
will be able to vote on a conjecture’s perceived diﬀiculty, its mathematical significance, and
their conviction regarding its truth value (e.g., True, False, or independent of ZFC).
Furthermore, references to the mathematical literature are currently handled inconsistently
across the repository, often requiring duplication in each file. We plan to improve this by
centralizing reference management in future iterations.
This vision is being integrated into an accompanying website15 for the repository. The
website already serves as a frontend for the benchmark, allowing users to explore the source
code, view LATEX-rendered docstrings, and search, sort, or filter conjectures. It also contains
metadata recording when a research open problem gets solved or when a research solved prob-
lem receives a formal proof; in the future, we plan to make these changes more prominently
visible.
 15 https://google-deepmind.github.io/formal-conjectures/




                                                   20
Moving forward, we plan to expand this platform into a collaborative hub with interactive
community features, including a public leaderboard to track successful AI-based solutions
and recognize groups taking on these problems.




                                           21
