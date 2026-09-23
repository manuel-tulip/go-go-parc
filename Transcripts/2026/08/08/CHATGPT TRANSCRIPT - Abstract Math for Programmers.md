# Abstract Math for Programmers

- URL: https://chatgpt.com/c/6a7618ed-62e4-83ea-86fb-050b69162fec
- Created: 2026-08-07T17:42:06.229Z

---

> [https://www.cmpnd.ai/blog/let-the-model-write-the-code.html](https://www.cmpnd.ai/blog/let-the-model-write-the-code.html)
>
> Analyze this setup and dspy and self evolving code and self-optimizing harnesses from a category theory point of view, from a dependent types and formal proof point of view, and from a homotopy type theory as well, to see how we can best model this new way of "evolving" code with LLMs as judges, which is maybe slightly different from traditional genetic programming.
>
> Write a textbook for programmers that are intesresting in abstract maths and how it helps formalize and conceptualize and decompose software, that introduces the different concepts nad has copious sources and references and exercise to gain familiarity with the concepts.
>
> As markdown and PDF

<details><summary>💭 Thinking</summary>

**Assessing the textbook request**

I’m planning to research the linked article and relevant mathematical foundations, distinguish the approach from genetic programming, and produce a programmer-friendly textbook with references and exercises in Markdown and PDF.

**Assessed the textbook request**

</details>

I’ll reconstruct the CMPND/DSPy architecture and related evolutionary optimizers, then develop categorical, dependent-type/proof-theoretic, and homotopical models into a programmer-focused textbook with exercises, references, Markdown, and PDF.

```unknown
bash -lc cat /home/oai/skills/pdfs/SKILL.md
```

<details><summary>💭 Thinking</summary>

**Read PDF creation requirements**

</details>

```json
{"open":[{"ref_id":"https://www.cmpnd.ai/blog/let-the-model-write-the-code.html"}],"response_length":"long"}
```

<details><summary>💭 Thinking</summary>

**Planning the research**

I’m outlining a substantial, programmer-friendly textbook covering category theory, dependent types, formal proof, HoTT, synthesis, and evolutionary methods, with Lean examples, references, and exercises.

**Planned the research**

</details>

```json
{"open":[{"ref_id":"turn951688view0","lineno":146},{"ref_id":"turn449087search4"},{"ref_id":"turn449087search24"},{"ref_id":"turn449087search2"},{"ref_id":"turn449087search7"},{"ref_id":"turn449087search27"}],"response_length":"long"}
```

<details><summary>💭 Thinking</summary>

**Shaping the framework**

I’m organizing the theory around typed wiring diagrams, operadic substitution, learner-style feedback, dependent specifications, effects, and synthesis–verification games. I’ll present speculative connections cautiously, distinguishing established mathematics from proposed modeling choices.

**Shaped the framework**

**Formalizing safe evolution**

I’m defining a graded categorical intermediate representation, probabilistic candidate generation, verification predicates, Pareto archives, and certified harnesses. I’m also emphasizing promotion gates, provenance, held-out evaluation, bounded effects, and controlled recompilation over unrestricted self-modification.

**Formalized safe evolution**

</details>

The organizing distinction is that Flex searches a dependent space including program structure, routing, deterministic logic, model calls, effects, and traces while preserving a typed external interface.

<details><summary>💭 Thinking</summary>

**Searched 1 website**

</details>

```json
{"search_query":[{"q":"site:arxiv.org DSPy Compiling Declarative Language Model Calls into Self-Improving Pipelines arxiv"},{"q":"site:arxiv.org TextGrad Automatic Differentiation via Text arxiv"},{"q":"site:arxiv.org Self-Taught Optimizer STOP recursively self-improving code generation arxiv"},{"q":"site:nature.com FunSearch mathematical discoveries large language models program search"}],"response_length":"long"}
```

<details><summary>💭 Thinking</summary>

**Synthesizing the textbook**

I’m integrating the reported DSPy/Flex architecture, GEPA’s reflective Pareto search, and Meta-Harness ideas into a mathematically careful textbook, separating established theory from proposed abstractions and empirical claims.

**Building references**

I’m grounding the textbook in DSPy/Flex, GEPA, recursive models, program synthesis, evolutionary search, category theory, dependent types, formal verification, and HoTT, while preserving careful distinctions between empirical reports and formal results.

**Synthesized textbook content and built references**

</details>

```json
{"search_query":[{"q":"site:people.csail.mit.edu asolar sketch CEGIS counterexample guided inductive synthesis paper"},{"q":"Counterexample-guided inductive synthesis Solar-Lezama paper CEGIS official PDF"},{"q":"Dijkstra monads for free POPL 2013 official paper"},{"q":"Program synthesis from polymorphic refinement types PLDI 2016 official paper"}],"response_length":"long"}
```

<details><summary>💭 Thinking</summary>

**Searched 10 websites**

</details>

```unknown
bash -lc which pandoc && pandoc --version | head -2 && which xelatex && xelatex --version | head -2 && which pdftoppm && python /home/oai/skills/pdfs/scripts/md_to_pdf.py --help | head -40
```

<details><summary>💭 Thinking</summary>

**Checked LaTeX document tools and available TeX Gyre Pagella fonts**

</details>

```json
{"search_query":[{"q":"AlphaEvolve coding agent scientific algorithmic discovery arXiv official"},{"q":"MIPROv2 DSPy paper arXiv official Bayesian prompt optimization"},{"q":"Promptbreeder self-referential self-improvement prompt evolution arXiv official"},{"q":"OPRO Optimization by PROmpting Large Language Models as Optimizers official paper"}],"response_length":"long"}
```

<details><summary>💭 Thinking</summary>

**Searched 24 websites**

</details>

```unknown
bash -lc mkdir -p /mnt/data/evolving_code_book && cat > /mnt/data/evolving_code_book/evolving-programs-with-language-models.md <<'EOF'
---
title: "Evolving Programs with Language Models"
subtitle: "Category Theory, Dependent Types, Formal Proof, and Homotopy for Self-Optimizing Software"
author: "An independent technical textbook for programmers"
date: "August 2026"
lang: en-US
documentclass: book
classoption:
  - oneside
  - openany
papersize: letter
fontsize: 10pt
geometry:
  - margin=0.82in
  - headheight=14pt
mainfont: "Noto Serif"
sansfont: "Noto Sans"
monofont: "DejaVu Sans Mono"
colorlinks: true
linkcolor: NavyBlue
urlcolor: NavyBlue
citecolor: NavyBlue
toc: true
toc-depth: 2
numbersections: true
secnumdepth: 3
header-includes:
  - |
    \usepackage{microtype}
    \usepackage{booktabs}
    \usepackage{longtable}
    \usepackage{array}
    \usepackage{enumitem}
    \usepackage{xcolor}
    \usepackage{fancyhdr}
    \usepackage{listings}
    \usepackage{amsmath,amssymb,mathtools}
    \usepackage{tcolorbox}
    \definecolor{BookBlue}{HTML}{17365D}
    \definecolor{BookGray}{HTML}{F3F5F7}
    \definecolor{CodeGray}{HTML}{F7F7F7}
    \lstset{basicstyle=\ttfamily\footnotesize,breaklines=true,breakatwhitespace=false,columns=fullflexible,frame=single,backgroundcolor=\color{CodeGray},showstringspaces=false,keepspaces=true,upquote=true}
    \pagestyle{fancy}
    \fancyhf{}
    \fancyhead[L]{\small Evolving Programs with Language Models}
    \fancyhead[R]{\small \leftmark}
    \fancyfoot[C]{\thepage}
    \setlength{\parskip}{0.35em}
    \setlength{\parindent}{1.2em}
    \setlist{nosep,leftmargin=*}
    \newtcolorbox{keyidea}{colback=BookGray,colframe=BookBlue,title=Key idea,breakable}
    \newtcolorbox{warningbox}{colback=white,colframe=black!65,title=Caution,breakable}
    \newtcolorbox{definitionbox}{colback=white,colframe=BookBlue,title=Definition,breakable}
    \newtcolorbox{engineeringbox}{colback=BookGray,colframe=black!65,title=Engineering rule,breakable}
---

\frontmatter

# Preface {-}

Software has entered a regime in which a model can inspect a program, read execution traces, receive textual criticism, rewrite the source, and submit the result to an evaluator. The evaluator may include tests, static checks, proof checkers, performance counters, human ratings, or another language model. An outer loop keeps useful candidates and asks for further revisions.

This looks evolutionary, but it is not simply the genetic programming of the 1990s with a larger mutation operator. The proposed edits are conditioned on language, source code, failure traces, and an enormous body of learned programming knowledge. The object being optimized may include prompts, code, tool policies, memory layouts, routing logic, and the boundary between deterministic computation and model calls. Selection can be multi-objective. The judge can itself be learned and fallible. The resulting system is best understood as a hybrid of evolutionary search, program synthesis, program repair, counterexample-guided refinement, online experimentation, and software architecture search.

The immediate motivation for this book is DSPy's experimental `Flex` module and its use with GEPA. In the setup described by Michael Isaac in August 2026, a `Flex` module exposes its source code as the optimizable parameter. GEPA can replace the whole implementation, including its decomposition, control flow, helper functions, and internal predictor calls. Candidate code executes in a sandbox, declared output types are checked at the boundary, and failed candidates receive failure scores rather than terminating the search. The public case study reports that optimization discovered a deterministic routing layer that avoided most model calls on easy examples, reserving a model for ambiguous cases. These are reported experimental results, not general guarantees, and the interface is explicitly marked experimental in the DSPy documentation.

The goal here is not to promote one library. It is to build a durable mathematical vocabulary for this class of systems. Three bodies of mathematics are especially useful:

1. **Category theory** explains composition, interfaces, effects, routing, resource accounting, feedback, recursion, and architecture-preserving rewrites.
2. **Dependent type theory and formal proof** separate admissibility from empirical quality, package code with machine-checkable evidence, and clarify exactly where an LLM judge is not a verifier.
3. **Homotopy type theory** supplies a language for equivalence, transport across refactorings, coherent families of rewrites, and the difference between preserving rich traces and collapsing them to scalar scores. It also exposes an important mismatch: ordinary identity paths are reversible, while optimization steps are directed. Directed type theory and enriched categories are therefore needed alongside HoTT.

The book is written for programmers who are comfortable with functions, types, tests, and ordinary software architecture. It assumes no prior category theory, proof assistant experience, or algebraic topology. Each chapter introduces the mathematics through code, derives a model of reflective program evolution, and ends with exercises. Exercises labeled **Code** ask for an implementation, **Proof** ask for a mathematical argument, **Design** ask for an architecture, and **Research** ask for an open-ended investigation.

## The thesis in one page {-}

Let $X$ be an input type and $Y$ an output type. A practical model harness is rarely a pure function $X \to Y$. It may call a language model, access tools, consume money and time, fail, log traces, and sample nondeterministically. We therefore model a harness as an effectful morphism

\[
    h : X \longrightarrow T_r(Y \times \mathrm{Trace}),
\]

where $T_r$ describes computational effects and $r$ is a resource grade such as model calls, tokens, latency, money, or capabilities.

A candidate is not merely source code. It is a package

\[
  \mathrm{Candidate}(C)
  \;=\;
  \sum_{h:\mathrm{Harness}(X,Y)}
  \mathrm{Admissible}_C(h),
\]

where $C$ is a contract and $\mathrm{Admissible}_C(h)$ contains evidence for interface conformance, sandbox policy, capability restrictions, resource bounds, and any proved functional properties. Soft quality measures are kept outside this proof package:

\[
  \mathrm{score}(h) \in \mathbb{R}^k.
\]

The optimizer maintains an archive $A$ of candidates, often an antichain under Pareto dominance. Evaluation produces not only scores but traces, counterexamples, proof failures, and textual feedback. A learned proposer defines a conditional mutation kernel

\[
  Q(h' \mid h,\; \tau,\; f,\; A),
\]

where $\tau$ is execution evidence and $f$ is feedback. One optimization step is a stochastic transition on optimizer state:

\[
  E : S \longrightarrow \mathcal{D}(O \times S),
\]

which is a coalgebra for the endofunctor $F(Z)=\mathcal{D}(O\times Z)$. Here $\mathcal{D}$ denotes a probability-distribution construction and $O$ records observations.

Program execution composes horizontally. Program versions evolve vertically. A rewrite is best represented by a square in a double category or by a 2-cell in a bicategory: it connects an old implementation to a new one and carries evidence that interfaces and hard invariants commute with the change. This is more informative than treating source strings as points in an unstructured search space.

At the HoTT level, implementations satisfying a contract form a type $\mathrm{Impl}(C)$. Equivalent implementations may be connected by paths, and higher paths express coherence between alternative refactoring sequences. Univalence permits properties to be transported across equivalences of representations. But an improvement relation $h \preceq h'$ is normally not invertible. HoTT therefore models semantic identity and equivalence, while directed type theory, preorder enrichment, or refinement categories model progress.

The practical conclusion is direct:

> Use models to propose semantic program transformations. Use types, capability systems, sandboxes, deterministic tests, solvers, and proof checkers to define the admissible region. Use calibrated statistical and human evaluation for the remaining soft objectives. Preserve traces and provenance. Select with explicit multi-objective policies. Never confuse a favorable judge score with a proof.

## Reading paths {-}

**The working engineer** can read Chapters 1-3, 5-8, 13-16, and 22-27.

**The category-theory reader** can read Chapters 4-12 and then 22.

**The formal-methods reader** can read Chapters 13-17 and the Lean appendix.

**The HoTT reader** can read Chapters 18-21 after Chapters 4 and 13.

**The researcher** should read the whole book, especially the explicit failure modes and open problems in Chapters 24 and 28.

## Notation {-}

| Notation | Meaning |
|---|---|
| $X,Y,Z$ | Types or schemas |
| $\mathcal{C}$ | A category |
| $f:X\to Y$ | A morphism or function |
| $T$ | An effect monad or related effect construction |
| $T_r$ | An effect indexed by resource grade $r$ |
| $\mathcal{D}(X)$ | Probability distributions or Markov kernels over $X$ |
| $\sum_{x:A}B(x)$ | Dependent sum: a value and evidence depending on it |
| $\prod_{x:A}B(x)$ | Dependent function: for each $x$, a value in $B(x)$ |
| $a =_A b$ | Identity type, interpreted homotopically as paths |
| $A \simeq B$ | Equivalence of types |
| $h \preceq h'$ | Directed refinement or no-worse relation |
| $\tau$ | Execution trace |
| $A$ | Candidate archive |
| $Q$ | Learned proposal or mutation kernel |
| $V$ | Verifier/evaluator |
| $J$ | Judge, often noisy or learned |

\mainmatter

# From Prompt Tuning to Program Evolution

## 1.1 The object being optimized has changed

Early prompt optimization treats an LM call as a fixed component with a tunable string. A program might have several such calls, but its graph, control flow, and tool topology remain fixed. The optimizer selects demonstrations, edits instructions, or tunes decoding parameters. DSPy's original contribution was to make those components declarative: programmers specify signatures and compose modules, while a compiler-like optimizer searches for prompts and examples that improve a metric.

A code-optimizing module changes the search boundary. The optimizer can decide:

- how many model calls to make;
- which subproblems receive separate predictors;
- which cases can be handled by deterministic code;
- which information to compute before a model call;
- which tools to expose and when to call them;
- how to route easy and hard cases;
- what state or memory to retain;
- how to recover from errors;
- which prompt each internal component receives.

The optimized artifact is consequently an architecture, not merely a string.

This shift is visible in `dspy.Flex`. Its baseline behaves like a simple prediction module, or like an RLM when tools are available. Its optimizable parameter is a source string representing a complete module. During GEPA compilation, a code proposer receives the signature, current source, allowed primitives, tools, failing examples, outputs, and metric feedback. It returns a revised module class. Candidate parse failures and runtime failures are mapped to failure scores. The source executes in a sandbox, with predictor and tool calls bridged to the host.

The important abstraction is not "an LLM writes Python." It is:

\[
  \text{specification} + \text{evidence} + \text{proposal model}
  \longrightarrow
  \text{new implementation candidate}.
\]

The candidate is admitted or rejected by a collection of boundaries. Some boundaries are syntactic and typed. Some are logical. Some are statistical. Some are economic. Some are social.

## 1.2 A minimal reflective evolution loop

The following pseudocode exposes the essential components.

```python
archive = {seed_candidate}
history = []

while budget.remaining():
    parent = select_parent(archive, history)
    evidence = evaluate(parent, training_cases)

    child_source = proposer.rewrite(
        source=parent.source,
        signature=contract.interface,
        traces=evidence.traces,
        counterexamples=evidence.counterexamples,
        feedback=evidence.feedback,
        archive=archive,
    )

    child = sandbox.build(child_source)
    if not hard_checks(child, contract):
        history.append(rejected(child, reason="inadmissible"))
        continue

    result = evaluate(child, validation_cases)
    archive = pareto_insert(archive, child, result.objectives)
    history.append(record(parent, child, evidence, result))
```

Five roles should remain conceptually distinct even when one model performs several of them:

1. **Executor**: runs the candidate on inputs.
2. **Observer**: records traces, resource use, and failures.
3. **Verifier**: checks hard, formally stated properties.
4. **Judge**: estimates soft or underspecified quality.
5. **Proposer**: generates a revision.

Collapsing these roles creates correlated failure. A model that proposes code and judges its own output may favor its own style, miss shared misconceptions, or exploit quirks in the rubric. A deterministic verifier can still be wrong because its specification is wrong, but it is auditable and repeatable in a way a stochastic judge is not.

## 1.3 What "self" means

The phrase *self-evolving code* can mislead. In most contemporary systems:

- the foundation model's weights do not change;
- the outer loop is hand-written and fixed;
- the objective and sandbox are externally supplied;
- the code artifact changes, not the substrate executing the optimizer;
- human operators decide whether a candidate is deployed.

A more exact phrase is **reflective program evolution**: a program-producing system receives evidence about candidate behavior and uses a learned code model to propose revised programs. Some systems also modify the proposer prompt, memory, or search policy, producing a limited form of meta-optimization. This is still not unrestricted recursive self-improvement.

The distinction matters for safety and for theory. If the optimizer cannot modify its verifier, capability policy, or promotion gate, those components form a trusted computing base. If it can modify them, the state space and proof obligations become substantially larger.

## 1.4 The four recurring transformations

The Flex location-conflation example illustrates four transformations that recur across reflective harness systems.

### Decomposition

A monolithic prediction is factored into parsing, feature computation, deterministic rules, and an ambiguity resolver. Mathematically, a morphism $h:X\to Y$ is replaced by a factorization

\[
  X \xrightarrow{f} Z \xrightarrow{g} Y.
\]

The intermediate type $Z$ makes latent structure explicit. Good decompositions expose independently testable invariants and reduce the entropy of later model calls.

### Method selection

A subproblem may be solved by plain code, a retrieval call, a symbolic solver, a small model, or a large model. The optimizer searches not only parameters but computational mechanisms. This resembles algorithm selection and mixture-of-experts routing, but the routes themselves are synthesized as source.

### Routing

Inputs are partitioned into cases. With a coproduct decomposition $X \cong X_e + X_h$, the harness has the form

\[
  [J(d),\; \ell] : X_e + X_h \longrightarrow T(Y),
\]

where $d$ is deterministic code embedded by $J$ and $\ell$ is an effectful model-backed branch. In ordinary Python this is an `if`; categorically it is a universal construction.

### Evolution

The architecture is revised in response to traces and feedback. A later candidate may introduce a new intermediate representation, merge two predictors, add a cache, or remove model calls. The mutation is semantic and context-conditioned rather than a random local edit.

## 1.5 Why scalar optimization is insufficient

Suppose a candidate is evaluated on accuracy, cost, latency, security risk, and interpretability:

\[
  s(h) = (a(h),-c(h),-\ell(h),-r(h),i(h)).
\]

A weighted sum hides tradeoffs and encodes a policy in coefficients that may be unstable. A Pareto archive instead retains candidates for which no other candidate is at least as good in every objective and strictly better in one. The archive can include a high-accuracy expensive harness, a near-accurate cheap harness, and a slower proof-producing harness.

A production decision still needs policy. Pareto optimality does not tell an organization which candidate to deploy. It prevents the search algorithm from discarding meaningful alternatives prematurely.

## 1.6 Exercises

1. **Concept.** List the mutable and immutable components in a code-optimizing harness you have used or can imagine. Which component is the trusted computing base?
2. **Code.** Implement the pseudocode loop with a proposer that performs rule-based source transformations rather than using an LLM. Record a complete history.
3. **Design.** Split a retrieval-augmented question-answering system into executor, observer, verifier, judge, and proposer. Identify every place where the same model is reused across roles.
4. **Proof.** Show that if $h=g\circ f$, and both $f$ and $g$ are total functions, then $h$ is total. Give a counterexample when effects include exceptions.
5. **Concept.** Explain why a source-code diff is not, by itself, evidence of semantic improvement.
6. **Design.** Define a five-dimensional score vector for a coding agent. State which dimensions are hard constraints and which are soft objectives.
7. **Research.** Compare the meanings of *self-improvement* in Promptbreeder, STOP, AlphaEvolve, Meta-Harness, and Flex. For each system, identify exactly what state is rewritten.
8. **Code.** Build a simple router that sends easy arithmetic expressions to a parser and hard natural-language questions to a model stub. Measure the model-call rate as the easy-case threshold changes.

# Anatomy of DSPy, GEPA, Flex, RLM, and Meta-Harness

## 2.1 DSPy as declarative LM programming

DSPy treats language-model applications as programs assembled from typed-ish signatures and modules. A signature such as

```python
"question: str -> answer: str"
```

states the input-output interface without fixing a prompt template. A module such as `Predict`, `ChainOfThought`, `ReAct`, or `RLM` supplies an execution pattern. An optimizer compiles the program against examples and a metric by selecting instructions, demonstrations, or other parameters.

This is usefully compared to traditional compilation, but the analogy has limits. A conventional compiler preserves semantics while improving representation or performance. A DSPy optimizer searches for an implementation whose *empirical behavior* scores well on a dataset. It may change behavior on unseen inputs. The word *compiler* describes an engineering interface, not a proof of semantic preservation.

The original DSPy paper models an LM pipeline as a graph of text transformations with declarative modules and optimizable parameters. MIPRO and MIPROv2 extend prompt and demonstration search. GEPA replaces low-bandwidth scalar optimization with reflective textual feedback and Pareto-based evolutionary selection. Flex then moves source code into the parameter space.

## 2.2 GEPA as reflective evolutionary search

GEPA stands for Genetic-Pareto. Its core loop can be described as follows:

1. Run a candidate system on a batch.
2. Collect system-level trajectories and metric feedback.
3. Ask a reflection model to diagnose failures and propose a mutation.
4. Evaluate the new candidate first on a small batch and, if promising, more broadly.
5. Retain candidates using a Pareto-based scheme that preserves per-instance strengths and diversity.

The GEPA paper emphasizes that natural-language reflection can carry richer information than a scalar reward. The proposition is plausible for program search: a message such as "the normalizer strips meaningful numeric branch identifiers" identifies a causal hypothesis and an edit target. A reward of $0.83$ does not.

Textual feedback is not a mathematical gradient. It does not necessarily satisfy linearity, a chain rule, local smoothness, or even consistency. It is better understood as a **semantic edit request** generated from evidence. Calling it a "text gradient" can be a productive metaphor, provided the missing calculus laws are not forgotten.

## 2.3 Flex as architecture search

A Flex source string defines a module with initialization and forward behavior. The optimizer may change internal predictors, instructions, control flow, helper functions, or the ratio of Python computation to model computation. The public documentation makes several design choices explicit:

- the whole module source is one optimization parameter;
- predictors created inside the module are owned by that source and not tuned independently;
- code reflection sees whole-program inputs, outputs, and metric feedback;
- parse and runtime failures are converted to failure scores;
- generated code runs in an interpreter rather than the host process;
- declared output types are parsed and enforced at the sandbox boundary;
- the saved state contains module source, while the interpreter remains a runtime dependency;
- the API is experimental.

This yields an important software-design pattern: **optimize an implementation behind a stable interface**. The interface is fixed enough to support substitution; the implementation is intentionally fluid.

A minimal usage shape is:

```python
program = dspy.Flex(TaskSignature, tools=allowed_tools)

optimizer = dspy.GEPA(
    metric=metric_with_feedback,
    reflection_lm=strong_code_model,
    max_metric_calls=budget,
)

optimized = optimizer.compile(
    program,
    trainset=train_examples,
    valset=validation_examples,
)
```

Because the interface and serialization format are experimental, production systems should pin a DSPy version and store the generated source, evaluation dataset hashes, model identifiers, tool versions, and interpreter configuration together.

## 2.4 RLM as programmable context access

A Recursive Language Model treats a long prompt as data in an external environment. Instead of placing the entire prompt in a single model context, the model writes or executes code that inspects portions, decomposes the problem, and recursively invokes a model on selected snippets.

Categorically, an RLM is not just recursion in the mathematical sense. It combines:

- an environment object containing data;
- an effect for reading selected regions;
- an effect for model invocation;
- recursive or iterative control;
- a trace of observations and subcalls.

Its type is closer to

\[
  X \times E \longrightarrow T_r(Y \times \mathrm{Trace})
\]

than to $X\to Y$. The environment $E$ is kept outside the token space and accessed through operations. This separation resembles the distinction between a store and a computation in programming-language semantics.

## 2.5 Meta-Harness and persistent search memory

Meta-Harness searches over harness code using an agentic proposer that can inspect the source, scores, and raw traces of prior candidates through a filesystem. The reported ablation is theoretically revealing: in its online text-classification experiment, access to full traces substantially outperformed interfaces containing only scores or scores plus summaries.

The result should not be universalized from one study, but it supports a general information principle:

\[
  \mathrm{Trace} \xrightarrow{\text{summary}} S
  \xrightarrow{\text{score}} \mathbb{R}
\]

is a sequence of many-to-one maps. Each map discards distinctions. A proposer can only condition on information that survives. Summaries may remove the exact anomaly needed to infer a repair. Scores remove almost everything except rank or magnitude.

A persistent filesystem also changes the optimizer from a memoryless kernel to a history-dependent process. If $H_t$ is the complete history, then

\[
  Q(h_{t+1}\mid h_t)
\]

is replaced by

\[
  Q(h_{t+1}\mid h_t,H_t).
\]

The history can include negative results, which are valuable only if the proposer can retrieve and interpret them.

## 2.6 The observed location-conflation transformation

The Flex case study begins with a single LM call that decides whether two place listings refer to the same physical location. The optimized code reportedly learns a pipeline with roughly this shape:

```text
raw records
    |
    v
normalize names and addresses
    |
    v
compute deterministic similarities and distance features
    |
    v
+--------------------+
| rule-based router  |
+--------------------+
   | easy        | ambiguous
   v             v
Boolean       focused LM judge
   |             |
   +------v------+
          |
       decision
```

The interesting move is not that the LLM wrote string-processing code. It is that optimization discovered a **partial evaluator**: deterministic computations settle cases for which the expensive stochastic component is unnecessary. The remaining model call receives a narrower, more structured problem.

In category-theoretic terms, the optimizer found a factorization through a feature object $Z$ and a coproduct-like decision boundary. In type-theoretic terms, it enriched the intermediate state with evidence. In information-theoretic terms, it transformed raw input into sufficient or approximately sufficient statistics for the remaining decision. In program-synthesis terms, it filled architectural holes using examples and counterexamples.

## 2.7 Limits of the setup

Several limitations must be explicit.

First, held-out accuracy does not prove correctness. A synthesized normalizer may exploit dataset-specific artifacts. Second, a sandbox limits capabilities but does not make semantic behavior safe. Third, typed JSON boundaries guarantee shape, not truth. Fourth, the same metric used repeatedly during search becomes a training signal and can be overfit. Fifth, an LLM judge may contain positional, verbosity, self-preference, and style biases. Sixth, code that calls a model remains nondeterministic even when the wrapper is deterministic. Seventh, cost measurements can shift with model pricing, caching, batching, and infrastructure.

The right response is not to abandon optimization. It is to stratify evidence and make each layer explicit.

## 2.8 Exercises

1. **Concept.** Draw the parameter boundary for `Predict`, MIPROv2, GEPA prompt optimization, and Flex code optimization.
2. **Code.** Create a DSPy signature and two hand-written modules with the same interface but different internal structures. Write a metric that exposes both score and textual feedback.
3. **Proof.** Explain why JSON schema validation establishes a proposition about representation but not a proposition about domain correctness.
4. **Design.** Specify the metadata needed to reproduce a Flex candidate one year later.
5. **Concept.** Give an example where a detailed trace enables a repair that no scalar score can identify.
6. **Code.** Implement a trace summarizer. Construct two distinct traces that map to the same summary but imply different fixes.
7. **Research.** Reproduce a small prompt-only versus code-plus-prompt optimization study. Use a meta-held-out test set that is never exposed during candidate selection.
8. **Design.** For an RLM-like system, identify the algebraic effects for context inspection, recursive calls, tools, exceptions, and logging.
9. **Concept.** Why is "compiler" an interface analogy rather than a semantic theorem in DSPy optimization?
10. **Proof.** If a summary map $q:T\to S$ is not injective, prove that no downstream function $g:S\to R$ can distinguish every pair of traces in $T$.

# Not Quite Genetic Programming

## 3.1 Classical genetic programming

Classical genetic programming (GP), associated especially with John Koza's work, represents programs as genomes, often syntax trees. A population is evaluated by a fitness function. Selection favors fitter programs. Mutation and crossover generate descendants. Repetition searches for executable structures that solve a task.

A simplified GP loop is:

```text
initialize population of syntax trees
repeat:
    evaluate fitness
    select parents
    apply mutation and crossover
    form next population
return best individual
```

GP contributed foundational ideas that remain directly relevant: executable genomes, syntax-aware variation, population diversity, bloat control, fitness shaping, multi-objective selection, and the danger of overfitting to test cases.

Reflective LLM-based code evolution inherits this skeleton. It evaluates executable candidates, selects parents, applies variation, and retains useful descendants. The difference lies in the variation operator, the evidence channel, the searched representation, and the role of learned judges.

## 3.2 Learned semantic mutation

In ordinary GP, mutation is intentionally generic: replace a subtree, perturb a constant, insert a node, or swap compatible fragments. It does not understand the task except through selection pressure.

An LLM proposer approximates a conditional distribution

\[
  Q(p'\mid p, D, \tau, f, L),
\]

where $p$ is source, $D$ is task data, $\tau$ is behavior, $f$ is criticism, and $L$ is learned prior knowledge. The prior includes programming idioms, algorithms, libraries, domain patterns, and natural-language concepts. A single proposal may perform a large coherent transformation: extract a parser, introduce a cache, replace brute force with dynamic programming, or add a verifier-backed branch.

Syntactically, that edit can be distant. Semantically, it can be local: it addresses one diagnosed failure while preserving the interface. Token edit distance is therefore a poor geometry for the search.

## 3.3 High-bandwidth feedback

A scalar fitness provides ordering but little causal structure. A trace and critique can identify:

- the input region where failure occurs;
- the internal call that introduced the error;
- a violated invariant;
- an unnecessary model invocation;
- a tool result that was ignored;
- a pattern shared across failures;
- a plausible architectural remedy.

This moves the system closer to program repair and CEGIS. In CEGIS, a synthesizer proposes a candidate and a verifier returns a counterexample. The counterexample refines the next synthesis problem. In reflective evolution, the verifier may be incomplete, the feedback may be linguistic, and the proposer may be stochastic, but the information flow is similar.

The closest conceptual formula is:

\[
  \text{evolutionary archive}
  + \text{learned program synthesizer}
  + \text{counterexample-rich feedback}
  + \text{multi-objective evaluation}.
\]

## 3.4 Genotype, phenotype, and trace

For a code candidate:

- the **genotype** is source, prompts, configuration, and perhaps persistent memory;
- the **phenotype** is observable behavior on an environment;
- the **developmental process** is interpretation, compilation, model sampling, and tool execution;
- the **fitness evidence** includes outputs, traces, costs, verifier results, and judge scores.

Unlike a fixed biological developmental process, the mapping from source to behavior can depend on mutable external models, APIs, tools, and data. The same genotype can produce a different phenotype after a model update. Reproducibility therefore requires versioned dependencies and recorded randomness.

The distinction also clarifies why saving only source is insufficient. The phenotype depends on the whole execution environment:

\[
  \mathrm{Behavior}
  =
  \mathrm{run}(\mathrm{source},\mathrm{model},\mathrm{tools},\mathrm{runtime},\mathrm{seed},\mathrm{input}).
\]

## 3.5 Crossover, merge, and recombination

LLM systems can recombine candidates without syntax-tree crossover. GEPA includes system-aware merging of complementary lessons. A proposer can inspect two programs and write a third that combines one candidate's router with another's prompt. This is semantic recombination.

However, semantic merge is difficult to reason about. Two individually valid optimizations may interact negatively. A cache key introduced by one candidate may omit a feature required by another. A proof of each component does not automatically prove the composition unless contracts line up.

Category theory makes this failure precise: composability requires matching objects and preservation of stated laws. Dependent types can encode those laws at boundaries. A merge operator should be judged not merely by textual plausibility but by whether it constructs a term in the target candidate type.

## 3.6 Quality diversity and niches

A single global best candidate encourages premature convergence. Pareto archives and quality-diversity methods preserve specialists. GEPA's per-instance Pareto selection keeps candidates that are strong on different examples. MAP-Elites preserves high-performing candidates in behaviorally defined cells.

For harness evolution, useful niche dimensions include:

- number of model calls;
- maximum context length;
- tool set;
- proof coverage;
- latency percentile;
- input-domain region;
- explanation format;
- memory footprint;
- failure-recovery strategy.

A niche archive can become an architecture library. A deployment controller may select a candidate based on current resource constraints rather than committing to one universal harness.

## 3.7 LLM judges introduce a moving fitness landscape

In classic GP, fitness can be noisy, but it is often generated by an explicit simulator or test suite. In LM systems, a judge may be another model. Its output can vary with prompt order, verbosity, stylistic similarity, model version, and adversarially crafted content.

Let the latent human-relevant quality be $q(h,x)$ and the judge output be

\[
  J(h,x;\omega)=q(h,x)+b(h,x)+\epsilon_{\omega},
\]

where $b$ is systematic bias and $\epsilon$ is stochastic noise. Optimization against $J$ can increase $b$ rather than $q$. This is a Goodhart effect: the proxy becomes a target.

A learned proposer may also know the judge's habits. The search can discover judge-specific exploits even without explicit malicious intent. Robust evaluation therefore uses hidden tests, deterministic checks, multiple judges, order randomization, calibration against humans, adversarial probes, and periodic objective renewal.

## 3.8 A taxonomy

| Dimension | Classical GP | Reflective LLM program evolution |
|---|---|---|
| Candidate | Usually AST/tree/program | Source, prompts, architecture, memory, tool policy |
| Mutation | Generic syntax variation | Learned semantic synthesis conditioned on evidence |
| Feedback | Mostly scalar fitness | Scores, traces, counterexamples, textual critique |
| Search prior | Grammar and operators | Pretrained code/language distribution plus constraints |
| Selection | Tournament, rank, elitism | Pareto, per-instance archive, best-of-N, agentic history use |
| Recombination | Tree or graph crossover | Model-mediated semantic merge |
| Evaluator | Tests/simulator/objective | Tests, proof tools, metrics, humans, LLM judges |
| Failure mode | Bloat, deception, overfit | Same, plus judge bias, prompt injection, tool abuse, model drift |
| Typical guarantee | Empirical fitness | Empirical fitness unless separate proof system is used |
| Closest neighboring field | Evolutionary computation | Program synthesis, repair, CEGIS, architecture search |

The best umbrella term is **reflective, language-mediated evolutionary program synthesis**. The phrase is long because the phenomenon is genuinely hybrid.

## 3.9 Exercises

1. **Concept.** For a Flex candidate, identify genotype, phenotype, environment, and fitness evidence.
2. **Proof.** Construct an example where two candidates have equal scalar fitness but different Pareto vectors.
3. **Code.** Implement subtree mutation for a tiny expression language. Compare it with a hand-written semantic mutation that uses a failing example.
4. **Design.** Define behavior dimensions for a MAP-Elites archive of retrieval harnesses.
5. **Concept.** Explain why model-mediated merge is not equivalent to syntax-tree crossover.
6. **Research.** Measure whether an LLM proposer produces syntactically larger but semantically more targeted changes than random AST mutation on a repair benchmark.
7. **Design.** Create an evaluation protocol that estimates positional bias in an LLM judge.
8. **Proof.** Let $J=q+b$. Show that maximizing $J$ need not maximize $q$, even when $J$ and $q$ are positively correlated on the initial population.
9. **Concept.** In what sense is reflective evolution Lamarckian, and in what sense is that analogy misleading?
10. **Code.** Build a replay tool that reconstructs candidate behavior from source, model identifier, tool versions, seed, and input. Deliberately omit one dependency and document the divergence.

# Mathematical Warm-Up: Types, Relations, Orders, and Evidence

## 4.1 Types are not merely sets

A programmer first meets a type as a collection of values accepted by an operation. Mathematics often begins with the same approximation: a type $X$ behaves like a set of possible values. A function $f:X\to Y$ assigns one output to every input.

This approximation is useful but incomplete for software. Types can also encode:

- how a value was constructed;
- what resources a computation may use;
- what proposition is known about a value;
- whether two values are definitionally or propositionally equal;
- how values vary with an index;
- whether a computation is total, partial, deterministic, or stochastic.

The progression in this book is:

```text
sets and functions
    -> categories and morphisms
    -> effectful computations
    -> dependent types and proofs
    -> identity types and homotopy
```

Each layer retains the earlier intuition but makes more structure explicit.

## 4.2 Relations and preorders

A binary relation $R\subseteq X\times X$ states when two values are related. We write $xRy$.

A **preorder** is a relation $\preceq$ that is:

- reflexive: $x\preceq x$;
- transitive: $x\preceq y$ and $y\preceq z$ imply $x\preceq z$.

It need not be antisymmetric. Two distinct source programs can be mutually no worse under all measured objectives. Quotienting by mutual comparison yields a partial order when the usual conditions hold.

For candidate score vectors, define Pareto dominance for objectives to be maximized:

\[
  u \succ v
  \quad\Longleftrightarrow\quad
  \bigl(\forall i,\; u_i\ge v_i\bigr)
  \land
  \bigl(\exists j,\;u_j>v_j\bigr).
\]

The nondominated set is an antichain: no two distinct members dominate one another.

## 4.3 Hard propositions and soft quantities

A central discipline of this book is to separate propositions from scores.

Examples of propositions:

- the source parses;
- every output conforms to a schema;
- no filesystem capability is available;
- every tool call is in an allowlist;
- the implementation preserves a specified invariant;
- worst-case model calls are at most three.

Examples of soft quantities:

- answer quality as estimated by humans;
- average latency;
- expected cost;
- style preference;
- benchmark accuracy;
- interpretability rating.

A proposition has evidence that can, in principle, be checked. A score supports comparison but does not inhabit a logical claim such as "correct for all inputs." Some statistical claims can be propositions once assumptions and confidence levels are made explicit, but they remain different from pointwise functional correctness.

## 4.4 Evidence as a first-class value

Suppose a normalizer returns a string and evidence that the result is uppercase:

\[
  \mathrm{normalize} : (s:\mathrm{String})
  \to
  \sum_{t:\mathrm{String}} \mathrm{IsUpper}(t).
\]

The output is a pair $(t,p)$, where $p$ is a proof or certificate. Downstream code can rely on the property without rerunning the normalizer's reasoning.

In ordinary Python, a runtime approximation is:

```python
from dataclasses import dataclass

@dataclass(frozen=True)
class UpperString:
    value: str

    def __post_init__(self) -> None:
        if self.value != self.value.upper():
            raise ValueError("not uppercase")
```

This constructor enforces an invariant dynamically. A dependent type system can express the invariant statically and retain the proof object.

## 4.5 Quotients and observational equivalence

Two programs can differ syntactically while being indistinguishable under a chosen observation. Let $O$ be a set of observations and let

\[
  \llbracket - \rrbracket : P \to O
\]

map programs to behavior. Define

\[
  p \sim q \quad\Longleftrightarrow\quad
  \llbracket p\rrbracket=\llbracket q\rrbracket.
\]

The quotient $P/{\sim}$ treats observationally equivalent programs as one semantic point.

In practice, observations are finite tests, so equivalence is approximate:

\[
  p \sim_D q
  \quad\Longleftrightarrow\quad
  \forall x\in D,\; p(x)=q(x).
\]

This relation may merge programs that differ outside $D$. Reflective optimization operates on such partial observational quotients unless a stronger verifier is present.

## 4.6 Resource monoids

Resources compose. If one stage costs $r$ and the next costs $s$, the pipeline costs approximately $r+s$. This suggests a commutative monoid $(R,+,0)$.

For multiple resources, take

\[
  R=\mathbb{R}_{\ge0}^{k}
\]

with componentwise addition. A grade might be

\[
  r=(\text{calls},\text{tokens},\text{dollars},\text{milliseconds}).
\]

Grades can represent upper bounds, exact symbolic costs, or expected values. Mixing those interpretations without labels is an error. A worst-case call bound composes differently from an empirical p95 latency estimate.

## 4.7 Exercises

1. **Proof.** Verify that componentwise $\le$ on $\mathbb{R}^k$ is a partial order.
2. **Code.** Implement Pareto insertion and test that the archive remains an antichain.
3. **Concept.** Classify ten properties of your current software system as propositions, measurements, or judgments.
4. **Proof.** Show that agreement on a finite dataset is an equivalence relation on deterministic programs.
5. **Concept.** Explain why finite-test equivalence is usually not a congruence under arbitrary program contexts.
6. **Code.** Implement a runtime evidence wrapper for a sorted list. Prevent construction through the public API unless the invariant holds.
7. **Design.** Define a resource monoid for an agent that uses an LM, a database, and a human escalation channel.
8. **Proof.** If resource grades are upper bounds and sequential composition adds them, show that replacing a stage by a lower-grade stage cannot increase the pipeline bound.
9. **Research.** Investigate whether the objectives in a real harness are commensurable enough for a weighted sum. Compare three weighting schemes with a Pareto archive.
10. **Concept.** Give one property that can be checked syntactically, one semantically, one statistically, and one only through human judgment.

EOF
```

Unlike genetic programming’s blind mutation, rewrites are semantic syntheses conditioned on traces and critique, with empirical Pareto selection. I’m separating stochastic optimization evidence from formal proof.

<details><summary>💭 Thinking</summary>

**Wrote Chapters 5–12 of a technical textbook on categorical software composition**

</details>

```unknown
bash -lc cat >> /mnt/data/evolving_code_book/evolving-programs-with-language-models.md <<'EOF'
# Propositions as Types and Programs as Proofs

## 13.1 Curry-Howard for working programmers

The Curry-Howard correspondence relates logic and type theory:

| Logic | Type theory | Programming intuition |
|---|---|---|
| proposition $P$ | type $P$ | specification |
| proof of $P$ | term $p:P$ | value satisfying the specification |
| implication $P\to Q$ | function type $P\to Q$ | transformer of evidence |
| conjunction $P\land Q$ | product $P\times Q$ | pair of proofs |
| disjunction $P\lor Q$ | sum $P+Q$ | tagged alternative |
| truth | unit type | trivial value |
| falsehood | empty type | impossible value |
| universal quantifier | dependent product | function returning evidence for each input |
| existential quantifier | dependent sum | witness packaged with evidence |

A proof checker is therefore a type checker for proof terms. This does not mean every production programming language makes all proofs explicit. It means types can be designed to carry logical content.

## 13.2 Dependent function types

A dependent function type

\[
  \prod_{x:A}B(x)
\]

contains functions that, for each $x:A$, produce a value in the type $B(x)$. The result type depends on the input value.

Universal correctness can be expressed as:

\[
  \prod_{x:X}\mathrm{Correct}(x,h(x)).
\]

A term of this type is a function that gives a proof for every input. The quantifier is computational: applying the proof to a particular $x$ yields evidence for that case.

In Lean-like notation:

```lean
-- Schematic, not tied to a particular domain library.
def CorrectHarness (h : X -> Y) : Prop :=
  forall x : X, Correct x (h x)
```

## 13.3 Dependent sum types

A dependent sum

\[
  \sum_{x:A}B(x)
\]

contains a witness $x:A$ paired with evidence $b:B(x)$. This is the type-theoretic existential.

A sorted vector package is:

\[
  \sum_{v:\mathrm{Vector}\;\mathbb{Z}\;n}\mathrm{Sorted}(v).
\]

A proof-carrying candidate is:

\[
  \sum_{h:\mathrm{Harness}(X,Y)}\mathrm{Admissible}_C(h).
\]

The evidence depends on the exact candidate. A proof that one source program obeys a capability policy cannot be silently attached to a different source hash.

## 13.4 Equality types

For $a,b:A$, the identity type

\[
  a=_A b
\]

contains evidence that $a$ and $b$ are equal. In intensional type theory, equality is not automatically reduced to an external Boolean comparison. Proofs can be constructed by reflexivity and transformed by induction.

Program equivalence is harder than value equality. One may seek:

\[
  h=_{{X\to Y}} h',
\]

but function equality often requires function extensionality:

\[
  \left(\prod_{x:X}h(x)=h'(x)\right)
  \to h=h'.
\]

For effectful or stochastic harnesses, the relevant equality may be equality of distributions, traces, or observations rather than definitional equality of code.

## 13.5 Inductive types and interpreters

A safe architecture language can be an inductive type:

```lean
inductive Harness : Type -> Type -> Type where
  | pure     : (X -> Y) -> Harness X Y
  | predict  : Signature X Y -> Harness X Y
  | compose  : Harness X Y -> Harness Y Z -> Harness X Z
  | route    : (X -> Either A B)
             -> Harness A Y -> Harness B Y -> Harness X Y
  | fallback : Harness X Y -> Harness X Y -> Harness X Y
```

Every architecture is built from approved constructors. An interpreter gives meaning:

```lean
def run : Harness X Y -> X -> Eff Y
```

Proofs proceed by induction on the architecture. For example, if every primitive respects a capability set and composition unions capabilities, one can prove a capability bound for every term.

## 13.6 Proof irrelevance and proof relevance

Some systems treat all proofs of the same proposition as interchangeable. For audit trails, evidence may be proof-relevant: two certificates can have different issuers, assumptions, costs, or derivations.

Distinguish:

- the proposition that a candidate passed a test suite;
- the detailed test report witnessing that proposition;
- the cryptographic identity of the artifact tested;
- the environment in which the test ran.

Erasing proof details can be safe for execution but unsafe for governance. A deployment artifact may retain hashes and provenance even when the runtime does not inspect the proof term.

## 13.7 Decidable propositions

A proposition $P$ is decidable when one can compute either evidence of $P$ or evidence of $\neg P$:

\[
  \mathrm{Decidable}(P)=P+\neg P.
\]

Examples include finite schema checks and bounded resource analyses. General semantic properties of arbitrary programs are not decidable. Rice's theorem and the halting problem prevent a universal checker for nontrivial behavior of unrestricted code.

This motivates restricted languages, bounded verification, proof-carrying annotations, and human review. The answer to undecidability is not "let the LLM decide." An LLM can suggest proofs or invariants, but the trusted checker must verify them in a decidable kernel.

## 13.8 Exercises

1. **Concept.** Translate implication, conjunction, disjunction, universal quantification, and existential quantification into programming constructs.
2. **Proof.** Construct a term of type $A\to(B\to A)$.
3. **Proof.** Construct functions in both directions between $A\times(B+C)$ and $(A\times B)+(A\times C)$.
4. **Code.** Encode a small harness AST as an algebraic data type and write a total interpreter.
5. **Design.** Define the dependent-sum fields of a proof-carrying deployment artifact.
6. **Concept.** Explain why a Boolean `passed=True` is weaker than a proof term tied to an artifact hash and assumptions.
7. **Proof.** Write the type of a function that returns a sorted permutation of its input list, including both properties.
8. **Research.** Formalize one deterministic helper from an LM harness in Lean, Coq, Agda, Idris, or F*. Measure how much code is specification and proof.
9. **Concept.** Give a semantic property that is undecidable for arbitrary Python but decidable for a restricted finite-state DSL.
10. **Proof.** Explain the role of function extensionality in moving from pointwise equality to function equality.

# Contracts, Refinement Types, and Specification Layers

## 14.1 A contract is layered

A realistic contract for a harness is not one predicate. It has several layers:

1. **Interface contract**: input and output schemas.
2. **Effect contract**: allowed operations and capabilities.
3. **Resource contract**: call, token, time, memory, and money bounds.
4. **Functional contract**: preconditions, postconditions, and invariants.
5. **Information-flow contract**: what data may reach which tools or models.
6. **Statistical contract**: calibrated error or risk under stated distributions.
7. **Governance contract**: provenance, review, and promotion requirements.

Only some layers are fully decidable or formally provable in a given implementation. The contract should mark which clauses are proved, tested, monitored, judged, or assumed.

## 14.2 Refinement types

A refinement type narrows a base type by a predicate:

\[
  \{x:A\mid P(x)\}.
\]

Examples:

\[
  \{n:\mathbb{N}\mid n\le 3\},
\]

\[
  \{s:\mathrm{String}\mid \mathrm{ValidJSON}(s)\},
\]

\[
  \{y:Y\mid \mathrm{Post}(x,y)\}.
\]

A function with a postcondition can have type

\[
  (x:X)\to\{y:Y\mid \mathrm{Post}(x,y)\}.
\]

Liquid types restrict refinements to decidable logical fragments and discharge obligations with SMT solvers. Systems such as Synquid use refinement types not only to verify but to synthesize programs.

## 14.3 Precondition and postcondition contracts

A Hoare triple

\[
  \{P\}\;c\;\{Q\}
\]

states that if precondition $P$ holds and command $c$ terminates, postcondition $Q$ holds. Total-correctness variants also establish termination.

For a harness:

\[
  \mathrm{pre}:X\to\mathrm{Prop},
\]

\[
  \mathrm{post}:\prod_{x:X}Y\to\mathrm{Prop}.
\]

The desired type is

\[
  (x:X)\to \mathrm{pre}(x)
  \to \sum_{y:Y}\mathrm{post}(x,y).
\]

This makes the precondition evidence an input and packages the output with postcondition evidence.

## 14.4 Intrinsic and extrinsic verification

In an **intrinsic** representation, only well-formed or correct programs can be constructed. A typed architecture AST is intrinsic with respect to interface compatibility. A constructor for a bounded loop might require a natural number bound.

In an **extrinsic** representation, programs are ordinary syntax and a separate predicate states correctness:

\[
  \mathrm{WellTyped}(p),
  \qquad
  \mathrm{Safe}(p),
  \qquad
  \mathrm{Correct}(p).
\]

Intrinsic representations eliminate classes of invalid proposals but can constrain expressiveness. Extrinsic checks are flexible but create proof obligations after generation. A practical system uses both: an intrinsic high-level DSL with extrinsic verification of embedded code and domain properties.

## 14.5 Contract refinement

A new contract $C'$ refines $C$ when every implementation satisfying $C'$ also satisfies $C$:

\[
  C'\Rightarrow C.
\]

For function contracts, refinement commonly permits weaker preconditions and stronger postconditions. If clients previously supplied inputs satisfying $P$, a replacement should not demand more. If clients expected $Q$, a replacement may guarantee more.

With effects and resources, refinement can mean:

- a subset of capabilities;
- a lower worst-case resource bound;
- a smaller set of possible errors;
- a more informative output type;
- an equal or stronger functional guarantee.

This creates a directed order on contracts and implementations.

## 14.6 Specifications as search-space shapers

A specification is not only a final filter. It shapes synthesis. Refinement types decompose obligations across components. An architecture grammar excludes irrelevant structures. Counterexamples eliminate candidate regions. Resource types prevent unbounded loops from entering the search.

Compare two prompts to a proposer:

```text
Write a better solution.
```

and

```text
Construct a term of Harness[X,Y] using only Pure, Predict,
Route, and Verify. It must inhabit CallsAtMost 2 and must
produce a proof of SchemaSafe. The failing case is x0.
```

The second search problem has more information and fewer invalid outputs. Formalization serves optimization efficiency as well as correctness.

## 14.7 Incomplete specifications and escape hatches

Overly narrow contracts can exclude useful solutions. A generated code system therefore needs a disciplined way to propose contract changes. The proposer may output either:

```text
ImplementationCandidate(C)
```

or

```text
ContractChangeProposal(C, C', rationale, migration, risk)
```

A contract change must not be accepted through the same automatic path as an implementation that satisfies the existing contract. It changes the problem and needs separate review.

This distinction blocks a common form of metric gaming: weakening the test or contract so the candidate appears successful.

## 14.8 Exercises

1. **Design.** Write a seven-layer contract for an email-triage harness.
2. **Proof.** Show that a function with weaker precondition and stronger postcondition can substitute for one with the original contract, under standard assumptions.
3. **Code.** Implement runtime refinement types for bounded integers and validated URLs. Document what remains unchecked statically.
4. **Concept.** Give one property best encoded intrinsically and one best checked extrinsically.
5. **Design.** Define a sum type separating implementation proposals from contract-change proposals.
6. **Proof.** If capability sets are ordered by inclusion, show that requiring a subset is a refinement.
7. **Research.** Compare synthesis success and candidate validity under an unrestricted prompt, JSON schema, typed DSL, and refinement-type specification.
8. **Concept.** Explain why tests are examples of a contract but are not generally the complete contract.
9. **Code.** Generate proof obligations from a small architecture AST and discharge the decidable ones automatically.
10. **Design.** Mark each clause of a real specification as proved, tested, monitored, judged, or assumed.

# Proof-Carrying Harnesses and a Typed Intermediate Representation

## 15.1 From source artifact to certified artifact

Proof-Carrying Code proposes that untrusted code arrive with a proof that it obeys a safety policy, while a small trusted checker validates the proof. The producer may use expensive theorem proving; the consumer trusts only the checker and policy.

For reflective harness evolution, define:

\[
  \mathrm{CertifiedHarness}(C)
  =
  \sum_{p:\mathrm{Program}}
  \mathrm{Typing}(p)
  \times\mathrm{CapabilitySafe}_C(p)
  \times\mathrm{ResourceSafe}_C(p)
  \times\mathrm{FunctionalEvidence}_C(p)
  \times\mathrm{Provenance}(p).
\]

Not every factor must be a full theorem. The type can distinguish proof, bounded-model-check report, signed test report, and statistical certificate. What matters is that evidence kind and assumptions are explicit.

## 15.2 Why arbitrary Python is a difficult proof target

Python includes reflection, dynamic imports, mutable global state, exceptions, metaprogramming, native extensions, and an evolving runtime. Proving arbitrary generated Python safe is difficult. A sandbox reduces operational risk but does not produce a semantic proof.

A better architecture has three layers:

```text
LLM proposal
    |
    v
Typed Harness IR  --static checks/proofs--> Certified IR
    |
    v
Verified or audited compiler
    |
    v
Sandboxed executable code
```

The intermediate representation contains only approved constructs. Its interpreter or compiler is part of the trusted base.

## 15.3 A sample typed IR

A compact IR might include:

```text
Pure(f)                    -- total approved function
Predict(sig, prompt_id)    -- one model call
Tool(tool_id, arg_map)     -- approved tool call
Seq(a, b)                  -- sequential composition
Pair(a, b)                 -- parallel dataflow
Route(test, left, right)   -- typed case split
Retry(policy, h)           -- bounded retry
Verify(predicate, h)       -- check output, return typed failure
Fallback(primary, backup)  -- explicit recovery
Memo(key, h)               -- policy-controlled cache
```

Each node has a typing rule, effect row, resource expression, and trace semantics. For example:

\[
  \frac{
    h_1:\mathrm{Harness}_{r_1}(X,Y)
    \quad
    h_2:\mathrm{Harness}_{r_2}(Y,Z)
  }{
    \mathrm{Seq}(h_1,h_2):
    \mathrm{Harness}_{r_1+r_2}(X,Z)
  }.
\]

A bounded retry with at most $n$ attempts multiplies a worst-case resource bound, while its expected cost requires a probabilistic failure model.

## 15.4 Capability typing

Associate each term with an effect or capability set $\epsilon$:

\[
  \Gamma\vdash h:X\to Y\;!\;\epsilon.
\]

Composition unions capabilities:

\[
  \epsilon(\mathrm{Seq}(h_1,h_2))
  =\epsilon(h_1)\cup\epsilon(h_2).
\]

A deployment policy supplies an allowlist $A$. Admissibility requires

\[
  \epsilon(h)\subseteq A.
\]

Dynamic tool arguments may require additional predicates, such as domain allowlists, data-classification checks, or rate limits. Capability typing states what can be requested; handlers enforce it at runtime.

## 15.5 Information-flow types

Suppose inputs contain public data $P$ and secrets $S$. A noninterference property says public outputs should not depend on secrets, except through approved declassification.

A simple security lattice might have labels

\[
  \mathrm{Public}\sqsubseteq\mathrm{Internal}
  \sqsubseteq\mathrm{Confidential}.
\]

Types track labels through transformations. A call to an external model may accept only `Public` data. A declassifier is an explicit privileged morphism with a proof obligation or human policy.

LLM-generated code is particularly likely to concatenate convenient context. Information-flow typing blocks accidental secret leakage structurally.

## 15.6 Resource proofs

Resource expressions can be derived compositionally:

```text
calls(Pure)                 = 0
calls(Predict)              = 1
calls(Seq(a,b))             = calls(a) + calls(b)
calls(Route(t,a,b))         = calls(t) + max(calls(a), calls(b))
calls(Retry(n,h))           = n * calls(h)
```

For input-dependent loops or recursion, one needs size indices and termination measures. A vector of length $n$ can carry $n$ in its type. A map operation then has a call bound proportional to $n$.

Expected cost is not derivable from syntax alone unless branch probabilities are known. Keep `WorstCase r` and `Expected model r` distinct.

## 15.7 Compiler and interpreter trust

Even a perfectly typed IR can be compiled incorrectly. Options include:

- execute a small verified interpreter directly;
- verify the compiler;
- validate compiled output with translation validation;
- keep the executable sandboxed and compare traces against IR semantics;
- reduce the compiler to a simple code generator with extensive property tests.

Translation validation is attractive for generated harnesses: instead of proving one optimizer or compiler correct for all time, validate each produced artifact against its IR-level meaning.

## 15.8 Proof-producing proposal workflow

An LLM can contribute to proof without becoming trusted:

1. propose an IR term;
2. propose invariants, lemmas, or proof scripts;
3. run a proof assistant or solver;
4. receive exact error messages and counterexamples;
5. revise the term or proof;
6. accept only when the kernel checks.

This is proof search with an untrusted heuristic. The trusted kernel remains small.

## 15.9 Exercises

1. **Design.** Define a typed IR for a tool-using research agent with no raw code escape hatch.
2. **Proof.** Derive the capability set and worst-case call bound for a nested `Route` and `Retry` term.
3. **Code.** Implement an IR type checker and interpreter. Reject mismatched composition before execution.
4. **Design.** Add information-flow labels and prevent confidential data from reaching an external predictor.
5. **Proof.** State a soundness theorem connecting the IR effect analysis to runtime handler calls.
6. **Concept.** Explain why a sandbox and proof-carrying code address different threats.
7. **Research.** Compare direct Python generation with IR generation on expressive power, candidate validity, and optimization performance.
8. **Code.** Implement translation validation for one IR node by comparing reference-interpreter and generated-code outputs over exhaustive finite inputs.
9. **Design.** Specify the trusted computing base and how each component is updated.
10. **Proof.** Explain why expected branch cost cannot be inferred from syntax without a distributional assumption.
11. **Concept.** Distinguish proof production, proof checking, and proof-certificate storage.

# Counterexample-Guided Synthesis with an LLM Proposer

## 16.1 Classical CEGIS

Counterexample-Guided Inductive Synthesis addresses problems of the form

\[
  \exists p\in\mathcal{P}.\;\forall x\in X.\;\varphi(p,x).
\]

It alternates two phases:

1. **Synthesis:** find a candidate $p$ satisfying the specification on a finite sample $S\subseteq X$.
2. **Verification:** ask whether there exists $x$ such that $\neg\varphi(p,x)$. If so, add the counterexample to $S$ and repeat. If not, accept.

```text
sample S = initial examples
loop:
    p = synthesize(S)
    x = verify_or_counterexample(p)
    if no counterexample exists:
        return p
    S = S union {x}
```

When the verifier is sound and complete for the chosen domain and candidate language, termination with `p` yields a proof that $p$ satisfies the specification.

## 16.2 LLM as inductive synthesizer

Replace the symbolic synthesizer with a language model:

\[
  p'\sim Q(-\mid\mathrm{spec},S,\mathrm{history},\mathrm{feedback}).
\]

The LLM can exploit broad priors and propose complex algorithms. The verifier remains symbolic, exhaustive, proof-assistant-based, or otherwise trusted. Failed proof attempts and counterexamples become high-bandwidth feedback.

This is a strong pattern because it assigns each component a suitable role:

- the LLM searches a huge structured space heuristically;
- the verifier decides a formal question in its supported fragment;
- the outer loop manages evidence and budget.

The model may repeatedly fail to find a valid program, but it cannot cause an invalid one to be certified if the checker is sound.

## 16.3 From one verifier to a verifier stack

Real harnesses need a stack:

```text
parse/type verifier
capability verifier
resource verifier
functional verifier
bounded model checker
property-based testing
statistical evaluator
LLM judge
human review
```

Only the first several may produce formal counterexamples. A statistical failure is a sampled witness. A judge critique is a heuristic diagnosis. The feedback algebra should retain source and strength.

A candidate can be in one of several states:

```text
IllFormed
WellTyped
PolicyAdmissible
FormallyVerified(fragment)
EmpiricallyQualified(dataset, confidence)
HumanApproved(scope)
```

Avoid a single Boolean called `verified`.

## 16.4 Counterexamples as dependent data

A counterexample should include the violated clause:

\[
  \mathrm{Counterexample}(p)
  =
  \sum_{x:X}\sum_{c:\mathrm{Clause}}
  \mathrm{Violates}(p,x,c).
\]

This package tells the proposer what failed and gives the checker evidence. For a resource violation, the witness may be a path through control flow. For information flow, it may be a taint trace. For equivalence, it is an input where outputs differ.

## 16.5 Proof repair

Generated code changes can invalidate proofs. A proof-repair loop treats compiler and proof-assistant errors as structured counterexamples. The proposer can revise:

- implementation only;
- proof only;
- both implementation and proof;
- an auxiliary lemma;
- the architecture, while preserving the external contract.

The contract itself is not automatically mutable. A proposal to weaken it enters a separate governance path.

## 16.6 Approximate CEGIS

Many LM tasks lack a decidable complete specification. The loop becomes approximate:

1. synthesize from current evidence;
2. search for failures using tests, fuzzing, adversarial generation, and judges;
3. add discovered failures;
4. stop under a budget and report residual uncertainty.

This resembles CEGIS but does not inherit its proof guarantee. Call it **counterexample-guided empirical synthesis** unless a formal verifier closes the universal quantifier.

A useful mixed objective is:

\[
  \text{first satisfy all decidable hard clauses, then maximize soft quality}.
\]

## 16.7 Adversarial counterexample generation

An LLM can also generate tests. This introduces an adversarial game:

\[
  \min_h\max_x \mathrm{loss}(h,x).
\]

The counterexample generator searches for inputs that expose failures. The harness proposer searches for repairs. A deterministic oracle or human must adjudicate expected behavior when possible; otherwise two models can co-evolve around shared errors.

Maintain separate models, prompts, data, and hidden test sources to reduce correlated blind spots.

## 16.8 A verified fast-path pattern

Consider a hybrid classifier:

```text
if proved_predicate(x):
    return proved_solver(x)
else:
    return model_solver(x)
```

The deterministic branch carries a theorem:

\[
  \forall x,\;p(x)\to \mathrm{Correct}(x,d(x)).
\]

The LLM branch is evaluated statistically. Optimization can widen $p$ only by proving the theorem for the wider region. This creates a monotone expansion of the certified fast path.

When full proofs are impossible, use a conservative runtime verifier: the deterministic branch returns either a result plus certificate or `Unknown`. Only certified results bypass the model.

## 16.9 Exercises

1. **Proof.** Write the $\exists\forall$ formula for synthesizing a bounded integer function from examples and a postcondition.
2. **Code.** Implement CEGIS for a small linear-arithmetic grammar using exhaustive verification over a finite domain.
3. **Design.** Replace the synthesizer with an LLM stub and define structured feedback from the verifier.
4. **Concept.** Explain exactly which CEGIS guarantee disappears when the verifier is replaced by random testing.
5. **Proof.** Define the dependent type of a counterexample tied to a contract clause.
6. **Code.** Implement a verifier stack that returns a tagged result rather than a Boolean.
7. **Research.** Compare proof-assistant error messages, minimized counterexamples, and free-form judge critiques as repair feedback.
8. **Design.** Create a conservative certified fast path for one domain operation.
9. **Proof.** Show that widening the fast-path predicate while preserving its theorem cannot reduce the set of certified inputs.
10. **Concept.** Why should a contract-change proposal be excluded from the ordinary repair loop?
11. **Research.** Build an adversarial test generator and measure whether it finds failures not present in a static benchmark.

# Effects, Weakest Preconditions, and What Can Be Proved

## 17.1 Specifications for effectful code

A postcondition for a pure function is a predicate on its output. For effectful code, specifications must account for state, exceptions, probability, and traces.

A weakest-precondition transformer maps a postcondition $Q$ to the weakest input condition required to ensure it:

\[
  \mathrm{wp}(c,Q):X\to\mathrm{Prop}.
\]

A Dijkstra monad indexes computations by such specifications. It connects monadic effect semantics with dependent verification. Systems such as F* use this approach to reason about effectful programs.

For a stateful computation, $Q$ may mention both result and final state. For exceptions, it may specify allowed errors. For logging, it may constrain trace events. For model calls, a deterministic postcondition cannot generally promise semantic correctness of an unconstrained stochastic output.

## 17.2 Three proof boundaries

Separate three layers:

### Wrapper correctness

One can prove that the harness:

- validates inputs;
- calls only allowed tools;
- never exceeds a static call bound;
- handles every parser outcome;
- logs required events;
- routes certified cases correctly;
- returns a schema-conforming output or typed failure.

### Model-conditional correctness

One can prove:

\[
  \mathrm{ModelAssumption}(x,y)
  \to \mathrm{Post}(x,h(x,y)).
\]

For example, if a model returns a valid proof term, the checker accepts only a true theorem. The system is correct conditional on successful certification, not conditional on the model being honest.

### Statistical quality

Claims such as 95% accuracy are about a distribution and estimation procedure:

\[
  \Pr_{x\sim P,\,y\sim h(x)}[\mathrm{Correct}(x,y)]\ge 0.95.
\]

A finite test yields a confidence statement under sampling assumptions, not an unconditional theorem about deployment.

## 17.3 Selective prediction and abstention

A safe harness can return

\[
  Y+\mathrm{Abstain}
\]

rather than pretending to solve every input. Let coverage be

\[
  \Pr[h(x)\ne\mathrm{Abstain}],
\]

and selective risk be error conditioned on answering. Optimization can trade coverage for risk. A certified branch plus an uncertain model branch can expose uncertainty explicitly.

A dependent output can carry evidence level:

```text
Result =
    Certified(value, proof)
  | Empirical(value, confidence, provenance)
  | Abstain(reason)
```

Downstream clients can require `Certified` for high-risk actions.

## 17.4 Probabilistic contracts

A probabilistic contract must name:

- input distribution or uncertainty set;
- randomness sources;
- metric or event;
- confidence level;
- sample size and sampling design;
- model and tool versions;
- validity period or drift assumptions.

Without these, "95% accurate" is underspecified.

Formal probabilistic verification is possible for finite-state or analyzable stochastic systems. Frontier LMs are generally treated as black-box stochastic components, so empirical certificates dominate. The wrapper can still be formally verified.

## 17.5 Resource and capability proofs with Dijkstra-style specs

A computation specification can return both postconditions and resource constraints. Schematically:

\[
  \mathrm{WP}_r(Y)
  = (Y\to\mathrm{Prop})\to X\to\mathrm{Prop}
a
\]

with an index $r$ or a trace predicate describing permitted effects. Sequential composition derives a combined weakest precondition. A generated term is accepted only when its inferred specification refines the required one.

In practice, one might use F*, Lean with an effect library, Coq, Dafny, Why3, Liquid Haskell, or a custom certified IR. The exact tool matters less than maintaining a small trusted checker.

## 17.6 Termination and totality

A total function terminates for every input. LM harnesses often include retries and agents that can loop. Enforce termination through:

- structural recursion;
- well-founded measures;
- fuel parameters;
- timeouts represented as typed outcomes;
- bounded tool and model calls.

A timeout is not the same as a proof of termination. It is an operational cutoff. A total wrapper can always terminate by returning `BudgetExceeded`, even if the internal strategy did not solve the task.

## 17.7 Noninterference and external models

Sending data to a remote model is an observable effect. A noninterference theorem for local code is invalid if the handler transmits secrets. The semantic model must include external calls and their observations.

Generated code should never construct arbitrary prompts from unlabeled context. An information-flow-aware prompt builder can require a proof that every field's label is permitted by the destination policy.

## 17.8 The specification-gap theorem, informally

No amount of proof can establish an unstated requirement. If contract $C$ omits a harmful behavior $H$, a proof of $C(h)$ does not imply $\neg H(h)$.

This obvious logical fact has practical force. Formal methods shift the failure mode from "implementation violates known rules" toward "rules were incomplete or assumptions false." That is a substantial improvement, but not omniscience.

## 17.9 Exercises

1. **Concept.** Separate wrapper, model-conditional, and statistical claims for a retrieval assistant.
2. **Proof.** Write a weakest-precondition rule for sequential composition.
3. **Design.** Define a typed result with certified, empirical, and abstaining cases.
4. **Code.** Implement a bounded retry that is total because it returns a typed budget error.
5. **Proof.** Show that conditional correctness of a proof-checking harness does not require trusting the model that generated the proof.
6. **Research.** Estimate selective risk as the abstention threshold varies.
7. **Design.** Write a complete probabilistic-contract statement for an LLM classifier.
8. **Concept.** Explain why a timeout is not a termination proof for the internal strategy.
9. **Proof.** Formalize the specification-gap observation as the non-derivability of $\neg H$ from $C$ without an implication $C\to\neg H$.
10. **Code.** Add information-flow labels to prompt fields and reject disallowed model destinations.
11. **Research.** Investigate a probabilistic proof assistant or model checker on a finite abstraction of a harness.

EOF
```

<details><summary>💭 Thinking</summary>

**Wrote propositions-as-types content and appended Part IV HoTT chapters**

</details>

```unknown
bash -lc cat >> /mnt/data/evolving_code_book/evolving-programs-with-language-models.md <<'EOF'
# A Reference Architecture for Reflective Program Evolution

## 22.1 Design goals

A production architecture should permit aggressive proposal while keeping acceptance conservative. It should support reproducibility, explicit contracts, multiple evidence kinds, resource-aware selection, and immutable deployment artifacts.

The core rule is:

> The proposer may be creative and unreliable. Every boundary that grants capability, certifies a property, or promotes a candidate must be narrow, typed, and independently checked.

## 22.2 System diagram

```text
                         +-----------------------+
                         |  Contract Registry    |
                         | schemas, policies,    |
                         | proofs, objectives    |
                         +-----------+-----------+
                                     |
                                     v
+------------+   evidence   +--------+---------+    proposal   +-------------+
| Evaluation |------------->| Search Controller|------------->| LLM Proposer|
| Workers    |              +--------+---------+              +------+------+ 
+-----+------+                       |                               |
      ^                              | candidate source/IR           |
      |                              v                               |
      |                    +---------+----------+                    |
      |                    | Build and Verify   |<-------------------+
      |                    | parser, typecheck, |
      |                    | proofs, policies   |
      |                    +---------+----------+
      |                              |
      | certified candidate          v
      +----------------------+-------+----------+
                             | Sandbox Runtime  |
                             | effect handlers, |
                             | tracing, limits  |
                             +-------+----------+
                                     |
                                     v
                         +-----------+-----------+
                         | Artifact and History  |
                         | content-addressed log |
                         +-----------+-----------+
                                     |
                                     v
                         +-----------+-----------+
                         | Promotion Gate        |
                         | hidden eval, review,  |
                         | signed release        |
                         +-----------------------+
```

## 22.3 Contract registry

The contract registry stores versioned definitions of:

- input and output schemas;
- allowed architecture primitives;
- effect and capability policies;
- resource limits;
- formal preconditions, postconditions, and invariants;
- statistical objectives and confidence requirements;
- judge prompts, rubrics, and calibration versions;
- promotion rules;
- data-governance and privacy policies.

Contracts are content-addressed. A candidate points to an immutable contract hash. A proposal that changes the contract produces a separate artifact and cannot masquerade as an implementation improvement.

## 22.4 Proposal interface

The proposer receives a controlled view:

```python
@dataclass(frozen=True)
class ProposalRequest:
    contract: ContractView
    parent_ir: str
    parent_metrics: ScoreVector
    selected_traces: tuple[RedactedTrace, ...]
    counterexamples: tuple[Counterexample, ...]
    prior_attempts: tuple[AttemptSummary, ...]
    allowed_primitives: tuple[PrimitiveDoc, ...]
    objective_policy: ObjectivePolicy
```

The response is structured:

```python
@dataclass(frozen=True)
class Proposal:
    candidate_ir: str
    claimed_transformations: tuple[str, ...]
    expected_effects: ScoreVector | None
    proof_hints: tuple[str, ...]
    assumptions: tuple[str, ...]
```

Claims are hypotheses. They are never copied into certificates without checking.

## 22.5 Build and verification boundary

The builder performs, in order:

1. parse into a typed IR;
2. reject unknown primitives;
3. infer types, effects, capabilities, and resource expressions;
4. compare inferred properties with the contract;
5. generate proof obligations;
6. invoke proof checkers, SMT solvers, or model checkers;
7. lower to executable code;
8. translation-validate or test the lowering;
9. package the artifact with evidence hashes.

The output type is explicit:

```text
BuildResult =
    Rejected(BuildError, diagnostics)
  | Certified(Candidate, EvidenceBundle)
```

No exception path should bypass this sum and insert an uncertified candidate into the archive.

## 22.6 Sandbox and effect handlers

The runtime executes generated code in isolation. It supplies only typed operations. Every effect crosses a host-controlled handler that:

- validates arguments;
- enforces capability and data-label policies;
- applies quotas and timeouts;
- records a trace event;
- attaches model/tool version metadata;
- returns a typed result.

A sandbox limits consequences of a mistake. It does not justify trusting output. Use both sandboxing and verification.

## 22.7 Evaluation workers

Evaluation workers should be hermetic where possible. An evaluation record includes:

```text
candidate hash
contract hash
dataset and split hash
model snapshot or provider version
sampling parameters and seeds
tool/runtime/container versions
judge version and randomized presentation
raw and redacted trace hashes
scores with uncertainty
verifier and test reports
start/end timestamps and resource measurements
```

External APIs can prevent exact replay. Record sufficient evidence to distinguish code changes from service drift.

## 22.8 Search controller

The controller is the coalgebraic outer loop. It manages:

- budget accounting;
- parent selection;
- evidence retrieval;
- proposal scheduling;
- candidate deduplication;
- staged evaluation;
- archive updates;
- stopping criteria;
- periodic reevaluation of incumbents;
- quarantine of suspicious improvements.

The controller should be deterministic given recorded randomness and external responses. Its own source and configuration are versioned.

## 22.9 Artifact store and provenance graph

Use content-addressed immutable artifacts. Store source/IR, compiled executable, evidence, traces, prompts, model identifiers, and data hashes. The provenance graph records:

```text
parent candidates
    -> proposal request
    -> proposal response
    -> build evidence
    -> evaluation runs
    -> archive decisions
    -> promotion decision
```

Never overwrite "the optimized program." Publish a new version and a signed pointer.

## 22.10 Promotion gate

Search metrics are training signals. Promotion uses stronger evidence:

1. re-run hard checks in a clean environment;
2. evaluate on a hidden test set inaccessible to the proposer and search controller;
3. run distribution-shift and adversarial suites;
4. verify resource limits under production-like load;
5. inspect trace and judge anomalies;
6. require human approval for policy-sensitive changes;
7. sign the candidate and evidence manifest.

Production does not rewrite itself in place. New candidates deploy through canary, shadow, or staged rollout with rollback.

## 22.11 Threat model

Threats include:

- accidental invalid code;
- prompt injection through traces or task data;
- generated code attempting unauthorized effects;
- metric exploitation;
- judge manipulation;
- secret leakage into prompts;
- dependency or model drift;
- poisoned historical evidence;
- archive corruption;
- contract weakening;
- human-review fatigue.

Map each threat to a boundary. "The model is capable" is not a mitigation.

## 22.12 Exercises

1. **Design.** Adapt the reference architecture to a code-review assistant.
2. **Code.** Define immutable Python data classes for proposal, build, evaluation, and promotion records.
3. **Proof.** Show how a sum-typed build result prevents a rejected artifact from being consumed by a function requiring `Certified`, assuming no unsafe cast.
4. **Design.** Write a capability policy for an optimizer that may query documentation but may not modify repositories.
5. **Research.** Measure replay divergence caused by model-provider drift over one month.
6. **Concept.** Explain why the contract registry and promotion gate must not be ordinary optimizer parameters.
7. **Code.** Build a content-addressed artifact store using SHA-256 and an append-only manifest.
8. **Design.** Create a redaction policy that preserves useful trace structure while removing secrets.
9. **Proof.** State the invariant maintained by staged evaluation: every archive member has passed hard checks under its cited contract.
10. **Threat modeling.** Construct an attack tree for a candidate that tries to manipulate its LLM judge.

# LLM Judges, Measurement, and Goodhart's Law

## 23.1 A judge is a measuring instrument

An LLM judge maps an evaluation context and candidate output to a score, label, preference, or critique:

\[
  J:R\times X\times Y\to\mathcal{D}(S\times F),
\]

where $R$ is a rubric, $S$ a score, and $F$ feedback. Treat it as a stochastic measuring instrument, not an oracle.

The measurement has construct validity only if it tracks the quality users care about. It has reliability only if repeated or equivalent presentations produce sufficiently stable outputs. It has calibration only if reported probabilities or score bands correspond to observed outcomes.

## 23.2 Known biases

Research on LLM-as-a-judge has documented several recurring biases:

- **position bias:** preference changes when answer order changes;
- **verbosity bias:** longer answers can be favored independent of correctness;
- **self-enhancement or family bias:** a model may favor outputs resembling its own style;
- **style bias:** formatting and confidence can dominate substance;
- **limited reasoning:** the judge may fail on tasks it cannot solve;
- **reference anchoring:** an imperfect reference answer can distort evaluation;
- **inconsistency:** repeated judgments may disagree.

These findings do not make LLM judges useless. They define the controls needed for responsible use.

## 23.3 Absolute scoring versus pairwise preference

Absolute scoring asks for a number or rubric category. Pairwise judging asks which of two outputs is better. Pairwise tasks are often easier, but introduce ordering effects and do not directly produce a cardinal scale.

A robust pairwise protocol:

1. blind candidate identities;
2. randomize order;
3. judge both orders for a subset or all pairs;
4. request a criterion-by-criterion decision before overall preference;
5. permit ties;
6. aggregate with a model such as Bradley-Terry, while checking fit;
7. calibrate against human judgments.

Do not use the same model's free-form rationale as independent evidence for its score. Both come from one stochastic process.

## 23.4 Rubric decomposition

A rubric should separate dimensions:

```text
factual correctness
instruction compliance
completeness
relevance
clarity
safety or policy compliance
citation support
```

For each dimension, specify observable criteria and an abstention option. Some dimensions should be replaced by deterministic tools. Citation validity can be checked by retrieval and entailment procedures; schema validity by a parser; code correctness by tests and proofs.

The judge should receive only the information needed. Revealing candidate source, model identity, cost, or previous score can introduce unwanted bias unless those are explicit criteria.

## 23.5 Judge calibration

Collect a human-labeled calibration set representative of deployment. Estimate:

- agreement by criterion;
- confusion matrices;
- order sensitivity;
- test-retest reliability;
- subgroup performance;
- sensitivity to verbosity and style controls;
- confidence calibration;
- failure modes on adversarial examples.

Calibration is version-specific. A model or prompt update creates a new judge instrument and requires reevaluation.

## 23.6 Ensembles and correlated error

Multiple judges reduce variance only when errors are not perfectly correlated. Three prompts to the same model may offer less diversity than one model, one deterministic checker, and one human review channel.

An ensemble can aggregate:

\[
  J_1,J_2,\ldots,J_m.
\]

But majority vote can amplify shared bias. Track disagreement. High disagreement is evidence for uncertainty and can trigger escalation rather than forced consensus.

## 23.7 Goodhart's law

When a measure becomes a target, it can cease to be a good measure. A useful taxonomy distinguishes:

- **regressional Goodhart:** extreme proxy values contain more noise;
- **extremal Goodhart:** optimization enters a regime where the prior proxy-quality relationship changes;
- **causal Goodhart:** intervening on the proxy breaks its relationship to the goal;
- **adversarial Goodhart:** an agent exploits the proxy.

Reflective program evolution is exposed to all four. Searching many candidates selects positive noise. Architectural changes move outside the judge's calibration distribution. A candidate can optimize surface features rather than substance. Generated content can include instructions that affect the judge.

## 23.8 Judge isolation

Candidate-controlled content must be treated as data. Defenses include:

- delimit and quote candidate output;
- use a judge prompt that explicitly ignores embedded instructions;
- parse outputs into structured fields before judging;
- strip irrelevant metadata and hidden text;
- use independent deterministic checks for injection markers;
- render content through a safe canonical form;
- keep judge tools and secrets unavailable;
- test with adversarial candidate outputs.

No prompt provides a formal isolation boundary. Use process and capability isolation as well.

## 23.9 Hidden objectives and rotating probes

A search process repeatedly exposed to the same judge can overfit. Keep some criteria hidden, rotate adversarial probes, and use meta-held-out evaluations. The hidden set must remain inaccessible through traces, logs, or proposal context.

A candidate that improves only on the exposed judge but not humans or hidden checks should be classified as judge overfitting, not progress.

## 23.10 Proof outranks preference on formal claims

If a proposition is decidable, use a checker. An LLM judge can prioritize proof attempts, explain counterexamples, or assess readability. It should not override a failed proof or test.

Evidence precedence can be encoded:

```text
formal contradiction     -> reject
hard policy violation    -> reject
schema/type failure      -> reject
statistical uncertainty  -> quantify/escalate
judge disagreement       -> escalate or retain both
preference difference    -> optimize only among admissible candidates
```

## 23.11 Exercises

1. **Design.** Write a decomposed judge rubric for technical explanations.
2. **Code.** Implement randomized pairwise judging with order reversal and disagreement tracking using a deterministic mock judge.
3. **Proof.** Show how selecting the maximum of many noisy unbiased estimates produces an upward-biased estimate of the winner's true score.
4. **Research.** Measure position and verbosity bias for two judge models on a human-labeled set.
5. **Concept.** Classify four optimizer failure examples by Goodhart type.
6. **Design.** Build an evidence-precedence lattice for a coding-agent benchmark.
7. **Code.** Detect and quarantine candidate outputs containing judge-directed instructions.
8. **Research.** Compare same-model prompt ensembles with cross-model and tool-plus-model ensembles.
9. **Proof.** Explain why correlated judge errors limit the benefit of majority voting.
10. **Design.** Specify a versioned judge-calibration report sufficient for an audit.
11. **Concept.** State one task where an LLM judge is appropriate and one where a formal checker should replace it.

# Experimental Design for Self-Optimizing Systems

## 24.1 The metric is part of training

Once an optimizer repeatedly queries a metric, the evaluation set becomes training data. Calling it a validation set does not preserve independence. A rigorous experiment distinguishes:

```text
proposal/feedback set
    used to generate critiques and counterexamples
selection set
    used to compare and retain candidates
development test set
    used sparingly by researchers
final hidden test set
    used once for reported selection
meta-held-out set
    different tasks, domains, models, or time periods
live shadow set
    production-like monitoring without user impact
```

The exact split depends on data volume, but independence must be designed, not assumed.

## 24.2 Nested selection

If hyperparameters, prompts, archive policies, and stopping rules are tuned, the final test must sit outside all of them. A nested protocol is:

1. inner search optimizes candidate programs;
2. middle validation selects optimizer settings;
3. outer test estimates the complete procedure.

Reporting only the best run from many optimizer configurations without correction estimates luck as skill.

## 24.3 Multiple comparisons and winner's curse

Suppose $N$ candidates have true quality $q_i$ and noisy estimates

\[
  \hat q_i=q_i+\epsilon_i.
\]

Selecting $i^*=\arg\max_i\hat q_i$ favors candidates with positive noise. The more candidates evaluated, the larger the expected optimism.

Mitigations include:

- independent reevaluation of finalists;
- confidence bounds;
- sequential racing with correction;
- bootstrap selection stability;
- preregistered budgets and stopping rules;
- reporting all runs, not only the maximum;
- final hidden evaluation.

## 24.4 Paired evaluation

When two candidates are tested on the same inputs and random seeds, compare paired differences:

\[
  d_i=\mu(h',x_i)-\mu(h,x_i).
\]

Pairing removes variation shared across examples. For stochastic LMs, common random numbers are not always available across different prompts or providers, but identical sampling seeds and repeated trials can still reduce variance when supported.

Report effect size and uncertainty, not only a p-value.

## 24.5 Staged evaluation and racing

Evaluation is expensive. Use stages:

```text
Stage 0: parse, type, policy, proof checks
Stage 1: tiny diagnostic batch
Stage 2: larger selection batch
Stage 3: full validation with repeated samples
Stage 4: hidden final test
Stage 5: shadow or canary deployment
```

Early elimination saves budget but can discard candidates with high variance or niche strengths. Preserve a small exploration quota and occasionally re-evaluate borderline candidates.

## 24.6 Distribution shift

The optimized harness learns properties of data, tools, model behavior, and evaluator. Test shifts in:

- input domain and language;
- class balance and prevalence;
- time;
- upstream data formatting;
- model version;
- tool errors and latency;
- adversarial behavior;
- cost regime;
- policy constraints.

For a routed system, monitor each branch separately. A small change in input distribution can move many cases across a threshold and sharply change error and cost.

## 24.7 Ablation and causal understanding

A complex generated harness can score well for the wrong reason. Ablate:

- deterministic preprocessing;
- router;
- each predictor;
- memory and retrieval;
- textual feedback;
- full history versus summaries;
- Pareto archive versus best-only selection;
- judge versus deterministic evaluator;
- code optimization versus prompt-only optimization.

Ablation does not prove causality under all interactions, but it reveals whether claimed components are necessary in the measured setting.

## 24.8 Cost and latency accounting

Record:

- input, output, and cached tokens;
- number and type of model calls;
- tool calls;
- wall-clock and CPU time;
- concurrency and batching;
- cold versus warm caches;
- retries and failures;
- price schedule and date;
- infrastructure overhead.

A claim such as "$0.70 per thousand records" is tied to a model, provider, price, and runtime date. Preserve raw token and call counts so later readers can recompute cost.

## 24.9 Reproducibility manifest

A result should include:

```yaml
candidate_hash: ...
contract_hash: ...
optimizer_commit: ...
optimizer_config_hash: ...
proposer_model: ...
execution_model: ...
judge_model: ...
dataset_hashes: ...
split_definition: ...
container_digest: ...
random_seeds: ...
tool_versions: ...
price_snapshot: ...
search_budget: ...
number_of_candidates: ...
selection_rule: ...
```

Without the number of attempted candidates and selection rule, the reported winner cannot be interpreted statistically.

## 24.10 Exercises

1. **Design.** Create a five-level split protocol for a small dataset with only 1,000 examples.
2. **Proof.** For two independent normal noise estimates, compute why selecting the larger estimate creates optimism even when true qualities are equal.
3. **Code.** Implement paired bootstrap confidence intervals for candidate score differences.
4. **Research.** Compare best-of-N performance before and after independent finalist reevaluation.
5. **Design.** Define staged evaluation thresholds that account for score uncertainty.
6. **Concept.** Explain why a repeatedly queried validation set is effectively training data.
7. **Code.** Generate a complete reproducibility manifest and verify hashes before replay.
8. **Research.** Stress-test a router under shifts in class prevalence and input formatting.
9. **Design.** Plan ablations for an optimized agent with retrieval, memory, verifier, and fallback.
10. **Concept.** Distinguish price, raw resource use, and infrastructure cost.
11. **Proof.** Show why the variance of paired differences can be lower than the variance of two independent sample means when outcomes are positively correlated.

EOF
```

<details><summary>💭 Thinking</summary>

**Appended Reflective Evolution Architecture**

</details>

```json
{"open":[{"ref_id":"turn214414view0","lineno":49},{"ref_id":"turn214414view0","lineno":53},{"ref_id":"turn214414view0","lineno":59},{"ref_id":"turn214414view0","lineno":139}],"response_length":"long"}
```

<details><summary>💭 Thinking</summary>

**Searched 1 website**

</details>

```unknown
bash -lc which lean || true; lean --version 2>/dev/null || true
```

<details><summary>💭 Thinking</summary>

**Outlined case studies, appendices, glossary, and manuscript fixes**

</details>

```json
{"search_query":[{"q":"site:arxiv.org/abs/2507.19457 GEPA Reflective Prompt Evolution Can Outperform Reinforcement Learning authors"},{"q":"site:arxiv.org/abs/2603.28052 Meta-Harness authors"},{"q":"site:arxiv.org/abs/2512.24601 Recursive Language Models authors"},{"q":"site:dspy.ai api modules Flex DSPy source code optimizable"}],"response_length":"long"}
```

<details><summary>💭 Thinking</summary>

**Searched 6 websites**

</details>

```unknown
bash -lc grep -n '^# ' /mnt/data/evolving_code_book/evolving-programs-with-language-models.md
```

<details><summary>💭 Thinking</summary>

**Inspected manuscript headings, references, citations, and character count**

</details>

```json
{"search_query":[{"q":"site:arxiv.org/abs/2310.02304 STOP recursively self-improving code generation"},{"q":"site:arxiv.org/abs/2406.07496 TextGrad automatic differentiation via text"},{"q":"site:arxiv.org/abs/2406.11695 Optimizing Instructions and Demonstrations for Multi-Stage Language Model Programs"},{"q":"site:arxiv.org/abs/2312.13382 DSPy Assertions"}],"response_length":"long"}
```

The formalism now separates certified equivalence from directed improvement and distinguishes hard invariants from statistical/judge evidence. The main text is complete; companion code, proofs, bibliography, and PDF validation remain.

<details><summary>💭 Thinking</summary>

**Searched 6 websites**

</details>

```unknown
bash -lc cat > /mnt/data/evolving_code_book/sources_appendix.md <<'EOF'

\backmatter

# Sources and Further Reading {-}

## How to use this guide {-}

This book distinguishes four kinds of source:

- **Primary research** introduces an algorithm, formalism, theorem, or empirical result.
- **Official documentation** specifies the behavior of a current software system. Documentation is authoritative about an interface, but not evidence that the interface is safe, stable, or generally effective.
- **Textbooks and surveys** supply mature exposition and historical context.
- **Case-study reports** motivate hypotheses. Their measurements remain conditional on the stated data, models, prices, hardware, and evaluation protocol.

The references below are deliberately broader than the claims made in the chapters. They form a curriculum for reconstructing, criticizing, and extending the framework. Web resources were checked on August 7, 2026. Preprints should be read as provisional until independently replicated or peer reviewed.

## Chapter-to-source map {-}

| Chapters | Core reading | Purpose |
|---|---|---|
| 1-3 | LLM-01 through LLM-17; EV-01 through EV-12 | Reflective optimization, whole-harness search, and its relation to genetic programming |
| 4-6 | CAT-01 through CAT-09; TYPE-04 through TYPE-06 | Mathematical language for interfaces, composition, products, sums, and universal properties |
| 7-8 | CAT-10 through CAT-24 | Effects, resource grades, probability, feedback, fixed points, traces, and coalgebra |
| 9-12 | CAT-25 through CAT-36; LLM-03, LLM-08, LLM-09 | Textual feedback, optics, learners, rewrites, double categories, and Pareto archives |
| 13-17 | TYPE-01 through TYPE-36; SYN-01 through SYN-12 | Curry-Howard, dependent and refinement types, synthesis, proof-carrying code, and weakest preconditions |
| 18-21 | HOTT-01 through HOTT-18; CAT-37 | Identity, equivalence, univalence, higher coherence, and directed refinement |
| 22 | All groups, especially SYS-01 through SYS-20 | Production architecture and trust boundaries |
| 23-24 | EVAL-01 through EVAL-27 | LLM judges, measurement, adaptive overfitting, paired statistics, and uncertainty |
| 25 | LLM-01 through LLM-03; EVAL-12 through EVAL-17 | The Flex location-conflation report and appropriate statistical interpretation |
| 26 | LLM-07, LLM-08, LLM-12, LLM-16, LLM-22 | Harness memory, coding agents, recursive scaffolds, and meta-optimization |
| 27-28 | SYN-01 through SYN-18; TYPE-20 through TYPE-36; SYS-13 through SYS-20 | Executable implementation, proof-assistant encodings, provenance, and deployment |

## Reflective LM programs and self-optimizing harnesses {-}

**LLM-01.** Michael Isaac. ["Introducing Flex: Let the Model Write the Code"](https://www.cmpnd.ai/blog/let-the-model-write-the-code.html), cmpnd, August 5, 2026. The motivating case-study report. Read it for the concrete optimization loop, location-conflation measurements, generated routing structure, and explicit pilot caveat on coding tasks.

**LLM-02.** DSPy project. ["Flex: Optimizable Module Code"](https://dspy.ai/diving-deeper/flex/) and the [Flex API reference](https://dspy.ai/api/modules/Flex/), 2026. Official description of source code as an optimizable parameter, sandboxed execution, output-type checks, persistence, failure handling, and experimental status.

**LLM-03.** Lakshya A. Agrawal et al. ["GEPA: Reflective Prompt Evolution Can Outperform Reinforcement Learning"](https://arxiv.org/abs/2507.19457), 2025. Introduces Genetic-Pareto optimization with trace-conditioned natural-language reflection and per-instance Pareto selection.

**LLM-04.** DSPy project. [GEPA documentation](https://dspy.ai/api/optimizers/GEPA/overview/) and [GEPA tutorials](https://dspy.ai/tutorials/gepa_ai_program/), 2025-2026. Useful for the operational metric interface, predictor-level and program-level feedback, trace exposure, and implementation constraints.

**LLM-05.** Omar Khattab et al. ["DSPy: Compiling Declarative Language Model Calls into Self-Improving Pipelines"](https://arxiv.org/abs/2310.03714), ICLR 2024. Establishes signatures, modules, teleprompters/optimizers, and compilation of declarative LM programs.

**LLM-06.** Krista Opsahl-Ong et al. ["Optimizing Instructions and Demonstrations for Multi-Stage Language Model Programs"](https://arxiv.org/abs/2406.11695), 2024. Introduces MIPRO and studies credit assignment across multi-stage LM programs before whole-code optimization.

**LLM-07.** Alex L. Zhang, Tim Kraska, and Omar Khattab. ["Recursive Language Models"](https://arxiv.org/abs/2512.24601), 2025. Treats long context as an external programmable environment and lets a model inspect, decompose, and recursively invoke itself over selected portions.

**LLM-08.** Yoonho Lee et al. ["Meta-Harness: End-to-End Optimization of Model Harnesses"](https://arxiv.org/abs/2603.28052), 2026. Searches harness code with an agentic proposer that can inspect source, scores, raw traces, and search history; especially relevant to the information-loss discussion.

**LLM-09.** Mert Yuksekgonul et al. ["TextGrad: Automatic 'Differentiation' via Text"](https://arxiv.org/abs/2406.07496), 2024. A general framework for textual feedback propagated through compound AI computation graphs. Its quotation marks around differentiation are mathematically important.

**LLM-10.** Aman Madaan et al. ["Self-Refine: Iterative Refinement with Self-Feedback"](https://arxiv.org/abs/2303.17651), NeurIPS 2023. A basic generate-feedback-refine loop that helps isolate what later systems add: persistent archives, code mutation, richer traces, and multi-objective selection.

**LLM-11.** Noah Shinn et al. ["Reflexion: Language Agents with Verbal Reinforcement Learning"](https://arxiv.org/abs/2303.11366), NeurIPS 2023. Stores verbal reflections in episodic memory to influence later attempts; a useful precursor to trace-mediated proposal systems.

**LLM-12.** Eric Zelikman et al. ["Self-Taught Optimizer (STOP): Recursively Self-Improving Code Generation"](https://arxiv.org/abs/2310.02304), COLM 2024. Applies an LM-infused improver to its own source and explicitly examines sandbox-bypass behavior.

**LLM-13.** Chengrun Yang et al. ["Large Language Models as Optimizers"](https://arxiv.org/abs/2309.03409), ICLR 2024. Introduces Optimization by PROmpting (OPRO), where solution history and objective values condition new candidates.

**LLM-14.** Chrisantha Fernando et al. ["Promptbreeder: Self-Referential Self-Improvement via Prompt Evolution"](https://arxiv.org/abs/2309.16797), ICML 2024. Evolves task prompts and mutation prompts, making the mutation policy itself part of the search state.

**LLM-15.** Bernardino Romera-Paredes et al. ["Mathematical Discoveries from Program Search with Large Language Models"](https://doi.org/10.1038/s41586-023-06924-6), *Nature* 625, 2024. FunSearch combines an LLM proposer with executable evaluation and an evolutionary database of programs.

**LLM-16.** Alexander Novikov et al. ["AlphaEvolve: A Gemini-Powered Coding Agent for Designing Advanced Algorithms"](https://arxiv.org/abs/2506.13131), 2025. Uses code generation, automated evaluators, and an evolutionary database for algorithm discovery and systems optimization.

**LLM-17.** Yecheng Jason Ma et al. ["Eureka: Human-Level Reward Design via Coding Large Language Models"](https://arxiv.org/abs/2310.12931), ICLR 2024. Evolves executable reward code using environment feedback, illustrating a mutable evaluator-adjacent artifact.

**LLM-18.** Guanzhi Wang et al. ["Voyager: An Open-Ended Embodied Agent with Large Language Models"](https://arxiv.org/abs/2305.16291), 2023. Builds a growing executable skill library with automatic curriculum and iterative code repair.

**LLM-19.** Shunyu Yao et al. ["ReAct: Synergizing Reasoning and Acting in Language Models"](https://arxiv.org/abs/2210.03629), ICLR 2023. Introduces interleaved reasoning and tool actions, one of the common inner-loop structures that a harness optimizer may select or rewrite.

**LLM-20.** Timo Schick et al. ["Toolformer: Language Models Can Teach Themselves to Use Tools"](https://arxiv.org/abs/2302.04761), NeurIPS 2023. Studies learned placement and use of API calls, an important precursor to optimizing the code/model boundary.

**LLM-21.** Luyu Gao et al. ["PAL: Program-Aided Language Models"](https://arxiv.org/abs/2211.10435), ICML 2023. Delegates deterministic computation to generated programs, directly motivating decompositions that reserve models for semantic uncertainty.

**LLM-22.** Shunyu Yao et al. ["Tree of Thoughts: Deliberate Problem Solving with Large Language Models"](https://arxiv.org/abs/2305.10601), NeurIPS 2023. Makes search structure explicit at inference time; useful for separating inner deliberation from outer program evolution.

**LLM-23.** Zhou et al. ["Language Agent Tree Search Unifies Reasoning, Acting, and Planning in Language Models"](https://arxiv.org/abs/2310.04406), ICML 2024. Combines tree search, environment feedback, and value estimation in an agent scaffold.

**LLM-24.** Arnav Singhvi et al. ["DSPy Assertions: Computational Constraints for Self-Refining Language Model Pipelines"](https://arxiv.org/abs/2312.13382), 2023. Introduces assertions that can trigger retry and self-refinement, but does not turn empirical compliance into formal proof.

**LLM-25.** Carlos E. Jimenez et al. ["SWE-bench: Can Language Models Resolve Real-World GitHub Issues?"](https://arxiv.org/abs/2310.06770), ICLR 2024. Defines a repository-level software-engineering benchmark and highlights the need for executable grading.

**LLM-26.** John Yang et al. ["SWE-agent: Agent-Computer Interfaces Enable Automated Software Engineering"](https://arxiv.org/abs/2405.15793), NeurIPS 2024. Shows that the harness/interface around a model materially changes coding performance.

**LLM-27.** Qian Huang et al. ["AgentCoder: Multi-Agent-Based Code Generation with Iterative Testing and Optimisation"](https://arxiv.org/abs/2312.13010), 2023. A representative generate-test-repair scaffold with specialized agent roles.

**LLM-28.** Maciej Besta et al. ["Graph of Thoughts: Solving Elaborate Problems with Large Language Models"](https://arxiv.org/abs/2308.09687), AAAI 2024. Generalizes linear and tree-shaped prompting to graph-structured transformations and aggregation.

## Genetic programming, evolutionary search, and quality diversity {-}

**EV-01.** John H. Holland. *Adaptation in Natural and Artificial Systems*. University of Michigan Press, 1975; MIT Press reprint, 1992. The foundational genetic-algorithm treatment of adaptation through selection and variation.

**EV-02.** David E. Goldberg. *Genetic Algorithms in Search, Optimization, and Machine Learning*. Addison-Wesley, 1989. Standard engineering introduction to representation, fitness, selection, crossover, and mutation.

**EV-03.** John R. Koza. *Genetic Programming: On the Programming of Computers by Means of Natural Selection*. MIT Press, 1992. The classic formulation of evolving executable syntax trees.

**EV-04.** Riccardo Poli, William B. Langdon, and Nicholas F. McPhee. [*A Field Guide to Genetic Programming*](http://www.gp-field-guide.org.uk/), 2008. Open textbook covering GP representations, operators, dynamics, bloat, and evaluation.

**EV-05.** Wolfgang Banzhaf et al. *Genetic Programming: An Introduction*. Morgan Kaufmann, 1998. Broad treatment of program representations and evolutionary operators.

**EV-06.** Kenneth A. De Jong. *Evolutionary Computation: A Unified Approach*. MIT Press, 2006. A careful account of evolutionary search as stochastic adaptation rather than biological metaphor alone.

**EV-07.** Kalyanmoy Deb et al. ["A Fast and Elitist Multiobjective Genetic Algorithm: NSGA-II"](https://doi.org/10.1109/4235.996017), *IEEE Transactions on Evolutionary Computation* 6(2), 2002. Canonical non-dominated sorting and crowding-distance selection.

**EV-08.** Jean-Baptiste Mouret and Jeff Clune. ["Illuminating Search Spaces by Mapping Elites"](https://arxiv.org/abs/1504.04909), 2015. Introduces MAP-Elites and behaviorally indexed archives.

**EV-09.** Justin K. Pugh, Lisa B. Soros, and Kenneth O. Stanley. ["Quality Diversity: A New Frontier for Evolutionary Computation"](https://doi.org/10.3389/frobt.2016.00040), *Frontiers in Robotics and AI* 3, 2016. Unifies optimization and diversity preservation.

**EV-10.** Joel Lehman and Kenneth O. Stanley. ["Abandoning Objectives: Evolution Through the Search for Novelty Alone"](https://doi.org/10.1162/EVCO_a_00025), *Evolutionary Computation* 19(2), 2011. Demonstrates the limitations of a single objective in deceptive spaces.

**EV-11.** Kenneth O. Stanley and Risto Miikkulainen. ["Evolving Neural Networks Through Augmenting Topologies"](https://doi.org/10.1162/106365602320169811), *Evolutionary Computation* 10(2), 2002. NEAT is relevant because it evolves both parameters and structure while protecting innovations.

**EV-12.** Stephanie Forrest et al. ["A Genetic Programming Approach to Automated Software Repair"](https://doi.org/10.1145/1569901.1570031), GECCO 2009. Evolves source patches against test suites and exposes the specification weakness of tests.

**EV-13.** Westley Weimer et al. ["Automatically Finding Patches Using Genetic Programming"](https://doi.org/10.1145/1555001.1555043), ICSE 2009. The GenProg line is the closest classical ancestor of test-driven program mutation.

**EV-14.** Nikolaus Hansen and Andreas Ostermeier. ["Completely Derandomized Self-Adaptation in Evolution Strategies"](https://doi.org/10.1162/106365601750190398), *Evolutionary Computation* 9(2), 2001. CMA-ES illustrates adaptation of a proposal distribution, useful when comparing language-conditioned mutation to learned search policies.

**EV-15.** Anne Auger and Benjamin Doerr, editors. *Theory of Randomized Search Heuristics*. World Scientific, 2011. Mathematical tools for analyzing stochastic search, drift, and runtime.

## Program synthesis, repair, and counterexample-guided refinement {-}

**SYN-01.** Sumit Gulwani, Oleksandr Polozov, and Rishabh Singh. ["Program Synthesis"](https://doi.org/10.1561/2500000010), *Foundations and Trends in Programming Languages* 4(1-2), 2017. The standard survey of specifications, search spaces, deductive methods, and practical synthesis.

**SYN-02.** Armando Solar-Lezama. [*Program Synthesis by Sketching*](https://people.csail.mit.edu/asolar/papers/thesis.pdf), PhD thesis, UC Berkeley, 2008. Develops partial programs with holes and constraint-based completion.

**SYN-03.** Armando Solar-Lezama et al. ["Combinatorial Sketching for Finite Programs"](https://doi.org/10.1145/1168857.1168907), ASPLOS 2006. A foundational Sketch paper.

**SYN-04.** Susmit Jha et al. ["Oracle-Guided Component-Based Program Synthesis"](https://doi.org/10.1109/ICSE.2010.5489505), ICSE 2010. Gives an early explicit counterexample-guided inductive synthesis architecture.

**SYN-05.** Rajeev Alur et al. ["Syntax-Guided Synthesis"](https://ieeexplore.ieee.org/document/6679385), FMCAD 2013. Separates a semantic specification from a grammar restricting admissible implementations.

**SYN-06.** Nadia Polikarpova, Ivan Kuraj, and Armando Solar-Lezama. ["Program Synthesis from Polymorphic Refinement Types"](https://doi.org/10.1145/2908080.2908093), PLDI 2016. Synquid demonstrates proof-directed search in a refinement-typed language.

**SYN-07.** Peter-Michael Osera and Steve Zdancewic. ["Type-and-Example-Directed Program Synthesis"](https://doi.org/10.1145/2737924.2738007), PLDI 2015. Combines type structure with input-output examples to prune synthesis.

**SYN-08.** Sumit Gulwani. ["Automating String Processing in Spreadsheets Using Input-Output Examples"](https://doi.org/10.1145/1926385.1926423), POPL 2011. FlashFill is a landmark example of domain-specific synthesis with a carefully designed DSL.

**SYN-09.** Rajeev Alur et al. ["Scaling Enumerative Program Synthesis via Divide and Conquer"](https://doi.org/10.1007/978-3-662-54580-5_18), TACAS 2017. Shows how decomposition changes synthesis complexity.

**SYN-10.** Hoang Duong Thien Nguyen et al. ["SemFix: Program Repair via Semantic Analysis"](https://doi.org/10.1109/ICSE.2013.6606623), ICSE 2013. Uses symbolic execution and constraint solving to synthesize repairs.

**SYN-11.** Sergey Mechtaev, Jooyong Yi, and Abhik Roychoudhury. ["Angelix: Scalable Multiline Program Patch Synthesis via Symbolic Analysis"](https://doi.org/10.1145/2818754.281878angelix), ICSE 2016. Combines fault localization, symbolic reasoning, and patch synthesis. Consult the publisher record for the canonical DOI because some bibliographic databases normalize this identifier differently.

**SYN-12.** Fan Long and Martin Rinard. ["Automatic Patch Generation by Learning Correct Code"](https://doi.org/10.1145/2837614.2837617), POPL 2016. Prophet learns a ranking model over candidate patches, illustrating the distinction between candidate generation and selection.

**SYN-13.** Johannes Bader et al. ["Getafix: Learning to Fix Bugs Automatically"](https://doi.org/10.1145/3360585), *Proceedings of the ACM on Programming Languages* 3(OOPSLA), 2019. Mines human patches into hierarchical transformation patterns.

**SYN-14.** Claire Le Goues et al. ["The ManyBugs and IntroClass Benchmarks for Automated Repair of C Programs"](https://doi.org/10.1109/TSE.2015.2454513), *IEEE Transactions on Software Engineering* 41(12), 2015. Benchmark methodology for repair systems.

**SYN-15.** Martin Monperrus. ["Automatic Software Repair: A Bibliography"](https://doi.org/10.1145/3105906), *ACM Computing Surveys* 51(1), 2018. Broad map of repair approaches and evaluation pitfalls.

**SYN-16.** Yu Pei et al. ["Automated Fixing of Programs with Contracts"](https://doi.org/10.1109/TSE.2013.19), *IEEE Transactions on Software Engineering* 40(5), 2014. Uses contracts as repair oracles, closer to the hard-admissibility layer advocated here.

**SYN-17.** Tom Schrijvers et al. ["Search Combinators"](https://doi.org/10.1017/S0956796813000091), *Journal of Functional Programming* 23(5), 2013. A compositional language for controlling search, relevant to typed optimizer policies.

**SYN-18.** Emina Torlak and Rastislav Bodik. ["Growing Solver-Aided Languages with Rosette"](https://doi.org/10.1145/2666356.2594340), Onward! 2013. Shows how host languages can expose solver-backed verification and synthesis through a disciplined semantic layer.

## Category theory, effects, probability, feedback, and rewrites {-}

**CAT-01.** Saunders Mac Lane. *Categories for the Working Mathematician*, second edition. Springer, 1998. The classical reference for categories, functors, natural transformations, adjunctions, limits, and monoidal structure.

**CAT-02.** Steve Awodey. *Category Theory*, second edition. Oxford University Press, 2010. A concise route from universal properties to categorical logic.

**CAT-03.** Emily Riehl. [*Category Theory in Context*](https://math.jhu.edu/~eriehl/context.pdf). Dover, 2016. Freely available, rigorous, and especially strong on universal constructions and adjunctions.

**CAT-04.** Brendan Fong and David I. Spivak. [*An Invitation to Applied Category Theory: Seven Sketches in Compositionality*](https://arxiv.org/abs/1803.05316). Cambridge University Press, 2019. The most directly useful applied-category-theory text for programmers.

**CAT-05.** David I. Spivak. *Category Theory for the Sciences*. MIT Press, 2014. Develops schemas, ologs, databases, and compositional modeling.

**CAT-06.** Bartosz Milewski. [*Category Theory for Programmers*](https://github.com/hmemcpy/milewski-ctfp-pdf), 2018. Programmer-oriented exposition; pair it with a formal text for proof details.

**CAT-07.** Benjamin C. Pierce. *Basic Category Theory for Computer Scientists*. MIT Press, 1991. Compact bridge between categorical concepts and programming-language semantics.

**CAT-08.** Michael Barr and Charles Wells. [*Category Theory for Computing Science*](https://www.math.mcgill.ca/triples/Barr-Wells-ctcs.pdf), third edition, 1999. Broad computer-science reference.

**CAT-09.** John C. Baez and Mike Stay. ["Physics, Topology, Logic and Computation: A Rosetta Stone"](https://arxiv.org/abs/0903.0340), 2011. Relates monoidal categories, proofs, processes, and computation through string diagrams.

**CAT-10.** Eugenio Moggi. ["Notions of Computation and Monads"](https://doi.org/10.1016/0890-5401(91)90052-4), *Information and Computation* 93(1), 1991. The foundational semantics of computational effects via monads.

**CAT-11.** Philip Wadler. ["The Essence of Functional Programming"](https://doi.org/10.1145/143165.143169), POPL 1992. Makes monadic programming concrete in a functional language.

**CAT-12.** Gordon Plotkin and John Power. ["Algebraic Operations and Generic Effects"](https://doi.org/10.1023/A:1023064908962), *Applied Categorical Structures* 11, 2003. Separates algebraic operations from handlers and models effects compositionally.

**CAT-13.** Gordon Plotkin and Matija Pretnar. ["Handling Algebraic Effects"](https://doi.org/10.2168/LMCS-9(4:23)2013), *Logical Methods in Computer Science* 9(4), 2013. A core reference for effect handlers.

**CAT-14.** Robert Atkey. ["Parameterised Notions of Computation"](https://doi.org/10.1017/S095679680800728X), *Journal of Functional Programming* 19(3-4), 2009. Introduces parameterized monads, useful when pre- and post-state indices matter.

**CAT-15.** Shin-ya Katsumata. ["Parametric Effect Monads and Semantics of Effect Systems"](https://doi.org/10.1145/2535838.2535846), POPL 2014. Connects effect systems and graded/parameterized semantic structures.

**CAT-16.** Dominic Orchard, Vilem-Benjamin Liepelt, and Harley Eades III. ["Quantitative Program Reasoning with Graded Modal Types"](https://doi.org/10.1145/3371119), *Proceedings of the ACM on Programming Languages* 3(ICFP), 2019. Develops grades as quantitative modalities.

**CAT-17.** Jean-Yves Girard. ["Linear Logic"](https://doi.org/10.1016/0304-0208(87)90045-4), *Theoretical Computer Science* 50, 1987. Foundational resource-sensitive logic.

**CAT-18.** Nick Benton. ["A Mixed Linear and Non-Linear Logic: Proofs, Terms and Models"](https://doi.org/10.1007/BFb0022861), CSL 1994. A categorical bridge between ordinary and resource-sensitive computation.

**CAT-19.** Tobias Fritz. ["A Synthetic Approach to Markov Kernels, Conditional Independence and theorems on Sufficient Statistics"](https://doi.org/10.1016/j.aim.2020.107239), *Advances in Mathematics* 370, 2020. Develops Markov categories as a compositional language for stochastic systems.

**CAT-20.** Kenta Cho and Bart Jacobs. ["Disintegration and Bayesian Inversion via String Diagrams"](https://doi.org/10.1017/S0960129518000488), *Mathematical Structures in Computer Science* 29(7), 2019. Graphical treatment of conditioning and Bayesian inversion.

**CAT-21.** Bart Jacobs. *Introduction to Coalgebra: Towards Mathematics of States and Observation*. Cambridge University Press, 2016. A systematic account of state-based and potentially infinite behavior.

**CAT-22.** Jan Rutten. ["Universal Coalgebra: A Theory of Systems"](https://doi.org/10.1016/S0304-3975(00)00056-6), *Theoretical Computer Science* 249(1), 2000. Classic survey of coalgebra, bisimulation, and final semantics.

**CAT-23.** André Joyal, Ross Street, and Dominic Verity. ["Traced Monoidal Categories"](https://doi.org/10.1017/S0305004100074338), *Mathematical Proceedings of the Cambridge Philosophical Society* 119(3), 1996. Axiomatizes feedback in monoidal categories.

**CAT-24.** Stephen L. Bloom and Zoltán Ésik. *Iteration Theories*. Springer, 1993. Algebraic laws for fixed points and iteration.

**CAT-25.** Brendan Fong, David Spivak, and Rémy Tuyéras. ["Backprop as Functor: A Compositional Perspective on Supervised Learning"](https://arxiv.org/abs/1711.10455), LICS 2019. Models learners and backpropagation compositionally.

**CAT-26.** Geoffrey Cruttwell et al. ["Categorical Foundations of Gradient-Based Learning"](https://arxiv.org/abs/2103.01931), ESOP 2022. Develops reverse derivative categories and clarifies which algebraic laws make gradients compositional.

**CAT-27.** Mitchell Riley. ["Categories of Optics"](https://arxiv.org/abs/1809.00738), 2018. A general categorical account of lenses, prisms, and related bidirectional structures.

**CAT-28.** Matthew Pickering, Jeremy Gibbons, and Nicolas Wu. ["Profunctor Optics: Modular Data Accessors"](https://doi.org/10.22152/programming-journal.org/2017/1/7), *The Art, Science, and Engineering of Programming* 1(2), 2017. Practical algebra of composable data access and updates.

**CAT-29.** David I. Spivak. ["The Operad of Wiring Diagrams: Formalizing a Graphical Language for Databases, Recursion, and Plug-and-Play Circuits"](https://arxiv.org/abs/1305.0297), 2013. Operadic syntax for composing architectures.

**CAT-30.** Michael Shulman. ["Framed Bicategories and Monoidal Fibrations"](https://www.tac.mta.ca/tac/volumes/20/18/20-18abs.html), *Theory and Applications of Categories* 20, 2008. A rigorous source for double-categorical structures and horizontal/vertical composition.

**CAT-31.** Tom Leinster. [*Basic Bicategories*](https://arxiv.org/abs/math/9810017), 1998. Compact introduction to bicategories and 2-cells.

**CAT-32.** Jean Bénabou. ["Introduction to Bicategories"](https://doi.org/10.1007/BFb0074299), 1967. Foundational source for weak two-dimensional composition.

**CAT-33.** F. William Lawvere. ["Metric Spaces, Generalized Logic, and Closed Categories"](https://www.tac.mta.ca/tac/reprints/articles/1/tr1abs.html), 1973; *Theory and Applications of Categories* reprint, 2002. The source for viewing generalized metrics as enrichment over ordered monoids.

**CAT-34.** G. M. Kelly. [*Basic Concepts of Enriched Category Theory*](https://www.tac.mta.ca/tac/reprints/articles/10/tr10abs.html), 1982; reprint 2005. Standard reference for order- and metric-enriched categories.

**CAT-35.** Peter Selinger. ["A Survey of Graphical Languages for Monoidal Categories"](https://arxiv.org/abs/0908.3347), 2011. A practical guide to string-diagram syntax and its soundness.

**CAT-36.** David I. Spivak, Patrick Schultz, and Dylan Rupel. ["String Diagrams for Trace Semantics"](https://arxiv.org/abs/1508.01069), 2015. Relates diagrams, systems, and behavior; useful for treating traces as semantic evidence.

**CAT-37.** Daniel R. Licata and Robert Harper. ["2-Dimensional Directed Type Theory"](https://doi.org/10.1016/j.entcs.2011.09.026), *Electronic Notes in Theoretical Computer Science* 276, 2011. A bridge from categorical directionality to a type theory of transformations.

## Dependent types, refinement, verification, and proof-carrying code {-}

**TYPE-01.** Per Martin-Löf. *Intuitionistic Type Theory*. Bibliopolis, 1984. Foundational dependent type theory.

**TYPE-02.** Bengt Nordström, Kent Petersson, and Jan M. Smith. [*Programming in Martin-Löf's Type Theory*](http://www.cse.chalmers.se/research/group/logic/book/), Oxford University Press, 1990. A programming-oriented account of constructive type theory.

**TYPE-03.** Thierry Coquand and Gérard Huet. ["The Calculus of Constructions"](https://doi.org/10.1016/0890-5401(88)90005-3), *Information and Computation* 76, 1988. A core dependent calculus underlying proof assistants.

**TYPE-04.** Haskell B. Curry and Robert Feys. *Combinatory Logic*, Volume I. North-Holland, 1958. One historical root of the propositions-as-types correspondence.

**TYPE-05.** William A. Howard. ["The Formulae-as-Types Notion of Construction"](https://doi.org/10.1016/S0049-237X(08)71941-0), written 1969, published 1980. The canonical statement of the correspondence now called Curry-Howard.

**TYPE-06.** Philip Wadler. ["Propositions as Types"](https://doi.org/10.1145/2699407), *Communications of the ACM* 58(12), 2015. Accessible modern exposition.

**TYPE-07.** Benjamin C. Pierce. *Types and Programming Languages*. MIT Press, 2002. Standard text on operational semantics and type systems.

**TYPE-08.** Robert Harper. [*Practical Foundations for Programming Languages*](https://www.cs.cmu.edu/~rwh/pfpl/), second edition, Cambridge University Press, 2016. Systematic type-theoretic account of programming languages.

**TYPE-09.** Simon Thompson. *Type Theory and Functional Programming*. Addison-Wesley, 1991. An accessible bridge from functional programs to constructive proof.

**TYPE-10.** Leonardo de Moura and Sebastian Ullrich. ["The Lean 4 Theorem Prover and Programming Language"](https://doi.org/10.1007/978-3-030-79876-5_37), CADE 2021. Describes Lean 4's kernel, elaborator, metaprogramming, and runtime.

**TYPE-11.** Lean community. [*Theorem Proving in Lean 4*](https://lean-lang.org/theorem_proving_in_lean4/) and [*Functional Programming in Lean*](https://lean-lang.org/functional_programming_in_lean/). Official, executable introductions.

**TYPE-12.** Yves Bertot and Pierre Castéran. [*Interactive Theorem Proving and Program Development: Coq'Art*](https://doi.org/10.1007/978-3-662-07964-5). Springer, 2004. Foundational Coq textbook.

**TYPE-13.** Adam Chlipala. [*Certified Programming with Dependent Types*](http://adam.chlipala.net/cpdt/). MIT Press, 2013. Proof engineering and verified programming in Coq.

**TYPE-14.** Ulf Norell. ["Dependently Typed Programming in Agda"](https://www.cse.chalmers.se/~ulfn/papers/afp08/tutorial.pdf), AFP 2008. Practical Agda introduction.

**TYPE-15.** Edwin Brady. ["Idris 2: Quantitative Type Theory in Practice"](https://doi.org/10.4230/LIPIcs.ECOOP.2021.9), ECOOP 2021. Combines dependent types with quantitative usage information.

**TYPE-16.** Niki Vazou et al. ["Refinement Types for Haskell"](https://doi.org/10.1145/2628136.2628161), ICFP 2014. Liquid Haskell integrates SMT-backed refinements with a general-purpose language.

**TYPE-17.** Patrick M. Rondon, Ming Kawaguchi, and Ranjit Jhala. ["Liquid Types"](https://doi.org/10.1145/1375581.1375602), PLDI 2008. Establishes predicate abstraction as a route to decidable refinement inference.

**TYPE-18.** Niki Vazou et al. ["Refinement Reflection: Complete Verification with SMT"](https://doi.org/10.1145/3158141), *Proceedings of the ACM on Programming Languages* 2(POPL), 2018. Makes reflected definitions available to refinement proofs.

**TYPE-19.** Nadia Polikarpova et al. Synquid, cited as SYN-06. Read from the type-theory side for proof-directed synthesis and from the synthesis side for search pruning.

**TYPE-20.** Daan Leijen. ["Koka: Programming with Row-Polymorphic Effect Types"](https://www.microsoft.com/en-us/research/publication/koka-programming-with-row-polymorphic-effect-types/), 2014. Practical effect typing with inferred effect rows.

**TYPE-21.** Daan Leijen. ["Type Directed Compilation of Row-Typed Algebraic Effects"](https://doi.org/10.1145/3009837.3009872), POPL 2017. Connects algebraic-effect typing to efficient implementation.

**TYPE-22.** Danel Ahman et al. ["Dijkstra Monads for Free"](https://arxiv.org/abs/1608.06499), POPL 2017. Derives weakest-precondition calculi from monadic semantics.

**TYPE-23.** Nikhil Swamy et al. ["Dependent Types and Multi-Monadic Effects in F*"](https://doi.org/10.1145/2837614.2837655), POPL 2016. A practical verification system for effectful programs.

**TYPE-24.** C. A. R. Hoare. ["An Axiomatic Basis for Computer Programming"](https://doi.org/10.1145/363235.363259), *Communications of the ACM* 12(10), 1969. Introduces Hoare triples.

**TYPE-25.** Robert W. Floyd. "Assigning Meanings to Programs." In *Mathematical Aspects of Computer Science*, AMS, 1967. Early inductive-assertion method.

**TYPE-26.** Edsger W. Dijkstra. ["Guarded Commands, Nondeterminacy and Formal Derivation of Programs"](https://doi.org/10.1145/360933.360975), *Communications of the ACM* 18(8), 1975. Develops weakest preconditions and calculational program derivation.

**TYPE-27.** John C. Reynolds. ["Separation Logic: A Logic for Shared Mutable Data Structures"](https://doi.org/10.1109/LICS.2002.1029817), LICS 2002. Local reasoning for heap-manipulating programs.

**TYPE-28.** Peter O'Hearn. ["Resources, Concurrency, and Local Reasoning"](https://doi.org/10.1016/j.tcs.2006.12.035), *Theoretical Computer Science* 375, 2007. Connects separation logic to resource semantics.

**TYPE-29.** Ralf Jung et al. ["Iris: Monoids and Invariants as an Orthogonal Basis for Concurrent Reasoning"](https://doi.org/10.1145/2818638), POPL 2015. A higher-order concurrent separation logic suitable for modular proof.

**TYPE-30.** George C. Necula. ["Proof-Carrying Code"](https://doi.org/10.1145/263699.263712), POPL 1997. Establishes the producer-supplies-proof, consumer-checks-proof architecture.

**TYPE-31.** Greg Morrisett et al. ["From System F to Typed Assembly Language"](https://doi.org/10.1145/289423.289462), POPL 1998. Shows how safety evidence can survive compilation to low-level code.

**TYPE-32.** Xavier Leroy. ["Formal Verification of a Realistic Compiler"](https://doi.org/10.1145/1538788.1538814), *Communications of the ACM* 52(7), 2009. Overview of CompCert and proof-preserving compilation.

**TYPE-33.** Amir Pnueli, Michael Siegel, and Eli Singerman. ["Translation Validation"](https://doi.org/10.1007/BFb0054170), TACAS 1998. Validates each translation result rather than proving the translator itself.

**TYPE-34.** K. Rustan M. Leino. ["Dafny: An Automatic Program Verifier for Functional Correctness"](https://doi.org/10.1007/978-3-642-17511-4_20), LPAR 2010. Combines contracts, SMT automation, and executable code.

**TYPE-35.** Jean-Christophe Filliâtre and Andrei Paskevich. ["Why3 - Where Programs Meet Provers"](https://doi.org/10.1007/978-3-642-37036-6_8), ESOP 2013. Intermediate verification language targeting multiple provers.

**TYPE-36.** Patrick Cousot and Radhia Cousot. ["Abstract Interpretation: A Unified Lattice Model for Static Analysis"](https://doi.org/10.1145/512950.512973), POPL 1977. The foundation for sound approximation and static analysis.

**TYPE-37.** Edmund M. Clarke, Orna Grumberg, and Doron Peled. *Model Checking*. MIT Press, 1999. Finite-state temporal verification and counterexample generation.

**TYPE-38.** Leslie Lamport. [*Specifying Systems: The TLA+ Language and Tools for Hardware and Software Engineers*](https://lamport.azurewebsites.net/tla/book.html). Addison-Wesley, 2002. State-machine specifications and refinement for concurrent systems.

**TYPE-39.** Robert Bruce Findler and Matthias Felleisen. ["Contracts for Higher-Order Functions"](https://doi.org/10.1145/581478.581484), ICFP 2002. Blame-aware run-time contracts for higher-order programs.

**TYPE-40.** Gerwin Klein et al. ["seL4: Formal Verification of an OS Kernel"](https://doi.org/10.1145/1629575.1629596), SOSP 2009. Demonstrates end-to-end machine-checked assurance at systems scale.

## Homotopy type theory, univalence, and direction {-}

**HOTT-01.** The Univalent Foundations Program. [*Homotopy Type Theory: Univalent Foundations of Mathematics*](https://homotopytypetheory.org/book/), Institute for Advanced Study, 2013. The central textbook for identity as paths, univalence, higher inductive types, and truncation.

**HOTT-02.** Martin Hofmann and Thomas Streicher. ["The Groupoid Interpretation of Type Theory"](https://doi.org/10.1090/conm/228/03319), 1998. Shows that identity proofs can carry nontrivial structure rather than collapsing to proof irrelevance.

**HOTT-03.** Steve Awodey and Michael A. Warren. ["Homotopy Theoretic Models of Identity Types"](https://doi.org/10.1017/S0305004108001783), *Mathematical Proceedings of the Cambridge Philosophical Society* 146(1), 2009. Connects intensional identity types to homotopy-theoretic path objects.

**HOTT-04.** Vladimir Voevodsky. ["Univalent Foundations of Mathematics"](https://www.math.ias.edu/vladimir/sites/math.ias.edu.vladimir/files/2014_04_29_univalent_foundations.pdf), 2014 lecture notes. Motivation and overview from the originator of the univalence program.

**HOTT-05.** Cyril Cohen, Thierry Coquand, Simon Huber, and Anders Mörtberg. ["Cubical Type Theory: A Constructive Interpretation of the Univalence Axiom"](https://arxiv.org/abs/1611.02108), TYPES 2015 / LIPIcs 2018. Gives computational content to paths and univalence.

**HOTT-06.** Thierry Coquand, Simon Huber, and Anders Mörtberg. ["On Higher Inductive Types in Cubical Type Theory"](https://arxiv.org/abs/1802.01170), LICS 2018. Computational treatment of higher inductive types.

**HOTT-07.** Benedikt Ahrens, Krzysztof Kapulkin, and Michael Shulman. ["Univalent Categories and the Rezk Completion"](https://doi.org/10.1017/S0960129514000486), *Mathematical Structures in Computer Science* 25(5), 2015. Applies univalence to categories and clarifies equality versus equivalence of objects.

**HOTT-08.** Emily Riehl and Michael Shulman. ["A Type Theory for Synthetic Infinity-Categories"](https://arxiv.org/abs/1705.07442), *Higher Structures* 1(1), 2017. Develops directed structure inside type theory using shapes and extension types.

**HOTT-09.** Daniel R. Licata and Robert Harper. "2-Dimensional Directed Type Theory," cited as CAT-37. A direct precursor for modeling transformations that are not invertible.

**HOTT-10.** Daniel R. Licata and Michael Shulman. ["Calculating the Fundamental Group of the Circle in Homotopy Type Theory"](https://doi.org/10.1109/LICS.2013.28), LICS 2013. A compact worked example of higher-inductive reasoning.

**HOTT-11.** Egbert Rijke, Michael Shulman, and Bas Spitters. ["Modalities in Homotopy Type Theory"](https://arxiv.org/abs/1706.07526), *Logical Methods in Computer Science* 16(1), 2020. Systematic treatment of reflective subuniverses and information-forgetting modalities.

**HOTT-12.** Carlo Angiuli, Robert Harper, and Todd Wilson. ["Computational Higher Type Theory I: Abstract Cubical Realizability"](https://doi.org/10.1145/2951919.2951921), POPL 2017. Computational semantics for higher-dimensional type theory.

**HOTT-13.** Guillaume Brunerie. [*On the Homotopy Groups of Spheres in Homotopy Type Theory*](https://arxiv.org/abs/1606.05916), PhD thesis, 2016. Demonstrates substantial machine-assisted mathematics inside HoTT.

**HOTT-14.** UniMath community. [UniMath library](https://github.com/UniMath/UniMath). A large Coq development based on univalent foundations, useful for studying proof engineering at scale.

**HOTT-15.** Cubical Agda community. [Cubical Agda library and documentation](https://agda.github.io/cubical/). Executable examples of paths, equivalences, univalence, and higher inductive types.

**HOTT-16.** Jonathan Sterling and Carlo Angiuli. ["Normalization for Cubical Type Theory"](https://arxiv.org/abs/2101.11479), LICS 2021. Metatheory relevant to trustworthy computation with cubical paths.

**HOTT-17.** Ulrik Buchholtz and Jonathan Weinberger. ["Synthetic Fibered (Infinity,1)-Category Theory"](https://arxiv.org/abs/2105.01724), 2021. Develops directed categorical structures internally; useful for version graphs and indexed architecture families.

**HOTT-18.** Peter LeFanu Lumsdaine and Michael Shulman. ["Semantics of Higher Inductive Types"](https://doi.org/10.1017/S096012951700015X), *Mathematical Structures in Computer Science* 29(5), 2019. Semantic foundations for freely generated points, paths, and higher coherences.

## LLM judges, Goodhart effects, uncertainty, and experimental design {-}

**EVAL-01.** Lianmin Zheng et al. ["Judging LLM-as-a-Judge with MT-Bench and Chatbot Arena"](https://arxiv.org/abs/2306.05685), NeurIPS 2023. Establishes common pairwise and single-answer judge protocols and documents position, verbosity, and self-enhancement biases.

**EVAL-02.** Yang Liu et al. ["G-Eval: NLG Evaluation Using GPT-4 with Better Human Alignment"](https://arxiv.org/abs/2303.16634), EMNLP 2023. Uses structured criteria and chain-of-thought-style evaluation forms.

**EVAL-03.** Peiyi Wang et al. ["Large Language Models Are Not Fair Evaluators"](https://arxiv.org/abs/2305.17926), ACL 2024. Studies order sensitivity and proposes calibration strategies.

**EVAL-04.** Rickard Stureborg et al. ["Large Language Models Are Inconsistent and Biased Evaluators"](https://arxiv.org/abs/2405.01724), 2024. Examines variability and systematic bias across evaluation settings.

**EVAL-05.** Arjun Panickssery et al. ["LLM Evaluators Recognize and Favor Their Own Generations"](https://arxiv.org/abs/2404.13076), NeurIPS 2024. Evidence for self-preference that matters when proposer and judge share a model family.

**EVAL-06.** Xinyang Yu et al. ["JudgeBench: A Benchmark for Evaluating LLM-Based Judges"](https://arxiv.org/abs/2410.12784), 2024. Tests judges on challenging pairwise comparisons and adversarial cases.

**EVAL-07.** Samuel Gehman et al. ["RealToxicityPrompts: Evaluating Neural Toxic Degeneration in Language Models"](https://arxiv.org/abs/2009.11462), Findings of EMNLP 2020. Illustrates benchmark construction for a soft but consequential property.

**EVAL-08.** David Manheim and Scott Garrabrant. ["Categorizing Variants of Goodhart's Law"](https://arxiv.org/abs/1803.04585), 2018. Distinguishes regressional, extremal, causal, and adversarial failures.

**EVAL-09.** Charles Goodhart. "Problems of Monetary Management: The U.K. Experience." In *Papers in Monetary Economics*, Reserve Bank of Australia, 1975. Historical source of Goodhart's law.

**EVAL-10.** Donald T. Campbell. "Assessing the Impact of Planned Social Change." *Evaluation and Program Planning* 2(1), 1979. Campbell's law emphasizes corruption of indicators under decision pressure.

**EVAL-11.** James E. Smith and Robert L. Winkler. ["The Optimizer's Curse: Skepticism and Postdecision Surprise in Decision Analysis"](https://doi.org/10.1287/mnsc.1050.0451), *Management Science* 52(3), 2006. Formalizes selection-induced optimism among noisy alternatives.

**EVAL-12.** Edwin B. Wilson. ["Probable Inference, the Law of Succession, and Statistical Inference"](https://doi.org/10.1080/01621459.1927.10502953), *Journal of the American Statistical Association* 22, 1927. Source of the Wilson binomial interval used in the Flex report.

**EVAL-13.** Quinn McNemar. ["Note on the Sampling Error of the Difference Between Correlated Proportions or Percentages"](https://doi.org/10.1007/BF02295996), *Psychometrika* 12, 1947. Paired binary-outcome test appropriate for comparing two classifiers on the same examples.

**EVAL-14.** Bradley Efron and Robert Tibshirani. *An Introduction to the Bootstrap*. Chapman and Hall/CRC, 1993. Standard resampling reference.

**EVAL-15.** Thomas G. Dietterich. ["Approximate Statistical Tests for Comparing Supervised Classification Learning Algorithms"](https://doi.org/10.1162/089976698300017197), *Neural Computation* 10(7), 1998. Explains dependence and variance problems in classifier comparisons.

**EVAL-16.** Janez Demšar. ["Statistical Comparisons of Classifiers over Multiple Data Sets"](https://jmlr.org/papers/v7/demsar06a.html), *Journal of Machine Learning Research* 7, 2006. Nonparametric comparison procedures across tasks.

**EVAL-17.** Yoav Benjamini and Yosef Hochberg. ["Controlling the False Discovery Rate"](https://doi.org/10.1111/j.2517-6161.1995.tb02031.x), *Journal of the Royal Statistical Society B* 57(1), 1995. Multiple-comparison control relevant to broad candidate sweeps.

**EVAL-18.** Glenn W. Brier. ["Verification of Forecasts Expressed in Terms of Probability"](https://doi.org/10.1175/1520-0493(1950)078%3C0001:VOFEIT%3E2.0.CO;2), *Monthly Weather Review* 78, 1950. Introduces the Brier score for probabilistic calibration.

**EVAL-19.** Morris H. DeGroot and Stephen E. Fienberg. ["The Comparison and Evaluation of Forecasters"](https://doi.org/10.2307/2987588), *The Statistician* 32, 1983. Calibration and refinement decomposition.

**EVAL-20.** Yonatan Geifman and Ran El-Yaniv. ["Selective Classification for Deep Neural Networks"](https://arxiv.org/abs/1705.08500), NeurIPS 2017. Formalizes risk-coverage tradeoffs for abstaining systems.

**EVAL-21.** Vladimir Vovk, Alexander Gammerman, and Glenn Shafer. *Algorithmic Learning in a Random World*. Springer, 2005. Foundational conformal prediction.

**EVAL-22.** Anastasios N. Angelopoulos and Stephen Bates. ["A Gentle Introduction to Conformal Prediction and Distribution-Free Uncertainty Quantification"](https://arxiv.org/abs/2107.07511), 2021. Practical modern tutorial.

**EVAL-23.** Cynthia Dwork et al. ["The Reusable Holdout: Preserving Validity in Adaptive Data Analysis"](https://doi.org/10.1126/science.aaa9375), *Science* 349(6248), 2015. Shows how adaptive reuse of evaluation data invalidates ordinary generalization assumptions and gives a privacy-based remedy.

**EVAL-24.** Avrim Blum and Moritz Hardt. ["The Ladder: A Reliable Leaderboard for Machine Learning Competitions"](https://doi.org/10.1145/2783258.278330榜), ICML 2015. Introduces mechanisms limiting leaderboard overfitting; consult the canonical proceedings record for the normalized DOI.

**EVAL-25.** Daniel Russo and James Zou. ["How Much Does Your Data Exploration Overfit? Controlling Bias via Information Usage"](https://doi.org/10.1109/TIT.2019.2945779), *IEEE Transactions on Information Theory* 66(1), 2020. Information-theoretic analysis of adaptivity and selection bias.

**EVAL-26.** Peter Grünwald and A. Philip Dawid. ["Game Theory, Maximum Entropy, Minimum Discrepancy and Robust Bayesian Decision Theory"](https://doi.org/10.1214/009053604000000571), *Annals of Statistics* 32(4), 2004. Connects proper scoring rules and decision-theoretic evaluation.

**EVAL-27.** NIST. [*Artificial Intelligence Risk Management Framework (AI RMF 1.0)*](https://www.nist.gov/itl/ai-risk-management-framework), 2023. Governance framework for mapping, measuring, managing, and documenting AI risk.

## Sandboxing, capabilities, provenance, and reproducible artifacts {-}

**SYS-01.** Jerome H. Saltzer and Michael D. Schroeder. ["The Protection of Information in Computer Systems"](https://doi.org/10.1109/PROC.1975.9939), *Proceedings of the IEEE* 63(9), 1975. Source of least privilege, complete mediation, economy of mechanism, and related design principles.

**SYS-02.** Butler W. Lampson. ["Protection"](https://doi.org/10.1145/361011.361067), *Operating Systems Review* 8(1), 1974; originally 1971. Access-control matrix and protection-domain foundations.

**SYS-03.** Dorothy E. Denning. ["A Lattice Model of Secure Information Flow"](https://doi.org/10.1145/360051.360056), *Communications of the ACM* 19(5), 1976. Formal basis for information-flow policies.

**SYS-04.** Andrei Sabelfeld and Andrew C. Myers. ["Language-Based Information-Flow Security"](https://doi.org/10.1109/JSAC.2002.806121), *IEEE Journal on Selected Areas in Communications* 21(1), 2003. Survey of noninterference and language enforcement.

**SYS-05.** Mark S. Miller. [*Robust Composition: Towards a Unified Approach to Access Control and Concurrency Control*](http://www.erights.org/talks/thesis/), PhD thesis, Johns Hopkins University, 2006. Capability-oriented composition under mutual distrust.

**SYS-06.** David Wagner and Dean Tribble. ["A Security Analysis of the Combex DarpaBrowser Architecture"](http://www.erights.org/talks/browser/), 2002. Concrete object-capability analysis.

**SYS-07.** Robert Watson et al. ["Capsicum: Practical Capabilities for UNIX"](https://www.usenix.org/legacy/events/sec10/tech/full_papers/Watson.pdf), USENIX Security 2010. Capability mode and fine-grained rights for sandboxing applications.

**SYS-08.** Bennet Yee et al. ["Native Client: A Sandbox for Portable, Untrusted x86 Native Code"](https://research.google/pubs/native-client-a-sandbox-for-portable-untrusted-x86-native-code/), IEEE Symposium on Security and Privacy 2009. Software validation plus process isolation for untrusted code.

**SYS-09.** Robert Wahbe et al. ["Efficient Software-Based Fault Isolation"](https://doi.org/10.1145/168619.168635), SOSP 1993. Foundational software fault isolation.

**SYS-10.** Andreas Rossberg. ["WebAssembly Core Specification"](https://www.w3.org/TR/wasm-core-2/), W3C Recommendation. A compact, typed, sandbox-oriented bytecode semantics suitable for restricted generated components.

**SYS-11.** W3C Provenance Working Group. [*PROV-DM: The PROV Data Model*](https://www.w3.org/TR/prov-dm/), 2013. Standard vocabulary for entities, activities, agents, derivations, and attribution.

**SYS-12.** Supply-chain Levels for Software Artifacts. [SLSA specification](https://slsa.dev/spec/), OpenSSF. Defines provenance and build-integrity levels for software artifacts.

**SYS-13.** in-toto project. ["in-toto: Providing Farm-to-Table Guarantees for Bits and Bytes"](https://www.usenix.org/conference/usenixsecurity19/presentation/torres-arias), USENIX Security 2019. Cryptographically records and verifies software-supply-chain steps.

**SYS-14.** Reproducible Builds project. [Documentation and practices](https://reproducible-builds.org/docs/). Techniques for making build outputs independently reproducible.

**SYS-15.** Ross Tate et al. ["Equality Saturation: A New Approach to Optimization"](https://doi.org/10.1145/1480881.1480915), POPL 2009. Represents many equivalent rewrites simultaneously and extracts according to a cost model.

**SYS-16.** Max Willsey et al. ["egg: Fast and Extensible Equality Saturation"](https://doi.org/10.1145/3434304), *Proceedings of the ACM on Programming Languages* 5(POPL), 2021. Practical e-graphs for rewrite systems and cost-based extraction.

**SYS-17.** Chris Lattner et al. ["MLIR: Scaling Compiler Infrastructure for Domain Specific Computation"](https://doi.org/10.1109/CGO51591.2021.9370308), CGO 2021. Multi-level intermediate representations and dialects; a strong model for a typed, evolvable harness IR.

**SYS-18.** Xavier Leroy and Sandrine Blazy. ["Formal Verification of a C-Like Memory Model and Its Uses for Verifying Program Transformations"](https://doi.org/10.1007/978-3-540-71316-6_38), JAR 2008. Demonstrates the semantic precision needed to certify low-level rewrites.

**SYS-19.** Patrice Godefroid, Michael Levin, and David Molnar. ["SAGE: Whitebox Fuzzing for Security Testing"](https://doi.org/10.1145/2090147.2094081), *Communications of the ACM* 55(3), 2012. Symbolic execution and generated counterexamples as an evidence source.

**SYS-20.** Tsong Yueh Chen et al. ["Metamorphic Testing: A New Approach for Generating Next Test Cases"](https://www.researchgate.net/publication/228556696_Metamorphic_Testing_A_New_Approach_for_Generating_Next_Test_Cases), 1998. Introduces relations among executions when exact test oracles are unavailable.

## A compact research program {-}

A reader intending to build a formally disciplined self-evolving harness can turn the literature into the following sequence:

1. Implement a small DSPy or equivalent program and make every model/tool call appear in a typed trace. Read LLM-02 through LLM-08.
2. Replace a scalar objective with a vector and maintain a non-dominated archive. Read EV-07 through EV-10.
3. Restrict candidate generation to a typed DSL or IR. Read SYN-02, SYN-05, SYN-18, and SYS-17.
4. Give the IR an effect and resource semantics. Read CAT-10 through CAT-20 and TYPE-20 through TYPE-23.
5. Make each rewrite carry machine-checkable boundary and resource evidence. Read TYPE-24 through TYPE-35.
6. Model exact semantic replacements as paths or equivalences, and one-way improvements as directed morphisms. Read HOTT-01 through HOTT-09 and CAT-33 through CAT-37.
7. Audit the evaluator as an adaptive measurement system. Read EVAL-01 through EVAL-27.
8. Promote only immutable, provenance-linked artifacts through capability-restricted deployment gates. Read SYS-01 through SYS-18.

The resulting system is not autonomous proof by statistical acclaim. It is a proof- and evidence-aware search process whose untrusted generative component is powerful precisely because the surrounding mathematical and operational boundaries are explicit.
EOF

python - <<'PY'
from pathlib import Path
p=Path('/mnt/data/evolving_code_book/evolving-programs-with-language-models.md')
s=p.read_text()
s=s.replace('linkcolor: NavyBlue','linkcolor: blue').replace('urlcolor: NavyBlue','urlcolor: blue').replace('citecolor: NavyBlue','citecolor: blue')
s=s.replace('    \\usepackage{tcolorbox}\n', '    \\usepackage{tcolorbox}\n    \\tcbuselibrary{breakable}\n')
s=s.replace('  = (Y\\to\\mathrm{Prop})\\to X\\to\\mathrm{Prop}\n\na\n\\]', '  = (Y\\to\\mathrm{Prop})\\to X\\to\\mathrm{Prop}\n\\]')
# Escape currency markers that are not mathematical delimiters.
for old,new in [('$0.98','\\$0.98'),('$2.88','\\$2.88'),('$0.70','\\$0.70'),('$0.45','\\$0.45'),('$0.18','\\$0.18'),('$0.09','\\$0.09'),('$0.01','\\$0.01')]:
    s=s.replace(old,new)
# Avoid double escaping if replacements occurred in already escaped strings.
s=s.replace('\\\\$','\\$')
append=Path('/mnt/data/evolving_code_book/sources_appendix.md').read_text()
if '# Sources and Further Reading {-}' not in s:
    s=s.rstrip()+append+'\n'
p.write_text(s)
print('lines', len(s.splitlines()), 'words', len(s.split()), 'bytes', len(s.encode()))
PY

grep -n '^a$\|NavyBlue\|^# Sources and Further Reading' /mnt/data/evolving_code_book/evolving-programs-with-language-models.md || true

```

<details><summary>💭 Thinking</summary>

**Prepared sources appendix references**

</details>

```json
{"search_query":[{"q":"Angelix Scalable Multiline Program Patch Synthesis via Symbolic Analysis DOI ICSE 2016"},{"q":"The Ladder A Reliable Leaderboard for Machine Learning Competitions ICML 2015 paper"},{"q":"JudgeBench A Benchmark for Evaluating LLM-Based Judges arXiv"},{"q":"String Diagrams for Trace Semantics Spivak Schultz Rupel arXiv"}],"response_length":"long"}
```

<details><summary>💭 Thinking</summary>

**Searched 30 websites**

</details>

```unknown
bash -lc grep -nE 'canonical DOI|normalized DOI|angelix|278330|Trace Semantics|SYN-11|EV-13|EVAL-24|HOTT-17|SYS-20' /mnt/data/evolving_code_book/evolving-programs-with-language-models.md
```

<details><summary>💭 Thinking</summary>

**Searched Markdown URLs for invalid and uncertain references**

</details>

```json
{"search_query":[{"q":"\"Automatically Finding Patches Using Genetic Programming\" DOI"},{"q":"\"A Genetic Programming Approach to Automated Software Repair\" DOI"},{"q":"\"Metamorphic Testing: A New Approach for Generating Next Test Cases\" 1998 pdf"},{"q":"\"Synthetic Fibered\" \"Category Theory\" Buchholtz Weinberger title"}],"response_length":"long"}
```

<details><summary>💭 Thinking</summary>

**Searched 28 websites**

</details>

```unknown
bash -lc python - <<'PY'
from pathlib import Path
p=Path('/mnt/data/evolving_code_book/evolving-programs-with-language-models.md')
s=p.read_text()
repls={
'https://doi.org/10.1145/1555001.1555043':'https://doi.org/10.1109/ICSE.2009.5070536',
'https://doi.org/10.1145/2818754.281878angelix':'https://doi.org/10.1145/2884781.2884807',
' Combines fault localization, symbolic reasoning, and patch synthesis. Consult the publisher record for the canonical DOI because some bibliographic databases normalize this identifier differently.':' Combines fault localization, symbolic reasoning, and patch synthesis.',
'["String Diagrams for Trace Semantics"](https://arxiv.org/abs/1508.01069)':'["String Diagrams for Traced and Compact Categories Are Oriented 1-Cobordisms"](https://arxiv.org/abs/1508.01069)',
'["Synthetic Fibered (Infinity,1)-Category Theory"](https://arxiv.org/abs/2105.01724), 2021.':'["Synthetic Fibered (Infinity,1)-Category Theory"](https://arxiv.org/abs/2105.01724), *Higher Structures* 7(1), 2023.',
'https://doi.org/10.1145/2783258.278330榜':'https://arxiv.org/abs/1502.04585',
' ICML 2015. Introduces mechanisms limiting leaderboard overfitting; consult the canonical proceedings record for the normalized DOI.':' ICML 2015. Introduces mechanisms limiting leaderboard overfitting.',
'https://www.researchgate.net/publication/228556696_Metamorphic_Testing_A_New_Approach_for_Generating_Next_Test_Cases':'https://arxiv.org/abs/2002.12543',
}
for old,new in repls.items():
    if old not in s: print('MISSING',old)
    s=s.replace(old,new)
p.write_text(s)
print('done')
for ch,name in [('—','emdash'),('–','endash'),('−','minus'),('∞','infinity')]: print(name,s.count(ch))
PY

grep -nE 'angelix|榜|canonical DOI|normalized DOI|Trace Semantics|Automatically Finding Patches' /mnt/data/evolving_code_book/evolving-programs-with-language-models.md || true
```

<details><summary>💭 Thinking</summary>

**Reviewed manuscript code, references, demos, Pareto methods, and artifact wording**

</details>

```unknown
bash -lc mkdir -p /mnt/data/evolving_code_book/build && python /home/oai/skills/pdfs/scripts/md_to_pdf.py /mnt/data/evolving_code_book/evolving-programs-with-language-models.md -o /mnt/data/evolving_code_book/build/evolving-programs-with-language-models.pdf --pdf_engine xelatex
```

<details><summary>💭 Thinking</summary>

**Compiled Markdown into PDF and completed LaTeX preflight checks**

</details>

```unknown
bash -lc rm -rf /mnt/data/evolving_code_book/rendered && python /home/oai/skills/pdfs/scripts/render_pdf.py /mnt/data/evolving_code_book/build/evolving-programs-with-language-models.pdf --out_dir /mnt/data/evolving_code_book/rendered --dpi 140
```

<details><summary>💭 Thinking</summary>

**Completing deliverables**

I’m finalizing the textbook artifacts, rebuilding the PDF after layout corrections, and checking representative pages, equations, tables, code listings, and source sections for visual integrity before providing the files.

**Completed deliverables**

</details>

```unknown
bash -lc ls -lh /mnt/data/evolving_code_book && ls -lh /mnt/data/evolving_code_book/build && wc -l -w -c /mnt/data/evolving_code_book/evolving-programs-with-language-models.md && python -m py_compile /mnt/data/evolving_code_book/reflective_evolution_demo.py
```

<details><summary>💭 Thinking</summary>

**Rendered, corrected, and validated the evolving programs textbook PDF deliverables**

</details>

# Evolving Programs with Language Models

The completed textbook contains **28 chapters, 150 PDF pages, more than 280 exercises, 33 selected solutions, two extended case studies, an annotated source guide, and a dependency-free executable optimizer example**.

Its central formalization is:

$$
h:X\longrightarrow T_r(Y\times \mathrm{Trace})
$$

for an effectful, resource-indexed harness, together with an admissible-candidate type

$$
\mathrm{Candidate}(C)
=
\sum_{h:\mathrm{Harness}(X,Y)}
\mathrm{Admissible}_C(h).
$$

This deliberately separates machine-checkable admissibility from empirical objectives such as quality, cost, latency, and judge score.

The book develops four complementary interpretations:

- **Category theory:** executions are effectful morphisms; architectures are compositional diagrams; optimizer iterations are stochastic coalgebras; program transformations are evidence-bearing 2-cells or double-category squares; Pareto archives are order-enriched structures.
- **Dependent types and formal proof:** generated programs are paired with interface, capability, resource, provenance, and functional evidence. LLM judgments remain defeasible observations unless converted into proof objects checked by a trusted kernel.
- **Homotopy type theory:** verified refactorings become paths between implementations, alternative rewrite sequences produce higher coherence questions, and univalence explains transport across equivalent representations. Directed refinement is added because optimization steps, unlike ordinary HoTT paths, are not generally reversible.
- **Evolutionary computation:** these systems are best modeled as a hybrid of semantic evolutionary search, counterexample-guided synthesis, program repair, architecture search, and multi-objective experimentation—not merely genetic programming with source strings as genomes. The proposal operator is a pretrained semantic synthesizer conditioned on traces and critiques rather than a local syntax mutation operator.

## Files

[Download the Markdown textbook](sandbox:/mnt/data/evolving-programs-with-language-models.md)

[Download the typeset PDF](sandbox:/mnt/data/evolving-programs-with-language-models.pdf)

[Download the companion Python optimizer](sandbox:/mnt/data/reflective-evolution-demo.py)

[Download SHA-256 checksums](sandbox:/mnt/data/evolving-programs-with-language-models-checksums.txt)

The PDF has embedded Unicode fonts, a 360-entry navigable outline, live source links, mathematical notation, and syntax-highlighted code. Representative chapter openings, long equations, tables, code listings, running headers, and bibliography pages were rendered and inspected. Automated page-boundary, missing-glyph, compilation, and PDF preflight checks passed.

