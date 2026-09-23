# Z1 Controller Review

- URL: https://chatgpt.com/c/6a7ca5bf-cee4-83ea-ae0b-38a891c9916d
- Created: 2026-08-12T16:56:32.742Z

---

> Review this implementation of the Z1 controller. There are multiple axes to revie:
>
>
>
> - the machine control design
> - the algorithms and path design
> - the JS API + language design for the CAM design language
>
>
>
> Study it all, clone whatever git repos you need, be diligent.
>
>
>
> Write a markdown + pdf report.

```unknown
bash -lc cat /home/oai/skills/pdfs/SKILL.md && printf '\n---ZIP CONTENTS---\n' && unzip -l /mnt/data/dropcut-studio.zip | sed -n '1,220p'
```

I’ll map the project architecture, run available builds/tests, trace controller and CAM execution paths, and inspect linked upstream repositories. Then I’ll deliver a cited Markdown review and rendered PDF.

<details><summary>💭 Thinking</summary>

**Reviewing the repository**

I’m assessing the Z1 controller implementation across the CLI and studio components, starting with structure, tests, and module metadata. I’ll compare available upstream code where possible, then verify findings through focused checks.

**Reviewed the repository**

</details>

```unknown
bash -lc cd /mnt/data/dropcut-review/dropcut-studio && printf '%s\n' '--- README ---' && sed -n '1,260p' README.md && printf '%s\n' '--- JS API handbook ---' && sed -n '1,320p' docs/javascript-api-handbook.md && printf '%s\n' '--- Go CLI README ---' && sed -n '1,280p' makera-z1-cli/README.md && printf '%s\n' '--- Go module ---' && cat makera-z1-cli/go.mod
```

<details><summary>💭 Thinking</summary>

**Auditing the codebase**

I’m mapping the repository, measuring its scope, and checking available runtimes before running tests. I’ll inspect dependencies, the Go module relationship, and the frontend build so I can separate confirmed failures from design concerns.

**Audited the codebase**

**Inspected ZIP/PDF requirements, repository configuration, origins, and controller APIs**

</details>

```json
{"search_query":[{"q":"site:github.com/go-go-golems makera-z1-cli"},{"q":"site:github.com \"dropcut-studio\" CAM"},{"q":"site:github.com/MakeraInc CarveraController"},{"q":"Makera Z1 developer protocol native network"}],"response_length":"long"}
```

<details><summary>💭 Thinking</summary>

**Searched 5 websites**

</details>

```unknown
bash -lc set -euo pipefail
cd /mnt/data/dropcut-review
for spec in \
  'https://github.com/go-go-golems/makera-z1-cli.git upstream-makera-z1-cli' \
  'https://github.com/go-go-golems/glazed.git glazed' \
  'https://github.com/MakeraInc/CarveraFirmware.git upstream-CarveraFirmware' \
  'https://github.com/MakeraInc/CarveraProfiles.git upstream-CarveraProfiles' \
  'https://github.com/MakeraInc/CarveraController.git upstream-CarveraController'; do
  url=${spec% *}; dir=${spec##* }
  if [ ! -d "$dir/.git" ]; then
    echo "CLONING $url -> $dir"
    git clone --depth=1 "$url" "$dir" || echo "FAILED $url"
  fi
done
printf '\n--- cloned commits ---\n'
for d in upstream-makera-z1-cli glazed upstream-CarveraFirmware upstream-CarveraProfiles upstream-CarveraController; do
  if [ -d "$d/.git" ]; then
    printf '%-32s ' "$d"
    git -C "$d" rev-parse HEAD
    git -C "$d" log -1 --format='%cI %s'
  fi
done
```

<details><summary>💭 Thinking</summary>

**Cloned CLI and reference repositories**

**Retrieved repository metadata and fetched the latest archive**

</details>

```unknown
bash -lc go version || true; node --version || true; pnpm --version || true; npm --version || true; printf '\nGOMODCACHE=%s\n' "$(go env GOMODCACHE 2>/dev/null || true)"; find "$(go env GOMODCACHE 2>/dev/null || echo /nonexistent)" -maxdepth 4 -type d -path '*go-go-golems*glazed*' 2>/dev/null | head -20; printf '\nPNPM STORE\n'; pnpm store path 2>/dev/null || true; find /root/.local/share/pnpm/store -maxdepth 2 -type d 2>/dev/null | head -20
```

<details><summary>💭 Thinking</summary>

**Inspecting implementation details**

I’m narrowing the review to controller behavior, safety handling, command coverage, and documentation accuracy. I’ll trace key packages and line-level evidence, then run focused tests and static checks to distinguish real defects from stale notes.

**Inspected implementation details**

</details>

The archive couples a TypeScript CAM/compiler workspace with a Go Z1 control CLI. I’m reviewing transport/safety, planning, postprocessing, scripting, and their integration as one safety boundary.

```unknown
bash -lc cd /mnt/data/dropcut-review/dropcut-studio && printf '%s\n' '--- TypeScript source inventory ---' && find packages apps -path '*/src/*' -type f \( -name '*.ts' -o -name '*.tsx' \) -printf '%p\n' | sort && printf '\n--- Go source inventory ---\n' && find makera-z1-cli -type f \( -name '*.go' -o -name '*.md' \) -printf '%p\n' | sort && printf '\n--- Go package tree ---\n' && find makera-z1-cli/pkg -maxdepth 3 -type f -name '*.go' -printf '%h\n' | sort -u
```

<details><summary>💭 Thinking</summary>

**Inspected Go and TypeScript projects, dependencies, tooling, and compiler errors**

**Planned machine analysis and inspected Carvera firmware repositories and commits**

</details>

```unknown
bash -lc cd /mnt/data/dropcut-review/dropcut-studio && sha256sum /mnt/data/dropcut-studio.zip > /mnt/data/dropcut-review/archive.sha256 && find packages apps makera-z1-cli -type f \( -name '*.ts' -o -name '*.tsx' -o -name '*.go' \) -print0 | sort -z | xargs -0 sha256sum > /mnt/data/dropcut-review/source-files.sha256 && python - <<'PY'
from pathlib import Path
from collections import defaultdict
root=Path('/mnt/data/dropcut-review/dropcut-studio')
groups=defaultdict(lambda:[0,0])
for p in root.rglob('*'):
    if p.suffix not in {'.ts','.tsx','.go','.md'} or not p.is_file(): continue
    rel=p.relative_to(root)
    top='/'.join(rel.parts[:2]) if rel.parts[0] in {'packages','apps'} else rel.parts[0]
    lines=p.read_text(errors='replace').splitlines()
    code=sum(1 for l in lines if l.strip() and not l.lstrip().startswith('//'))
    groups[top][0]+=len(lines); groups[top][1]+=code
for k in sorted(groups): print(f'{k:32s} total={groups[k][0]:6d} nonblank_non//={groups[k][1]:6d}')
PY
```

<details><summary>💭 Thinking</summary>

**Evaluating geometry validation**

I’m checking whether path construction actually guarantees continuity and valid arcs. Early concerns include weak frame checks, unvalidated radii and axes, and polyline sampling that may permit unintended jumps despite the continuity claim.

</details>

```unknown
bash -lc cd /mnt/data/dropcut-review/dropcut-studio && nl -ba packages/compiler/src/lower.ts | sed -n '1,420p' && printf '\n--- recertify ---\n' && nl -ba packages/compiler/src/recertify.ts | sed -n '1,360p' && printf '\n--- compiler index ---\n' && nl -ba packages/compiler/src/index.ts
```

<details><summary>💭 Thinking</summary>

**Assessing geometry validation**

I’m verifying whether path construction truly guarantees continuity and valid arcs. Current concerns include weak frame checks, unvalidated radii and axes, and polyline sampling that may allow unintended jumps despite continuity claims.

**Testing safety boundaries**

I’m examining command completion, decoder concurrency, simulation fidelity, and certificate construction. I’m also checking whether machine profiles and tool geometry reject invalid inputs or merely clamp them, since that can hide unsafe assumptions.

**Assessed geometry validation**

</details>

```unknown
bash -lc ls -la /mnt/data/dropcut-review && find /mnt/data/dropcut-review/dropcut-studio -maxdepth 3 -type f | sed 's#^#/##' | head -200
```

<details><summary>💭 Thinking</summary>

**Inspected codebase, validation, safety, motion, and control-flow implementations**

</details>

```unknown
bash -lc cd /mnt/data/dropcut-review/dropcut-studio/makera-z1-cli && nl -ba pkg/makera/report.go | sed -n '1,560p' && nl -ba pkg/makera/parse.go | sed -n '1,520p'
```

I’ve reproduced four stop-ship issues: unknown commands treated read-only, motion continuing after refusal, gouge certification without target checking, and exact-travel claims without resolving work-to-machine coordinates.

<details><summary>💭 Thinking</summary>

**Finalizing the review**

I’m consolidating the verified findings into a structured report, separating release-blocking safety issues from architectural and API concerns. I’ll include reproducible evidence, recommended fixes, test limitations, and clearly documented provenance.

</details>

```unknown
bash -lc find /mnt/data/dropcut-review/dropcut-studio/packages -maxdepth 3 -type f | sort | sed -n '1,240p'
```

<details><summary>💭 Thinking</summary>

**Inspected compiler, geometry, transport, documentation, and dependency code thoroughly**

</details>

```unknown
bash -lc cd /mnt/data/dropcut-review/dropcut-studio && printf '===== CL FIELD =====\n'; nl -ba packages/geometry/src/cl-field.ts; printf '\n===== CONTOURS 1-340 =====\n'; nl -ba packages/geometry/src/contours.ts
```

The HTTP layer is comparatively disciplined. Geometry is stronger for ball/flat cutters, but V-bit handling is non-conservative and bull-nose behavior falls short of its documented toroidal method.

```json
{"paths":["GitHub"],"query":"repository"}
```


---

> hello what's up?

<details><summary>💭 Thinking</summary>

**Checking in briefly**

Hello! I’m here and ready to help. I’m still organizing the repository review and identifying the relevant firmware pieces, but I haven’t completed the full analysis yet.

**Checked in briefly**

</details>

Hello. I’m here and continuing the Z1 review: tracing the controller and CAM layers, then producing the Markdown and PDF report.

The snapshot lacks usable Git history, and the Go CLI is not independently buildable as-is due to its Go 1.26.1 requirement and local `glazed` replacement.

I’ve confirmed critical controller flaws: command-gate bypasses and timeout sentinel reuse, plus canceled jogs sustaining motion. Separately, the JS “sandbox” uses same-realm evaluation without enforced timeouts.

Hello. I’m here. I had only begun the Z1 controller review; the code analysis and markdown/PDF report are not complete yet.

The CAM “verification” is also overstated: travel checks are sampled and simulation never compares cuts to the target surface. Emergency actions can block behind motion, while malformed status may appear safe.


---

> finish it.

```json
{"paths":["GitHub"],"query":"contents"}
```

```json
{"paths":["GitHub"],"query":"tree"}
```

# Z1 Controller Review

Completed. The report covers the machine-control layer, CAM algorithms and path generation, JavaScript API/language semantics, postprocessing, certificate design, controller-to-CAM trust boundaries, build reproducibility, and a staged remediation plan.

**Disposition: NO-GO for production cutting, unattended jobs, or operation over an untrusted network.** The implementation remains suitable for development, simulation, controlled dry runs, and physically attended air-cut testing.

Four independently confirmed release blockers are:

1. **False gouge certification:** sampled stock-removal evidence is promoted into a gouge-verification result without comparing the cut against a target surface.
2. **Ineffective JavaScript isolation:** same-realm `new Function` execution can reach host globals, and the configured timeout is not enforced.
3. **Fail-open controller authorization:** the generic command classifier examines only the first token and treats unknown commands as read-only.
4. **Contour topology corruption:** endpoint keys repeat every **67.108864 mm**, allowing unrelated paths to merge within the Z1 work envelope.

The report contains 46 numbered findings, executable counterexamples, source-level evidence, prioritized P0/P1/P2 remediation, acceptance gates, and a minimum release checklist. Limitations such as the unavailable physical machine and blocked clean-room test-suite execution are documented explicitly.

- [Download the Markdown report](sandbox:/mnt/data/z1_review_deliverables/Z1_Controller_Implementation_Review.md)
- [Download the 42-page PDF report](sandbox:/mnt/data/z1_review_deliverables/Z1_Controller_Implementation_Review.pdf)


---

> research the theory behind building this kind of compiler and IR / compiler passes / semantics / operational research  and the creation of certificates and assertions and invariants and such.

<details><summary>💭 Thinking</summary>

**Researching compiler theory**

I’m identifying the project’s needs: intermediate representations, semantics, transformation passes, operational-research connections, and machine-checkable certificates. I’ll ground the explanation in established theory and tailor it to this compiler architecture.

**Researched compiler theory**

</details>

I’ll ground the theory in the reviewed Dropcut/Z1 architecture, mapping compiler stages to formal semantics, optimization theory, proof obligations, and certificate design.

```unknown
bash -lc ls -lah /mnt/data && find /mnt/data -maxdepth 3 -type f | sed -n '1,120p'
```

<details><summary>💭 Thinking</summary>

**Structuring the theory**

I’m connecting compiler pipelines, formal semantics, geometric reasoning, numerical guarantees, and certificate design. I’ll frame each pass as a contract-preserving refinement, with explicit invariants and checkable evidence.

**Structured the theory**

**Formalizing the compiler**

I’m modeling the pipeline with typed, state-aware intermediate representations, explicit units and frames, and semantics for motion, stock, tooling, and safety. I’m also defining conservative geometric certificates with numerical error bounds.

**Formalized the compiler**

**Gathering foundational sources**

I’m selecting primary references on semantics, verification, abstract interpretation, certified compilation, IR design, and planning. I’ll connect these foundations to CAM-specific scheduling, path linking, machine states, and evidence-producing transformations.

**Gathered foundational sources**

**Inspected project files, documentation, and compiler analysis sources**

</details>

```unknown
bash -lc cd /mnt/data/dropcut-studio-src/dropcut-studio && for f in packages/ir/src/path.ts packages/ir/src/provenance.ts packages/compiler/src/validate.ts packages/compiler/src/lower.ts packages/compiler/src/recertify.ts packages/analysis/src/pipeline-certificate.test.ts packages/planner/src/types.ts packages/planner/src/run.ts packages/planner/src/linker.ts packages/planner/src/refine.ts packages/script-host/src/api.ts packages/script-host/src/sandbox.ts packages/math/src/frames.ts packages/geometry/src/cl-field.ts packages/geometry/src/eikonal.ts packages/geometry/src/contours.ts packages/strategies/src/pocket.ts packages/strategies/src/constant-scallop.ts packages/post-makera/src/index.ts; do echo "===== $f ====="; nl -ba "$f" | sed -n '1,420p'; done
```

<details><summary>💭 Thinking</summary>

**Inspected source files with line numbers**

</details>

```json
{"search_query":[{"q":"site:nist.gov RS274 NGC interpreter canonical machining functions PDF Kramer Proctor Messina"},{"q":"CompCert verified compiler semantic preservation official paper PDF Leroy"},{"q":"translation validation Pnueli Siegel Singerman validating optimizing compiler PDF"},{"q":"proof-carrying code Necula 1997 PDF"}],"response_length":"long"}
```

<details><summary>💭 Thinking</summary>

**Searched 12 websites**

</details>

```unknown
bash -lc cd /mnt/data/dropcut-studio-src/dropcut-studio && sed -n '1,340p' packages/compiler/src/validate.ts && echo '--- LOWER ---' && sed -n '1,300p' packages/compiler/src/lower.ts && echo '--- RECERTIFY ---' && sed -n '1,340p' packages/compiler/src/recertify.ts && echo '--- PROVENANCE ---' && sed -n '1,320p' packages/ir/src/provenance.ts && echo '--- PLANNER TYPES ---' && sed -n '1,360p' packages/planner/src/types.ts && echo '--- PLANNER RUN ---' && sed -n '1,420p' packages/planner/src/run.ts
```

I’ll distinguish operational semantics from operations research, and separate type/API-level evidence from genuine semantic proof, noting where current validation, provenance, and error-budget mechanisms remain nominal.

<details><summary>💭 Thinking</summary>

**Inspected compiler architecture, passes, planner, documentation, and APIs**

</details>

```json
{"search_query":[{"q":"site:arxiv.org \"MLIR: Scaling Compiler Infrastructure for Domain Specific Computation\""},{"q":"site:dl.acm.org MLIR scaling compiler infrastructure domain specific computation"},{"q":"site:llvm.org MLIR language reference dialect conversion official"},{"q":"site:mlir.llvm.org/docs DialectConversion official"}],"response_length":"long"}
```

<details><summary>💭 Thinking</summary>

**Defining verified compilation**

I’m treating the system as a refinement pipeline, not merely a source-to-text compiler. I’m separating logical machine semantics, physical assumptions, numerical approximation, and certificates that preserve safety properties across passes.

**Defined verified compilation**

**Searched 1 website**

</details>

```json
{"search_query":[{"q":"site:nist.gov RS274NGC canonical machining functions interpreter PDF"},{"q":"site:compcert.org verified compiler semantic preservation translation validation"},{"q":"site:mlir.llvm.org rationale progressive lowering dialect conversion legality"},{"q":"proof carrying code Necula PDF Carnegie Mellon primary source"}],"response_length":"long"}
```

<details><summary>💭 Thinking</summary>

**Searched 8 websites**

</details>

```unknown
bash -lc set -e
cd /mnt/data/dropcut-studio-src/dropcut-studio
printf '%s\n' '--- README pipeline ---'
grep -n -A14 -B3 'ManufacturingPlan' README.md | head -80 || true
printf '%s\n' '--- IR program types ---'
sed -n '1,260p' packages/ir/src/program.ts
printf '%s\n' '--- canonical commands ---'
sed -n '1,280p' packages/ir/src/commands.ts
printf '%s\n' '--- path ---'
sed -n '1,280p' packages/ir/src/path.ts
```

<details><summary>💭 Thinking</summary>

**Inspected IR pipeline paths, validation, certificates, sandbox, and analysis checks**

</details>

The emerging architecture is a certificate-carrying refinement pipeline: per-pass validation, conservative approximation bounds, separate feasibility and optimization, and runtime admission tied to the exact hashed job.

# Theory for a Certificate-Carrying CAM Compiler

I interpret “operational research” in both relevant senses:

1. **Operational semantics**: a mathematical account of how programs change machine, controller, geometry, and stock state.
2. **Operations research**: optimization of sequencing, linking, feeds, tool changes, and machining time under hard constraints.

The central conclusion is:

> Dropcut should be treated as a **certificate-carrying refinement compiler for a cyber-physical system**, not as a JavaScript-to-G-code translator.

Its target is not text. Its target is a set of possible physical executions of a particular machine, controller, tool, setup, and workpiece. The compiler is correct when every possible target execution refines the source manufacturing intent within declared error bounds and assumptions.

NIST’s canonical machining commands provide an established precedent for separating controller syntax from machining meaning: the NIST RS274 interpreter maps modal G-code into canonical machining operations. Dropcut is largely traversing the opposite direction—from manufacturing intent through canonical operations into a controller dialect—but the same “canonical semantic waist” is useful. citeturn662326search0turn662326search1

---

## 1. What kind of compiler is this?

A conventional compiler approximately has:

$$
\text{source program}
\longrightarrow
\text{machine program}
$$

and a semantic preservation theorem of the form:

$$
\operatorname{compile}(S)=T
\quad\Longrightarrow\quad
\operatorname{Beh}(T)\preceq\operatorname{Beh}(S)
$$

where $\operatorname{Beh}$ means observable behavior. CompCert proves such preservation by composing proofs for individual compiler passes. Importantly, a compiler is allowed to reject a source program rather than emit code it cannot compile correctly. citeturn662326search8turn662326search9turn662326search10

For CAM, the source and target semantics are richer:

$$
\text{manufacturing intent}
\rightarrow
\text{geometric construction}
\rightarrow
\text{toolpath}
\rightarrow
\text{machine trajectory}
\rightarrow
\text{controller commands}
\rightarrow
\text{physical material removal}
$$

The source often does not specify a unique execution. A pocket operation, for example, specifies an acceptable **result**, not one particular zigzag path. Therefore, the source meaning is best modeled as a set of permitted executions or outcomes:

$$
\operatorname{Allowed}(I)
=
\{\text{executions that satisfy manufacturing intent } I\}
$$

Compilation selects one implementation from that set:

$$
\operatorname{compile}(I)=P
$$

Correctness then means:

$$
\forall \tau\in\operatorname{Exec}(P,A):
\quad
\alpha(\tau)\in N_\varepsilon(\operatorname{Allowed}(I))
$$

where:

- $A$ is the set of assumptions about the machine and setup;
- $\tau$ is a possible physical execution trace;
- $\alpha$ abstracts a low-level physical trace back to manufacturing observations;
- $N_\varepsilon$ allows declared geometric and numerical error.

This is **refinement under assumptions and bounded approximation**.

The certificate’s ultimate theorem should resemble:

$$
\operatorname{verify}(B)=\text{true}
\land
\operatorname{AssumptionsHold}(A)
\quad\Longrightarrow\quad
\forall\tau\in\operatorname{Execute}(B,A):
\operatorname{Safe}(\tau)
\land
\operatorname{ConformsToIntent}_\varepsilon(\tau)
$$

Here $B$ is the exact deployed bundle, including emitted bytes, profile, tools, setup, configuration, and evidence.

---

## 2. The four semantics you need

No single semantic style is sufficient. This compiler needs at least four complementary views.

| Semantic view | Question answered | CAM application |
|---|---|---|
| Denotational | “What does this program mean?” | Manufacturing intent, path geometry, resulting stock |
| Operational | “How does execution proceed step by step?” | Modal G-code, controller state, probing, pause/resume |
| Axiomatic | “What must be true before and after this operation?” | Interlocks, travel limits, spindle/tool sequencing |
| Trace/temporal | “What is always or eventually true over time?” | Job lifecycle, stop behavior, connection loss, acknowledgements |

Hoare logic introduced reasoning with preconditions and postconditions, while abstract interpretation provides a framework for computing sound approximations of possible program behavior. citeturn409138search0turn409138search1

### 2.1 Denotational semantics

A machine state can be modeled as:

$$
\sigma =
(q,\dot q,F,W,T_{\text{active}},S_{\text{spindle}},
C,S_{\text{stock}},P_{\text{target}},O,M,t)
$$

where:

- $q,\dot q$: axis positions and velocities;
- $F$: frame graph and transforms;
- $W$: active work coordinate system;
- $T_{\text{active}}$: tool and holder;
- $S_{\text{spindle}}$: spindle state;
- $C$: coolant and other process state;
- $S_{\text{stock}}$: current stock solid;
- $P_{\text{target}}$: target part or protected material;
- $O$: fixtures and obstacles;
- $M$: controller mode and modal state;
- $t$: time.

A command should generally denote a relation rather than a deterministic function:

$$
\llbracket c\rrbracket :
\Sigma
\rightarrow
\mathcal P(\Sigma\times\operatorname{Trace}\times\operatorname{Outcome})
$$

The powerset accounts for:

- probe uncertainty;
- controller nondeterminism;
- measurement noise;
- communication failure;
- machine-following error;
- possible fault outcomes.

At higher levels, an operation such as `rectPocket` should not denote one polyline. It should denote a predicate on acceptable residual stock:

$$
\llbracket \operatorname{Pocket}(R,d,\delta)\rrbracket
=
\{S' \mid \operatorname{PocketSpecification}(S',R,d,\delta)\}
$$

A toolpath strategy then produces a **witness** that it believes satisfies this predicate.

That changes the conceptual type of a planner from:

```ts
Intent -> Toolpath
```

to:

```ts
Intent -> Result<{
  toolpath: Toolpath;
  witness: PlanningWitness;
}>
```

with an independent checker:

```ts
checkPlanningWitness(intent, toolpath, witness): CheckResult
```

### 2.2 Operational semantics

Operational semantics describes transitions:

$$
\langle c,\sigma\rangle
\rightarrow
\langle c',\sigma'\rangle
$$

or, for atomic canonical commands:

$$
\langle c,\sigma\rangle
\Downarrow
(\sigma',e)
$$

where $e$ is the emitted event or trace fragment.

A simplified cutting rule might be:

$$
\frac{
  \operatorname{Homed}(\sigma)
  \quad
  \operatorname{WCSKnown}(\sigma)
  \quad
  \operatorname{ToolLoaded}(\sigma,T)
  \quad
  \operatorname{SpindleValid}(\sigma)
  \quad
  f>0
}{
  \langle\operatorname{Cut}(\gamma,T,f),\sigma\rangle
  \Downarrow
  \left(
    \sigma[
      q:=\operatorname{end}(\gamma),
      S_{\text{stock}}:=S_{\text{stock}}\setminus
      \operatorname{Sweep}(T,\gamma)
    ],
    \operatorname{motionTrace}(\gamma,f)
  \right)
}
$$

This semantics belongs in a pure `@cam/semantics` package. It should be usable by:

- the verifier;
- the simulator;
- the time estimator;
- tests;
- the postprocessor validator;
- the controller protocol model.

The UI renderer can remain approximate, but it should not silently become the reference semantics.

### 2.3 Axiomatic semantics and weakest preconditions

For commands, use Hoare triples:

$$
\{P\}\ c\ \{Q\}
$$

For example:

$$
\{
\operatorname{Homed}
\land
\operatorname{WCSKnown}
\land
\operatorname{Tool}=T
\land
\operatorname{SpindleOn}
\land
\operatorname{PathSafe}(\gamma)
\}
$$

$$
\operatorname{cut}(\gamma,T,f)
$$

$$
\{
\operatorname{Pose}=\operatorname{end}(\gamma)
\land
S'=S\setminus\operatorname{Sweep}(T,\gamma)
\}
$$

A weakest-precondition function is especially useful:

$$
wp(c,Q)
$$

It computes the weakest condition required before $c$ so that $Q$ holds afterward. For a sequence:

$$
wp(c_1;c_2,Q)=wp(c_1,wp(c_2,Q))
$$

This gives the compiler a principled way to derive preflight requirements rather than maintaining ad hoc boolean checks.

For instance:

$$
wp(\operatorname{Cut}(\gamma,T,f),Q)
$$

would include:

- homed machine;
- known work transform;
- matching tool;
- valid spindle state;
- positive and supported feed;
- path inside the travel envelope;
- no forbidden swept-volume intersection;
- the postcondition $Q$ evaluated on the updated stock state.

### 2.4 Trace and temporal semantics

The controller is not merely a function from commands to responses. It is a concurrent state machine involving:

- host connection;
- upload;
- machine storage;
- acknowledgement;
- preparation;
- start;
- execution;
- pause;
- resume;
- abort;
- disconnect;
- alarm;
- recovery.

Temporal logic is appropriate here. TLA models systems as state-transition relations and supports reasoning about safety and liveness over traces. citeturn538704search0

Example properties:

$$
\Box(\operatorname{Motion}
\Rightarrow
\operatorname{Homed}\land\operatorname{Authorized})
$$

“Motion always implies that the machine is homed and the operation was authorized.”

$$
\Box(\operatorname{AbortRequested}
\Rightarrow
\Diamond(\operatorname{Stopped}\lor\operatorname{Faulted}))
$$

“An abort request eventually results in an explicit stopped or faulted state.”

$$
\Box(
\operatorname{ExecuteHash}=h
\Rightarrow
\operatorname{StoredHash}=h
)
$$

“The bytes executed are the bytes acknowledged after upload.”

These cannot be established by checking an array of canonical commands. They concern the entire host-controller protocol.

---

## 3. Separate path, trajectory, and process semantics

The current design correctly distinguishes a `Path` from G-code syntax, but a robust model needs three separate objects.

### Geometric path

$$
\gamma:[0,1]\rightarrow SE(3)
$$

For a fixed-orientation three-axis machine, this can be simplified to:

$$
\gamma:[0,1]\rightarrow\mathbb R^3
$$

It says where the tool is, but not when it is there.

### Time parameterization

$$
s:[0,T]\rightarrow[0,1]
$$

with $s$ monotone. The physical trajectory is:

$$
x(t)=\gamma(s(t))
$$

Velocity, acceleration, jerk, servo limitations, and contour-following error belong to $s(t)$ and the machine dynamics—not to the geometric curve alone.

### Process semantics

For a tool solid $B$, the swept volume is:

$$
\operatorname{Sweep}(B,x)
=
\bigcup_{t\in[0,T]}x(t)B
$$

Stock evolves as:

$$
S_{i+1}=S_i\setminus R_i
$$

where $R_i$ is the material provably removed by operation $i$.

Important properties can then be stated precisely.

Travel safety:

$$
\forall t,\quad q(t)\in Q_{\text{admissible}}
$$

Fixture and holder clearance:

$$
\operatorname{Sweep}(B_{\text{tool}}\cup B_{\text{holder}},x)
\cap O
=
\varnothing
$$

Rapid safety against current stock:

$$
\operatorname{Sweep}(B_{\text{tool}}\cup B_{\text{holder}},x_i)
\cap(S_i\cup O)
=
\varnothing
$$

No gouge, with tolerance $\delta$:

$$
\operatorname{Sweep}(B_{\text{tool}},x)
\cap
(P_{\text{target}}\ominus B_\delta)
=
\varnothing
$$

The erosion by $B_\delta$ expresses that penetration into a $\delta$-wide tolerance layer may be allowed, while penetration farther into target material is forbidden.

Required removal is a different property from no gouge. One concerns avoiding excessive removal; the other concerns removing enough material. They require different approximations and should be separate certificate claims.

---

## 4. The correct IR hierarchy

The current pipeline is:

```text
script
→ ManufacturingPlan
→ ToolpathProgram
→ CanonicalProgram
→ MachineProgram
→ ValidatedProgram
→ GCodeBlock[]
→ .nc
```

That direction is sound, but some stages need sharper semantic boundaries. MLIR’s central lesson is that domain-specific compilers benefit from representations at several abstraction levels, with explicit legality rules for each conversion target. citeturn628227search3turn628227search5

I would use these levels.

| IR | Meaning | Excludes |
|---|---|---|
| Authoring AST | User syntax, macros, source locations | Direct machine effects |
| Elaborated Plan IR | Units, frames, tools and references resolved | Unresolved names or implicit units |
| Manufacturing Intent IR | Features, operations, tolerances, precedence | Tool-center trajectories |
| Geometric Toolpath IR | Continuous cut curves and process parameters | Linking and machine-specific behavior |
| Scheduled Program IR | Ordered cuts, entries, retracts and traverses | Controller syntax |
| Machine IR | Machine frames, capabilities, limits and concrete trajectories | Modal G-code state |
| Controller IR | Explicit controller operations and dialect semantics | Text formatting ambiguity |
| Serialized Job Bundle | Exact bytes, metadata and certificate graph | Unbound assumptions |

### Validation is not really an IR level

`ValidatedProgram` is useful as a software engineering gate: it prevents accidental calls to the postprocessor before a validation function has run.

But semantically, “validated” should not be another language. It is evidence about an artifact.

Prefer:

```ts
interface Certified<T> {
  readonly artifact: T;
  readonly artifactHash: Hash;
  readonly claims: readonly Claim[];
  readonly evidence: readonly Evidence[];
}
```

rather than making certification part of the artifact’s structural identity.

This matters because different properties may be certified at different times:

```text
GeometricToolpath
  + path/target evidence

MachineProgram
  + travel/capability evidence

ControllerProgram
  + modal-equivalence evidence

Serialized bytes
  + parse-back and content-binding evidence

Execution setup
  + runtime assumption evidence
```

A single `ValidatedProgram` brand cannot express this proof graph.

---

## 5. Every compiler pass needs a semantic contract

A pass should not merely be:

```ts
I -> O
```

It should conceptually be:

```ts
interface CertifyingPass<I, O, W> {
  readonly id: string;
  readonly version: string;

  transform(
    input: I,
    config: PassConfig
  ): Result<{ output: O; witness: W }, Diagnostic[]>;

  check(
    input: I,
    output: O,
    witness: W,
    config: PassConfig
  ): CheckResult;
}
```

The checker should establish a relation:

$$
R_{I,O}(i,o)
$$

with a theorem:

$$
\operatorname{check}(i,o,w)=\text{true}
\Longrightarrow
R_{I,O}(i,o)
$$

The relation depends on the class of pass.

### Exact semantic preservation

Used for:

- harmless normalization;
- canonicalization;
- modal compression when interpreted semantics are identical;
- syntax serialization and parse-back.

$$
\operatorname{Sem}(o)=\operatorname{Sem}(i)
$$

### Trace refinement

Used when the target resolves choices left open by the source:

$$
\operatorname{Traces}(o)
\subseteq
\operatorname{Traces}(i)
$$

For example, a high-level `Traverse` allows any safe route. Lowering it to retract–XY–descend selects one allowed route.

### Bounded geometric refinement

Used for curve discretization and arc linearization:

$$
d_H(\gamma_i,\gamma_o)\le\varepsilon
$$

where $d_H$ is Hausdorff distance.

For swept-volume safety, centerline Hausdorff distance may be insufficient by itself. The pass must show how path deviation propagates through the tool shape and frame transforms.

### Witness selection

Used for CAM planning:

$$
o\in\llbracket i\rrbracket
$$

A pocket strategy is producing a witness satisfying a manufacturing specification.

### Optimization preservation

Used for path ordering or feed optimization:

$$
\operatorname{Feasible}(o)
\land
\operatorname{Sem}(o)\approx\operatorname{Sem}(i)
\land
J(o)\le J(i)
$$

The safety and semantic constraints are hard. The objective $J$ is secondary.

### Typical pass obligations

| Pass | Required proof or checker |
|---|---|
| Unit/frame elaboration | Dimensions valid; every coordinate has one known frame |
| Feature planning | Output path satisfies feature and allowance specification |
| Surface sampling | Surface approximation enclosed within declared bound |
| Curve refinement | Endpoint preservation and Hausdorff/chord bound |
| Path reordering | Dependency order preserved; process effects remain valid |
| Link generation | Every added move is inside certified free space |
| Machine lowering | Every operation is supported or soundly transformed |
| Feed clamping | Geometry unchanged; process assumptions revalidated |
| Arc lowering | Endpoints, orientation and sweep preserved within bound |
| Modal compression | Modal interpreter produces the same canonical trace |
| Serialization | Reparse yields equivalent controller IR |
| Upload | Stored and executed byte hash matches certified artifact |

This is essentially CompCert’s compositional strategy, but translation validation is probably more practical for this project initially: rather than proving the TypeScript implementation correct for all inputs, independently validate each actual input/output pair produced by a pass. Translation validation was introduced precisely as a way to validate individual compiler runs using a common semantic framework and refinement relation. citeturn840691search2turn840691search3

---

## 6. Paths as a category: useful, but be precise

The existing `Path<F>` design has a strong algebraic intuition:

- objects: poses or points;
- morphisms: paths between them;
- identity: `emptyPath(at)`;
- composition: `concat(a,b)` when `a.end = b.start`.

This is the free-category view of path construction.

There are, however, three qualifications.

### 6.1 Paths are generally equal only up to reparameterization

Two concatenated geometric paths can describe the same image with different parameterizations. Therefore, literal object equality is too strong. The appropriate equivalence is generally equality modulo monotone reparameterization.

### 6.2 Approximate equality is not equality

The current `JOIN_EPS` relation:

$$
d(p,q)<\varepsilon
$$

is not transitive:

$$
d(p,q)<\varepsilon,\quad d(q,r)<\varepsilon
$$

does not imply:

$$
d(p,r)<\varepsilon
$$

Consequently, endpoint matching by tolerance does not create an ordinary category with exact laws. Repeated composition may also accumulate error.

Better choices include:

- canonical snapping to exact point identities;
- symbolic endpoint identifiers;
- explicit join witnesses;
- exact rational or algebraic endpoints where practical;
- paths carrying accumulated endpoint uncertainty;
- a metric-enriched structure where error is part of the composition result.

For example:

```ts
interface JoinedPath<F> {
  readonly path: Path<F>;
  readonly joinErrors: readonly DistanceBound[];
}
```

### 6.3 Construction invariants are not semantic proofs

`PathBuilder` is valuable because it prevents an `end` field from disagreeing with the final segment. That is a **representation invariant**.

It does not establish:

- that an arc really starts at the prior endpoint;
- that arc radius is consistent at both ends;
- that a polysegment begins at the current cursor;
- that a path lies inside travel limits;
- that the path avoids the target and fixtures;
- that numerical evaluation respects its stated tolerance.

Keep the categorical API, but describe it as a compositional construction discipline rather than formal verification.

---

## 7. Commands as effects: monads, Kleisli composition, and typestate

Machine commands are effectful. They can:

- mutate machine state;
- fail;
- produce probe results;
- emit diagnostics;
- consume time;
- alter stock;
- interact with external controller state.

An ordinary state-and-error interpretation has a shape such as:

$$
M(A)=\Sigma\rightarrow\operatorname{Result}(\Sigma\times A,E)
$$

A command is:

$$
A\rightarrow M(B)
$$

and commands compose by Kleisli composition.

For CNC, a plain monad does not capture enough because the type of the machine state changes. A parameterized or indexed monad is a better model:

$$
\operatorname{Cmd}\langle S_{\text{before}},
S_{\text{after}},A\rangle
$$

with composition:

$$
\operatorname{bind}:
\operatorname{Cmd}\langle S_0,S_1,A\rangle
\rightarrow
(A\rightarrow\operatorname{Cmd}\langle S_1,S_2,B\rangle)
\rightarrow
\operatorname{Cmd}\langle S_0,S_2,B\rangle
$$

Parameterized monads were developed specifically to model effects whose pre-state and post-state types differ. Typestate similarly restricts which operations are permitted in a particular state and detects invalid operation sequences. citeturn409138search8turn628227search8

Conceptually:

```ts
type SelectTool<T, S> =
  Cmd<S, S & { tool: T }, void>;

type StartSpindle<R, S extends { tool: Tool }> =
  Cmd<S, S & { spindle: Running<R> }, void>;

type Cut<P, S extends {
  homed: true;
  wcs: KnownWcs;
  tool: Tool;
  spindle: RunningRpm;
}> =
  Cmd<S, S & { pose: EndOf<P> }, void>;
```

TypeScript cannot make the physical machine satisfy these states. It can only constrain program construction. Runtime preflight and controller-state checking remain mandatory.

### A practical SSA-style state token

A simpler IR encoding is:

```text
%s0 = machine.initial

%s1 = machine.require_homed %s0
%s2 = tool.select %s1 @T1
%s3 = spindle.start %s2 12000rpm
%s4 = motion.traverse %s3 to=(10,10,5)
%s5 = motion.cut %s4 path=@p1 feed=400
%s6 = spindle.stop %s5
```

Every state-changing operation consumes one state token and produces another. This:

- makes order explicit;
- prevents accidental reordering;
- supports dataflow analysis;
- gives probe results explicit dependencies;
- resembles the memory-token discipline used in compiler IRs.

It is usually easier to implement and inspect than advanced phantom-state types throughout a TypeScript API.

---

## 8. The JavaScript language should be a macro language over an inert AST

For assurance purposes, user JavaScript should not itself be the CAM semantic model. It should be a meta-language that constructs an immutable domain AST.

The important boundary is:

```text
arbitrary JavaScript computation
            ↓
       inert Plan AST
            ↓
    trusted semantic pipeline
```

After the AST is produced:

- no closures should remain;
- no arbitrary callbacks should be invoked by compiler passes;
- all values should be finite and validated;
- all frames and units should be explicit;
- every operation should have provenance;
- the AST should be serializable and content-addressable.

The current capability API already moves in this direction by allowing scripts to create plans rather than directly emit machine commands. The remaining problem is that `new Function` executes the macro language in the host realm. Isolation is a security requirement, but it is also a semantic requirement: deterministic, reproducible compilation is difficult if a program can read time, randomness, network state, storage, or host globals.

A good compilation record should capture:

```ts
interface ScriptEvaluationRecord {
  sourceHash: Hash;
  languageVersion: string;
  apiVersion: string;
  declaredInputs: readonly ArtifactRef[];
  resultAstHash: Hash;
  diagnostics: readonly Diagnostic[];
}
```

The resulting AST, not the live JavaScript environment, is what subsequent certificates should reference.

---

## 9. Assertions, invariants, assumptions, and proofs are different objects

These terms should not be conflated.

### Assertion

A proposition at a point in the program:

$$
x\in[0,100]
$$

### Precondition/postcondition

A proposition required before or promised after an operation:

$$
\{P\}\ c\ \{Q\}
$$

### Invariant

A property that holds initially and is preserved by every relevant transition:

$$
I(\sigma_0)
$$

$$
I(\sigma)\land\sigma\rightarrow\sigma'
\Longrightarrow I(\sigma')
$$

### Assumption

An external fact the software does not prove:

- tool diameter is 3.175 mm;
- fixture model matches reality;
- WCS was probed correctly;
- firmware implements the documented rapid semantics;
- spindle calibration is within a specified tolerance.

### Evidence

Data supporting a claim:

- interval bounds;
- a proof term;
- abstract states;
- a collision-separation witness;
- a parse-back comparison;
- an exhaustive transition table;
- a solver proof trace.

### Certificate

A machine-checkable package binding:

- one precise proposition;
- one artifact;
- assumptions;
- evidence;
- checker identity;
- result and quantitative bounds.

### Attestation or signature

Evidence about origin and integrity. A signature can establish that a certificate came from a particular compiler build. It does not prove that the certificate’s claim is mathematically valid.

### Important invariant classes for CAM

**Representation invariants**

- numbers are finite;
- lengths are nonnegative where required;
- frame identifiers exist;
- tool diameters are positive;
- arc endpoints and radii are coherent.

**Path invariants**

- segment continuity;
- endpoint consistency;
- valid parameter domains;
- bounded curvature where required;
- tolerance metadata corresponds to construction.

**Machine-state invariants**

- cutting implies a loaded tool;
- cutting implies a valid spindle state;
- motion implies homed axes and a known frame transform;
- tool change implies spindle stopped.

**Geometric invariants**

$$
S_{i+1}\subseteq S_i
$$

Stock only decreases.

$$
P_{\text{protected}}\subseteq S_i
$$

Protected target material remains.

$$
O_{i+1}=O_i
$$

Fixtures are not altered.

**Compiler invariants**

- provenance is total;
- every artifact has a stable hash;
- no unsupported operation survives a full lowering pass;
- every approximation has an attached bound;
- raw commands are absent from production-certifiable programs.

**Temporal invariants**

- an executing job is the acknowledged uploaded job;
- authorization is not separated from execution by an unchecked state change;
- abort does not return success before motion cessation is confirmed;
- disconnection cannot silently become continued host-controlled motion.

---

## 10. Abstract interpretation is the right foundation for many validators

Abstract interpretation executes a program over an abstract domain that conservatively represents many concrete states. Its purpose is not to simulate one likely execution, but to over-approximate all possible executions relevant to a property. citeturn409138search1

Possible abstract domains for this compiler include:

```text
Position     = exact point | axis-aligned box | unknown
Velocity     = interval
Tool         = exact tool | set of tools | unknown
Spindle      = off | on[rpm interval] | unknown
Homing       = homed | unhomed | maybe
WCS          = known transform interval | unknown
Modal motion = G0 | G1 | G2 | G3 | set thereof
Stock        = conservative occupancy/height bounds
Frames       = known graph | inconsistent | unknown
```

An abstract interpreter for final G-code would update modal state and machine state block by block.

For example:

$$
\widehat\sigma_{i+1}
=
\widehat{\operatorname{transfer}}
(\widehat\sigma_i,b_i)
$$

The analysis is sound when:

$$
\sigma_i\in\gamma(\widehat\sigma_i)
\Longrightarrow
\operatorname{step}(\sigma_i,b_i)
\in
\gamma(
\widehat{\operatorname{transfer}}
(\widehat\sigma_i,b_i)
)
$$

where $\gamma$ maps an abstract state to the concrete states it represents.

### Applications

- modal-state validation;
- definite tool/spindle state;
- machine travel bounds;
- unreachable controller modes;
- possibly active coordinate systems;
- feed and spindle ranges;
- state after pause or resume;
- raw command effect propagation;
- loop and subprogram analysis.

A `RawCmd` should generally map affected abstract components to **unknown**. Its self-declared `effects` list may be displayed as an assumption, but should not be trusted as a proof unless independently parsed and checked.

### Proof-carrying abstract interpretation

A compiler can attach the abstract state before every block:

```ts
interface BlockInvariant {
  block: number;
  before: AbstractMachineState;
  after: AbstractMachineState;
}
```

A small checker verifies:

1. the first invariant includes the initial state;
2. each block transfer is sound;
3. adjacent block states connect;
4. each claimed safety predicate follows from the abstract state.

The expensive analyzer is then untrusted. The checker is the trusted component.

---

## 11. Numerical soundness and robust computational geometry

This is the hardest part of a credible CAM certificate.

The implementation must distinguish:

1. ideal mathematical geometry;
2. finite-precision representation;
3. numerical algorithm output;
4. a conservative enclosure of the true result.

Floating-point predicates used for topology—orientation, sidedness, intersections, contour joining—can give incorrect signs near degeneracies. Adaptive or exact predicates are a standard approach to making these decisions robust. citeturn525981search8

Interval arithmetic provides values guaranteed to enclose the exact mathematical result when implemented with the required rounding behavior. IEEE 1788.1 specifies a simplified interval arithmetic standard over binary64 endpoints. citeturn525981search4

### 11.1 Inner and outer approximations

For a geometric solid $X$, maintain:

$$
X^-\subseteq X_{\text{true}}\subseteq X^+
$$

where:

- $X^-$ is a guaranteed inner approximation;
- $X^+$ is a guaranteed outer approximation.

For collision avoidance, use outer approximations:

$$
\operatorname{Sweep}^+
\cap
O^+
=
\varnothing
\quad\Longrightarrow\quad
\operatorname{Sweep}_{\text{true}}
\cap
O_{\text{true}}
=
\varnothing
$$

For guaranteed removal, use an inner approximation:

$$
R^-\subseteq R_{\text{true}}
$$

For conservative residual stock, if $S_{\text{true}}\subseteq S^+$, then:

$$
S'_{\text{true}}
=
S_{\text{true}}\setminus R_{\text{true}}
\subseteq
S^+\setminus R^-
$$

Therefore:

$$
S'^+=S^+\setminus R^-
$$

is a sound outer bound on remaining stock.

This asymmetry is important:

- **outer swept volume** proves absence of collision or gouge;
- **inner swept volume** proves guaranteed removal;
- using one sampled sweep for both claims is generally unsound.

### 11.2 A grid size is not a proof

A statement such as “verified to a 0.2 mm grid” is meaningful only if the checker proves that unsampled behavior is bounded by the cell representation.

A point-sampling algorithm can miss:

- a narrow fixture;
- a thin target feature;
- a rapid crossing between samples;
- a small gouge between grid cells;
- a topology change;
- an acute cusp.

A sound grid certificate needs, for example:

- conservative cell occupancy;
- interval bounds over each cell;
- a Lipschitz bound;
- adaptive subdivision until a separating condition is proved;
- a guaranteed enclosure of the tool sweep.

Otherwise, the honest status is:

```text
sampled simulation; no continuous-domain guarantee
```

not:

```text
verified to resolution
```

### 11.3 Error budgets must be typed by metric

The current scalar `totalGeometric` is a useful warning mechanism, but formal error composition needs more structure.

Different errors use different metrics:

- Hausdorff path deviation;
- normal-direction surface error;
- maximum gouge penetration;
- frame-transform uncertainty;
- axis-following error;
- time or velocity error;
- tool-radius uncertainty.

They cannot all be added indiscriminately.

For a pass $f$ with Lipschitz constant $L_f$:

$$
\varepsilon_{\text{out}}
\le
L_f\varepsilon_{\text{in}}
+
\varepsilon_f
$$

A plain sum is sound only when:

- every contribution is a proven upper bound;
- all contributions use a compatible metric and frame;
- each transformation has amplification factor at most one, or amplification is included;
- correlations do not introduce an unmodeled effect.

A better representation is:

```ts
type ErrorBound =
  | {
      metric: "hausdorff-position";
      frame: FrameId;
      value: Mm;
    }
  | {
      metric: "normal-surface";
      surface: ArtifactRef;
      value: Mm;
    }
  | {
      metric: "max-gouge-depth";
      target: ArtifactRef;
      value: Mm;
    }
  | {
      metric: "transform-translation";
      transform: ArtifactRef;
      value: Mm;
    }
  | {
      metric: "transform-rotation";
      transform: ArtifactRef;
      value: Radians;
    };
```

### 11.4 Configuration-space reasoning

Collision checking can be formulated in configuration space: the moving tool/holder becomes a point, while obstacles are expanded into forbidden configuration regions. This is a standard motion-planning formulation. citeturn525981search2turn525981search11

For a fixed-orientation three-axis mill:

$$
O_{\text{C-space}}
=
O\oplus(-B_{\text{tool+holder}})
$$

A tool-center path is safe when it avoids this expanded obstacle.

This gives a clean semantic distinction between:

- free-space linking;
- material-removing motion;
- machine-axis limits;
- target protection.

---

## 12. Certificate design

Proof-carrying code separates an untrusted producer from a relatively small consumer-side checker: the producer supplies code plus evidence that the code satisfies a defined policy, and the consumer validates that evidence. citeturn662326search4turn662326search11

That architecture maps directly to CAM:

```text
large, complex, heuristic CAM compiler
              ↓
       program + evidence
              ↓
small independent certificate checker
              ↓
       accept or reject
```

The strategy generator, optimizer, simulator, and even most compiler passes can remain untrusted if their outputs are checked independently.

### 12.1 Claim schema

A claim should name an actual proposition, not merely a category such as “gouge.”

```ts
interface Claim {
  readonly id: ClaimId;

  readonly subject: ArtifactRef;
  readonly proposition: StructuredPredicate;

  readonly result:
    | "proved-exact"
    | "proved-bounded"
    | "exhaustive-finite-check"
    | "translation-validated"
    | "simulation-only"
    | "assumed"
    | "unknown"
    | "refuted";

  readonly method: MethodRef;
  readonly assumptions: readonly AssumptionRef[];
  readonly evidence: readonly EvidenceRef[];
  readonly dependencies: readonly ClaimId[];

  readonly bound?: ErrorBound;

  readonly checker: {
    id: string;
    version: string;
    binaryHash: Hash;
  };
}
```

Example propositions:

```text
forall t:
  machinePose(job, t) ∈ profile.travelEnvelope
```

```text
maxPenetration(
  sweptTool(job),
  protectedTarget
) ≤ 0.020 mm
```

```text
forall rapid r at stock state S_r:
  sweptToolHolder(r) ∩ (S_r ∪ fixtures) = ∅
```

```text
interpretRS274(emittedBytes, initialModalState)
  = controllerProgramTrace
```

```text
storedJobHash = certifiedJobHash
```

### 12.2 Evidence methods

| Method | Appropriate claim |
|---|---|
| Symbolic proof | Modal equivalence, state-machine invariants |
| Interval enclosure | Numeric bounds, transforms, curve extrema |
| Exact geometric predicates | Topology and intersection decisions |
| Abstract interpretation | State and range properties over a program |
| Translation validation | Individual compiler-pass output |
| Exhaustive finite-state checking | Controller protocol and interlock FSM |
| Conservative spatial cover | Collision and gouge bounds |
| Simulation | Diagnostics and testing, not universal proof |
| Physical calibration record | External machine/tool assumption |

### 12.3 Certificate dependency graph

Claims should form a DAG:

```text
source hash
   ↓
elaborated-plan hash
   ↓  unit/frame evidence
intent hash
   ↓  planning witness
toolpath hash
   ↓  approximation and target evidence
machine-program hash
   ↓  capability/travel evidence
controller-IR hash
   ↓  modal-equivalence evidence
G-code byte hash
   ↓  parse-back evidence
uploaded byte hash
   ↓  controller acknowledgement
execution-state snapshot
```

Changing any of these must invalidate dependent claims:

- machine profile;
- firmware semantics;
- tool or holder geometry;
- stock;
- target;
- fixture model;
- WCS transform;
- postprocessor settings;
- coordinate precision;
- safe height;
- emitted bytes.

### 12.4 Trusted computing base

The trusted base should be deliberately small:

- formal definitions of claim predicates;
- independent certificate checker;
- exact or interval numerical kernel used by the checker;
- final G-code parser and controller semantics;
- canonical serialization and hashing;
- runtime identity/hash handshake;
- physical assumptions explicitly accepted by the operator.

The following should ideally not be trusted:

- toolpath strategy implementations;
- contour stitching;
- heuristic ordering;
- simulator rendering;
- editor;
- JavaScript runtime;
- optimizer;
- main compiler orchestration.

### 12.5 Current `CheckStatus` redesign

The existing four-way distinction—

- exact;
- to-resolution;
- not checked;
- unverifiable—

is better than `safe: true`.

But it combines three different dimensions:

1. **What proposition was checked?**
2. **What method was used?**
3. **What result was obtained?**

Those should be separate.

For example:

```ts
{
  proposition: {
    kind: "max-gouge-depth",
    targetHash,
    maxAllowed: mm(0.02)
  },
  method: {
    kind: "conservative-interval-sweep",
    spatialSubdivisionLimit: mm(0.01)
  },
  result: "proved-bounded",
  bound: {
    metric: "max-gouge-depth",
    value: mm(0.017)
  }
}
```

This is substantially harder to misinterpret than:

```ts
gouge: {
  kind: "verified-to-resolution",
  spatial: 0.1,
  numerical: 0.01
}
```

---

## 13. Operations research belongs after feasibility semantics

Optimization should be expressed as:

$$
\min_x J(x)
$$

subject to:

$$
x\in\mathcal F
$$

where $\mathcal F$ is the independently checkable feasible set.

Typical hard constraints include:

- feature precedence;
- tool compatibility;
- fixture clearance;
- target protection;
- axis limits;
- maximum feed, velocity, acceleration, and jerk;
- maximum contour error;
- probing dependencies;
- stock-state dependencies;
- entry and engagement constraints.

The objective may include:

$$
J(x)=
T_{\text{cycle}}
+\lambda_1N_{\text{tool changes}}
+\lambda_2D_{\text{rapid}}
+\lambda_3J_{\text{wear}}
$$

but safety should not be a weighted penalty. It belongs in $\mathcal F$.

### 13.1 Operation sequencing

Toolpath ordering with precedence constraints can be modeled using variants of the precedence-constrained traveling salesman problem. This has been applied directly to CNC toolpath optimization. citeturn538704search2turn538704search15

Nodes can represent:

- operations;
- possible path orientations;
- entry points;
- tool/setup alternatives.

Edges represent transition costs:

- retract;
- free-space link;
- tool change;
- spindle acceleration;
- probing;
- setup transition.

A precedence graph captures constraints such as:

```text
rough before finish
probe before dependent geometry
drill pilot before large drill
machine internal feature before releasing surrounding stock
```

### 13.2 Reordering is not generally semantics-preserving

Geometrically:

$$
(S\setminus R_1)\setminus R_2
=
(S\setminus R_2)\setminus R_1
$$

But machining operations may still not commute because intermediate stock affects:

- entry feasibility;
- tool engagement;
- remaining support;
- chip evacuation;
- thin-wall deflection;
- workholding;
- rapid safety;
- probe results.

Each operation therefore needs effect summaries:

```ts
interface OperationEffects {
  readsStock: RegionSet;
  removesStock: RegionSet;
  readsProbeValues: readonly BindingId[];
  writesProbeValues: readonly BindingId[];
  requiresTool: ToolId;
  requiresFrame: FrameId;
  precedenceTags: readonly string[];
}
```

Two operations can be freely reordered only if an independence checker proves their effects commute under the process model.

### 13.3 Free-space linking

Link generation is a shortest-path or optimal-motion problem in configuration space:

$$
\min_\gamma
\int_0^1 c(\gamma(s),\dot\gamma(s))\,ds
$$

subject to:

$$
\gamma(s)\notin O_{\text{C-space}}
$$

For a simple three-axis machine, this might be a visibility graph, A*, or a conservative retract policy. More advanced linkers can use distance fields or Eikonal solvers.

Fast marching is a numerical method for solving the Eikonal equation and monotonically advancing fronts; it is useful for distance fields and optimal-path extraction. It does not by itself prove that a generated constant-scallop path achieves a physical scallop bound. That requires a separate theorem connecting the field discretization, surface model, tool geometry, and extracted contours. citeturn525981search0turn525981search5

### 13.4 Feed scheduling

Given a geometric path, feed scheduling is an optimal-control problem:

$$
\min T
$$

subject to:

$$
|\dot q_i|\le v_i^{\max}
$$

$$
|\ddot q_i|\le a_i^{\max}
$$

$$
|\dddot q_i|\le j_i^{\max}
$$

plus:

- contour-error bounds;
- servo tracking limits;
- spindle and chip-load constraints;
- process-force limits.

CNC minimum-time trajectory research formulates this as constrained optimal control, often including velocity, acceleration, jerk, and tracking-error constraints. citeturn538704search1turn538704search7

The optimizer’s certificate should distinguish:

- **feasibility**: independently verified constraints;
- **objective value**: measured cycle-time estimate;
- **optimality**: proven only when a lower bound or solver certificate supports it;
- **optimality gap**:

$$
\frac{J_{\text{candidate}}-L}{L}
$$

where $L$ is a valid lower bound.

A greedy heuristic can still be useful. Its result should be called “verified feasible with estimated cost $J$,” not “optimal.”

---

## 14. Runtime assurance is part of the proof

A compile-time certificate proves a conditional statement:

```text
this program is safe if these assumptions hold
```

At execution time, the system must establish those assumptions.

A minimum execution protocol should bind:

- machine identity;
- firmware version or semantics profile;
- machine-profile hash;
- tool and holder identity;
- active WCS and transform;
- homing state;
- fixture/setup identity;
- stock/target version;
- uploaded byte hash;
- current alarm and interlock state.

Conceptually:

```text
host:       propose job hash H and assumptions A
controller: report machine state M and stored hash H'
host:       verify H = H' and M satisfies A
host:       authorize execution of H
controller: acknowledge exact execution instance
```

For additional protection, runtime assurance can place a small trusted monitor around a more complex controller or planner. Simplex architectures use a trusted safety component that takes control when an advanced component would violate a safety condition. Formal runtime-assurance frameworks extend this idea to cyber-physical and hybrid systems. citeturn840691search0turn840691search6

For the Z1, a realistic small monitor could enforce:

- allowed controller state transitions;
- no command execution before hash-bound authorization;
- axis and feed command envelopes;
- no spindle/tool-state contradictions;
- watchdog and communication-loss policy;
- explicit abort acknowledgement;
- safe-stop state.

The monitor must account for latency and stopping distance. “Stop requested” is not equivalent to “motion has stopped.”

---

## 15. Applying this directly to the current implementation

Several current decisions are theoretically sound foundations.

### Good foundations

**Non-modal canonical commands**

This makes local analysis possible and delays modal state to one controlled lowering step. It aligns well with canonical machine semantics.

**Manufacturing intent before G-code**

This correctly treats G-code as a backend rather than the source language.

**Explicit provenance**

Provenance is required for diagnostics, certificate dependencies, and assurance-case explanations.

**`RawCmd` as visibly unanalysable**

Explicitly marking an escape hatch is better than silently embedding unknown syntax.

**Distinct pipeline types**

The `MachineProgram`/`ValidatedProgram` distinction prevents an important class of accidental API misuse.

**Check statuses more detailed than a boolean**

This is the right direction toward honest assurance.

### Where the theory exposes gaps

**`ValidatedProgram` proves only that one function was called**

The source comment already acknowledges this. The brand should remain an API gate, but evidence needs independent semantics and checkers.

**Travel is marked exact after sampling paths**

Sampling a curve is not an exact travel proof. Analytic line and arc bounds can often be computed exactly or conservatively; polysegments can be checked segment by segment. Unknown transforms should make the result conditional or unknown.

**The sampled certificate has no target-part input**

`buildCertificate()` receives simulation depth information but not target geometry. Therefore it cannot establish a proposition such as “maximum target gouge is below $x$.”

**One sampled status is reused for two different claims**

Rapid-through-stock and target gouge have different semantics, inputs, and evidence requirements.

**The scalar error-budget sum lacks a formal metric**

It is useful as a warning but not yet a compositional geometric proof.

**Path endpoint tolerance is treated like equality**

That supports practical construction but not strict categorical laws or non-accumulating proof.

**Certification occurs before all lowering is complete**

Any postprocessor operation—traverse expansion, arc lowering, modal compression, rounding, inserted spindle stops—must itself preserve the claims. The exact final bytes need a final certificate.

**Self-declared raw effects are not trustworthy**

They can help explain intent, but an unparsed raw command must conservatively invalidate affected analyses.

---

## 16. Recommended target architecture

```text
┌───────────────────────────────────────────────────────────┐
│ JavaScript macro environment                              │
│ isolated, deterministic, capability-limited               │
└───────────────────────────┬───────────────────────────────┘
                            │ immutable AST + source map
┌───────────────────────────▼───────────────────────────────┐
│ Elaborator                                                 │
│ units, frames, tools, references, finite-value checks      │
└───────────────────────────┬───────────────────────────────┘
                            │ typed Plan IR + evidence
┌───────────────────────────▼───────────────────────────────┐
│ Manufacturing planner                                     │
│ heuristic/optimization allowed                            │
└───────────────────────────┬───────────────────────────────┘
                            │ toolpaths + planning witness
┌───────────────────────────▼───────────────────────────────┐
│ Independent geometric checker                             │
│ intent conformance, target, stock, robust predicates       │
└───────────────────────────┬───────────────────────────────┘
                            │ certified Geometric Toolpath
┌───────────────────────────▼───────────────────────────────┐
│ Scheduler/linker/feed planner                             │
│ precedence, C-space, optimal control                       │
└───────────────────────────┬───────────────────────────────┘
                            │ scheduled trajectory + witness
┌───────────────────────────▼───────────────────────────────┐
│ Machine lowering                                          │
│ capabilities, frames, travel, controller interpolation     │
└───────────────────────────┬───────────────────────────────┘
                            │ Machine IR
┌───────────────────────────▼───────────────────────────────┐
│ Postprocessor                                              │
│ controller dialect, modality, serialization                │
└───────────────────────────┬───────────────────────────────┘
                            │ exact bytes
┌───────────────────────────▼───────────────────────────────┐
│ Independent final validator                               │
│ reparse, interpret, compare, geometric/temporal claims      │
└───────────────────────────┬───────────────────────────────┘
                            │ certificate DAG + byte hash
┌───────────────────────────▼───────────────────────────────┐
│ Runtime preflight and assurance monitor                    │
│ machine state, setup assumptions, upload/execution binding │
└───────────────────────────────────────────────────────────┘
```

The most important package additions would be:

```text
@cam/semantics
@cam/certificate-schema
@cam/checker-core
@cam/gcode-semantics
@cam/robust-geometry
@cam/controller-model
```

---

## 17. Practical implementation sequence

### Stage 1: Make claims precise and honest

- Replace generic certificate fields with structured propositions.
- Downgrade sampled simulation to `simulation-only`.
- Bind every claim to artifact and configuration hashes.
- Forbid “exact” unless the method genuinely covers the continuous domain.
- Treat raw controller text as unknown.

### Stage 2: Create executable reference semantics

Implement pure interpreters for:

- Plan IR;
- canonical commands;
- Machine IR;
- controller IR;
- emitted G-code modal state.

Add trace comparison and structured state snapshots.

### Stage 3: Add translation validators

Begin with passes that are discrete and comparatively easy to validate:

- modal compression;
- coordinate rounding;
- serialization/parse-back;
- traverse expansion;
- arc linearization;
- feed clamping;
- inserted preamble and shutdown commands.

This provides substantial confidence without proving the complete compiler.

### Stage 4: Build the geometric assurance kernel

- robust predicates;
- interval bounds;
- tool and holder solids;
- target and fixture models;
- conservative swept-volume subdivision;
- separate inner and outer material approximations;
- typed error metrics.

Keep complex strategy generators outside the trusted base.

### Stage 5: Model the controller protocol

Specify upload/start/pause/resume/abort/disconnect as a state machine. Check safety and liveness properties with model checking or a TLA-style specification.

### Stage 6: Mechanize the small trusted core

Do not begin by formalizing all CAM geometry.

The highest-value mechanization targets are:

- canonical command semantics;
- controller modal semantics;
- modal compression;
- interlock state machine;
- certificate checker;
- proof composition;
- artifact/hash binding.

The complex planners can remain ordinary TypeScript so long as independently checked evidence accompanies their output.

---

## 18. Primary reading path

A focused theoretical curriculum for this compiler is:

1. **Canonical machine semantics:** the NIST canonical machining-command and RS274 interpreter reports. citeturn662326search0turn662326search1
2. **Program contracts and invariants:** Hoare’s axiomatic semantics. citeturn409138search0
3. **Sound static approximation:** Cousot and Cousot’s abstract interpretation. citeturn409138search1
4. **State-indexed APIs:** typestate and parameterized monads. citeturn628227search8turn409138search8
5. **Multi-level IR architecture:** MLIR’s design and dialect-conversion legality model. citeturn628227search3turn628227search5
6. **Whole-compiler proof:** CompCert’s pass-by-pass semantic preservation. citeturn662326search8turn662326search12
7. **Per-compilation proof:** translation validation. citeturn840691search2turn840691search3
8. **Producer/checker separation:** proof-carrying code. citeturn662326search4
9. **Robust geometry:** adaptive exact predicates and interval arithmetic. citeturn525981search8turn525981search4
10. **Motion and path planning:** configuration spaces and fast marching. citeturn525981search11turn525981search0
11. **Controller protocols:** TLA and runtime-assurance/Simplex architectures. citeturn538704search0turn840691search0
12. **Machining optimization:** precedence-constrained sequencing and constrained feedrate optimal control. citeturn538704search2turn538704search1

## Bottom line

The decisive design change is this:

> Every pass should produce both an artifact and independently checkable evidence relating that artifact to its input. The final certificate should compose those relations and bind them to the exact G-code bytes, machine profile, tools, setup, controller semantics, and live execution state.

That gives a coherent foundation for the IR, compiler passes, invariants, geometry algorithms, optimization passes, safety certificates, and Z1 controller protocol.


---

> make a full textbook as markdown and pdf

I’ll build a self-contained, source-grounded textbook around Dropcut/Z1, covering formal semantics, IRs, certifying passes, geometry, controller protocols, exercises, and implementation guidance, then validate Markdown and PDF editions.

<details><summary>💭 Thinking</summary>

**Planning textbook creation**

I’m preparing the requested Markdown and PDF by inspecting the existing project materials, researching the relevant theory, and organizing chapters with examples, exercises, diagrams, and technical explanations.

**Planned textbook creation**

</details>

```unknown
bash -lc cat /home/oai/skills/pdfs/SKILL.md && printf '\n---DOCX?---\n' && ls -la /home/oai/skills/pdfs
```

<details><summary>💭 Thinking</summary>

**Building the textbook framework**

I’m shaping a self-contained textbook around compiler theory, intermediate representations, certified geometry, optimization, invariants, and assurance. I’ll connect those ideas to the project case study and include references, exercises, and examples.

**Built the textbook framework**

**Reviewed PDF requirements and inspected project archive and existing review**

</details>

```unknown
bash -lc set -e
cd /mnt/data/z1_textbook_work
rm -rf dropcut-studio
unzip -q /mnt/data/dropcut-studio.zip
find dropcut-studio/packages -maxdepth 3 -type f | sort | sed -n '1,240p'
printf '\nTop-level docs:\n'
find dropcut-studio -maxdepth 3 -type f \( -name '*.md' -o -name '*.ts' -o -name '*.go' \) | sort | sed -n '1,220p'
```

<details><summary>💭 Thinking</summary>

**Organizing implementation details**

I’m organizing the material into theory, verified compilation, geometry, optimization, certification, runtime assurance, and a project-specific implementation section, while keeping the final textbook coherent and practical.

**Organized implementation details**

**Inspected Dropcut repository and key implementation files**

</details>

```json
{"search_query":[{"q":"site:acm.org Hoare 1969 axiomatic basis computer programming DOI"},{"q":"site:dl.acm.org Cousot Cousot abstract interpretation 1977 paper"},{"q":"site:compcert.org CompCert semantic preservation documentation"},{"q":"site:research.google/pubs MLIR scaling compiler infrastructure domain specific computation paper"}],"response_length":"long"}
```

<details><summary>💭 Thinking</summary>

**Preparing final files**

I’m consolidating the case study, theory chapters, implementation guidance, exercises, and bibliography into the requested Markdown and PDF deliverables, then I’ll verify the rendered PDF before sharing links.

**Defining the textbook scope**

I’m covering semantics, layered IR, effectful machine state, compiler correctness, geometric certification, optimization, runtime assurance, and a Dropcut case study, supported by primary references and practical exercises.

**Prepared final files and defined textbook scope**

</details>

The implementation inventory is complete; I’ll structure the book as an eight-part course using actual pipeline boundaries and failure modes, with the canonical non-modal IR as a running case study.

<details><summary>💭 Thinking</summary>

**Searched 2 websites**

</details>

```unknown
bash -lc sed -n '1,240p' /home/oai/skills/pdfs/SKILL.md && printf '\n--- create ---\n' && sed -n '1,220p' /home/oai/skills/pdfs/tasks/create.md && printf '\n--- convert ---\n' && sed -n '1,220p' /home/oai/skills/pdfs/tasks/convert.md
```

<details><summary>💭 Thinking</summary>

**Created certificate-carrying CAM compiler textbook with verified PDF figures**

</details>

```unknown
bash -lc cat >> /mnt/data/z1_textbook_work/book/Certificate_Carrying_CAM_Compilers.md <<'EOF'

\part{Part II - Language and Intermediate Representation Design}

# JavaScript as a Staged Macro Language

> **Learning objectives.** The reader should be able to separate an authoring language from the stable CAM language, explain staging and elaboration, and design a deterministic capability-limited script boundary.

## 7.1 The convenience and danger of embedded JavaScript

JavaScript is attractive as a CAM authoring language. It has familiar control flow, functions, data structures, packages, editors, and a large ecosystem. Parametric geometry becomes concise:

```ts
for (let i = 0; i < holeCount; i++) {
  drill({
    at: p(origin.x + i * spacing, origin.y, topZ),
    diameter: mm(3),
    depth: mm(8),
  });
}
```

But unrestricted JavaScript is a poor stable semantic core. It can inspect time, randomness, environment variables, files, network state, prototypes, and host globals. It can loop forever, mutate shared objects, invoke asynchronous callbacks after lexical scopes have ended, or depend on implementation details of the runtime.

The solution is not to discard JavaScript. It is to give it a precise role: **JavaScript is a macro language that constructs an inert CAM abstract syntax tree.**

## 7.2 Two languages, not one

The authoring language includes JavaScript syntax and its computational power. The stable CAM language is a serializable AST with explicit constructors and no executable closures.

```text
JavaScript source
     |
     | evaluate in isolated staged environment
     v
Immutable authoring AST
     |
     | elaborate names, units, frames, tools
     v
Plan IR
```

After staging, no compiler pass should call user-provided functions. The AST should contain only finite data, identifiers, source spans, and references to declared artifacts.

This resembles multi-stage programming: one program executes now to construct another program that will be analyzed and compiled later [R37]. The staging boundary is a semantic boundary and a security boundary.

## 7.3 Capability design

The script should receive an explicit capability object:

```ts
interface CamAuthoringCapabilities {
  units: UnitConstructors;
  geometry: GeometryConstructors;
  tools: ToolRegistryBuilder;
  plan: PlanBuilder;
  diagnostics: DiagnosticSink;
}
```

Capabilities prevent accidental ambient access, but ordinary lexical shadowing is not a security sandbox. Same-realm evaluation with `new Function` still exposes standard constructors and prototype chains. A hostile or simply defective script can also block the event loop indefinitely.

A production design should execute scripts in a separately terminable worker, process, or isolate with:

- no ambient network or filesystem access unless explicitly granted;
- a wall-clock deadline enforced outside the script;
- a memory limit;
- deterministic time and randomness sources;
- a versioned API module;
- structured input and output serialization;
- process termination on cancellation;
- no shared mutable object graph with the compiler.

## 7.4 Determinism and declared inputs

A reproducible authoring run should be modeled as:

$$
\operatorname{eval}(	ext{source},\text{apiVersion},\text{inputs},\text{seed})
=\text{AST}.
$$

Every input must be declared and content-addressed. If a script reads a mesh, tool library, material table, or project parameter, the compilation record should include its hash.

```ts
interface ScriptEvaluationRecord {
  sourceHash: Hash;
  languageVersion: string;
  apiVersion: string;
  inputArtifacts: readonly ArtifactRef[];
  deterministicSeed?: bigint;
  resultAstHash: Hash;
  diagnostics: readonly Diagnostic[];
}
```

The same record should be sufficient to reproduce the AST in a clean environment.

## 7.5 Scope combinators

An authoring API may use scoped operations:

```ts
withTool(tool, () => {
  withFeed(mmPerMin(400), () => {
    pocket(feature);
  });
});
```

A synchronous implementation usually saves state, invokes the callback, and restores state in `finally`. If the callback returns a promise, restoration can happen before awaited work completes. The apparent lexical semantics are broken.

There are three sound choices:

1. Prohibit asynchronous callbacks and detect promises at runtime.
2. Make the combinator explicitly asynchronous and await the callback before restoration.
3. Avoid dynamic scopes in the AST builder and pass immutable context explicitly.

For a deterministic macro language, the third option is often simplest.

## 7.6 Mutability at the boundary

If a tool object is registered and then retained by reference, later user mutation can change the plan after validation:

```ts
const tool = { diameter: mm(3.175), fluteLength: mm(12) };
registerTool("T1", tool);
tool.diameter = mm(8); // changes meaning if reference was retained
```

The builder should deep-copy and freeze boundary objects, or convert them immediately into canonical immutable records. Hashing an object only helps if the object cannot change afterward.

## 7.7 Worked example: staged pocket program

A good authoring run produces data such as:

```ts
const ast: AuthoringProgram = {
  version: "cam-authoring/1",
  tools: [{
    id: "T1",
    geometry: { kind: "flatEndMill", diameter: 3.175, fluteLength: 12 },
    source: { file: "job.cam.js", line: 3, column: 14 },
  }],
  operations: [{
    kind: "rectPocket",
    featureId: "P1",
    frame: "work:G54",
    origin: [10, 10, 0],
    size: [30, 20],
    depth: 4,
    tool: "T1",
    radialAllowance: 0.2,
    axialAllowance: 0.2,
    source: { file: "job.cam.js", line: 8, column: 3 },
  }],
};
```

The AST contains no closure that can later inspect the host environment. It can be validated, displayed, serialized, hashed, diffed, and compiled by another implementation.

## 7.8 Design rules

```latex
\begin{designrule}
Use JavaScript to construct an inert, immutable, content-addressed AST. Do not make the JavaScript realm, closures, mutable objects, or ambient globals part of the CAM semantics.
\end{designrule}
```

## 7.9 Exercises

1. List five ambient JavaScript capabilities that damage reproducibility.
2. Design a JSON-serializable AST node for a probing operation.
3. Explain why a timeout checked after a script returns is not an enforced timeout.
4. Show how a synchronous scope combinator fails with an async callback.
5. Define an isolation protocol between a Studio UI and a worker process.
6. Specify which fields must be hashed to reproduce an authoring run.

# A Multi-Level IR Architecture

> **Learning objectives.** The reader should be able to assign concerns to IR levels, define legality at each stage, and avoid both a monolithic universal IR and premature lowering.

## 8.1 Why one IR is not enough

A universal node type such as:

```ts
interface Operation {
  kind: string;
  data: unknown;
}
```

appears flexible but erases the guarantees that make passes understandable. At the other extreme, lowering directly from authoring syntax to G-code forces every planner to know controller details and destroys manufacturing provenance.

A multi-level compiler retains the right information at each stage and defines explicit conversion points. MLIR demonstrates the value of multiple dialects and legality-controlled transformations for domain-specific compilation [R16]. A CAM compiler benefits even more because its abstraction levels correspond to distinct physical meanings.

![A ladder of CAM intermediate representations.](figures/ir_ladder.png){width=98%}

## 8.2 Authoring AST

The authoring AST preserves:

- source spans;
- names and declarations;
- macros already expanded into data;
- user-level concepts;
- unresolved references where diagnostics benefit.

It should exclude arbitrary executable values after the staging boundary.

## 8.3 Elaborated Plan IR

Elaboration resolves:

- units;
- frames;
- tool references;
- geometry artifact references;
- defaults;
- scope-derived settings;
- identifier uniqueness;
- finite values and domain constraints.

The elaborated IR is the first stable, language-independent project representation. It should be possible to save it and compile it without re-running JavaScript.

## 8.4 Manufacturing Intent IR

Intent IR represents features and operations:

- pockets, holes, slots, surfaces, profiles;
- roughing and finishing requirements;
- allowances and tolerances;
- protected and permitted regions;
- dependencies and setup requirements;
- process constraints.

It deliberately excludes exact tool-center paths.

## 8.5 Geometric Toolpath IR

Toolpath IR contains continuous or piecewise-continuous curves with process semantics:

```ts
interface CuttingPath<F extends FrameId> {
  geometry: Path<F>;
  tool: ToolRef;
  feedPolicy: FeedPolicy;
  operation: OperationRef;
  phase: "entry" | "rough" | "finish" | "leadOut";
  directionality: "reversible" | "forwardOnly";
}
```

It should still be independent of a controller's modal syntax.

## 8.6 Scheduled Program IR

Scheduling introduces:

- a total or partially ordered operation sequence;
- path orientation choices;
- entries, retracts, and links;
- tool changes;
- probe dependencies;
- feed schedules or time laws;
- evolving stock-state references.

This is where semantics become stateful. A link that was safe before roughing may be unnecessary afterward; a path that was safe after roughing may be unsafe before it.

## 8.7 Machine IR

Machine lowering resolves:

- axis and kinematic capabilities;
- supported interpolation primitives;
- machine and work frames;
- travel limits;
- spindle and feed limits;
- tool-change behavior;
- probe and accessory capabilities;
- safe expansion of abstract traverses.

Every remaining operation must be supported by the selected machine profile or rejected.

## 8.8 Controller IR

Controller IR makes the controller's semantics explicit without committing to final formatting. It may contain:

- set units;
- select plane;
- select work offset;
- set absolute mode;
- linear and arc motion;
- probe cycle;
- spindle and accessory actions;
- upload metadata;
- program end.

The controller IR should have an interpreter. Final G-code text is then a serialization of this IR plus an optional modal-compression optimization.

## 8.9 Serialized Job Bundle

The final bundle contains more than `.nc` bytes:

- exact controller program bytes;
- content hash;
- machine and firmware profile hash;
- tool and holder manifest;
- stock, target, fixture, and frame artifacts;
- certificate graph;
- declared runtime assumptions;
- optional preview data generated from the same artifact.

## 8.10 Legality

Each IR has a legality predicate. Examples:

```text
Authoring AST legal:
  no executable closures; all nodes schema-valid

Plan IR legal:
  all units/frames/references resolved; all values finite

Toolpath IR legal:
  all paths continuous; operation provenance total

Machine IR legal:
  every operation supported; all coordinates machine-resolved

Controller IR legal:
  initial modal state explicit; no unknown raw effects

Job bundle legal:
  hashes match; required claims present; assumptions well formed
```

A conversion should fail when it cannot produce legal output.

## 8.11 Validation is evidence, not a dialect

A type named `ValidatedProgram` is useful as an API guard, but validation does not create a new language. It creates evidence about an artifact.

```ts
interface Certified<T> {
  artifact: T;
  artifactHash: Hash;
  claims: readonly Claim[];
  evidence: readonly Evidence[];
}
```

Different claims attach at different stages. Path continuity evidence belongs to a toolpath artifact; modal equivalence belongs to controller bytes; runtime identity belongs to an execution instance. One global boolean brand cannot express this graph.

## 8.12 Exercises

1. Assign each concern to an IR level: source span, scallop tolerance, tool-center curve, G17 plane, decimal formatting, upload filename.
2. Write legality predicates for a probing node in Plan IR and Machine IR.
3. Explain why a preview mesh should reference an artifact hash.
4. Give an example of information that must survive planning for later diagnostics.
5. Design an IR conversion that is partial and returns structured diagnostics.
6. Compare a multi-level IR with a universal stringly typed operation list.

# Paths and Curves as Composable Objects

> **Learning objectives.** The reader should be able to model paths categorically, distinguish path image from parameterization, identify the failure of approximate equality, and define safe composition contracts.

## 9.1 Paths as arrows

A path has a start and end pose:

$$
p:A\to B.
$$

If $q:B\to C$, then composition is defined:

$$
q\circ p:A\to C.
$$

A stationary path $\mathrm{id}_A:A\to A$ acts as an identity, and composition is associative. This is the free-category intuition behind a path builder.

```ts
interface Path<F extends FrameId> {
  frame: F;
  start: Point3<F>;
  end: Point3<F>;
  segments: readonly Segment<F>[];
}
```

A builder that derives `end` from appended segments establishes a valuable representation invariant: the declared endpoint cannot disagree with the final segment.

## 9.2 Geometry versus parameterization

A curve is often written:

$$
\gamma:[0,1]\to\mathbb{R}^3.
$$

Two parameterizations can trace the same geometric image at different rates. For geometric path equivalence, curves are commonly considered modulo monotone reparameterization. Concatenating two curves changes parameterization even when the physical trace is unchanged.

This matters because a geometric path is not a trajectory. Time enters later through a monotone map:

$$
s:[0,T]\to[0,1],\qquad x(t)=\gamma(s(t)).
$$

Velocity, acceleration, jerk, and controller following error belong to $s(t)$ and machine dynamics, not to the curve alone.

## 9.3 Segment algebra

Useful primitive segments include:

- line segments;
- circular or helical arcs with geometric center, axis, and sweep;
- splines with declared basis and knot domain;
- polylines with explicit approximation provenance;
- stationary segments or dwells at a pose.

Controller-specific arc offsets such as `I`, `J`, and `K` do not belong in geometric path IR. They are one encoding of the same geometry under a selected plane and endpoint convention.

## 9.4 Exact joins and approximate joins

Suppose path composition accepts endpoints when:

$$
d(a.end,b.start)<\varepsilon.
$$

This relation is not transitive. It cannot serve as exact object identity in a category. Repeated approximate joins can drift, and topology construction can merge unrelated endpoints.

Safer designs include:

1. Canonical snapping to exact grid or symbolic point identities.
2. Explicit join witnesses recording the displacement.
3. A path result carrying accumulated endpoint uncertainty.
4. Exact rational or integer coordinates for topology decisions.
5. A metric-enriched algebra where composition returns a new error bound.

```ts
interface JoinWitness<F extends FrameId> {
  leftEnd: Point3<F>;
  rightStart: Point3<F>;
  displacement: Mm;
  repair: "none" | "snap-right-to-left" | "insert-link";
}
```

An inserted link is not merely a numerical repair. It is a new motion that needs cut or traverse semantics and clearance checking.

## 9.5 Reversal and orientation

A geometric path can often be reversed, but a machining action may not be reversible. Direction affects:

- climb versus conventional milling;
- lead-in and lead-out geometry;
- cutter compensation;
- helical entry;
- probe direction;
- one-way process constraints;
- stock engagement.

Directionality belongs in metadata or the action type. An optimizer must not reverse paths solely because the point list is reversible.

## 9.6 Path continuity is not enough

A syntactically continuous path may still be invalid:

- an arc's declared endpoint may not lie on its circle;
- a polyline segment may include a first point inconsistent with the cursor;
- a spline may have a singular or non-finite evaluation;
- curvature may exceed process or dynamics limits;
- the path may cross forbidden material;
- the frame may be inconsistent.

Distinguish representation invariants from semantic properties.

## 9.7 Worked example: arc witness

An arc segment can be represented as:

```ts
interface ArcSegment<F extends FrameId> {
  to: Point3<F>;
  center: Point3<F>;
  axis: UnitVec3;
  sweep: Radians;
}
```

A checker given the start point verifies:

1. the axis is unit length within a certified bound;
2. start and end radial distances agree within tolerance;
3. the declared sweep rotates the start radius to the end radius;
4. any axial displacement is consistent with a helical interpretation;
5. all values are finite;
6. the chosen linearization, if any, satisfies its sagitta bound.

## 9.8 Design rules

```latex
\begin{designrule}
Use path composition to enforce endpoint discipline, but do not confuse numerical proximity with equality or structural continuity with machining safety. Make every repair an explicit, semantically classified operation.
\end{designrule}
```

## 9.9 Exercises

1. Prove associativity of exact segment-list concatenation.
2. Explain why parameterized-curve equality is too strict for geometric paths.
3. Design a metric-aware result type for approximate concatenation.
4. Give three reasons a path reversal may be illegal.
5. Specify checks for a helical arc.
6. Construct three endpoints that demonstrate non-transitivity of tolerance joins.
7. Explain why automatically inserting a line between discontinuous cut paths can be dangerous.

# Actions, Effects, and Indexed Commands

> **Learning objectives.** The reader should be able to model commands as effectful computations, explain Kleisli composition, and use indexed state to encode legal command sequencing.

## 10.1 A path is not an action

The same curve can denote a rapid traverse, cutting feed, probe motion, inspection scan, or air move. The geometry alone does not determine effects. A machining command changes machine and stock state, can fail, emits a trace, and may produce a value.

A simple state-and-error command type is:

$$
M(A)=\Sigma\to\operatorname{Result}(A\times\Sigma,E).
$$

In TypeScript:

```ts
type Command<A> =
  (state: MachineState) =>
    Result<{ value: A; state: MachineState }, CommandError>;
```

A probe command returns a measurement; a cut commonly returns `void` but changes stock and pose.

## 10.2 Why ordinary composition fails

Let:

$$
f:A\to M(B),\qquad g:B\to M(C).
$$

Ordinary composition $g\circ f$ is ill typed because $f$ returns $M(B)$ while $g$ expects $B$. A monad supplies `bind`:

$$
\operatorname{bind}:M(B)\times(B\to M(C))\to M(C).
$$

For a result-and-state computation, `bind` propagates errors and threads the updated state into the next command.

```ts
function bind<A, B>(ma: Command<A>, f: (a: A) => Command<B>): Command<B> {
  return state0 => {
    const ra = ma(state0);
    if (!ra.ok) return ra;
    return f(ra.value.value)(ra.value.state);
  };
}
```

This is Kleisli composition. Monads provide a disciplined way to compose effectful computations [R10, R11].

## 10.3 CNC effects

A realistic command effect includes more than mutable state:

```ts
interface CommandResult<A> {
  value: A;
  state: MachineState;
  trace: readonly Event[];
  assumptionsUsed: readonly AssumptionRef[];
  claimsProduced: readonly Claim[];
}
```

Potential effects include:

- failure and alarms;
- machine-state mutation;
- stock removal;
- logging and provenance;
- nondeterministic measurement;
- asynchronous controller interaction;
- resource use and time;
- uncertainty propagation.

An effect system can record which operations read or modify which resources [R14].

## 10.4 Indexed commands

A plain state monad does not express that the type of legal state changes. A parameterized or indexed command type does:

$$
\operatorname{Cmd}\langle S_{before},S_{after},A\rangle.
$$

Composition requires the post-state index of one command to match the pre-state index of the next [R13]. Typestate uses the same idea to restrict operations by protocol state [R12].

```ts
type StartSpindle<S extends Homed & HasTool> =
  Cmd<S, S & SpindleRunning, void>;

type Cut<S extends Homed & HasTool & SpindleRunning & KnownWcs> =
  Cmd<S, S & AtPathEnd, void>;
```

The source API can make impossible sequences difficult to construct.

## 10.5 Limits of type-level safety

TypeScript types are erased. A forged value, unchecked deserialization, stale controller state, or physical mismatch can violate the index. Type-level typestate proves a property of the host program under its model; it does not prove the machine is physically in that state.

Runtime preflight must re-establish assumptions at the execution boundary.

## 10.6 Algebraic effects versus monolithic state

One large `MachineState` can become difficult to reason about. An alternative is to describe effects separately:

```ts
type Effect =
  | ReadPose
  | RequireHomed
  | SelectTool
  | SetSpindle
  | Move
  | RemoveStock
  | Probe
  | EmitDiagnostic;
```

Handlers interpret these effects for simulation, validation, preview, or controller execution. This can improve modularity, but it still requires a coherent ordering and state model. The key is not the syntax of monads versus effect handlers; it is the explicit representation of effects and their laws.

## 10.7 Worked example: probe then offset

A probe returns a measured coordinate:

```ts
type Probe = Cmd<ProbeReady, ProbeReady, Measurement>;
type SetWorkOrigin =
  (m: Measurement) => Cmd<ProbeReady, KnownWcs, void>;
```

Kleisli composition connects the returned value to the next operation:

```ts
const establishWcs = probeSurface(direction, maxTravel)
  .flatMap(measurement => setWorkOrigin(measurement));
```

The data dependency is explicit. A command list that merely places `probe` before `set offset` without binding the result is semantically incomplete.

## 10.8 Exercises

1. Implement `pure` and `bind` for a result-and-state command type.
2. State the three monad laws and explain their practical value for command sequencing.
3. Design indexed states for unhomed, homed, tool-selected, and spindle-running modes.
4. Explain one invariant that TypeScript typestate cannot establish about a physical machine.
5. Model a probe command that can return contact, no contact, or alarm.
6. Compare a state monad with an explicit effect algebra for CAM.

# State Tokens, SSA, and Ordering

> **Learning objectives.** The reader should be able to use an SSA-style state token to make effects explicit, construct def-use dependencies, and identify which transformations are legal around stateful commands.

## 11.1 The machine state as a linear resource

A practical IR need not encode every typestate distinction in TypeScript generics. It can make ordering explicit with a state token. Each effectful operation consumes one token and produces the next.

![An SSA-style machine state token threads through commands.](figures/state_token.png){width=98%}

```text
%s0 = machine.initial
%s1 = machine.require_homed %s0
%s2 = tool.select %s1 @T1
%s3 = spindle.start %s2 12000rpm
%s4 = motion.cut %s3 path=@p feed=400
%s5 = spindle.stop %s4
```

The token is not the full runtime state. It is an ordering and dependency witness.

## 11.2 Relation to SSA

Static single assignment form gives each value one definition and makes data dependencies explicit [R15]. A machine-state token applies the same discipline to side effects. Operations cannot be silently reordered across token dependencies.

Pure geometry computations need no token:

```text
%p1 = path.offset %feature by=1.2mm
%p2 = path.reverse %p1
```

Effectful program construction does:

```text
%s1 = motion.traverse %s0 to=%p1.start
%s2 = motion.cut %s1 path=%p1
```

## 11.3 Multiple resources

One global token is simple but can over-serialize independent work. A richer IR can use separate tokens for:

- controller state;
- stock state;
- tool library state;
- measurement environment;
- diagnostic/provenance stream.

However, splitting resources requires precise alias and commutativity rules. Two cuts that affect disjoint stock regions might commute geometrically but not mechanically if they change support or linking clearance.

For an initial implementation, a single machine/process token is usually safer.

## 11.4 Probe values and control flow

SSA makes measurements explicit values:

```text
%m, %s1 = probe.toward %s0 direction=-Z max=10mm
%t       = frame.from_probe %m datum=@top_surface
%s2      = frame.install %s1 %t as=G54
```

A failed probe can branch:

```text
switch %m.status:
  contact -> continue
  no_contact -> abort
  alarm -> quarantine_session
```

The IR can represent merge points with block arguments or phi-like values. A validator must ensure that state invariants hold along every incoming path.

## 11.5 Effect summaries

Optimization and scheduling require summaries:

```ts
interface EffectSummary {
  reads: readonly ResourceRegion[];
  writes: readonly ResourceRegion[];
  requires: readonly Predicate[];
  ensures: readonly Predicate[];
  mayFail: readonly FailureClass[];
}
```

A pass may commute two operations only if their effects are independent and the reordered preconditions remain valid.

## 11.6 Linear and affine use

A state token should usually be consumed exactly once. Duplicating it would fork the machine into two contradictory futures. Dropping it can omit required shutdown or recovery behavior.

A linear type system enforces exactly-once use; an affine system permits dropping but not duplication. Most mainstream TypeScript code cannot enforce this statically, but the IR verifier can check def-use counts.

## 11.7 Worked example: preventing an unsafe reorder

Suppose an optimizer sees:

```text
%s1 = spindle.start %s0 12000rpm
%s2 = motion.cut %s1 @p
%s3 = spindle.stop %s2
```

Moving `spindle.stop` before the cut would require consuming `%s1` and producing a new state passed to the cut. The cut's `SpindleRunning` requirement fails. The token graph exposes the invalid transformation.

## 11.8 Exercises

1. Convert a small imperative command list into state-token SSA.
2. Explain why duplicating a machine state token is unsound.
3. Design a verifier for single-definition and single-consumption token use.
4. Show a legal reordering of two pure geometry operations.
5. Give a case where two cuts in disjoint regions still should not commute.
6. Model a branch after probing and the merge of its safe paths.

# Provenance, Identity, and Reproducibility

> **Learning objectives.** The reader should be able to design total provenance, content-address artifacts, distinguish identity from display names, and bind diagnostics and certificates to exact inputs.

## 12.1 Provenance is semantic data

When a final move fails a check, the system should explain which source operation, feature, strategy, and compiler pass produced it. Provenance is therefore not an optional debug string. It supports:

- diagnostics;
- certificate dependency graphs;
- incremental recompilation;
- audit and review;
- visual selection in the UI;
- comparison between compiler versions;
- fault localization.

## 12.2 A provenance chain

```ts
interface Provenance {
  sourceSpan?: SourceSpan;
  authoringNode?: NodeId;
  operation?: OperationId;
  feature?: FeatureId;
  strategy?: { id: string; version: string };
  passHistory: readonly PassRecord[];
  parentArtifacts: readonly Hash[];
}
```

Every transformation either preserves provenance, refines it, or introduces a synthetic operation with an explicit reason such as `safety-retract` or `postprocessor-spindle-stop`.

## 12.3 Content addressing

An artifact hash should cover canonical serialization of:

- semantic content;
- schema version;
- relevant configuration;
- referenced artifact hashes.

A display filename is not identity. Two jobs named `part.nc` may differ; the same job may have several names.

Canonical serialization must define:

- map key order;
- number format;
- treatment of negative zero;
- Unicode normalization;
- omitted versus null fields;
- endianness for binary data;
- schema versioning.

## 12.4 Reproducible passes

A pass result should be a function of explicit inputs:

$$
O=F(I,C,V,S),
$$

where $C$ is configuration, $V$ identifies the pass implementation, and $S$ is any declared random seed. Hidden time, locale, thread interleaving, or unordered iteration can break reproducibility.

Reproducibility does not guarantee correctness, but it makes evidence, debugging, and regression analysis tractable.

## 12.5 Machine and firmware identity

A machine profile named `z1` is not sufficient if firmware revisions change protocol or motion semantics. The executable bundle should identify:

- machine model and configured limits;
- controller dialect and firmware compatibility range;
- relevant capability flags;
- postprocessor version;
- calibration profile version;
- known semantic deviations.

Runtime preflight compares live identity with the bundle assumptions.

## 12.6 Provenance through optimization

An optimizer may merge, split, or reorder paths. It should retain a many-to-many mapping:

```ts
interface OriginMap {
  outputRange: CommandRange;
  inputs: readonly {
    artifact: Hash;
    operation?: OperationId;
    pathRange?: ParameterInterval;
  }[];
  transformation: string;
}
```

This allows a gouge counterexample at final block 813 to highlight the source finishing operation and the arc-fitting pass that changed it.

## 12.7 Worked example: cache key

A toolpath-planning cache key should include more than the feature geometry:

```text
hash(
  intentIR,
  targetMeshHash,
  stockHash,
  toolAssemblyHash,
  strategyIdAndVersion,
  planningTolerance,
  machine-relevant constraints,
  deterministicSeed
)
```

Omitting the tool hash can reuse a path computed for a different cutter. Omitting the tolerance can attach an outdated witness to a stricter request.

## 12.8 Exercises

1. Design a canonical serialization rule for floating-point numbers.
2. Explain why a filename is not an artifact identity.
3. List the inputs to a deterministic contour-planning cache key.
4. Define provenance for an automatically inserted retract.
5. Describe how a certificate becomes stale after a machine-profile change.
6. Give one source of nondeterminism in JavaScript object iteration or parallel planning and show how to control it.

# Designing an Extensible CAM API

> **Learning objectives.** The reader should be able to design an API that is composable, explicit about context, extensible through strategies and kernels, and resistant to invalid states.

## 13.1 Separate stable concepts from plugins

The stable API should expose semantic concepts:

- frames and units;
- stock, target, fixtures, and tools;
- manufacturing features and operations;
- paths and motion classes;
- tolerances, assumptions, and diagnostics;
- compilation and certification stages.

Strategies should be plugins:

```ts
interface Strategy<I extends OperationIntent, W> {
  id: string;
  version: string;
  supports(intent: I, context: PlanningContext): SupportResult;
  plan(intent: I, context: PlanningContext): Result<{
    paths: readonly PlannedPath[];
    witness: W;
  }, Diagnostic[]>;
}
```

A strategy may propose output; it should not mint final safety claims.

## 13.2 Kernel independence

Geometry algorithms should depend on interfaces rather than one mesh library:

```ts
interface SurfaceOracle<F extends FrameId> {
  bounds(): Box3<F>;
  heightAtXY(x: Mm, y: Mm): Interval<Mm> | "outside";
  closestPoint(p: Point3<F>): ClosestPointBound<F>;
  raycast(ray: Ray3<F>): readonly HitBound<F>[];
}
```

Different kernels can implement exact B-rep queries, mesh acceleration structures, interval fields, or remote computation. The semantic contract says what bounds the result provides.

## 13.3 Explicit contexts

Avoid ambient mutable settings such as “current feed,” “current tool,” or “current frame” inside planners. Pass immutable contexts:

```ts
interface PlanningContext {
  machine: MachineProfileRef;
  setup: SetupRef;
  activeTool: ToolRef;
  frame: FrameId;
  toleranceBudget: ErrorBudget;
  stockState: StockStateRef;
  seed: bigint;
}
```

The authoring API may offer convenient scopes, but elaboration should convert them into explicit fields.

## 13.4 Result types and diagnostics

Exceptions are appropriate for programmer errors and violated internal invariants. User-level compilation failures should be values:

```ts
type CompileResult<T> =
  | { ok: true; value: T; diagnostics: readonly Diagnostic[] }
  | { ok: false; diagnostics: readonly Diagnostic[] };
```

A diagnostic should include severity, stable code, source provenance, artifact context, quantitative details, and suggested remediation.

## 13.5 Escape hatches

Advanced users may need raw controller operations. An escape hatch should be isolated:

```ts
interface RawControllerBlock {
  text: string;
  declaredDialect: DialectId;
  declaredEffects?: EffectSummary;
  provenance: Provenance;
}
```

Self-declared effects are assumptions, not proof. An independent parser may establish actual effects for a supported grammar. Otherwise, affected analyses become unknown and production certification should fail closed.

## 13.6 API layers

A pleasant system can offer three layers:

**Feature API** for most jobs:

```ts
roughPocket(feature, { tool: "T1", strategy: "adaptive" });
finishPocket(feature, { tool: "T2" });
```

**Path API** for custom machining geometry:

```ts
cut(path, { tool: "T1", feed: mmPerMin(350), intent: "finish" });
```

**Machine API** for exact canonical actions:

```ts
program.append(traverse(path, clearance));
program.append(dwell(seconds(1)));
```

Lower layers carry more responsibility and require stronger evidence.

## 13.7 Law-driven API testing

Algebraic laws become property tests:

- path identity and associativity under exact endpoints;
- frame-transform identity and inverse;
- serialization round trip;
- deterministic planning under fixed inputs;
- pass idempotence for canonicalization;
- effect-summary conservativeness;
- certificate invalidation under changed dependencies.

The API design should make laws visible enough to test.

## 13.8 Worked example: compiling explicitly

```ts
const authored = evaluateScript(source, scriptEnvironment);
const plan = elaborate(authored.ast, projectContext);
const intent = normalizeIntent(plan.value);
const proposed = strategyRegistry.plan(intent, planningContext);
const checkedPaths = checkPlanningWitness(intent, proposed);
const scheduled = schedule(checkedPaths, schedulingPolicy);
const machine = lowerToMachine(scheduled, z1Profile);
const controller = lowerToMakera(machine, makeraDialect);
const bytes = serialize(controller);
const final = validateFinalArtifact({
  intent,
  machine,
  controller,
  bytes,
  setup,
});
```

Each call has an explicit input and output. There is no hidden global “current job” whose meaning changes between preview and export.

## 13.9 Exercises

1. Design a strategy interface for constant-Z waterline finishing.
2. Define a geometry-kernel query with a sound outer bound.
3. Explain when to use an exception versus a diagnostic result.
4. Design three API layers for drilling.
5. Specify how a raw controller block affects certification.
6. Write five algebraic or metamorphic properties for the API.
7. Explain why plugin version identity belongs in provenance.
EOF
wc -l -w -c /mnt/data/z1_textbook_work/book/Certificate_Carrying_CAM_Compilers.md
```

The first ten chapters are drafted, including bounded refinement, stock semantics, path/effect modeling, modal lowering, and JavaScript staging. Numerical guarantees now explicitly distinguish inner from outer approximations.

<details><summary>💭 Thinking</summary>

**Appended language design chapters and wrote compiler passes**

</details>

```unknown
bash -lc cat >> /mnt/data/z1_textbook_work/book/Certificate_Carrying_CAM_Compilers.md <<'EOF'

\part{Part IV - Assertions, Invariants, and Certificates}

# Contracts, Hoare Logic, and Weakest Preconditions

> **Learning objectives.** The reader should be able to distinguish assertions, invariants, assumptions, and guarantees; derive weakest preconditions; and use contracts to structure compiler and controller checks.

## 22.1 Vocabulary matters

Safety discussions become confused when different logical objects share the word “check.” The following distinctions should appear in code and certificate schemas.

An **assertion** is a proposition about one program point or artifact.

A **precondition** must hold before an operation.

A **postcondition** is guaranteed after successful execution, subject to assumptions.

An **invariant** holds initially and is preserved by all relevant transitions.

An **assumption** is an external fact not established by the current checker.

A **guarantee** is a proposition established when the assumptions hold.

A **witness** is data chosen by a producer to help establish a proposition.

A **proof or evidence object** is checked by a specified procedure.

An **attestation** establishes origin or integrity; it does not establish semantic truth.

## 22.2 Hoare triples

A Hoare triple has the form [R4]:

$$
\{P\}\ c\ \{Q\}.
$$

It means that if command $c$ starts in a state satisfying $P$ and terminates normally, the resulting state satisfies $Q$. Total-correctness variants also establish termination.

A traverse contract might be:

$$
\{
\operatorname{Pose}=a\land
\operatorname{Homed}\land
\operatorname{Free}(\gamma,T,O,S)
\}
$$

$$
\operatorname{Traverse}(\gamma)
$$

$$
\{
\operatorname{Pose}=b\land
S'=S\land
\operatorname{ProcessState}'=\operatorname{ProcessState}
\}.
$$

The stock-equality postcondition distinguishes traverse from cut.

## 22.3 Sequential composition

If:

$$
\{P\}\ c_1\ \{R\}
$$

and:

$$
\{R\}\ c_2\ \{Q\},
$$

then:

$$
\{P\}\ c_1;c_2\ \{Q\}.
$$

The intermediate assertion $R$ is the interface between commands. Compiler IR design should expose enough state to state $R$.

## 22.4 Weakest preconditions

The weakest precondition $wp(c,Q)$ is the least restrictive condition that guarantees $Q$ after $c$.

For sequential commands:

$$
wp(c_1;c_2,Q)=wp(c_1,wp(c_2,Q)).
$$

For an assignment $x:=e$:

$$
wp(x:=e,Q)=Q[e/x].
$$

For a conditional:

$$
wp(\mathrm{if}\ b\ \mathrm{then}\ c_1\ \mathrm{else}\ c_2,Q)
=(b\Rightarrow wp(c_1,Q))\land(\neg b\Rightarrow wp(c_2,Q)).
$$

A preflight engine can derive requirements backward from the program rather than maintaining an unrelated checklist.

## 22.5 CNC weakest-precondition example

Suppose the desired final condition is:

$$
Q=\operatorname{SpindleOff}\land\operatorname{Pose}=p_{safe}.
$$

The program is:

```text
cut path P
retract to p_safe
stop spindle
```

Working backward:

1. `stop spindle` requires a valid controller session and guarantees `SpindleOff`.
2. `retract` requires a collision-free path from `end(P)` to $p_{safe}$.
3. `cut` requires homing, known WCS, selected tool, valid spindle state, safe cutting sweep, and feasible feed.

The derived precondition becomes the basis of compile-time claims and runtime preflight.

## 22.6 Invariant induction

To prove invariant $I$ over a transition system:

1. **Initialization:** $I(\sigma_0)$.
2. **Preservation:** $I(\sigma)\land T(\sigma,\sigma')\Rightarrow I(\sigma')$.

Examples:

- stock monotonically decreases under cut and remains unchanged under traverse;
- every motion command has a known frame;
- cutting implies a selected tool and active spindle;
- an executing job has one content hash;
- an alarm state cannot transition directly to running without explicit recovery.

## 22.7 Separation of resources

Separation logic reasons about disjoint mutable resources [R38]. Its central intuition is useful even without a full separation-logic implementation. An operation that removes stock in region $A$ should not affect a disjoint fixture region $B$. Effect summaries can state footprints, enabling local reasoning and safe parallel analysis.

## 22.8 Design by contract in APIs

Contracts should be executable where possible:

```ts
function cut<S extends ReadyToCut>(
  state: S,
  motion: CuttingMotion,
): Result<CutResult, Diagnostic[]> {
  requireFinitePath(motion.path);
  requirePositiveFeed(motion.feed);
  requireToolMatch(state.tool, motion.tool);
  // geometric and runtime obligations remain explicit claims
}
```

Do not pretend that a runtime assertion about metadata proves physical collision freedom. Contracts should state the boundary of what they establish.

## 22.9 Exercises

1. Write a Hoare triple for spindle start.
2. Derive $wp$ for `select tool; start spindle; cut` with final condition `stock conforms to roughing intent`.
3. State and prove a stock-monotonicity invariant for a simplified semantics.
4. Distinguish an assumption from a precondition in a live tool check.
5. Give an example of a local resource footprint for two independent operations.
6. Explain partial versus total correctness for an abort command.

# Abstract Interpretation for Machine Programs

> **Learning objectives.** The reader should be able to define concrete and abstract domains, implement sound transfer functions, compute invariants over control flow, and use unknown states conservatively.

## 23.1 Simulating one trace is not analyzing all traces

A simulator executes one concrete state through one control path. A validator often needs to cover many possible states: unknown initial modal settings, uncertain positions, branches after probing, controller faults, or values from macros. Abstract interpretation computes over-approximations of these possibilities [R7].

Let $C$ be a concrete domain and $A$ an abstract domain. A concretization function:

$$
\gamma:A\to\mathcal{P}(C)
$$

maps an abstract value to the concrete states it represents.

A sound abstract transfer function $\widehat{F}$ satisfies:

$$
F(\gamma(a))\subseteq\gamma(\widehat{F}(a)).
$$

## 23.2 Abstract machine state

```ts
interface AbstractMachineState {
  position: Box3 | "unknown";
  homing: "homed" | "unhomed" | "maybe";
  tool: ToolRef | Set<ToolRef> | "unknown";
  spindle: "off" | RpmInterval | "unknown";
  wcs: TransformInterval | "unknown";
  motionMode: Set<MotionMode>;
  feed: Interval<number> | "unknown";
  playing: "yes" | "no" | "maybe";
  alarm: "yes" | "no" | "maybe";
}
```

The domain should be just expressive enough for the claims it checks.

## 23.3 Interval transfer

For a linear absolute move to $X=x$, the abstract X interval becomes $[x,x]$ after accounting for rounding and transform uncertainty. In incremental mode, it becomes:

$$
X' = X + [x-\rho,x+\rho].
$$

If distance mode is `{absolute, incremental}`, the successor joins both possibilities. Precision drops, but soundness remains.

## 23.4 Modal-state analysis

An abstract G-code interpreter can prove:

- units definitely metric;
- distance mode definitely absolute;
- spindle definitely on before each cut;
- position remains inside travel bounds;
- no motion occurs with unknown WCS;
- raw commands do not leave required modal components unknown;
- final spindle state is definitely off.

Each block records an invariant before and after:

```ts
interface BlockInvariant {
  blockIndex: number;
  before: AbstractMachineState;
  after: AbstractMachineState;
}
```

A small proof checker replays abstract transfers and verifies safety predicates.

## 23.5 Joins and loss of precision

If one branch selects tool T1 and another selects T2, the merge state contains `{T1,T2}`. A later operation requiring exactly T1 cannot be proved safe without a guard.

Widening may be necessary for loops. For example, repeated incremental motion can make position unbounded unless the loop count is bounded. A production-certifiable dialect may reject unbounded macros rather than analyze them imprecisely.

## 23.6 Reduced products

Different abstract domains can cooperate. A position box and a linear relation domain may jointly prove tighter bounds. A modal-state domain and typestate domain can reduce each other: if an alarm is definite, playing is false; if spindle is off, RPM interval is zero.

Such combinations increase checker complexity. Begin with simple domains tied to explicit claims.

## 23.7 Unknown raw effects

A raw block that is not parsed should conservatively set affected state to unknown. Self-declared effects can be recorded as assumptions, but they do not justify a proved claim.

```ts
function transferRaw(state: AbstractState, raw: RawBlock): AbstractState {
  return {
    ...state,
    position: "unknown",
    motionMode: allMotionModes,
    feed: "unknown",
    spindle: "unknown",
    wcs: "unknown",
  };
}
```

A later explicit preamble can re-establish some components.

## 23.8 Worked example: final spindle state

A program branches around an optional finishing pass. Both branches eventually execute `M5`. At the merge, spindle is definitely off. If one branch omits `M5`, the merge state is `{off,on}` and the final safety epilogue claim fails.

## 23.9 Exercises

1. Define a concretization function for an interval.
2. Write abstract transfer rules for G90, G91, G20, and G21.
3. Explain why joining branches loses precision.
4. Design a sound state update for an unknown raw command.
5. Show how a loop of incremental X moves can require widening.
6. Propose a reduced product relevant to probing and frames.

# Robust Numerics and Computational Geometry

> **Learning objectives.** The reader should be able to distinguish topological predicates from metric constructions, use exact or adaptive predicates, apply interval enclosures, and identify failure modes of floating-point geometry.

## 24.1 Why geometric bugs are discontinuous

A small floating-point error in a distance often causes a small distance error. A small error in a sign predicate can change topology completely: two contours connect instead of remaining separate, a polygon changes orientation, or an intersection is missed.

Computational geometry therefore distinguishes:

- **predicates**, which decide discrete facts such as orientation or intersection;
- **constructions**, which compute coordinates.

Predicates deserve stronger numerical methods.

## 24.2 Orientation predicates

For points $a,b,c$ in 2D, orientation is the sign of:

$$
\operatorname{orient2d}(a,b,c)=
(b_x-a_x)(c_y-a_y)-(b_y-a_y)(c_x-a_x).
$$

Near collinearity, floating-point cancellation can return the wrong sign. Adaptive exact predicates evaluate cheaply in ordinary cases and increase precision only near degeneracy [R22].

Use robust predicates for:

- polygon orientation;
- segment intersection;
- point-in-polygon decisions;
- Delaunay or Voronoi topology;
- contour stitching;
- mesh adjacency and ray intersections.

## 24.3 Exact topology, approximate geometry

A practical architecture can keep topology exact while allowing bounded approximate coordinates. For grid-generated contours, use grid-edge identifiers rather than re-quantized endpoint coordinates. For polygon kernels, use integer-scaled coordinates within a proven range or exact rational predicates.

The endpoint-key failure discussed later is a violation of this principle: a lossy packed coordinate is used as topological identity.

## 24.4 Interval arithmetic

An interval $[a,b]$ represents every real number between its endpoints. Arithmetic operations use outward rounding so the exact result is enclosed. IEEE 1788.1 specifies interval arithmetic over binary floating-point endpoints [R23]; Moore, Kearfott, and Cloud provide a broad treatment of interval analysis [R24].

If:

$$
x\in[a,b],\quad y\in[c,d],
$$

then:

$$
x+y\in[a+c,b+d]
$$

with outward-rounded endpoints. Multiplication takes the min and max of all endpoint products.

Intervals can bound:

- curve coordinates over a parameter range;
- transform uncertainty;
- distance to a surface;
- polynomial extrema;
- swept-volume occupancy;
- numerical residuals.

## 24.5 The dependency problem

Interval arithmetic can overestimate when the same variable appears repeatedly. For $x\in[0,1]$:

$$
x-x=[-1,1]
$$

under naive interval evaluation, although the true result is zero. Subdivision, affine arithmetic, Taylor models, or symbolic simplification can improve tightness.

An inconclusive wide interval is not a false result. The checker can subdivide or reject.

## 24.6 Conservative meshing

A triangle mesh is often treated as exact geometry, but it approximates a design surface. A certificate should record:

- source artifact hash;
- tessellation tolerance;
- orientation and watertightness status;
- whether the mesh encloses or is enclosed by the intended solid;
- repairs performed;
- unresolved non-manifold or self-intersection issues.

Without an enclosure relation, mesh-based collision checks prove facts about the mesh, not necessarily the intended CAD solid.

## 24.7 Tolerance and topology

Using one epsilon everywhere is dangerous. Distinct tolerances are needed for:

- numeric comparison;
- geometric construction;
- topological snapping;
- machining allowance;
- certification bound.

A topological snap modifies geometry. Its displacement must be recorded and charged to an error budget.

## 24.8 Worked example: collision of two nearly touching paths

Suppose a line passes $2\,\mu$m from a fixture in nominal double precision, while tool-radius uncertainty is $5\,\mu$m and frame uncertainty is $10\,\mu$m. An exact floating-point distance does not make the move safe. The relevant outer enclosure intersects the obstacle. Numerical exactness and physical robustness are different dimensions.

## 24.9 Exercises

1. Compute `orient2d` for three nearly collinear points and explain cancellation risk.
2. Distinguish a predicate from a construction.
3. Give a use of interval subdivision in curve bounding.
4. Explain the interval dependency problem.
5. Design metadata for a mesh enclosure claim.
6. List four different tolerances in a CAM compiler and their roles.
7. Explain why exact arithmetic does not eliminate model uncertainty.

# Swept Volumes, Stock Models, and Collision Proofs

> **Learning objectives.** The reader should be able to define swept volume, choose conservative stock representations, distinguish cutting from holder collision, and formulate no-gouge and guaranteed-removal claims.

## 25.1 Swept volume

For a tool solid $T$ and pose trajectory $x(t)$, the swept volume is:

$$
\operatorname{Sweep}(T,x)=\bigcup_{t\in[0,T]}x(t)T.
$$

Swept-volume computation is central to collision detection, stock simulation, and manufacturing verification [R26]. Exact computation is difficult for general geometry and trajectories, so practical systems use conservative enclosures or discrete representations.

## 25.2 Stock evolution

For cutting command $i$ with removed volume $R_i$:

$$
S_{i+1}=S_i\setminus R_i.
$$

A simulator may approximate $R_i$ using the swept cutting geometry. The semantic distinction among commands remains important:

- cut updates stock;
- traverse must not update stock;
- probe ideally stops at first contact and may touch without intended removal;
- tool change and dwell preserve stock.

If a missing traverse is silently converted to a cut, the stock semantics change, not merely the visualization.

## 25.3 Tool versus holder

Let $T_c$ be cutting geometry and $T_a$ the full assembly. Then:

**No target gouge:**

$$
\operatorname{Sweep}(T_c,x)^+\cap P_{protected}=\varnothing.
$$

**No fixture collision:**

$$
\operatorname{Sweep}(T_a,x)^+\cap O^+=\varnothing.
$$

**Guaranteed removal:**

$$
R_{required}\subseteq \operatorname{Sweep}(T_c,x)^-.
$$

The superscripts indicate outer and inner enclosures.

## 25.4 Dexel and voxel models

A dexel model stores material intervals along parallel rays. A height field stores one surface value per XY cell and cannot represent undercuts or multiple layers. Triple-dexel models use three orthogonal directions and improve surface representation [R27, R28]. Voxels represent occupancy in three dimensions.

Tradeoffs include:

- memory;
- update speed;
- ability to represent overhangs and cavities;
- surface error;
- ease of conservative enclosure;
- suitability for cutter contact.

For a three-axis no-overhang part, a height field can be efficient, but its resolution must be connected to a continuous-domain bound.

## 25.5 A grid size is not a guarantee

Sampling motion at spacing $h$ and stock on a grid of cell size $g$ does not by itself prove “verified to $\max(h,g)$.” A narrow fixture or brief penetration can occur between samples.

A sound cell method needs one of:

- conservative occupancy of every cell touched by the continuous sweep;
- interval bounds over each cell and motion interval;
- a Lipschitz bound plus adaptive subdivision;
- exact primitive sweep tests;
- a certified distance-field enclosure.

Otherwise, label the result simulation-only.

## 25.6 Configuration-space collision

For fixed orientation, configuration-space obstacles reduce moving-solid collision to point-path collision [R25]:

$$
O_C=O\oplus(-T_a).
$$

A clearance checker can build an outer enclosure $O_C^+$ and prove that the tool-reference path is separated by a positive bound.

For rotating tools or multi-axis orientation, configuration space has more dimensions and the expansion varies with orientation.

## 25.7 Continuous path checking

Lines and arcs often admit analytic bounds. Splines and sampled paths can be recursively subdivided. A generic branch-and-bound checker operates on parameter intervals:

1. Bound path positions over interval $I$.
2. Expand by tool assembly and uncertainty.
3. If disjoint from obstacle enclosure, accept $I$.
4. If definitely intersecting, return a counterexample interval.
5. Otherwise subdivide until a limit.
6. If the limit is reached unresolved, return inconclusive.

This produces honest coverage of the continuous parameter domain.

## 25.8 Worked example: rapid through stock

A rapid from A to B at low Z is safe only if the entire outer swept assembly is disjoint from current stock and fixtures. Checking endpoints misses an obstacle between them. Checking sampled points can miss a thin wall. A segment-versus-expanded-obstacle test or conservative recursive enclosure addresses the whole move.

## 25.9 Exercises

1. Write set formulas for no-gouge, fixture collision, and guaranteed removal.
2. Compare height fields, dexels, triple dexels, and voxels.
3. Explain why one grid resolution cannot be attached blindly to all claims.
4. Design a recursive continuous collision checker.
5. Give a case where cutting geometry is clear but holder geometry collides.
6. Explain how stock state affects link verification.

# Error Budgets and Quantitative Refinement

> **Learning objectives.** The reader should be able to construct typed error budgets, compose bounds through passes, allocate tolerances, and distinguish numerical, model, calibration, and process uncertainty.

## 26.1 A budget is a proof structure

An error budget is not merely a UI sum. It records how a final bound follows from component bounds under explicit propagation rules.

Sources include:

- design-surface tessellation;
- tool geometry approximation;
- tool dimension tolerance and runout;
- path planning discretization;
- curve fitting and linearization;
- coordinate transform uncertainty;
- numeric rounding;
- controller interpolation;
- servo following error;
- probing and calibration;
- thermal and material effects.

Some are compiler-controlled; others are runtime assumptions.

## 26.2 Typed metrics

```ts
type ErrorBound =
  | { metric: "hausdorff-position"; frame: FrameId; value: Mm }
  | { metric: "normal-surface"; surface: Hash; value: Mm }
  | { metric: "max-gouge-depth"; target: Hash; value: Mm }
  | { metric: "transform-translation"; transform: Hash; value: Mm }
  | { metric: "transform-rotation"; transform: Hash; value: Radians }
  | { metric: "axis-following"; axis: AxisId; value: Mm };
```

Only compatible bounds can be combined directly. Rotational error becomes positional error only after multiplying by a radius or applying a more precise transform bound.

## 26.3 Budget allocation

Suppose a feature tolerance is $0.05$ mm. The compiler may allocate:

```text
CAD tessellation             0.010 mm
planning and refinement      0.012 mm
postprocessor rounding       0.003 mm
frame and probing            0.010 mm
machine following            0.010 mm
reserve                      0.005 mm
```

This allocation is meaningful only if each number is a valid bound in a compatible metric and the composition theorem supports addition. A planner that consumes more than its allocation must refine or fail.

## 26.4 Correlation and worst-case composition

Worst-case scalar addition is conservative when errors can align. Root-sum-square composition assumes statistical independence and a probabilistic interpretation; it is not a deterministic maximum bound. Certificates must identify whether a claim is worst-case, probabilistic, empirical, or nominal.

## 26.5 Pass amplification

A small angular error $\delta\theta$ at radius $r$ creates positional error approximately $r\delta\theta$. An offset operation can amplify boundary error near sharp corners or topology changes. A coordinate transform with scale should not exist in rigid machining frames, but a calibration map may have local condition numbers.

Each pass needs a sensitivity or Lipschitz bound when it propagates prior error.

## 26.6 Residual-driven refinement

An adaptive algorithm should report a residual related to the claimed metric. For a height field, comparing neighboring samples is not automatically a surface-error residual. A useful refinement loop is:

```text
propose approximation
compute certified local bound
if bound <= allocated budget: accept cell
else if subdivision limit not reached: subdivide
else: inconclusive
```

The residual, subdivision depth, and unresolved regions become evidence.

## 26.7 Runtime budgets

Some budget components are checked at runtime. A tool measurement may tighten diameter uncertainty; a probe sequence may establish a frame bound; a machine calibration record may establish following-error limits. If live bounds exceed the bundle allocation, execution is refused or the job is recompiled.

## 26.8 Worked example: final surface error

Suppose:

- target mesh outer deviation: $0.008$ mm;
- drop-cutter field bound: $0.012$ mm;
- arc fitting: $0.004$ mm;
- output rounding: $0.001$ mm;
- frame translation: $0.010$ mm;
- angular frame uncertainty: $0.0002$ rad at 50 mm radius, contributing $0.010$ mm.

A conservative additive position bound is $0.045$ mm if the metrics and directions align. If the requested bound is $0.04$ mm, the program is not certified merely because each individual pass met its local default.

## 26.9 Exercises

1. Classify six error sources as numerical, model, calibration, or process uncertainty.
2. Convert an angular bound to a positional bound at a given radius.
3. Explain when root-sum-square composition is inappropriate.
4. Design a typed budget for a planar pocket floor.
5. State a residual-driven refinement algorithm.
6. Explain how a runtime measurement can discharge a compile-time assumption.

# Certificate Schemas and Proof Graphs

> **Learning objectives.** The reader should be able to write precise claims, bind them to artifacts and assumptions, organize dependencies as a DAG, and avoid ambiguous status labels.

## 27.1 A certificate is a graph of propositions

A certificate should not be one boolean or one table of reassuring labels. It is a graph connecting artifacts, assumptions, claims, evidence, and checkers.

![A certificate dependency graph binds source, IRs, final bytes, setup, and runtime state.](figures/certificate_dag.png){width=86%}

A change to any dependency invalidates downstream claims.

## 27.2 Structured claims

```ts
interface Claim {
  id: ClaimId;
  subject: ArtifactRef;
  proposition: StructuredPredicate;
  result:
    | "proved-exact"
    | "proved-bounded"
    | "translation-validated"
    | "exhaustive-finite-check"
    | "simulation-only"
    | "assumed"
    | "unknown"
    | "refuted";
  method: MethodRef;
  assumptions: readonly AssumptionRef[];
  evidence: readonly EvidenceRef[];
  dependencies: readonly ClaimId[];
  bound?: ErrorBound;
  checker: CheckerIdentity;
}
```

The proposition is not a string such as `"gouge"`. It is structured:

```ts
{
  kind: "max-penetration",
  sweptArtifact: "sha256:...",
  protectedTarget: "sha256:...",
  maximum: mm(0.02),
  metric: "signed-normal-depth",
}
```

## 27.3 Results and methods are orthogonal

“Checked to resolution” combines method and conclusion. Separate:

- proposition;
- method;
- result;
- quantitative bound;
- coverage;
- assumptions.

A sampled simulation method may produce a counterexample and thus refute a claim. Failure to find a counterexample does not upgrade it to proof.

## 27.4 Assumption records

```ts
interface Assumption {
  id: AssumptionId;
  proposition: StructuredPredicate;
  source: "operator" | "calibration" | "machine-attestation" | "library";
  evidence?: ArtifactRef;
  validFrom?: Timestamp;
  validUntil?: Timestamp;
  runtimeCheck?: RuntimeCheckSpec;
}
```

Examples:

- tool T1 diameter lies in $[3.170,3.180]$ mm;
- fixture model hash matches setup QR code;
- machine firmware belongs to a compatible semantic profile;
- G54 transform lies inside an interval;
- stock dimensions meet a measured bound.

## 27.5 Evidence types

```ts
type Evidence =
  | AbstractInterpretationTrace
  | IntervalSubdivisionTree
  | CollisionSeparationWitness
  | CoverageWitness
  | ParseBackTraceComparison
  | SolverCertificate
  | ModelCheckingTrace
  | Counterexample
  | CalibrationRecord
  | SignatureAttestation;
```

Evidence schemas should be stable, versioned, and independently checkable.

## 27.6 Claim granularity

Separate claims by meaning:

- target no-gouge;
- fixture collision;
- holder collision;
- rapid-through-stock;
- required removal;
- machine travel;
- feed and dynamics;
- modal equivalence;
- final spindle stop;
- exact upload hash;
- controller start acknowledgement.

One generic evidence object should not be able to mint unrelated rows. Strong typing can enforce this:

```ts
function certifyGouge(
  claim: GougeClaim,
  evidence: GougeEvidence,
): CertifiedClaim;
```

## 27.7 Completeness policy

A bundle policy states which claims are required for a use class:

```text
Preview-only:
  schema, finite values, parse success

Attended air cut:
  travel, controller parse-back, exact bytes, runtime identity

Attended material cut:
  + target, fixture, holder, stock, tool and WCS assumptions

Unattended production:
  + protocol liveness, runtime monitor, calibrated dynamic bounds,
    recovery and interlock claims
```

A function such as `isFullyVerified` must derive from explicit policy, not from absence of severe diagnostics.

## 27.8 Worked example: false evidence reuse

Suppose a dexel simulation checks low rapids and spoilboard penetration but receives no target surface. It can support:

```text
rapid-through-current-stock sampled simulation
spoilboard penetration sampled simulation
```

It cannot support:

```text
maximum gouge into protected target <= 0.02 mm
```

because the proposition's target artifact is absent. A schema that requires `protectedTargetHash` and target-specific evidence prevents the incorrect promotion.

## 27.9 Exercises

1. Write a structured claim for machine travel.
2. Design separate evidence types for rapid collision and target gouge.
3. Explain why a digital signature is not a semantic proof.
4. Define a completeness policy for an attended air cut.
5. Draw a dependency graph for an arc-linearized final job.
6. Describe certificate invalidation after a tool change.

# Trusted Checkers and Proof-Carrying CAM

> **Learning objectives.** The reader should be able to minimize a trusted computing base, explain proof-carrying code, design producer-consumer separation, and evaluate checker independence.

## 28.1 The producer is complicated

CAM planners use spatial indices, heuristics, solvers, floating-point kernels, caches, parallelism, and UI state. Treating this entire implementation as trusted makes assurance fragile.

Proof-carrying code separates an untrusted producer from a consumer-side checker: code arrives with evidence that it satisfies a policy, and the consumer validates the evidence before execution [R20]. Foundational proof-carrying code reduces reliance on specialized verification-condition generators by grounding evidence in a smaller logic [R21].

The analogous CAM architecture is:

```text
complex planner / optimizer / postprocessor
                 |
                 v
        artifact + evidence
                 |
                 v
       small independent checker
                 |
           accept or reject
```

## 28.2 Trusted computing base

A realistic trusted base includes:

- definitions of claim predicates;
- canonical artifact hashing and serialization;
- independent parsers and semantic interpreters;
- robust numeric primitives used by checkers;
- certificate dependency validation;
- runtime identity and upload-hash handshake;
- a small execution monitor;
- explicitly accepted physical assumptions.

The UI, heuristic planners, optimizers, and preview renderer should not need to be trusted.

## 28.3 Independence

A checker that calls the same buggy helper as the producer is not strongly independent. Independence can be improved by:

- separate implementations;
- different algorithms or representations;
- reduced feature set;
- smaller codebase;
- strict schemas;
- deterministic behavior;
- extensive property and differential testing;
- optional mechanized proofs for critical kernels.

Independence is a spectrum, not a binary property.

## 28.4 Proof objects versus recomputation

A checker can:

1. recompute the property independently;
2. verify a compact witness;
3. check a formal proof term;
4. combine these methods.

For contour coverage, a cell decomposition witness may be cheaper than re-running planning. For modal equivalence, replaying both programs is simple. For a linear or mixed-integer optimizer, a solver certificate or dual bound may support optimality.

## 28.5 Checker resource bounds

Evidence can be adversarial or malformed. Checkers need:

- schema validation;
- size and recursion limits;
- deterministic resource bounds;
- integer overflow protection;
- denial-of-service resistance;
- explicit version compatibility;
- no execution of producer-supplied code.

## 28.6 Compositional certificates

If pass $P_1$ establishes $R_1(A,B)$ and $P_2$ establishes $R_2(B,C)$, a composition theorem establishes $R(A,C)$:

$$
R_1(A,B)\land R_2(B,C)\Longrightarrow R(A,C).
$$

The theorem may accumulate quantitative bounds. Certificate composition should be implemented by a checker, not inferred from matching stage names.

## 28.7 Mechanization strategy

Formalize the small semantic core first:

- canonical command semantics;
- controller modal semantics;
- pass-relation composition;
- certificate validity;
- state-machine authorization;
- numeric lemmas for common primitives.

Leave complex search algorithms unverified but validated. This yields more assurance per unit effort than attempting to prove an entire CAM application at once.

## 28.8 Worked example: validating a solver schedule

An untrusted optimizer returns operation order $\pi$, path orientations, total cost $J$, and a lower bound $L$. The checker verifies:

1. $\pi$ is a permutation of required operations;
2. all precedence edges are respected;
3. every selected orientation is legal;
4. each transition cost is recomputed;
5. total cost equals the sum;
6. the lower-bound certificate is valid;
7. the reported gap $(J-L)/L$ is correct.

The optimizer's internal search does not enter the trusted base.

## 28.9 Exercises

1. List the trusted components in a minimal CAM checker.
2. Give an example where a checker is insufficiently independent.
3. Compare recomputation with witness checking.
4. Design resource limits for a certificate checker.
5. State a composition theorem for two bounded geometric passes.
6. Choose three components suitable for formal mechanization and justify them.

# Temporal Semantics and Controller Protocols

> **Learning objectives.** The reader should be able to model the host-controller interaction as a state machine, state safety and liveness properties, and reason about ambiguous failures and authorization races.

## 29.1 The protocol is part of the compiler target

A final G-code file is useless unless the correct bytes are transferred, stored, selected, and executed. The controller interface is therefore part of the compilation and deployment semantics.

![A simplified controller and job lifecycle state machine.](figures/controller_fsm.png){width=96%}

## 29.2 States and transitions

A controller model should include states such as:

- disconnected;
- connected but unidentified;
- idle;
- uploading;
- ready with a specific stored hash;
- running a specific execution instance;
- held;
- stopped;
- alarmed;
- ambiguous or quarantined after timeout.

Transitions have guards and effects. `Resume` is not a read-only command; it enables motion. `FeedHold` is a stop-class action and should remain available even when ordinary command admission is blocked.

## 29.3 Safety properties

Examples:

$$
\Box(\operatorname{Running}(h)\Rightarrow
\operatorname{Authorized}(h)).
$$

$$
\Box(\operatorname{Start}(h)\Rightarrow
\operatorname{StoredHash}=h).
$$

$$
\Box(\operatorname{Motion}\Rightarrow
\neg\operatorname{Alarm}).
$$

$$
\Box(\operatorname{GenericReadPath}\Rightarrow
\neg\operatorname{MotionEffect}).
$$

The last property requires complete parsing, not prefix classification.

## 29.4 Liveness properties

$$
\Box(\operatorname{UploadStarted}\Rightarrow
\Diamond(\operatorname{Ready}\lor\operatorname{Failed}\lor\operatorname{Quarantined})).
$$

$$
\Box(\operatorname{AbortRequested}\Rightarrow
\Diamond(\operatorname{Stopped}\lor\operatorname{Alarm})).
$$

Liveness depends on assumptions about network delivery, controller scheduling, and machine responsiveness. Those assumptions must be stated.

## 29.5 Atomic admission and execution

A preflight that checks state, releases a lock, and later sends motion has a time-of-check/time-of-use gap. Another command can change the state between admission and execution.

A safer design serializes:

```text
acquire session authority
refresh live state
check preconditions
bind authorization to command/job hash and state epoch
send command
observe acknowledgement or quarantine
release authority
```

The state epoch invalidates admission if intervening events occur.

## 29.6 Ambiguous timeout

After sending a command, a timeout does not imply that the machine did nothing. The command may have executed while the reply was lost. The correct successor state is a set of possibilities. The session should enter an ambiguous/quarantined state until re-synchronized through a trusted status query and protocol boundary.

Blind retry is especially dangerous for motion or state-changing commands.

## 29.7 Message streams and loss

Safety-relevant events should not share a lossy queue designed for UI telemetry. A dropped alarm, completion marker, or protocol sentinel can make the host state inconsistent. Separate durable control events from best-effort display updates.

Partial writes must also be handled. A transport `Write` may write fewer bytes than requested without a fatal error; command framing must loop until complete or fail before execution can be assumed.

## 29.8 Model checking

A finite abstraction of the protocol can be exhaustively checked for invariants and deadlocks. TLA-style specifications are well suited to concurrency and temporal properties [R8, R34]. Hybrid automata extend state machines with continuous dynamics when stop distance and watchdog timing matter [R35].

## 29.9 Worked example: compound command classification

A classifier that examines only the first whitespace token may label:

```text
status\nG0 X100
```

as read-only because `status` is first. The semantic policy concerns every parsed command in the payload. A fail-closed grammar rejects embedded newlines or parses all blocks and proves that every effect belongs to the allowed class.

## 29.10 Exercises

1. Define states and transitions for upload, start, hold, resume, and abort.
2. State three safety and two liveness properties.
3. Explain the time-of-check/time-of-use race in preflight.
4. Model an ambiguous timeout as a set of successor states.
5. Explain why stop commands should bypass ordinary motion admission.
6. Design a fail-closed read-only command grammar.
7. Identify which messages require durable delivery.

# Runtime Assurance and Physical Assumptions

> **Learning objectives.** The reader should be able to bind compile-time evidence to live machine state, design a runtime assurance monitor, and distinguish logical proof from physical validation.

## 30.1 Conditional assurance

A compile-time certificate proves a conditional theorem:

```text
if assumptions A hold, artifact B satisfies claims C
```

Runtime preflight must establish as much of $A$ as possible. The remaining assumptions require operator acceptance, calibration records, or physical interlocks.

## 30.2 Hash-bound execution

![A runtime handshake binds authorization to exact bytes and live state.](figures/runtime_handshake.png){width=88%}

A robust protocol is:

1. Host proposes certified bundle hash $H$ and assumptions $A$.
2. Controller stores exact bytes and reports stored hash $H'$.
3. Controller reports identity, firmware, homing, WCS, tool state, alarm state, and job state $M$.
4. Host verifies $H'=H$ and $M\models A$.
5. Host authorizes one execution instance of $H$.
6. Controller acknowledges start of that exact instance.
7. Host monitors state until terminal completion, abort, or fault.

## 30.3 Runtime checks

Possible checks include:

- machine identity and firmware semantics profile;
- homed axes;
- active work coordinate system and measured transform;
- tool ID, length, and optional diameter measurement;
- fixture/setup identifier;
- stock presence and dimensions;
- door, probe, and accessory interlocks;
- no active alarm;
- exact stored job hash;
- controller idle or permitted paused state;
- calibration validity period.

## 30.4 Runtime assurance monitor

A runtime assurance architecture places a small trusted monitor around a more capable controller or host planner. Simplex-style systems switch to a trusted safety action when an advanced component approaches an unsafe region; modern runtime-assurance frameworks apply this to cyber-physical systems [R36].

For a Z1-class machine, a realistic monitor can enforce:

- authorized state transitions;
- command classes;
- job-hash binding;
- axis and feed envelopes;
- spindle/tool consistency;
- watchdog policy;
- communication-loss behavior;
- explicit confirmation of stop.

## 30.5 Stopping distance and latency

A stop request is not an instantaneous stop. If velocity is $v$ and guaranteed deceleration is $a$, a simple lower bound on stopping distance is:

$$
d_{stop}\ge\frac{v^2}{2a},
$$

plus command, communication, and controller latency. A safety envelope must reserve this distance. Feed hold may preserve the job and decelerate differently from emergency stop or reset.

## 30.6 Physical model validation

Even perfect software cannot prove that the CAD fixture model matches reality. Useful physical validation practices include:

- setup identifiers and photographs;
- measured stock and tool records;
- probing routines with uncertainty;
- air cuts and reduced-feed first runs;
- witness marks or sacrificial stock;
- calibration artifacts;
- independent inspection of critical dimensions;
- bounded validity periods for calibration.

These produce assumptions and attestations, not mathematical facts from the compiler.

## 30.7 Degradation policies

A runtime system should define what happens when an assumption cannot be established:

- refuse execution;
- downgrade to preview or air-cut mode;
- require explicit operator override with recorded rationale;
- reduce feed and restrict motion envelope;
- re-probe or re-measure;
- recompile with wider uncertainty;
- quarantine the session after ambiguity.

Silent continuation is not a policy.

## 30.8 Worked example: changed G54

A job was certified under work transform $T_0$ with uncertainty set $\Xi$. Before execution, the live controller reports $T_1$. The runtime checker computes whether $T_1$ lies inside the certified set. If not, the travel and collision claims are stale. The correct response is to revalidate or recompile, not to rely on the same file hash.

## 30.9 Design rules

```latex
\begin{warningbox}
A certificate is valid only for the exact artifact and assumption set named by its claims. Live machine identity, tools, frames, setup, and controller state are inputs to execution, not incidental operator details.
\end{warningbox}
```

## 30.10 Exercises

1. Design a runtime assumption manifest for a pocket job.
2. Explain why upload success is weaker than exact-byte execution.
3. Derive stopping distance for a given velocity and deceleration, then add latency distance.
4. List five monitor-enforceable properties and five physical assumptions it cannot prove.
5. Design a degradation policy for an unknown tool measurement.
6. Explain how a changed WCS invalidates geometric certificates.
EOF
wc -l -w -c /mnt/data/z1_textbook_work/book/Certificate_Carrying_CAM_Compilers.md
```

<details><summary>💭 Thinking</summary>

**Drafted contract, CAM, architecture, appendix, and implementation chapters**

</details>

```unknown
bash -lc cat >> /mnt/data/z1_textbook_work/book/Certificate_Carrying_CAM_Compilers.md <<'EOF'

\appendix

# Notation and Mathematical Reference

This appendix collects the notation used throughout the book. It is intended as a working reference rather than a substitute for a course in analysis, geometry, logic, or optimization.

## A.1 Sets and functions

| Symbol | Meaning |
|---|---|
| $x\in A$ | $x$ is an element of set $A$ |
| $A\subseteq B$ | every element of $A$ belongs to $B$ |
| $A\cup B$ | union |
| $A\cap B$ | intersection |
| $A\setminus B$ | set difference |
| $A\times B$ | Cartesian product |
| $\mathcal{P}(A)$ | powerset of $A$ |
| $f:A\to B$ | total function from $A$ to $B$ |
| $R\subseteq A\times B$ | relation between $A$ and $B$ |
| $R;S$ | relational composition |

A partial function can be modeled as a total function into an option or result type, or as a relation with no successor for some inputs.

## A.2 Logic

| Symbol | Meaning |
|---|---|
| $\neg P$ | not $P$ |
| $P\land Q$ | $P$ and $Q$ |
| $P\lor Q$ | $P$ or $Q$ |
| $P\Rightarrow Q$ | implication |
| $P\Leftrightarrow Q$ | equivalence |
| $\forall x.P(x)$ | for every $x$, $P(x)$ |
| $\exists x.P(x)$ | there exists an $x$ satisfying $P(x)$ |
| $\Box P$ | always $P$ in temporal logic |
| $\Diamond P$ | eventually $P$ in temporal logic |

A safety property states that a bad event never occurs. A liveness property states that a good event eventually occurs. Many controller requirements combine both.

## A.3 Orders and lattices

A preorder $\sqsubseteq$ is reflexive and transitive. A partial order is also antisymmetric. In compiler refinement, $Q\sqsubseteq P$ commonly means that $Q$ has no behaviors outside those allowed by $P$.

A lattice provides least upper bounds $a\sqcup b$ and greatest lower bounds $a\sqcap b$. Abstract interpretation uses joins to combine control-flow paths.

## A.4 Metric spaces

A metric $d$ satisfies:

1. $d(x,y)\ge0$;
2. $d(x,y)=0$ iff $x=y$;
3. $d(x,y)=d(y,x)$;
4. $d(x,z)\le d(x,y)+d(y,z)$.

The open ball of radius $\varepsilon$ is:

$$
B_{\varepsilon}(x)=\{y\mid d(x,y)<\varepsilon\}.
$$

The distance from point $x$ to set $A$ is:

$$
d(x,A)=\inf_{a\in A}d(x,a).
$$

The Hausdorff distance between compact sets is:

$$
d_H(A,B)=\max\left(
\sup_{a\in A}d(a,B),
\sup_{b\in B}d(b,A)
\right).
$$

## A.5 Geometry and morphology

| Symbol | Meaning |
|---|---|
| $\mathbb{R}^n$ | $n$-dimensional Euclidean space |
| $SO(3)$ | three-dimensional rotation group |
| $SE(3)$ | rigid motions in three dimensions |
| $A\oplus B$ | Minkowski sum |
| $A\ominus B$ | erosion / Minkowski difference in morphological usage |
| $\partial A$ | boundary of $A$ |
| $\operatorname{int}(A)$ | interior of $A$ |
| $A^-$ | guaranteed inner approximation |
| $A^+$ | guaranteed outer approximation |

For sets $A,B\subseteq\mathbb{R}^n$:

$$
A\oplus B=\{a+b\mid a\in A,b\in B\}.
$$

The configuration obstacle for a translating tool $T$ and obstacle $O$ is $O\oplus(-T)$.

## A.6 Paths and trajectories

A geometric path is:

$$
\gamma:[0,1]\to Q,
$$

where $Q$ is configuration space. A time law is a monotone function:

$$
s:[0,T]\to[0,1].
$$

The trajectory is $q(t)=\gamma(s(t))$.

For a tool solid $T$ and pose $X(t)$:

$$
\operatorname{Sweep}(T,X)=\bigcup_t X(t)T.
$$

## A.7 Error and uncertainty

A deterministic bound states:

$$
|x-\hat{x}|\le\varepsilon.
$$

An interval enclosure states:

$$
x\in[x^-,x^+].
$$

A probabilistic statement has the form:

$$
\Pr(|X-\hat{x}|\le\varepsilon)\ge1-\alpha.
$$

These are not interchangeable.

## A.8 Optimization

A constrained optimization problem is:

$$
\min_x J(x)\quad\text{subject to}\quad g_i(x)\le0,\ h_j(x)=0.
$$

A lower bound $L$ and feasible candidate cost $J$ satisfy:

$$
L\le J^*\le J.
$$

The gap quantifies the possible distance from global optimality.

# Reference IR and Certificate Schemas

The following schemas are intentionally explicit. They illustrate a coherent design; a production implementation may split fields or use generated codecs.

## B.1 Primitive identities and units

```ts
type Hash = string & { readonly __brand: "sha256" };
type SchemaId = string & { readonly __brand: "schema" };
type ArtifactId = string & { readonly __brand: "artifact-id" };
type FrameId = string & { readonly __brand: "frame" };
type ToolId = string & { readonly __brand: "tool-id" };
type FeatureId = string & { readonly __brand: "feature-id" };
type OperationId = string & { readonly __brand: "operation-id" };
type ClaimId = string & { readonly __brand: "claim-id" };
type AssumptionId = string & { readonly __brand: "assumption-id" };

type Mm = number & { readonly __unit: "mm" };
type MmPerMin = number & { readonly __unit: "mm/min" };
type Rpm = number & { readonly __unit: "rpm" };
type Radians = number & { readonly __unit: "rad" };
type Seconds = number & { readonly __unit: "s" };

interface ArtifactRef<T = unknown> {
  readonly id: ArtifactId;
  readonly hash: Hash;
  readonly schema: SchemaId;
  readonly mediaType: string;
  readonly byteLength: number;
  readonly _type?: T;
}
```

## B.2 Frames and transforms

```ts
interface Point3<F extends FrameId = FrameId> {
  readonly x: Mm;
  readonly y: Mm;
  readonly z: Mm;
  readonly frame: F;
}

interface Quaternion {
  readonly x: number;
  readonly y: number;
  readonly z: number;
  readonly w: number;
}

interface RigidTransform<From extends FrameId, To extends FrameId> {
  readonly from: From;
  readonly to: To;
  readonly translation: readonly [Mm, Mm, Mm];
  readonly rotation: Quaternion;
}

interface TransformUncertainty {
  readonly translationBox: readonly [
    readonly [Mm, Mm],
    readonly [Mm, Mm],
    readonly [Mm, Mm],
  ];
  readonly angularRadius: Radians;
  readonly confidence: "deterministic-bound" | "probabilistic";
}
```

## B.3 Geometry and setup

```ts
type GeometryRef = ArtifactRef<GeometryArtifact>;

interface GeometryArtifact {
  readonly kind:
    | "mesh"
    | "brep"
    | "implicit"
    | "voxel"
    | "dexel"
    | "height-field"
    | "primitive";
  readonly frame: FrameId;
  readonly enclosure?: {
    readonly direction: "inner" | "outer" | "two-sided" | "none";
    readonly metric: ErrorMetric;
    readonly bound?: ErrorBound;
  };
}

interface ToolAssembly {
  readonly id: ToolId;
  readonly cuttingGeometry: GeometryRef;
  readonly assemblyGeometry: GeometryRef;
  readonly fluteLength: Mm;
  readonly stickout: Mm;
  readonly measurementUncertainty: readonly ErrorBound[];
}

interface SetupManifest {
  readonly stock: GeometryRef;
  readonly target: GeometryRef;
  readonly fixtures: readonly GeometryRef[];
  readonly tools: readonly ArtifactRef<ToolAssembly>[];
  readonly frameGraph: ArtifactRef<FrameGraph>;
  readonly workSystem: string;
  readonly material?: ArtifactRef;
  readonly setupIdentity?: string;
}
```

## B.4 Paths

```ts
interface LineSegment<F extends FrameId> {
  readonly kind: "line";
  readonly to: Point3<F>;
}

interface ArcSegment<F extends FrameId> {
  readonly kind: "arc";
  readonly to: Point3<F>;
  readonly center: Point3<F>;
  readonly axis: readonly [number, number, number];
  readonly sweep: Radians;
}

interface SplineSegment<F extends FrameId> {
  readonly kind: "spline";
  readonly basis: "bezier" | "bspline" | "nurbs";
  readonly degree: number;
  readonly controlPoints: readonly Point3<F>[];
  readonly knots?: readonly number[];
  readonly weights?: readonly number[];
}

type Segment<F extends FrameId> =
  | LineSegment<F>
  | ArcSegment<F>
  | SplineSegment<F>;

interface Path<F extends FrameId = FrameId> {
  readonly frame: F;
  readonly start: Point3<F>;
  readonly end: Point3<F>;
  readonly segments: readonly Segment<F>[];
  readonly identityPolicy: "exact" | "snapped" | "witnessed-approximate";
  readonly approximation?: readonly ErrorBound[];
}
```

## B.5 Intent IR

```ts
interface RegionSpecification {
  readonly geometry: GeometryRef;
  readonly interpretation:
    | "required-removal"
    | "forbidden-removal"
    | "permitted-removal";
}

interface SurfaceRequirement {
  readonly surface: GeometryRef;
  readonly metric: "normal-deviation" | "hausdorff" | "scallop-height";
  readonly maximum: Mm;
}

interface OperationIntentBase {
  readonly id: OperationId;
  readonly feature: FeatureId;
  readonly frame: FrameId;
  readonly toolConstraints: readonly ToolConstraint[];
  readonly predecessors: readonly OperationId[];
  readonly regions: readonly RegionSpecification[];
  readonly surfaceRequirements: readonly SurfaceRequirement[];
  readonly provenance: Provenance;
}

interface PocketIntent extends OperationIntentBase {
  readonly kind: "pocket";
  readonly floor: GeometryRef;
  readonly boundary: GeometryRef;
  readonly roughingAllowance: {
    readonly radial: Mm;
    readonly axial: Mm;
  };
}

type OperationIntent = PocketIntent | HoleIntent | SurfaceIntent | CustomIntent;

interface IntentProgram {
  readonly schemaVersion: string;
  readonly setup: ArtifactRef<SetupManifest>;
  readonly operations: readonly OperationIntent[];
}
```

## B.6 Toolpath and schedule IR

```ts
interface PlannedPath {
  readonly id: string;
  readonly path: ArtifactRef<Path>;
  readonly operation: OperationId;
  readonly tool: ToolId;
  readonly phase: "entry" | "rough" | "semi-finish" | "finish" | "exit";
  readonly directionality:
    | { readonly kind: "reversible" }
    | { readonly kind: "fixed"; readonly reason: string };
  readonly feedPolicy: FeedPolicy;
  readonly provenance: Provenance;
}

interface ScheduledStep {
  readonly id: string;
  readonly beforeState: string;
  readonly afterState: string;
  readonly beforeStock: ArtifactRef;
  readonly afterStock: ArtifactRef;
  readonly command: CanonicalCommand;
  readonly dependencies: readonly string[];
}

interface ScheduledProgram {
  readonly setup: ArtifactRef<SetupManifest>;
  readonly steps: readonly ScheduledStep[];
  readonly finalState: string;
}
```

## B.7 Canonical commands

```ts
type CanonicalCommand =
  | {
      readonly kind: "selectTool";
      readonly tool: ToolId;
    }
  | {
      readonly kind: "startSpindle";
      readonly rpm: Rpm;
      readonly direction: "cw" | "ccw";
    }
  | {
      readonly kind: "stopSpindle";
    }
  | {
      readonly kind: "traverse";
      readonly path: ArtifactRef<Path>;
      readonly clearanceClaim?: ClaimId;
    }
  | {
      readonly kind: "cut";
      readonly path: ArtifactRef<Path>;
      readonly tool: ToolId;
      readonly feed: FeedPolicy;
      readonly operation: OperationId;
    }
  | {
      readonly kind: "probe";
      readonly path: ArtifactRef<Path>;
      readonly expectedContact: ContactModel;
      readonly outputBinding: string;
    }
  | {
      readonly kind: "dwell";
      readonly duration: Seconds;
    }
  | {
      readonly kind: "pause";
      readonly reason: string;
    };
```

## B.8 Machine and controller IR

```ts
interface MachineCommandBase {
  readonly beforeToken: string;
  readonly afterToken: string;
  readonly provenance: Provenance;
}

type MachineCommand =
  | (MachineCommandBase & {
      readonly kind: "axisMove";
      readonly interpolation: "rapid" | "linear" | "cwArc" | "ccwArc";
      readonly target: Point3<"machine">;
      readonly center?: Point3<"machine">;
      readonly feed?: MmPerMin;
    })
  | (MachineCommandBase & {
      readonly kind: "setSpindle";
      readonly rpm: Rpm;
      readonly direction: "cw" | "ccw" | "off";
    })
  | (MachineCommandBase & {
      readonly kind: "probeMove";
      readonly direction: readonly [number, number, number];
      readonly maximumTravel: Mm;
      readonly feed: MmPerMin;
      readonly outputBinding: string;
    });

interface ControllerBlock {
  readonly words: readonly ControllerWord[];
  readonly comments: readonly string[];
  readonly provenance: Provenance;
}

interface ControllerProgram {
  readonly dialect: string;
  readonly declaredInitialState: ModalState;
  readonly blocks: readonly ControllerBlock[];
}
```

## B.9 Diagnostics and provenance

```ts
interface SourceSpan {
  readonly artifact: Hash;
  readonly start: { readonly line: number; readonly column: number };
  readonly end: { readonly line: number; readonly column: number };
}

interface PassRecord {
  readonly passId: string;
  readonly passVersion: string;
  readonly relation: string;
  readonly inputHashes: readonly Hash[];
  readonly configurationHash: Hash;
}

interface Provenance {
  readonly source?: SourceSpan;
  readonly feature?: FeatureId;
  readonly operation?: OperationId;
  readonly parents: readonly Hash[];
  readonly passHistory: readonly PassRecord[];
}

interface Diagnostic {
  readonly code: string;
  readonly severity: "info" | "warning" | "error";
  readonly message: string;
  readonly provenance?: Provenance;
  readonly claim?: ClaimId;
  readonly counterexample?: ArtifactRef;
  readonly remediation?: string;
}
```

## B.10 Quantitative claims

```ts
type ErrorMetric =
  | "hausdorff-position"
  | "normal-surface"
  | "max-gouge-depth"
  | "minimum-clearance"
  | "transform-translation"
  | "transform-rotation"
  | "axis-following";

interface ErrorBound {
  readonly metric: ErrorMetric;
  readonly value: number;
  readonly unit: "mm" | "rad";
  readonly frame?: FrameId;
  readonly subject?: Hash;
  readonly interpretation: "deterministic" | "probabilistic" | "empirical";
  readonly confidence?: number;
}

type StructuredPredicate =
  | {
      readonly kind: "disjoint";
      readonly left: Hash;
      readonly right: Hash;
      readonly minimumSeparation?: Mm;
    }
  | {
      readonly kind: "max-penetration";
      readonly swept: Hash;
      readonly protectedTarget: Hash;
      readonly maximum: Mm;
      readonly metric: "signed-normal-depth" | "euclidean-depth";
    }
  | {
      readonly kind: "contains";
      readonly outer: Hash;
      readonly inner: Hash;
      readonly tolerance?: Mm;
    }
  | {
      readonly kind: "trace-refines";
      readonly source: Hash;
      readonly target: Hash;
      readonly relation: string;
    }
  | {
      readonly kind: "runtime-state-satisfies";
      readonly state: Hash;
      readonly assumptionSet: Hash;
    };
```

## B.11 Certificate graph

```ts
interface CheckerIdentity {
  readonly id: string;
  readonly version: string;
  readonly binaryHash: Hash;
  readonly relationVersion: string;
}

interface Claim {
  readonly id: ClaimId;
  readonly subject: ArtifactRef;
  readonly proposition: StructuredPredicate;
  readonly result:
    | "proved-exact"
    | "proved-bounded"
    | "translation-validated"
    | "exhaustive-finite-check"
    | "simulation-only"
    | "assumed"
    | "unknown"
    | "refuted";
  readonly method: string;
  readonly assumptions: readonly AssumptionId[];
  readonly evidence: readonly ArtifactRef[];
  readonly dependencies: readonly ClaimId[];
  readonly bound?: ErrorBound;
  readonly checker: CheckerIdentity;
}

interface Assumption {
  readonly id: AssumptionId;
  readonly proposition: StructuredPredicate;
  readonly source: "operator" | "calibration" | "machine" | "library";
  readonly evidence?: ArtifactRef;
  readonly runtimeCheck?: string;
  readonly validUntil?: string;
}

interface CertificateGraph {
  readonly schemaVersion: string;
  readonly rootSubject: ArtifactRef;
  readonly artifacts: readonly ArtifactRef[];
  readonly assumptions: readonly Assumption[];
  readonly claims: readonly Claim[];
  readonly policy: string;
}
```

# Checker Algorithms

This appendix gives reference algorithms. They emphasize the shape of soundness obligations rather than a particular implementation language.

## C.1 Certificate graph checker

```text
checkCertificate(graph, policy):
  validate schema and version compatibility
  verify every artifact hash against its bytes
  build maps for artifacts, assumptions, and claims

  for each claim:
    require unique claim id
    require subject exists and hash matches
    require all dependencies exist
    require all evidence artifacts exist
    require all assumptions exist
    require checker identity allowed by policy

  require claim dependency graph is acyclic
  process claims in topological order:
    require dependencies have acceptable results
    invoke claim-specific checker
    compare returned proposition, result, and bound
    reject if producer metadata overstates checker result

  require every policy-required proposition exists
  require no required claim is unknown, assumed-only, or simulation-only
  return accepted graph plus normalized summary
```

Soundness depends on claim-specific checkers and policy definitions. The graph checker prevents missing, stale, cyclic, or cross-applied evidence.

## C.2 Translation-validation skeleton

```text
validatePass(input I, output O, witness W, relation R):
  verify hash(I), hash(O), hash(W)
  verify schemas and pass versions
  switch R:
    ExactTraceEquality:
      ti = interpret(I)
      to = interpret(O)
      return compareExact(ti, to)

    TraceRefinement:
      return checkSimulationRelation(I, O, W)

    BoundedGeometry(metric, epsilon):
      return checkGeometricWitness(I, O, W, metric, epsilon)

    IntentSatisfaction:
      return checkIntentWitness(I, O, W)

    FeasibleOptimization:
      f = checkFeasibility(O, W.feasibility)
      j = recomputeObjective(O)
      l = checkLowerBound(W.lowerBound)
      return combine(f, j, l)
```

## C.3 Abstract-state proof checker

```text
checkAbstractTrace(program, proof):
  require proof has one entry per block
  state = abstractInitialState(program.initialAssumptions)

  for i in 0 .. program.blocks.length-1:
    require state is included in proof[i].before
    computed = abstractTransfer(program.blocks[i], proof[i].before)
    require computed is included in proof[i].after
    require localSafetyPredicates(proof[i].before, program.blocks[i])
    state = proof[i].after

  require finalPolicy(state)
  return success
```

“Included” uses the abstract-domain order. The producer may provide less precise states than the checker computes, but they must remain conservative.

## C.4 Continuous collision checker

```text
checkPath(path gamma, assembly T, obstacles O, interval I, budget):
  P = boundPath(gamma, I)             // outer pose enclosure
  W = sweepEnclosure(P, T, uncertainty)

  if disjoint(W, outer(O)) with separation delta > 0:
    return ProvedSafe(I, delta)

  if definitelyIntersects(inner(W), inner(O)):
    return Refuted(I, counterexampleRegion)

  if width(I) <= budget.parameterLimit
     or diameter(P) <= budget.spatialLimit
     or recursionDepth >= budget.maxDepth:
    return Inconclusive(I, W)

  split I into I1, I2
  r1 = checkPath(gamma, T, O, I1, budget)
  r2 = checkPath(gamma, T, O, I2, budget)
  return combine(r1, r2)
```

The `definitelyIntersects` branch requires inner enclosures. If these are unavailable, the checker may prove safety or return inconclusive but cannot always prove collision.

## C.5 Required-removal checker

```text
checkRequiredRemoval(required R, cutMotions M):
  guaranteed = empty set
  for motion in M:
    innerSweep = computeInnerSweep(motion.tool, motion.path)
    guaranteed = union(guaranteed, innerSweep)

  residual = difference(R, guaranteed)
  if residual is empty by exact/conservative test:
    return proved
  if a definitely nonempty inner subset of residual is found:
    return refuted with residual witness
  return inconclusive with unresolved cells
```

## C.6 Modal parse-back checker

```text
checkFinalBytes(controllerIR C, bytes B, dialect D, initialState M0):
  parsed = independentParse(B, D)
  if parse error: reject

  sourceTrace = interpretControllerIR(C, M0)
  byteTrace = interpretParsedBlocks(parsed, M0)

  compare:
    event kinds and ordering
    tool/spindle/accessory state
    path endpoints and interpolation semantics
    probe command/result bindings
    final modal state
    numeric deviation against formatting budget

  verify required preamble and epilogue predicates
  return trace-equivalence or bounded-refinement claim
```

## C.7 Schedule checker

```text
checkSchedule(intent, candidate, witness):
  require candidate contains each required operation exactly once
  require no unknown operations

  positions = map operation -> index
  for each precedence edge (a,b):
    require positions[a] < positions[b]

  state = initial process state
  cost = 0
  for each step:
    require step preconditions hold in state
    verify chosen orientation and entry
    verify link against referenced stock state
    state = apply certified effects(step, state)
    cost += recompute transition and operation cost

  require state satisfies final policy
  require cost == witness.objective within numeric bound
  optionally verify lower-bound certificate
```

## C.8 Error-budget composition

```text
composeBound(inputBound e, passLocal p, sensitivity L, metric m):
  require e.metric == m or verified metric conversion exists
  require p.metric == m
  require L is a valid upper Lipschitz/sensitivity bound
  return L * e.value + p.value
```

For vector or transform bounds, use a matrix or interval propagation rule rather than a scalar function.

## C.9 Runtime authorization checker

```text
authorize(bundle B, liveState M, storedHash H'):
  verify certificate graph of B under requested operating policy
  require H' == B.jobHash
  require live machine identity matches B.machineProfile
  require firmware semantics compatible
  require no alarm and permitted controller state
  require homing state satisfies assumptions
  require active WCS lies inside certified transform set
  require tool and setup identity satisfy assumptions
  require calibration records valid

  epoch = read controller state epoch
  token = sign(jobHash, epoch, assumptionSnapshotHash, expiry)
  return one-use authorization token
```

Execution consumes the token only if the state epoch remains unchanged.

# A Temporal Controller Model

The following TLA+-style pseudocode illustrates a model suitable for refinement and model checking. It is not tied to a specific syntax version.

## D.1 Variables

```text
VARIABLES
  conn,                 \* disconnected | connected
  identity,             \* unknown or machine/profile identity
  ctrlState,            \* idle | uploading | ready | running | held | alarm | quarantined
  storedHash,           \* hash or none
  executingHash,        \* hash or none
  authorizedHash,       \* hash or none
  stateEpoch,           \* monotonically increasing integer
  commandQueue,
  durableEvents,
  telemetry,
  homed,
  activeWcs,
  tool,
  alarm,
  lastOutcome
```

## D.2 Initial state

```text
Init ==
  /\ conn = "disconnected"
  /\ identity = "unknown"
  /\ ctrlState = "idle"
  /\ storedHash = None
  /\ executingHash = None
  /\ authorizedHash = None
  /\ stateEpoch = 0
  /\ commandQueue = << >>
  /\ durableEvents = << >>
  /\ telemetry = << >>
  /\ homed = FALSE
  /\ activeWcs = Unknown
  /\ tool = Unknown
  /\ alarm = FALSE
  /\ lastOutcome = None
```

## D.3 Connection and identification

```text
Connect ==
  /\ conn = "disconnected"
  /\ conn' = "connected"
  /\ identity' = "unknown"
  /\ UNCHANGED <<ctrlState, storedHash, executingHash, ...>>

Identify(id) ==
  /\ conn = "connected"
  /\ identity' = id
  /\ stateEpoch' = stateEpoch + 1
  /\ UNCHANGED <<conn, ctrlState, storedHash, ...>>
```

## D.4 Upload

```text
BeginUpload(h) ==
  /\ conn = "connected"
  /\ ctrlState = "idle"
  /\ ctrlState' = "uploading"
  /\ storedHash' = None
  /\ lastOutcome' = None
  /\ stateEpoch' = stateEpoch + 1

UploadSucceeded(h) ==
  /\ ctrlState = "uploading"
  /\ ctrlState' = "ready"
  /\ storedHash' = h
  /\ Append(durableEvents, [kind |-> "upload-ack", hash |-> h])
  /\ stateEpoch' = stateEpoch + 1

UploadAmbiguous ==
  /\ ctrlState = "uploading"
  /\ ctrlState' = "quarantined"
  /\ storedHash' = Unknown
  /\ lastOutcome' = "ambiguous-upload"
  /\ stateEpoch' = stateEpoch + 1
```

## D.5 Authorization and start

```text
Authorize(h, epoch) ==
  /\ ctrlState = "ready"
  /\ storedHash = h
  /\ epoch = stateEpoch
  /\ homed
  /\ ~alarm
  /\ RuntimeAssumptionsHold(identity, activeWcs, tool)
  /\ authorizedHash' = h
  /\ UNCHANGED <<ctrlState, executingHash, stateEpoch, ...>>

Start(h) ==
  /\ ctrlState = "ready"
  /\ storedHash = h
  /\ authorizedHash = h
  /\ ctrlState' = "running"
  /\ executingHash' = h
  /\ authorizedHash' = None        \* consume one-use authorization
  /\ stateEpoch' = stateEpoch + 1
```

## D.6 Hold, resume, abort, and alarm

```text
FeedHold ==
  /\ ctrlState = "running"
  /\ ctrlState' = "held"
  /\ stateEpoch' = stateEpoch + 1

Resume(h, epoch) ==
  /\ ctrlState = "held"
  /\ executingHash = h
  /\ authorizedHash = h
  /\ epoch = stateEpoch
  /\ ctrlState' = "running"
  /\ authorizedHash' = None
  /\ stateEpoch' = stateEpoch + 1

Abort ==
  /\ ctrlState \in {"running", "held", "uploading", "ready"}
  /\ ctrlState' = "idle"
  /\ executingHash' = None
  /\ authorizedHash' = None
  /\ Append(durableEvents, [kind |-> "aborted"])
  /\ stateEpoch' = stateEpoch + 1

Fault(reason) ==
  /\ ctrlState \in {"running", "held", "uploading", "ready"}
  /\ ctrlState' = "alarm"
  /\ alarm' = TRUE
  /\ lastOutcome' = reason
  /\ authorizedHash' = None
  /\ stateEpoch' = stateEpoch + 1
```

## D.7 Next-state relation

```text
Next ==
  \/ Connect
  \/ \E id : Identify(id)
  \/ \E h : BeginUpload(h)
  \/ \E h : UploadSucceeded(h)
  \/ UploadAmbiguous
  \/ \E h, epoch : Authorize(h, epoch)
  \/ \E h : Start(h)
  \/ FeedHold
  \/ \E h, epoch : Resume(h, epoch)
  \/ Abort
  \/ \E reason : Fault(reason)
  \/ StatusUpdate
  \/ Disconnect
```

## D.8 Invariants

```text
TypeInvariant ==
  ctrlState \in {"idle", "uploading", "ready", "running", "held", "alarm", "quarantined"}

RunningIsAuthorized ==
  ctrlState = "running" => executingHash # None

RunningMatchesStored ==
  ctrlState = "running" => executingHash = storedHash

NoMotionInAlarm ==
  alarm => ctrlState # "running"

UnknownUploadCannotRun ==
  storedHash = Unknown => ctrlState # "running"

OneUseAuthorization ==
  ctrlState = "running" => authorizedHash = None
```

## D.9 Temporal properties

```text
AbortEventuallyTerminal ==
  [](AbortRequested => <>(ctrlState \in {"idle", "alarm", "quarantined"}))

UploadEventuallyResolves ==
  [](ctrlState = "uploading" => <>(ctrlState \in {"ready", "alarm", "quarantined", "idle"}))

NoHashSubstitution ==
  [](ctrlState = "running" => executingHash = storedHash)
```

These liveness properties require fairness and environment assumptions. A model checker should search for deadlocks, unauthorized transitions, stale-epoch authorizations, and dropped durable events.
EOF
wc -l -w -c /mnt/data/z1_textbook_work/book/Certificate_Carrying_CAM_Compilers.md
```

<details><summary>💭 Thinking</summary>

**Appended appendices and selected exercise solutions to textbook**

</details>

```json
{"search_query":[{"q":"site:doi.org 10.2493/jjspe.76.361 triple dexel"},{"q":"site:doi.org 10.1115/1.3086034 triple dexel swept volume"},{"q":"site:doi.org 10.1155/2014/835098 CNC minimum time feedrate"},{"q":"site:ntrs.nasa.gov 20230017350 runtime assurance framework"}],"response_length":"long"}
```

<details><summary>💭 Thinking</summary>

**Building the reference list**

I’m reconciling publication details, correcting uncertain entries, and assembling a reliable bibliography covering semantics, verification, geometry, optimization, runtime assurance, and the project’s implementation context.

**Searched 2 websites**

</details>

```unknown
bash -lc tail -n 120 /mnt/data/z1_textbook_work/book/Certificate_Carrying_CAM_Compilers.md && printf '\n---FILES---\n' && find /mnt/data/z1_textbook_work/book -maxdepth 2 -type f -printf '%P %s bytes\n' | sort | tail -n 30
```

<details><summary>💭 Thinking</summary>

**Inspected textbook files, headings, references, and citation numbers**

</details>

```json
{"search_query":[{"q":"site:nist.gov NISTIR 5970 Canonical Machining Commands Proctor Kramer Michaloski DOI"},{"q":"\"Precedence Constrained Traveling Salesman Problem in CNC Tool Path Optimization\" DOI authors"},{"q":"\"Conversion between Triple Dexel Model and Polygon Model\" DOI Inui Sakurai Umezu"},{"q":"\"STEPNC++ - An Effective Tool for Feature-based CAM/CNC\" NIST authors 2009"}],"response_length":"long"}
```

<details><summary>💭 Thinking</summary>

**Searched 6 websites**

</details>

```unknown
bash -lc grep -n '^\\appendix\|^# Notation\|^# Reference IR\|^# Selected' /mnt/data/z1_textbook_work/book/Certificate_Carrying_CAM_Compilers.md | head -20
```

<details><summary>💭 Thinking</summary>

**Audited textbook appendix headings and citations for references R42 and R43**

</details>

```json
{"search_query":[{"q":"site:nist.gov/publications \"Testing STEP-NC Implementations\""},{"q":"\"Dijkstra Monads for All\" DOI authors"},{"q":"\"Efficient Representation and Validation of Proofs\" DOI Necula Lee"},{"q":"site:compcert.org \"Formal Verification of a Realistic Compiler\""}],"response_length":"long"}
```

<details><summary>💭 Thinking</summary>

**Searched 16 websites**

</details>

```unknown
bash -lc cat >> /mnt/data/z1_textbook_work/book/Certificate_Carrying_CAM_Compilers.md <<'EOF'

# Glossary

This glossary uses the meanings intended throughout the book. Several terms have broader meanings in compilers, formal methods, computational geometry, or manufacturing; the definitions below identify the interpretation relevant to a certificate-carrying CAM system.

**Abstract domain.** A mathematical domain whose elements conservatively represent sets of concrete program or machine states. Examples include intervals, axis-aligned boxes, finite sets of modal states, and symbolic frame relations.

**Abstract interpretation.** A framework for computing sound approximations of program behavior by interpreting a program over an abstract domain rather than enumerating concrete executions.

**Abstraction function.** A mapping from detailed physical or controller traces to the observations relevant at a higher semantic level, such as final stock, protected-surface penetration, or feature dimensions.

**Acceptance gate.** A machine-enforced condition that an artifact must satisfy before it can advance to a later lifecycle stage, such as preview, air cut, attended cutting, or production execution.

**Acyclic dependency graph.** A directed graph with no cycles. Certificate dependencies should normally form such a graph so that artifacts and claims can be checked in a finite topological order.

**Admissible set.** The subset of states, configurations, paths, or schedules satisfying all hard constraints.

**Affine transform.** A transform consisting of a linear map and a translation. Rigid frame transforms are the special case preserving distances and orientation or reflection, depending on the determinant.

**Alarm state.** A controller or machine state in which ordinary execution is blocked or modified because a fault, interlock, or exceptional condition has been detected.

**Alias collision.** Two distinct semantic objects receiving the same identifier or lookup key. In geometry this can merge unrelated endpoints, contours, cells, or topology components.

**Artifact.** An immutable, content-addressed input or output of a compiler stage: source, AST, IR, mesh, tool model, machine profile, controller program, serialized bytes, evidence, or certificate.

**Artifact identity.** The stable identity of an artifact, normally a cryptographic content hash plus a schema or media type. A filename or in-memory object address is not sufficient.

**Assertion.** A proposition intended to hold at one program point, controller state, geometric stage, or runtime checkpoint.

**Assumption.** An external fact required by a proof but not established by that proof. Tool measurement, machine calibration, fixture identity, controller conformance, and work-coordinate registration are typical assumptions.

**Assumption discharge.** The act of replacing an assumption with evidence or a runtime check that establishes it for a specific execution.

**Attestation.** Signed evidence about provenance, identity, configuration, or execution. Attestation authenticates a statement; it does not by itself establish the statement's mathematical truth.

**Authorization epoch.** A monotonically changing identifier binding an authorization decision to the machine state on which it was based. It prevents stale preflight results from authorizing later, changed states.

**Backend.** The portion of a compiler that lowers machine-independent operations to a target machine, controller dialect, serialization, or transport protocol.

**Bounded refinement.** A refinement relation that permits a quantified deviation under a named metric, such as Hausdorff distance, normal-direction surface error, or timing error.

**Canonical command.** A machine-oriented action with explicit machining meaning but without target-controller syntax or accidental modal dependence.

**Certificate.** A machine-checkable package binding claims, artifact identities, assumptions, evidence, dependency claims, checker identities, and quantitative bounds.

**Certificate checker.** A comparatively small program that validates evidence and decides whether a certificate claim follows for the named artifact under the named assumptions.

**Certificate DAG.** The dependency graph connecting source artifacts, transformed artifacts, claims, evidence, runtime facts, and final execution authorization.

**Certified artifact.** An artifact accompanied by one or more successfully checked claims. Certification is property-specific; it does not mean that every desirable property has been proved.

**Checker independence.** The degree to which a checker avoids sharing the producer's algorithms, data normalizations, hidden state, and defect modes. Independent implementation is often more valuable than nominal modular separation.

**Claim.** A precise proposition about a precise subject artifact, such as a travel-envelope inclusion or a maximum target-penetration bound.

**Clearance.** A distance or separation condition between the tool assembly and stock, target, fixtures, machine structures, or forbidden configuration-space regions.

**Closed-world command language.** A command language in which every permitted operation is explicitly enumerated and unknown operations are rejected. This is preferred for machine-control authorization.

**Compiler pass.** A transformation or analysis from one IR stage to another, ideally accompanied by an explicit semantic relation and a checker or proof obligation.

**Concrete semantics.** The detailed semantics of actual states and transitions, as opposed to an abstract analysis that represents sets of them.

**Configuration space.** A space whose points represent complete machine configurations. Collision of a moving solid can be transformed into point avoidance in an expanded forbidden region of configuration space.

**Conformance.** Satisfaction of a specification, standard, target intent, controller dialect, or certificate proposition.

**Conservative approximation.** An approximation oriented so that a successful check implies the desired property. Collision checks use outer obstacle and sweep enclosures; guaranteed-removal checks use inner removal enclosures.

**Constraint.** A hard condition defining feasibility. A safety constraint must not be converted into a soft objective penalty unless the resulting violations are categorically rejected later.

**Content-addressing.** Naming an artifact by a digest of its exact bytes and relevant encoding metadata, making changes observable and dependency invalidation mechanical.

**Controller dialect.** The syntax and operational interpretation implemented by a particular controller and firmware profile, including modal groups, commands, extensions, numeric ranges, and protocol behavior.

**Controller IR.** A structured representation of controller-level operations after machine lowering but before textual serialization.

**Controller semantics profile.** A versioned, content-addressed description of how a target firmware interprets commands, modes, uploads, acknowledgements, and lifecycle operations.

**Counterexample.** A concrete input, state, trace, geometry, or schedule showing that a claimed invariant or transformation relation is false.

**Cutting sweep.** The swept volume of the material-removing portion of the tool along a trajectory.

**Cyber-physical compiler.** A compiler whose target semantics includes physical mechanisms, continuous dynamics, sensors, actuators, material state, faults, and communication rather than only abstract machine instructions.

**Denotation.** The mathematical meaning assigned to a syntax element or IR object. A manufacturing operation often denotes a set of acceptable outcomes rather than one path.

**Denotational semantics.** A compositional mapping from programs or operations to mathematical objects such as functions, relations, traces, or sets of acceptable workpiece states.

**Dexel.** A depth element representing intervals of material along a ray. A triple-dexel model uses three orthogonal ray families.

**Diagnostic.** A structured explanation of an error, warning, unproved obligation, assumption, or source-to-output provenance relationship.

**Dialect conversion.** A checked transformation from one IR dialect or abstraction level to another under explicit legality and semantic-preservation rules.

**Dimensional type.** A type carrying physical dimension, such as length, angle, speed, acceleration, or spindle rate, so dimensionally invalid operations are rejected.

**Dijkstra monad.** A specification-indexed computational abstraction that associates effectful computations with predicate transformers or Hoare-style contracts.

**Discretization.** Replacement of a continuous object by finite samples, cells, segments, time steps, or basis coefficients. A discretization parameter alone is not a proof of continuous-domain error.

**Effect summary.** A conservative description of the state, resources, stock regions, probe values, frames, or modalities read and written by an operation.

**Effect system.** A static system that records and constrains computational or machine effects in addition to ordinary value types.

**Elaboration.** The pass that resolves names, defaults, units, frames, tools, parameters, and syntactic sugar into an explicit, typed representation.

**Enclosure.** A set guaranteed to contain an exact but potentially unknown quantity or geometry. Intervals and conservative swept volumes are enclosures.

**End-to-end theorem.** A statement relating checked source intent and assumptions to all permitted final physical executions, composed across every compiler, controller, and runtime boundary.

**Evidence.** Data consumed by a checker to establish a claim: proof terms, interval bounds, abstract states, parse-back traces, separating axes, spatial covers, solver certificates, or exhaustive state tables.

**Exact claim.** A claim established without an approximation tolerance relative to the stated mathematical input model. It can still depend on assumptions connecting the model to reality.

**Execution instance.** One uniquely identified controller run of one stored job under one machine-state epoch. A filename does not uniquely identify an execution instance.

**Feasible set.** The set of candidates satisfying all hard constraints. Optimization should search within this set rather than trade safety against cost.

**Final-byte validation.** Re-parsing and interpreting the exact serialized bytes that will be uploaded, then checking equivalence or refinement against the certified controller IR.

**Frame.** A coordinate system with an identity and transform relationships. Coordinates without frames are incomplete semantic values.

**Frame graph.** A graph of named coordinate frames and transforms, possibly with interval-valued uncertainty and time-varying measurements.

**Free-space link.** A non-cutting connection between machining segments whose tool-and-holder sweep is certified to avoid current stock, fixtures, protected geometry, and forbidden machine regions.

**G-code block.** One controller input record containing words evaluated under modal and dialect-specific semantics. Textual order inside a block does not necessarily imply sequential execution.

**Gouge.** Material removal beyond the allowed target or allowance region. A gouge claim requires a target or protected-material model.

**Hash binding.** Inclusion of an artifact hash in a claim, protocol step, authorization, or signature so the statement cannot silently transfer to different bytes.

**Hausdorff distance.** A metric measuring the greatest nearest-point deviation between two sets. It is useful for path approximation but does not alone encode orientation, process, or topology preservation.

**Height field.** A surface representation with one height per planar location. It is efficient for three-axis material models but cannot represent arbitrary undercuts or multiple layers.

**Hoare triple.** A contract of the form $\{P\}\;c\;\{Q\}$ stating that command $c$, when started in a state satisfying $P$, establishes $Q$ if it terminates.

**Hybrid system.** A system combining discrete mode transitions with continuous state evolution, such as controller states plus machine position, velocity, and braking dynamics.

**Identity morphism.** In a path category, the zero-motion path at a pose. It acts as the neutral element for path composition under the chosen equality notion.

**Information order.** A partial order describing precision of abstract values, often written $a\sqsubseteq b$ when $b$ contains at least as much uncertainty or information according to the selected convention.

**Inner approximation.** A set guaranteed to lie inside the true set. Inner removal approximations support claims that material was definitely removed.

**Intent IR.** A representation of manufacturing features, working steps, allowances, tolerances, resources, and dependencies before a specific tool-center path is selected.

**Interlock.** A condition preventing or terminating an operation when required safety or process state is absent.

**Interval arithmetic.** Arithmetic on closed intervals with outward rounding so the exact real-valued result remains enclosed.

**Invariant.** A property true initially and preserved by every relevant transition or compiler step.

**IR legality.** The syntactic, typing, capability, and semantic conditions an artifact must satisfy at a given intermediate representation level.

**Job bundle.** The complete execution package: exact program bytes, machine and firmware profiles, tool/holder models, stock/target/fixture artifacts, frame data, assumptions, certificates, and metadata.

**Kleisli composition.** Composition of effectful functions through a monad or indexed effect abstraction rather than ordinary function composition.

**Language sandbox.** An execution environment intended to restrict a macro or scripting language. A same-realm wrapper that retains access to host globals is not a security boundary.

**Lattice.** A partially ordered set in which every pair has a least upper bound and greatest lower bound. Many abstract domains use lattices to merge control-flow information and compute fixed points.

**Legality checker.** A checker deciding whether an IR contains only operations, types, frames, units, and capabilities permitted at that level.

**Lipschitz bound.** A constant $L$ satisfying $d(f(x),f(y))\le Ld(x,y)$. It describes how input uncertainty or approximation can be amplified by a transformation.

**Liveness property.** A temporal property stating that some desired event eventually occurs, such as an abort eventually reaching a stopped or faulted state.

**Lowering.** Refinement from a higher-level IR to a more concrete IR by selecting machine, controller, geometry, or serialization details.

**Machine envelope.** The admissible set of axis configurations or tool poses under travel, soft-limit, fixture, and machine-structure constraints.

**Machine IR.** A representation after target-machine capabilities, frames, kinematics, limits, and trajectories have been made explicit but before controller syntax is serialized.

**Machine profile.** A versioned artifact describing kinematics, axis limits, rates, acceleration, jerk, spindle and tool capabilities, controller dialect, and other target constraints.

**Macro language.** A language executed at compile time to construct an inert AST or plan. It should not retain arbitrary executable closures inside trusted compiler passes.

**Material-removal semantics.** A semantics in which cutting commands transform stock solids, typically by set difference with a cutting sweep.

**Metric.** A distance function satisfying non-negativity, identity, symmetry, and triangle inequality. Approximation claims must name the metric under which their bounds hold.

**Modal state.** Controller state that persists across blocks until replaced, such as motion mode, units, plane, feed, spindle speed, or work offset.

**Modal compression.** Omission of redundant modal words during serialization. It is correct only if interpreted traces remain equivalent under the specified initial state and dialect.

**Model checking.** Exhaustive or symbolic exploration of a finite or finitely abstracted transition system to establish temporal properties or find counterexamples.

**Monad.** A compositional abstraction for computations with effects. For CAM, state, failure, nondeterminism, logging, and external interaction are relevant effects.

**Monotone analysis.** An analysis whose transfer functions preserve the abstract-domain order, enabling fixed-point computation and sound iteration.

**Nondeterminism.** Multiple possible successor states or traces arising from underspecified intent, sensor uncertainty, communication outcomes, faults, or environmental variation.

**Numerical kernel.** The small collection of arithmetic, predicates, interval operations, and geometric primitives trusted by certificate checkers.

**Objective.** A quantity minimized or maximized among feasible candidates, such as cycle time, rapid distance, tool changes, energy, or predicted wear.

**Operational semantics.** Rules describing how a configuration changes step by step as commands execute.

**Operations research.** Mathematical modeling and optimization of decisions such as operation sequencing, tool assignment, linking, and feed scheduling under constraints.

**Outer approximation.** A set guaranteed to contain the true set. Outer sweeps and obstacles support collision-absence and no-gouge claims.

**Parse-back validation.** Parsing emitted controller bytes back into structured IR and comparing their interpreted semantics with the pre-serialization artifact.

**Partial correctness.** A guarantee that the postcondition holds if execution terminates. It does not prove termination or eventual progress.

**Pass contract.** A specification of a pass's accepted input, produced output, semantic relation, error bound, assumptions, diagnostics, witness, and checker.

**Path.** A parameterized geometric curve through a frame. It does not by itself define timing, controller interpolation, or material-removal process.

**Path equivalence.** The chosen relation under which two path values are considered semantically equal, often equality modulo monotone reparameterization and a stated geometric tolerance.

**Path parameterization.** A monotone function mapping time to geometric path progress. It determines velocity, acceleration, jerk, and cycle time along a fixed path.

**Planner.** A generally complex and heuristic producer that chooses a toolpath, schedule, or process implementation satisfying an intent specification.

**Postcondition.** A proposition promised after an operation terminates from a state satisfying its precondition.

**Postprocessor.** A target-specific compiler backend lowering machine or canonical IR into a controller dialect and exact serialized job bytes.

**Precondition.** A proposition that must hold before an operation may execute or a theorem may be applied.

**Predicate transformer.** A function mapping desired postconditions backward to sufficient preconditions. Weakest-precondition semantics is a principal example.

**Process model.** A model of cutting, probing, spindle, stock, tool engagement, or machine dynamics used to interpret and check operations.

**Proof obligation.** A proposition that must be established before a pass result, job bundle, or runtime action can be accepted.

**Proof-producing analysis.** An analyzer that emits evidence allowing a smaller checker to validate its result rather than requiring the analyzer itself to be trusted.

**Protected material.** Target or fixture material that a claim forbids the cutting sweep from entering beyond a stated tolerance.

**Provenance.** Structured information linking output objects and diagnostics to source spans, compiler passes, parameters, input artifacts, and tool versions.

**Quantization.** Mapping continuous or high-precision values to discrete integer bins. Quantization can be useful, but a lossy packed key must not be mistaken for unique topology identity.

**Rapid safety.** A claim that a non-cutting motion's tool-and-holder sweep avoids current stock and obstacles under controller rapid semantics and machine uncertainty.

**Raw command.** An escape hatch containing target syntax whose effects have not been derived from a trusted parser. Conservative analyses must reject it or set affected abstract state to unknown.

**Reachability.** The set of states obtainable from an initial state under the transition relation and assumptions.

**Reference semantics.** A simple, explicit semantic implementation used as the standard against which optimized or target-specific implementations are compared.

**Refinement.** A relation in which a concrete implementation removes choices or adds detail without introducing behavior forbidden by the abstract specification.

**Refinement mapping.** A mapping from concrete states and traces to abstract states and traces used to demonstrate that one system implements another.

**Representation invariant.** A property ensuring an in-memory value is internally coherent, such as a path endpoint matching its last segment. It is narrower than a machining-safety claim.

**Residual stock.** Material remaining after the modeled removal operations. Conservative residual stock usually requires outer stock and inner removal approximations.

**Robust predicate.** A predicate whose result is correct for the mathematical input model despite floating-point degeneracy, normally through filtered, adaptive, exact, or interval methods.

**Runtime assurance.** A small trusted mechanism that monitors an advanced component or physical system and intervenes before a safety property can be violated.

**Safety property.** A temporal property stating that a bad event never occurs. A finite violation has a counterexample prefix.

**Semantic preservation.** Equality, refinement, or bounded correspondence between the meanings of a pass input and output.

**Semantic waist.** A compact intermediate language separating many high-level producers from many low-level targets while retaining the physical distinctions needed for correctness.

**Serialization.** Conversion of structured controller IR to exact bytes, including number formatting, line endings, comments, checksums, and encoding.

**Signature.** A cryptographic authentication of bytes or statements. A signature establishes origin and integrity under a key-management assumption, not semantic correctness.

**Simulation-only result.** Evidence from one or more concrete executions or samples without a theorem covering all relevant states or the continuous domain.

**Small-step semantics.** An operational semantics in which each rule performs one local transition, making interleavings, faults, and protocol states explicit.

**Soundness.** The property that every fact reported as established is true of all represented concrete behaviors under the stated assumptions. A sound analysis may conservatively reject safe programs.

**Source map.** A mapping from generated IR nodes, commands, and diagnostics back to source syntax and macro-expansion provenance.

**SSA state token.** A single-assignment value consumed and produced by state-changing IR operations, making effect order and data dependencies explicit.

**Staged programming.** Execution of one program phase to construct code or data for a later phase. The phase boundary should remove ambient authority and retain only inert, validated artifacts.

**Stock monotonicity.** The ideal subtractive-process invariant $S_{i+1}\subseteq S_i$. It excludes material addition but does not by itself establish correct removal.

**Swept volume.** The union of all poses of a solid along a trajectory. Different claims require the cutting tool sweep or the complete tool-and-holder assembly sweep.

**Target surface.** The desired final boundary or protected part geometry against which gouge, allowance, and residual-material claims are stated.

**Temporal logic.** A logic with operators over traces, such as always $\Box$, eventually $\Diamond$, and next, used for controller safety and liveness properties.

**Time-optimal path parameterization.** Selection of progress $s(t)$ along a fixed geometric path to minimize time while satisfying velocity, acceleration, torque, jerk, tracking, and process constraints.

**Total correctness.** Partial correctness plus termination or liveness under stated assumptions.

**Trace.** A finite or infinite sequence of states and observable events representing one system execution.

**Trace refinement.** Inclusion of concrete traces, after abstraction, in the set allowed by an abstract program.

**Trajectory.** A time-indexed pose or configuration function. A path becomes a trajectory only after time parameterization.

**Translation validation.** Independent checking that one actual pass output correctly refines its actual input, instead of proving the transformer correct for all inputs.

**Trusted computing base.** The code, semantics, numeric primitives, key material, and assumptions whose correctness must be trusted for the assurance argument to hold.

**Typestate.** Static representation of protocol state in types so only operations valid in the current state can be expressed.

**Uncertainty set.** A set of possible values for a physical or numerical quantity, such as a transform interval, tool-radius interval, or following-error bound.

**Validation.** Checking an artifact against a relation, policy, or specification. Validation should state exactly what was checked and by what method.

**Verification.** Establishment of a formal or mathematically justified claim. In this book the term is reserved for claims with explicit propositions, assumptions, and evidence rather than visual inspection alone.

**Weakest precondition.** The least restrictive precondition sufficient to ensure a desired postcondition after execution of a command.

**Witness.** Producer-supplied data demonstrating a construction or optimization choice, such as a path decomposition, correspondence, abstract invariant, separating plane, or schedule assignment.

**Work coordinate system.** A frame relating part-program coordinates to machine coordinates. Its identity and uncertainty are runtime-critical inputs to travel and collision claims.

# Guided Reading and Project Tracks

The chapters are intentionally cross-disciplinary. This appendix gives compact routes through the material for different implementation goals.

## G.1 Compiler and language track

Read Chapters 1, 2, 7-15, 18-20, 27, 28, 36, 37, and 40. Implement the inert plan AST, the multi-level IR ladder, pass contracts, content-addressed artifacts, and parse-back validation before adding advanced planning strategies. The central external readings are multi-stage programming [R37], MLIR [R16], SSA [R15], CompCert [R17], translation validation [R18, R19], and NIST's canonical machining interface [R1, R2].

## G.2 Static-analysis and formal-methods track

Read Chapters 3, 5, 6, 10, 11, 14, and 22-30. Begin with Hoare logic and weakest preconditions [R4, R5], structural operational semantics [R6], abstract interpretation [R7], refinement mappings [R9], temporal logic [R8, R34], and proof-carrying code [R20, R21]. Parameterized effects [R12-R14] and Dijkstra monads [R39] provide a route from API typing to machine-checkable contracts.

## G.3 Robust geometry and verification track

Read Chapters 3, 4, 9, 16, 24-28, 33, and 37. Build exact or adaptive topology predicates before accelerating constructions [R22]. Use interval enclosures [R23, R24], configuration-space reasoning [R25], conservative swept-volume techniques [R26], and representations such as triple dexels [R27, R28]. Keep target protection, fixture clearance, and guaranteed removal as separate propositions.

## G.4 Controller and runtime track

Read Chapters 1, 5, 18-20, 22, 23, 29, 30, 37, and 39. Implement a closed command grammar, explicit modal interpreter, protocol state machine, state epochs, hash-bound upload/start operations, and abort recovery. NIST's interpreters and canonical commands provide the machining semantics foundation [R1, R2]. TLA-style specification [R8, R34], hybrid systems [R35], and runtime assurance [R36] cover the protocol and physical-monitoring boundary.

## G.5 Planning and optimization track

Read Chapters 2-4, 6, 9, 16, 17, and Part V. Treat every optimizer as an untrusted producer of candidates inside a separately checked feasible set. Relevant foundations include configuration spaces [R25], fast marching and geodesics [R29, R30], precedence-constrained routing [R31], and constrained feed scheduling [R32, R33].

## G.6 Manufacturing-information track

Read Chapters 1, 2, 7, 8, 12, 13, 16, 18, 27, and 37. Compare the semantic-waist architecture with STEP-NC's feature and working-step model [R3, R42, R43]. Conformance testing is as important as schema design; Barnard Feeney and Frechette provide a manufacturing-specific testing perspective [R40].

## G.7 A twelve-week implementation course

| Week | Reading | Laboratory |
|---:|---|---|
| 1 | Chapters 1-2 | Define one pocket intent and three acceptable implementations. |
| 2 | Chapters 3-4 | Implement dimensional types and a checked frame graph. |
| 3 | Chapters 5-6 | Write denotational and small-step semantics for five canonical commands. |
| 4 | Chapters 7-9 | Build an isolated macro-to-AST boundary and path algebra. |
| 5 | Chapters 10-13 | Add effects, machine-state tokens, provenance, and extensible operation schemas. |
| 6 | Chapters 14-15 | Implement pass manifests and one translation validator. |
| 7 | Chapters 16-20 | Lower a pocket to controller IR and validate emitted bytes by parse-back. |
| 8 | Chapters 22-23 | Implement weakest-precondition rules and an interval/modal abstract interpreter. |
| 9 | Chapters 24-26 | Add robust predicates, interval transforms, and typed error budgets. |
| 10 | Chapters 27-30 | Build the certificate DAG, protocol model, and runtime preflight handshake. |
| 11 | Chapters 31-35 | Add precedence-aware sequencing and a checked free-space linker. |
| 12 | Chapters 36-40 | Integrate the headless compiler, checker process, CLI, and Z1 dry-run workflow. |

## G.8 Research directions

The architecture leaves several substantive research problems open:

1. A compositional specification language for machining features whose denotation covers tolerance zones, surface texture, process constraints, and intermediate stock support.
2. Efficient conservative swept-volume bounds for arbitrary tool assemblies and spline trajectories under uncertain transforms.
3. Proof-producing adaptive stock representations that combine dexel speed with local volumetric refinement.
4. Translation validators for geometry algorithms that emit compact correspondence or separation witnesses.
5. Robust scheduling with stock-dependent transition costs and structural-support constraints.
6. Controller semantics learned from traces but converted into explicit, reviewable, versioned profiles.
7. Small proof formats for geometric certificates; compact proof representation and checking remain important engineering concerns [R41].
8. Runtime monitors that combine discrete protocol assurance with bounded stopping dynamics and sensor uncertainty.

\backmatter

# References {-}

The bracketed identifiers in the text refer to the entries below. DOI links name the version of record when available; institutional pages are used for standards and technical reports.

**[R1]** Thomas R. Kramer, Frederick M. Proctor, and Elena R. Messina. *The NIST RS274/NGC Interpreter, Version 3*. NISTIR 6556, National Institute of Standards and Technology, 2000. <https://www.nist.gov/publications/nist-rs274ngc-interpreter-version-3>.

**[R2]** Frederick M. Proctor, Thomas R. Kramer, and John L. Michaloski. *Canonical Machining Commands*. NISTIR 5970, National Institute of Standards and Technology, 1997. <https://doi.org/10.6028/NIST.IR.5970>.

**[R3]** ISO 14649-1. *Industrial Automation Systems and Integration -- Physical Device Control -- Data Model for Computerized Numerical Controllers -- Part 1: Overview and Fundamental Principles*. International Organization for Standardization.

**[R4]** C. A. R. Hoare. “An Axiomatic Basis for Computer Programming.” *Communications of the ACM* 12, no. 10 (1969): 576-580, 583. <https://doi.org/10.1145/363235.363259>.

**[R5]** Edsger W. Dijkstra. “Guarded Commands, Nondeterminacy and Formal Derivation of Programs.” *Communications of the ACM* 18, no. 8 (1975): 453-457. <https://doi.org/10.1145/360933.360975>.

**[R6]** Gordon D. Plotkin. “A Structural Approach to Operational Semantics.” Originally DAIMI FN-19, Aarhus University, 1981; reprinted in *Journal of Logic and Algebraic Programming* 60-61 (2004): 17-139. <https://doi.org/10.1016/j.jlap.2004.03.009>.

**[R7]** Patrick Cousot and Radhia Cousot. “Abstract Interpretation: A Unified Lattice Model for Static Analysis of Programs by Construction or Approximation of Fixpoints.” In *Proceedings of POPL 1977*, 238-252. <https://doi.org/10.1145/512950.512973>.

**[R8]** Leslie Lamport. “The Temporal Logic of Actions.” *ACM Transactions on Programming Languages and Systems* 16, no. 3 (1994): 872-923. <https://doi.org/10.1145/177492.177726>.

**[R9]** Martín Abadi and Leslie Lamport. “The Existence of Refinement Mappings.” *Theoretical Computer Science* 82, no. 2 (1991): 253-284. <https://doi.org/10.1016/0304-3975(91)90224-P>.

**[R10]** Eugenio Moggi. “Notions of Computation and Monads.” *Information and Computation* 93, no. 1 (1991): 55-92. <https://doi.org/10.1016/0890-5401(91)90052-4>.

**[R11]** Philip Wadler. “The Essence of Functional Programming.” In *Proceedings of POPL 1992*, 1-14. <https://doi.org/10.1145/143165.143169>.

**[R12]** Robert E. Strom and Shaula Yemini. “Typestate: A Programming Language Concept for Enhancing Software Reliability.” *IEEE Transactions on Software Engineering* SE-12, no. 1 (1986): 157-171. <https://doi.org/10.1109/TSE.1986.6312929>.

**[R13]** Robert Atkey. “Parameterised Notions of Computation.” *Journal of Functional Programming* 19, nos. 3-4 (2009): 335-376. <https://doi.org/10.1017/S095679680900728X>.

**[R14]** John M. Lucassen and David K. Gifford. “Polymorphic Effect Systems.” In *Proceedings of POPL 1988*, 47-57. <https://doi.org/10.1145/73560.73564>.

**[R15]** Ron Cytron, Jeanne Ferrante, Barry K. Rosen, Mark N. Wegman, and F. Kenneth Zadeck. “Efficiently Computing Static Single Assignment Form and the Control Dependence Graph.” *ACM Transactions on Programming Languages and Systems* 13, no. 4 (1991): 451-490. <https://doi.org/10.1145/115372.115320>.

**[R16]** Chris Lattner, Mehdi Amini, Uday Bondhugula, Albert Cohen, Andy Davis, Jacques Pienaar, River Riddle, Tatiana Shpeisman, Nicolas Vasilache, and Oleksandr Zinenko. “MLIR: Scaling Compiler Infrastructure for Domain Specific Computation.” In *Proceedings of CGO 2021*, 2-14. <https://doi.org/10.1109/CGO51591.2021.9370308>.

**[R17]** Xavier Leroy. “Formal Verification of a Realistic Compiler.” *Communications of the ACM* 52, no. 7 (2009): 107-115. <https://doi.org/10.1145/1538788.1538814>.

**[R18]** Amir Pnueli, Michael Siegel, and Eli Singerman. “Translation Validation.” In *Tools and Algorithms for the Construction and Analysis of Systems, TACAS 1998*, 151-166. <https://doi.org/10.1007/BFb0054170>.

**[R19]** Nuno P. Lopes, Juneyoung Lee, Chung-Kil Hur, Zhengyang Liu, and John Regehr. “Alive2: Bounded Translation Validation for LLVM.” In *Proceedings of PLDI 2021*. <https://doi.org/10.1145/3453483.3454030>.

**[R20]** George C. Necula. “Proof-Carrying Code.” In *Proceedings of POPL 1997*, 106-119. <https://doi.org/10.1145/263699.263712>.

**[R21]** Andrew W. Appel. “Foundational Proof-Carrying Code.” In *Proceedings of the 16th Annual IEEE Symposium on Logic in Computer Science*, 247-256, 2001. <https://doi.org/10.1109/LICS.2001.932501>.

**[R22]** Jonathan Richard Shewchuk. “Adaptive Precision Floating-Point Arithmetic and Fast Robust Geometric Predicates.” *Discrete & Computational Geometry* 18 (1997): 305-363. <https://doi.org/10.1007/PL00009321>.

**[R23]** IEEE. *IEEE Standard for Interval Arithmetic (Simplified)*. IEEE Std 1788.1-2017. <https://standards.ieee.org/ieee/1788.1/6074/>.

**[R24]** Ramon E. Moore, R. Baker Kearfott, and Michael J. Cloud. *Introduction to Interval Analysis*. SIAM, 2009. <https://doi.org/10.1137/1.9780898717716>.

**[R25]** Tomás Lozano-Pérez. “Spatial Planning: A Configuration Space Approach.” *IEEE Transactions on Computers* C-32, no. 2 (1983): 108-120. <https://doi.org/10.1109/TC.1983.1676196>.

**[R26]** Silvia Sellán, Noam Aigerman, and Alec Jacobson. “Swept Volumes via Spacetime Numerical Continuation.” *ACM Transactions on Graphics* 40, no. 4 (2021). <https://doi.org/10.1145/3450626.3459780>.

**[R27]** Masatomo Inui, Takashi Sakurai, and Nobuyuki Umezu. “Data Conversion Technology between Triple Dexel Model and Polygonal Model.” *Journal of the Japan Society for Precision Engineering* 76, no. 2 (2010): 226-231. <https://doi.org/10.2493/jjspe.76.226>.

**[R28]** Weihan Zhang and Ming-Chuan Leu. “Surface Reconstruction Using Dexel Data from Three Sets of Orthogonal Rays.” *Journal of Computing and Information Science in Engineering* 9, no. 1 (2009): 011008. <https://doi.org/10.1115/1.3086034>.

**[R29]** J. A. Sethian. “A Fast Marching Level Set Method for Monotonically Advancing Fronts.” *Proceedings of the National Academy of Sciences* 93, no. 4 (1996): 1591-1595. <https://doi.org/10.1073/pnas.93.4.1591>.

**[R30]** Ron Kimmel and J. A. Sethian. “Computing Geodesic Paths on Manifolds.” *Proceedings of the National Academy of Sciences* 95, no. 15 (1998): 8431-8435. <https://doi.org/10.1073/pnas.95.15.8431>.

**[R31]** Ilker Kucukoglu, Tulin Gunduz, Fatma Balkancioglu, Emine Chousein Topal, and Oznur Sayim. “Application of Precedence Constrained Travelling Salesman Problem Model for Tool Path Optimization in CNC Milling Machines.” *An International Journal of Optimization and Control: Theories & Applications* 9, no. 3 (2019): 59-68. <https://doi.org/10.11121/ijocta.01.2019.00662>.

**[R32]** Qiang Zhang, Shurong Li, and Jianxin Guo. “Minimum Time Trajectory Optimization of CNC Machining with Tracking Error Constraints.” *Abstract and Applied Analysis* 2014, Article 835098. <https://doi.org/10.1155/2014/835098>.

**[R33]** Hung Pham and Quang-Cuong Pham. “A New Approach to Time-Optimal Path Parameterization Based on Reachability Analysis.” *IEEE Transactions on Robotics* 34, no. 3 (2018): 645-659. <https://doi.org/10.1109/TRO.2018.2819195>.

**[R34]** Leslie Lamport. *Specifying Systems: The TLA+ Language and Tools for Hardware and Software Engineers*. Addison-Wesley, 2002. <https://lamport.azurewebsites.net/tla/book.html>.

**[R35]** Rajeev Alur, Costas Courcoubetis, Thomas A. Henzinger, and Pei-Hsin Ho. “The Algorithmic Analysis of Hybrid Systems.” *Theoretical Computer Science* 138, no. 1 (1995): 3-34. <https://doi.org/10.1016/0304-3975(94)00202-T>.

**[R36]** J. Tanner Slagel, Lauren M. White, Aaron Dutle, César A. Muñoz, and Nicolas Crespo. “A Formal Verification Framework for Runtime Assurance.” In *NASA Formal Methods 2024*, 322-328. <https://doi.org/10.1007/978-3-031-60698-4_19>.

**[R37]** Walid Taha and Tim Sheard. “MetaML and Multi-Stage Programming with Explicit Annotations.” *Theoretical Computer Science* 248, nos. 1-2 (2000): 211-242. <https://doi.org/10.1016/S0304-3975(00)00053-0>.

**[R38]** John C. Reynolds. “Separation Logic: A Logic for Shared Mutable Data Structures.” In *Proceedings of the 17th Annual IEEE Symposium on Logic in Computer Science*, 55-74, 2002. <https://doi.org/10.1109/LICS.2002.1029817>.

**[R39]** Kenji Maillard, Danel Ahman, Robert Atkey, Guido Martínez, Cătălin Hriţcu, Exequiel Rivas, and Éric Tanter. “Dijkstra Monads for All.” *Proceedings of the ACM on Programming Languages* 3, ICFP, Article 104 (2019). <https://doi.org/10.1145/3341708>.

**[R40]** Allison Barnard Feeney and Simon P. Frechette. “Testing STEP-NC Implementations.” In *Proceedings of World Automation Congress 2002*. National Institute of Standards and Technology. <https://www.nist.gov/publications/testing-step-nc-implementations>.

**[R41]** George C. Necula and Peter Lee. “Efficient Representation and Validation of Proofs.” In *Proceedings of the 13th Annual IEEE Symposium on Logic in Computer Science*, 93-104, 1998. <https://doi.org/10.1109/LICS.1998.705646>.

**[R42]** Thomas R. Kramer and Frederick M. Proctor. *Feature-Based Control of a Machining Center*. NISTIR 5926, National Institute of Standards and Technology, 1996. <https://www.nist.gov/publications/feature-based-control-machining-center>.

**[R43]** John L. Michaloski, Thomas R. Kramer, Frederick M. Proctor, Xun Xu, Sid Venkatesh, and David Odendahl. “STEPNC++ -- An Effective Tool for Feature-Based CAM/CNC.” In *Advanced Design and Manufacturing Based on STEP*. Springer, 2009. <https://www.nist.gov/publications/stepnc-effective-tool-feature-based-camcnc>.

# Source Snapshot and Reproducibility Notes {-}

The implementation-specific case study is based on the supplied `dropcut-studio.zip` snapshot and the public repository branch `task/cnc-control-dropcut` near commit `e82bed1e5a00f38f4441e6ea13e1265edc775928`, inspected in August 2026. The case study is not a statement about later revisions. Where firmware behavior is discussed, the reviewed source evidence used the Makera stock Carvera firmware repository at commit `1683b6fb5c7ec1d341c476c6fdb2a22f7a26220e` and explicitly distinguished stock behavior from community-firmware changes.

The textbook's diagrams are generated from Graphviz or Matplotlib source stored with the Markdown edition. The PDF is rendered from the same Markdown source. Equations, algorithms, and TypeScript interfaces are pedagogical specifications; they must be implemented, tested, and connected to machine-specific assumptions before they can support a production certificate.

EOF

python - <<'PY'
from pathlib import Path
p=Path('/mnt/data/z1_textbook_work/book/Certificate_Carrying_CAM_Compilers.md')
s=p.read_text()
print('lines',s.count('\n')+1,'words',len(s.split()),'bytes',p.stat().st_size)
PY
```

<details><summary>💭 Thinking</summary>

**Appended glossary and reading paths**

</details>

```json
{"search_query":[{"q":"Robert Atkey Parameterised Notions of Computation DOI Journal Functional Programming"},{"q":"MetaML multi-stage programming explicit annotations DOI"},{"q":"Polymorphic effect systems Lucassen Gifford DOI"},{"q":"SSA control dependence graph DOI Cytron 1991"}],"response_length":"long"}
```

<details><summary>💭 Thinking</summary>

**Searched 13 websites**

</details>

```unknown
bash -lc cat /home/oai/skills/pdfs/SKILL.md
```

<details><summary>💭 Thinking</summary>

**Read PDF skill instructions**

</details>

```unknown
bash -lc set -e
cd /mnt/data/z1_textbook_work/book
printf 'pandoc: '; pandoc --version | head -n 1
printf 'xelatex: '; xelatex --version | head -n 1
python - <<'PY'
from pathlib import Path
import re
p=Path('Certificate_Carrying_CAM_Compilers.md')
s=p.read_text()
# Fences
fences=[(i+1,l) for i,l in enumerate(s.splitlines()) if re.match(r'^```',l)]
print('code fences:',len(fences),'balanced',len(fences)%2==0)
# tcolor boxes
for env in ['designrule','warningbox','workedexample']:
    a=s.count(r'\begin{'+env+'}')
    b=s.count(r'\end{'+env+'}')
    print(env,a,b,'ok',a==b)
# Citation identifiers
used=set()
for m in re.finditer(r'\[([^\]]*R\d+[^\]]*)\]',s):
    used.update(map(int,re.findall(r'R(\d+)',m.group(1))))
defined=set(map(int,re.findall(r'^\*\*\[R(\d+)\]\*\*',s,re.M)))
print('references used',len(used),min(used),max(used))
print('references defined',len(defined),min(defined),max(defined))
print('missing defs',sorted(used-defined))
print('unused defs',sorted(defined-used))
# Figures
figs=re.findall(r'!\[[^]]*\]\(([^)]+)\)',s)
missing=[f for f in figs if not Path(f).exists()]
print('figures',len(figs),'missing',missing)
# headings with duplicate exact titles
from collections import Counter
hs=re.findall(r'^#{1,3} (.+)$',s,re.M)
dup=[(h,n) for h,n in Counter(hs).items() if n>1 and not h.startswith('Exercises')]
print('headings',len(hs),'duplicates sample',dup[:20])
PY
```

<details><summary>💭 Thinking</summary>

**Built and validated textbook PDF with font and figure adjustments**

</details>

```unknown
bash -lc rm -rf /mnt/data/z1_textbook_work/renders && mkdir -p /mnt/data/z1_textbook_work/renders
python /home/oai/skills/pdfs/scripts/render_pdf.py \
  /mnt/data/z1_textbook_work/book/Certificate_Carrying_CAM_Compilers.pdf \
  --out_dir /mnt/data/z1_textbook_work/renders \
  --dpi 150
printf '\nRendered pages: '
find /mnt/data/z1_textbook_work/renders -maxdepth 1 -name '*.png' | wc -l
ls -lh /mnt/data/z1_textbook_work/renders | sed -n '1,8p'
```

<details><summary>💭 Thinking</summary>

**Rebuilt and validated the textbook PDF with corrected headings and references**

</details>

```unknown
bash -lc set -e
OUT=/mnt/data/z1_textbook_deliverables
SRC=/mnt/data/z1_textbook_work/book
rm -rf "$OUT"
mkdir -p "$OUT"
cp "$SRC/Certificate_Carrying_CAM_Compilers.md" "$OUT/Certificate_Carrying_CAM_Compilers.md"
cp "$SRC/Certificate_Carrying_CAM_Compilers.pdf" "$OUT/Certificate_Carrying_CAM_Compilers.pdf"

BUNDLE=/mnt/data/z1_textbook_work/source_bundle/Certificate_Carrying_CAM_Compilers
rm -rf /mnt/data/z1_textbook_work/source_bundle
mkdir -p "$BUNDLE/figures"
cp "$SRC/Certificate_Carrying_CAM_Compilers.md" "$BUNDLE/"
cp "$SRC"/figures/*.png "$BUNDLE/figures/"
cp "$SRC"/figures/*.dot "$BUNDLE/figures/"
cp "$SRC/make_geometry_figure.py" "$BUNDLE/"
cat > "$BUNDLE/README.md" <<'EOF'
# Certificate-Carrying CAM Compilers - source bundle

This bundle contains the Markdown source and generated figures for the textbook.

## Render to PDF

Requirements: Pandoc, XeLaTeX, Linux Libertine O, Linux Biolinum O, DejaVu Sans Mono, and the LaTeX packages named in the Markdown YAML header.

Run from this directory:

```bash
pandoc Certificate_Carrying_CAM_Compilers.md \
  --from=markdown+raw_tex \
  --pdf-engine=xelatex \
  --top-level-division=chapter \
  --highlight-style=tango \
  --resource-path=. \
  -o Certificate_Carrying_CAM_Compilers.pdf
```

The `.dot` files are the Graphviz sources for most architecture diagrams. `make_geometry_figure.py` generates the inner/outer approximation figure.
EOF
cd /mnt/data/z1_textbook_work/source_bundle
zip -X -r "$OUT/Certificate_Carrying_CAM_Compilers_Source.zip" Certificate_Carrying_CAM_Compilers >/tmp/z1_zip.log
zip -T "$OUT/Certificate_Carrying_CAM_Compilers_Source.zip"
sha256sum "$OUT"/* > "$OUT/SHA256SUMS.txt"
ls -lh "$OUT"
cat "$OUT/SHA256SUMS.txt"
```

<details><summary>💭 Thinking</summary>

**Packaged final textbook deliverables and source bundle**

</details>

The manuscript is complete with 34 chapters, exercises, solutions, proof patterns, checklist, and bibliography. Final PDF verification and appendix reflow produced a clean 159-page edition.

# Certificate-Carrying CAM Compilers

Completed as a full textbook:

- **213 pages**
- **40 chapters in six parts**
- **Seven appendices**
- Formal semantics, refinement, IR design, compiler-pass contracts, translation validation, robust computational geometry, abstract interpretation, proof-carrying code, certificates, temporal controller models, runtime assurance, and operations research
- TypeScript-oriented implementation patterns and checker algorithms
- End-to-end certified-pocket example
- Detailed Dropcut Studio / Makera Z1 case study
- Exercises for every chapter with selected solutions
- Glossary, guided reading tracks, twelve-week course plan, research directions, and 43 primary references

Files:

- [Download the Markdown textbook](sandbox:/mnt/data/z1_textbook_deliverables/Certificate_Carrying_CAM_Compilers.md)
- [Download the 213-page PDF textbook](sandbox:/mnt/data/z1_textbook_deliverables/Certificate_Carrying_CAM_Compilers.pdf)
- [Download the complete source bundle](sandbox:/mnt/data/z1_textbook_deliverables/Certificate_Carrying_CAM_Compilers_Source.zip) — Markdown, PNG figures, Graphviz sources, figure-generation script, and build instructions
- [Download SHA-256 checksums](sandbox:/mnt/data/z1_textbook_deliverables/SHA256SUMS.txt)

The final PDF was rendered and visually inspected across the front matter, tables of contents, chapter pages, equations, code listings, diagrams, long tables, case study, solutions, glossary, and references.


---

> Let’s try again, more structured and pedagogical: 4 big chapters, and after writing the first draft, go back and make sure each definition and term worth defining or introducing is properly motivated and defined and then applied in a few examples. Pretend you are a student reading the text and trying to make sense of it, and then rewrite it.

```unknown
bash -lc cat /home/oai/skills/pdfs/SKILL.md && printf '\n---FILES---\n' && find /mnt/data -maxdepth 3 -type f | sed 's#^#/##' | head -200
```

I’ll rebuild the textbook as four major conceptual chapters, using the existing manuscript only as source material, then perform a pedagogical rewrite emphasizing motivation, definitions, examples, and continuity.

<details><summary>💭 Thinking</summary>

**Read PDF instructions and inspected textbook structure and length**

**Restructuring the manuscript**

I’m organizing the material into four major chapters, then checking each technical term for motivation, definition, application, and examples. I’m also rewriting from a student’s perspective so the progression feels clear rather than merely rearranged.

**Restructured the manuscript**

</details>

```unknown
bash -lc rm -rf /mnt/data/z1_textbook_v2_work && mkdir -p /mnt/data/z1_textbook_v2_work && unzip -l /mnt/data/z1_textbook_deliverables/Certificate_Carrying_CAM_Compilers_Source.zip | head -100 && printf '\n--- first 220 lines ---\n' && sed -n '1,220p' /mnt/data/z1_textbook_deliverables/Certificate_Carrying_CAM_Compilers.md
```

<details><summary>💭 Thinking</summary>

**Inspected textbook source and assets**

**Creating a pedagogical rewrite**

I’m turning the sprawling material into four coherent chapters, using a consistent pattern: motivation, definition, application, examples, and common misunderstandings. I’ll then audit terminology and revise unclear explanations from a student’s viewpoint.

**Created a pedagogical rewrite**

</details>

```unknown
bash -lc grep -n '^# References' /mnt/data/z1_textbook_deliverables/Certificate_Carrying_CAM_Compilers.md && tail -n 340 /mnt/data/z1_textbook_deliverables/Certificate_Carrying_CAM_Compilers.md | sed -n '1,340p'
```

<details><summary>💭 Thinking</summary>

**Inspected manuscript references and source content**

**Designing the textbook**

I’m building four large chapters around a running pocket example, with appendices for notation, schemas, exercises, a glossary, and references. Each key term will be motivated, defined, applied in multiple examples, and checked for clarity.

**Designed the textbook**

**Planning the rewrite**

I’m consolidating the material into four chapters with fewer, stronger sections. I’ll preserve useful examples while adding clearer transitions, student-oriented explanations, recurring definitions, and chapter-level exercises.

**Planned the rewrite**

</details>

```unknown
bash -lc cd /mnt/data/z1_textbook_v2_work && unzip -q /mnt/data/z1_textbook_deliverables/Certificate_Carrying_CAM_Compilers_Source.zip && cp -R Certificate_Carrying_CAM_Compilers/figures . && find figures -maxdepth 1 -type f -printf '%f %s bytes\n' | sort
```

I’ll anchor all four chapters in one running pocket-machining example, introducing concepts only as needed around four questions: meaning, representation, evidence, and execution.

<details><summary>💭 Thinking</summary>

**Built a certificate-carrying CAM compiler from source archives**

</details>

```unknown
bash -lc sed -n '120,620p' /mnt/data/z1_textbook_v2_work/first_draft.md | head -500
```

The structural draft is complete; I’m now auditing terms individually for motivation, precise definition, application, and counterexample, while removing remaining stitched-section assumptions and improving narrative continuity.

<details><summary>💭 Thinking</summary>

**Inspected draft structure, analyzed images, and checked figure references**

</details>

```unknown
bash -lc cat > /mnt/data/z1_textbook_v2_work/term_cards.py <<'PY'
# Pedagogical term cards used by build_final.py.
# Each card: (term, motivation, definition, pocket application, second application, do-not-confuse)

TERMS = {
"1. The puzzle hidden inside a simple pocket": [
("Artifact",
 "Once a compiler has several stages, the phrase 'the program' becomes ambiguous. We need a name for the exact object produced or consumed at one stage.",
 "An artifact is an immutable, versioned input or output of the toolchain: source text, an IR module, a tool model, a machine profile, a G-code byte sequence, or a certificate. In an assurance-oriented system it should have a stable identity, usually a content hash.",
 "The pocket intent, its planned toolpath, and the final `.nc` file are three different artifacts. A claim about one does not automatically apply to the others.",
 "A probed work-offset record is also an artifact. Reprobing creates a new artifact even when the displayed offset changes by only a few micrometers.",
 "Do not confuse an artifact with a mutable in-memory object. Mutation destroys the ability to tell which exact value a certificate described."),
("Manufacturing intent",
 "The operator asks for a result, but a toolpath algorithm asks for a procedure. Those are different questions.",
 "Manufacturing intent is a specification of acceptable physical outcomes and process conditions: which material must be removed, which material must remain, what tolerances apply, and which assumptions or resources are required. It deliberately leaves implementation choices open.",
 "The pocket intent says that material inside the pocket must be removed to a depth and that the surrounding wall and floor must remain within tolerance. It does not require a raster, offset, or adaptive path.",
 "A drilling intent may specify hole axis, depth, diameter class, and breakthrough behavior without requiring a particular canned cycle.",
 "Do not confuse intent with a feature name. `rectPocket` is useful only if its physical meaning is defined."),
("Strategy",
 "If intent leaves choices open, the compiler needs a name for one chosen way of realizing it.",
 "A strategy is an algorithmic policy that selects a concrete implementation for an intent, such as offset roughing, raster finishing, helical entry, or retract-to-safe-plane linking.",
 "The running pocket may use concentric offsets with a helical entry. That is one strategy among many that could satisfy the same intent.",
 "A probe operation may choose a single approach, a double-touch routine, or an outlier-resistant repeated measurement strategy.",
 "Do not confuse a popular strategy with the meaning of the operation. Replacing the strategy should not force a change to the intent checker."),
("Execution trace",
 "A final workpiece alone does not record whether the machine passed through an unsafe state on the way there.",
 "An execution trace is an ordered history of relevant events and states: poses, velocities, spindle changes, controller messages, probe contacts, alarms, stock updates, pauses, and timing. A behavior is one possible trace or observable outcome of a program under stated assumptions.",
 "The pocket trace includes spindle start, entry, cutting passes, retracts, and spindle stop. A fixture collision is visible in the trace even if a later cut accidentally hides the mark in the final stock model.",
 "For upload and start, the trace includes bytes sent, acknowledgements, hashes, timeouts, and the exact transition into execution.",
 "Do not confuse a rendered animation with the set of possible traces. A preview usually shows one nominal trace."),
("Semantics",
 "Terms such as 'equivalent path' or 'safe command' are empty until we say what observations count.",
 "Semantics is a mathematical or executable account of meaning. It maps syntax or IR operations to outcomes, state transitions, traces, or logical contracts. Different semantic views answer different questions, but they must agree where they overlap.",
 "The semantics of `cut(path, feed)` includes motion along the path, elapsed time, and material removal by the tool sweep, not just a list of points.",
 "The semantics of `G91` is a persistent change to distance mode, so it affects later blocks even when those blocks do not repeat `G91`.",
 "Do not confuse semantics with documentation prose. Prose is useful, but a checker needs a precise model it can execute or reason from."),
("Specification",
 "To check a result, the checker needs a proposition rather than an informal success label.",
 "A specification is a predicate or relation describing acceptable inputs, outputs, states, or traces. A program satisfies the specification when its possible behavior is contained in the allowed set, subject to explicit assumptions and error bounds.",
 "A pocket specification can separately state required removal, forbidden removal, fixture clearance, and machine-envelope constraints.",
 "A controller specification can state that an abort request must eventually lead to a stopped or faulted state.",
 "Do not confuse a specification with a test case. A test checks selected examples; a specification states the general property those examples illustrate."),
],
"2. The minimum mathematical language": [
("Set",
 "Manufacturing constantly asks whether a point or volume is inside stock, target, fixture, or free space.",
 "A set is a collection of objects. A solid is idealized as a set of points in three-dimensional space; membership `x in S` means that point `x` belongs to solid `S`. Union, intersection, and difference then express occupancy, collision, and removal.",
 "If `S0` is stock and `R` is removed material, the residual stock is `S0 \\ R`.",
 "If the tool-holder sweep intersects the fixture set, the motion is unsafe.",
 "Do not confuse the mathematical set with one mesh or voxel array. Those are representations that may approximate the set."),
("Relation",
 "A pocket request can have many valid plans, and a command can have several outcomes when sensing or communication is uncertain.",
 "A relation connects zero, one, or many elements of one domain to elements of another. Unlike a function, it need not choose exactly one output. Relations are therefore natural for specifications and nondeterministic execution.",
 "The planning relation connects one pocket intent to every toolpath that satisfies it.",
 "The controller relation after a timeout may connect the host's prior state to both 'command executed' and 'command not executed' until further evidence resolves the ambiguity.",
 "Do not confuse relational semantics with vagueness. A relation can be mathematically exact while allowing several legitimate results."),
("Metric",
 "A tolerance such as 0.02 mm is meaningless until we know what kind of distance it bounds.",
 "A metric is a distance function on a space. It must identify zero distance with equality, be nonnegative and symmetric, and satisfy the triangle inequality. Approximation claims must name the metric because different metrics capture different manufacturing errors.",
 "Hausdorff distance can bound how far an approximated tool-center curve strays from an ideal curve.",
 "Maximum normal surface deviation may be more relevant than Hausdorff distance for a finishing pass; rotational frame error needs angular units instead of millimeters.",
 "Do not confuse a numerical threshold with a metric. 'Within 0.02' is incomplete without the measured quantity and frame."),
("Tolerance neighborhood",
 "Real machines and numerical algorithms rarely achieve literal equality, so specifications need a controlled way to admit bounded deviation.",
 "The tolerance neighborhood `N_e(A)` is the set of points within metric distance `e` of set `A`. It converts an exact specification into a bounded one while retaining an explicit metric and bound.",
 "The pocket wall may be permitted to lie inside a 0.02 mm neighborhood of the nominal wall surface.",
 "An uploaded feed value rounded by the postprocessor may be permitted to differ from the Machine IR value by a separately declared rate error.",
 "Do not confuse tolerance with approximate equality used as a data-structure key. Nearness is generally not transitive and therefore is not a safe replacement for identity."),
("Frame",
 "The same coordinate triple can name different physical locations depending on whether it is measured from machine home, the stock center, or a fixture datum.",
 "A frame is a coordinate system with an origin and orientation. A point is meaningful only together with its frame. Frame-aware types prevent operations on coordinates that have not been explicitly transformed into a common system.",
 "The pocket boundary is defined in the work frame, while travel limits are defined in the machine frame. The compiler must transform the entire path before checking travel.",
 "A probe result may update the transform from a fixture frame to the machine frame rather than directly changing feature geometry.",
 "Do not confuse a frame with a work-offset number such as G54. G54 is one controller mechanism for selecting a transform; the semantic concept is broader."),
("Transform",
 "Once coordinates live in frames, the compiler needs an explicit operation that moves information between them.",
 "A transform maps coordinates or poses from one frame into another. For rigid three-dimensional geometry it is commonly an element of `SE(3)`, containing rotation and translation. An uncertain transform maps a point to a bounded region rather than one exact point.",
 "The work-to-machine transform places the pocket path within the Z1 travel envelope.",
 "A tool-length transform maps the spindle reference point to the tool tip; a camera calibration transform maps image measurements into machine coordinates.",
 "Do not confuse applying a transform with relabeling a point. Relabeling changes the type name without changing the physical location and is unsound."),
],
"3. Four complementary meanings of a program": [
("Machine state",
 "A command such as 'move to X10' cannot be interpreted without knowing current units, frame, position, motion mode, and interlocks.",
 "Machine state is the collection of physical, controller, coordinate, modal, process, and protocol facts relevant to execution. The exact state model depends on the question, but omitted components must not be silently assumed irrelevant.",
 "Before the pocket cut, relevant state includes homing, active work transform, selected tool, spindle speed, current pose, stock, and alarm state.",
 "Before a probe result is consumed, state also includes whether contact occurred, measurement uncertainty, and the binding that receives the result.",
 "Do not confuse controller-reported state with complete physical state. A controller may report position while fixture location or tool stick-out remains an external assumption."),
("Denotational semantics",
 "We often want to ask what result an entire operation permits without following every intermediate command.",
 "Denotational semantics assigns a mathematical meaning to a program or operation, such as a set of acceptable final stocks or a relation between initial and final states. It is useful for expressing intent and comparing implementations at a high level.",
 "The pocket intent denotes every final stock that has the required cavity while preserving protected material within tolerance.",
 "A probing operation can denote a relation from uncertain initial frames to updated frame estimates and measurement records.",
 "Do not confuse denotational semantics with a claim that execution is atomic. It abstracts away intermediate steps for one kind of reasoning."),
("Operational semantics",
 "Controller behavior and modal commands are easiest to understand as a sequence of small state changes.",
 "Operational semantics defines step-by-step transition rules. A configuration contains a command or remaining program and a state; a rule describes the next configuration and emitted event.",
 "A `cut` step advances the pose, updates elapsed time, and removes the tool sweep from stock.",
 "A `G91` block changes distance mode; the next coordinate block is then interpreted relative to the current position.",
 "Do not confuse operational semantics with a high-fidelity simulator. The reference rules may be deliberately simple while still defining the intended meaning."),
("Axiomatic semantics",
 "Engineers often reason in the form 'this command is allowed only when these facts hold, and afterward these other facts are guaranteed.'",
 "Axiomatic semantics describes programs with logical assertions, especially preconditions, postconditions, and invariants. A Hoare triple `{P} c {Q}` means that if `P` holds and command `c` terminates normally, then `Q` holds afterward.",
 "A cut may require a homed machine, known frame, loaded tool, running spindle, and safe path; afterward the pose is at the path end and stock has been updated.",
 "A tool-change contract may require spindle-off and promise that the selected-tool state has changed.",
 "Do not confuse a precondition with a runtime check. A precondition is a proposition; the implementation must still decide how it is established."),
("Temporal semantics",
 "Upload, hold, resume, abort, and disconnect are properties of whole histories rather than one state transition.",
 "Temporal semantics describes propositions over traces, including safety properties that must always hold and liveness properties that require eventual progress. Temporal logic supplies operators such as 'always' and 'eventually.'",
 "The controller should always execute the byte hash that was authorized for the current job.",
 "After an abort request, the protocol should eventually report stopped or faulted rather than remain indefinitely ambiguous.",
 "Do not confuse eventuality with a deadline. 'Eventually stopped' needs an additional real-time bound before it can justify physical stopping-distance claims."),
],
"4. Refinement, nondeterminism, and approximation": [
("Nondeterminism",
 "The same program can have several possible outcomes because the source leaves choices open or the environment is uncertain.",
 "Nondeterminism means that a state or input may have more than one allowed successor state or trace. It can represent intentional freedom, sensing uncertainty, communication loss, faults, or physical variation.",
 "The pocket intent nondeterministically permits many valid toolpaths before the planner chooses one.",
 "A probe move may end with contact in an uncertainty interval, no contact, or an alarm, depending on the real setup.",
 "Do not confuse nondeterminism with randomness. A nondeterministic model need not assign probabilities; it conservatively includes possibilities."),
("Abstraction",
 "Low-level traces contain more detail than a high-level intent cares about, so the compiler needs a disciplined way to forget detail.",
 "An abstraction maps concrete states or traces to observations at a higher semantic level. It may retain final stock and protected-surface deviation while discarding individual step pulses and packet timings.",
 "To compare the executed pocket with the intent, an abstraction extracts residual stock and relevant process violations from the physical trace.",
 "To compare G-code with Controller IR, an abstraction can ignore whitespace and comments while retaining interpreted canonical actions.",
 "Do not confuse abstraction with approximation. Abstraction changes the questions being observed; approximation introduces bounded error within an observation."),
("Refinement",
 "Compilation should make choices without adding behavior that the source forbids.",
 "A concrete artifact refines an abstract specification when every concrete behavior, after the chosen abstraction, is allowed by the abstract meaning. Refinement is directional: the target may be more specific than the source.",
 "Selecting an offset roughing pattern refines the pocket intent if every resulting execution satisfies the pocket specification.",
 "Expanding an abstract traverse into retract, XY move, and descend refines it only if that concrete route satisfies the traverse's free-space contract.",
 "Do not confuse refinement with syntactic expansion. More detailed code can fail to refine the source when it introduces an unsafe route or unsupported controller behavior."),
("Semantic equivalence",
 "Some passes should preserve all relevant behavior rather than merely choose one allowed implementation.",
 "Two artifacts are semantically equivalent when their meanings are equal under a stated observation model. Equivalence is symmetric; refinement is not.",
 "Removing redundant modal words is correct when interpreting both G-code streams from the same initial modal state yields the same canonical trace.",
 "Reordering independent metadata fields in a deterministic job manifest may be equivalent if canonical serialization normalizes the order.",
 "Do not confuse equal final endpoints with equivalent motion. Two paths can share endpoints but cross different stock and fixtures."),
("Bounded refinement",
 "Curve sampling, rounding, and machine following cannot usually preserve ideal geometry exactly.",
 "Bounded refinement relates an output to an input with an explicit error metric and upper bound. The relation must also explain how the bound propagates through later transforms and physical models.",
 "Linearizing an arc can be a bounded refinement when the maximum chordal deviation is proven below the allocated path error.",
 "Rounding coordinates to three decimal places is a bounded refinement only after the induced spatial error and controller interpretation are accounted for.",
 "Do not confuse a sampling interval with an error bound. The interval becomes evidence only through a theorem linking it to maximum deviation."),
("Assumption",
 "No software proof can infer the actual tool diameter, fixture placement, or machine calibration from source code alone.",
 "An assumption is an external proposition on which a claim depends but which the checker does not establish from the artifact being checked. Assumptions must be explicit, versioned, and discharged by runtime checks, calibration records, or operator acceptance.",
 "The no-gouge claim for the pocket assumes that the selected tool and holder models match the hardware installed in the spindle.",
 "A protocol claim may assume a particular firmware version implements the documented command semantics.",
 "Do not confuse an assumption with a hidden default. Hidden defaults make a claim appear stronger than it is; explicit assumptions delimit the theorem."),
],
"1. JavaScript should construct programs, not be the program": [
("Source language",
 "The person authoring the job needs a convenient notation, but convenience does not determine the trusted semantic representation.",
 "A source language is the notation in which users express a program. It may include variables, functions, loops, modules, and syntactic sugar that disappear during compilation.",
 "The user writes a TypeScript-like call to `pocket(...)` and loops over repeated features.",
 "A graphical editor can be another source language that produces the same Plan IR without using JavaScript at all.",
 "Do not confuse source syntax with semantic authority. A pleasant API may elaborate into a much stricter representation."),
("Macro language",
 "Arbitrary JavaScript is useful for generating repeated geometry but dangerous inside trusted compiler passes.",
 "A macro language runs at compile time to construct an inert program representation. Its values and effects are not themselves machine actions unless explicitly reified into the AST or IR.",
 "A loop creates twelve hole-intent nodes; after evaluation, the compiler receives twelve data records rather than a closure that will run during postprocessing.",
 "A parameterized fixture template can construct frame and keep-out artifacts from declared dimensions.",
 "Do not confuse a same-realm `new Function` wrapper with a sandbox. A macro language still needs isolation, deterministic inputs, and resource limits."),
("Abstract syntax tree",
 "After parsing or macro evaluation, the compiler needs a finite, inspectable representation of what was written.",
 "An abstract syntax tree, or AST, records the structural constructs of a program while discarding irrelevant textual details. An assurance-oriented AST should be serializable, finite, and free of arbitrary executable closures.",
 "The pocket AST records dimensions, depth, allowances, tool reference, and source span.",
 "A conditional probe routine AST records both branches and the condition instead of hiding them inside a callback.",
 "Do not confuse an AST with a fully elaborated IR. Names, units, defaults, and frames may still need resolution."),
("Staging",
 "The system must distinguish computations performed while building the job from effects performed by the machine.",
 "Staging separates phases of execution. In this compiler, stage one executes the authoring language to construct a plan; later stages analyze and lower that plan; physical machine actions occur only after certification and authorization.",
 "Computing pocket corner coordinates is a compile-time calculation; moving to the first corner is a runtime machine action.",
 "Reading a CAD file may be a declared compile-time input, while reading the live probe result belongs to machine execution.",
 "Do not confuse a compile-time function call named `move` with physical motion. The API should return an inert action node, not contact the machine."),
("Capability",
 "A macro should receive only the powers it needs, and a target machine should advertise only operations it can realize.",
 "A capability is an explicit authority or supported operation. In the authoring environment it limits access to host services; in Machine IR it describes target features such as arcs, probing, spindle control, or single-axis homing.",
 "The pocket macro receives geometry and plan-construction capabilities but no network or controller connection.",
 "The Z1 profile may advertise supported arc planes and spindle ranges; unsupported cycles must be lowered or rejected.",
 "Do not confuse a capability declaration with evidence that an implementation is correct. It states availability, not semantic conformance."),
],
"2. The intermediate-representation ladder": [
("Intermediate representation",
 "One representation cannot simultaneously preserve user intent, support geometric algorithms, expose machine limits, and encode controller modality clearly.",
 "An intermediate representation, or IR, is a language used between compilation stages. It has explicit syntax, types or schemas, semantics, and legality rules appropriate to one abstraction level.",
 "Intent IR represents the pocket as a feature and tolerance contract; Geometric Toolpath IR represents tool-center curves; Controller IR represents explicit controller operations.",
 "A probe-result IR may bind a measurement value before later elaboration resolves it into a frame update.",
 "Do not confuse an IR with a TypeScript interface alone. The interface is syntax; the IR also needs semantics and legality."),
("IR legality",
 "Each stage should know what unresolved or unsupported constructs are still allowed.",
 "IR legality is the set of well-formedness, typing, capability, and semantic conditions required at a particular level. A pass declares which illegal constructs it eliminates and which legal constructs it may introduce.",
 "Machine IR is illegal if it still contains an unresolved work-frame name or an unsupported abstract pocket operation.",
 "Controller IR is illegal if an arc survives even though the target profile disallows that arc plane.",
 "Do not confuse legality with safety. A legal cut operation can still collide unless geometric claims are checked."),
("Elaboration",
 "Friendly source programs omit details, use names, and rely on defaults; later passes need explicit values.",
 "Elaboration resolves names, units, defaults, frames, overloads, and references to produce a more explicit representation. It should preserve provenance and emit diagnostics rather than silently guessing.",
 "The pocket's `depth: 4` becomes a typed 4 mm value, its tool name becomes a content-addressed tool reference, and its origin becomes an explicit frame.",
 "A probe result name is resolved to a binding whose uncertainty type is known.",
 "Do not confuse elaboration with planning. Elaboration clarifies what was requested; planning chooses how to realize it."),
("Lowering",
 "After elaboration, abstract operations still need progressively more implementation detail.",
 "Lowering transforms a higher-level IR into a more concrete IR by resolving strategy, geometry, machine, controller, or serialization choices. A correct lowering establishes a stated semantic relation between input and output.",
 "A pocket intent lowers to offset curves; abstract traverses lower to concrete clearance motions; Controller IR lowers to G-code blocks.",
 "A probing intent may lower differently for controllers with native probe cycles and controllers requiring primitive moves.",
 "Do not confuse lowering with arbitrary translation. Unsupported semantics must be rejected rather than approximated without a contract."),
("Canonical representation",
 "Planners and postprocessors need a stable shared language that is neither feature-level nor controller-syntax-level.",
 "A canonical representation is a small, explicit semantic waist of machine-independent actions such as select tool, start spindle, traverse, cut, probe, dwell, and pause. It removes controller modality while preserving physical distinctions needed by analysis.",
 "The pocket planner emits `cut(path, feed, intentRef)` rather than `G1` strings.",
 "A controller backend maps canonical `traverse` to a target-specific sequence that may or may not use `G0`.",
 "Do not confuse canonical with universally executable. Canonical actions still require capability resolution for a particular machine."),
],
"3. Composable paths and effectful machine actions": [
("Path",
 "Geometry algorithms need an object that can be joined, reversed, sampled, bounded, and transformed without yet deciding speed or spindle state.",
 "A path is a parameterized geometric curve in a named frame. It describes where a reference point moves as a progress parameter varies, but it does not by itself specify time, process state, or controller interpolation.",
 "The pocket's offset contour is a closed path in the work frame.",
 "A probe approach is a line path even though its execution semantics include possible early termination on contact.",
 "Do not confuse a path with a polyline. Lines, arcs, splines, and analytic curves can all represent paths."),
("Trajectory",
 "Machine feasibility depends on velocity and acceleration, which a geometric path does not contain.",
 "A trajectory is a path together with a time parameterization, or directly a pose as a function of time. It determines velocity, acceleration, jerk, and elapsed time.",
 "The same pocket contour becomes two different trajectories at 300 mm/min and 900 mm/min.",
 "A feed hold changes the time evolution and possibly the physical trace without changing the remaining geometric path.",
 "Do not confuse geometric smoothness with dynamic feasibility. A smooth curve can still require excessive acceleration at a chosen speed."),
("Effect",
 "Selecting a tool, cutting stock, probing, and sending a message change state or may fail; they are not pure geometric functions.",
 "An effect is an observable interaction or state change produced by a computation. CAM effects include machine-state updates, stock removal, sensor results, time, diagnostics, communication, and failure.",
 "`cut` changes pose, time, and stock; `selectTool` changes the active-tool state.",
 "`upload` changes controller storage and can time out with ambiguous completion.",
 "Do not confuse returning an action node with performing the effect. A staged API constructs descriptions first."),
("Indexed command",
 "The type of valid next operations depends on the machine state before them.",
 "An indexed command is parameterized by pre-state and post-state types, conceptually `Cmd<S_before, S_after, A>`. Composition is permitted only when the first command's post-state matches the second command's pre-state. This is closely related to typestate and parameterized monads.",
 "A cut command can require a state indexed as homed, tool-loaded, and spindle-running, then return a state whose pose is at the path end.",
 "A probe command returns both a new state and a typed measurement value used by later commands.",
 "Do not confuse type-level state with physical truth. Runtime checks must establish that the real machine matches the indexed assumption."),
("State token",
 "Advanced type encodings can become cumbersome in TypeScript, but ordering still needs an explicit representation.",
 "A state token is a single-use IR value representing the current version of a mutable resource. Each state-changing operation consumes one token and produces the next. This resembles Static Single Assignment form, where every value has one definition.",
 "The pocket sequence consumes `%s2` to start the spindle and produces `%s3`; the cut cannot be moved before `%s3` without breaking dataflow.",
 "A probe result and the machine-state token can be separate outputs, making later frame updates depend on the exact measurement.",
 "Do not confuse the token with a lock. It is an IR ordering and dependency device, not a runtime synchronization primitive by itself."),
],
"4. Identity, provenance, and an extensible API": [
("Provenance",
 "When a segment fails a check, the user needs to know which source operation, parameter, pass, and imported model produced it.",
 "Provenance is structured lineage connecting an artifact or diagnostic to source spans, input artifacts, pass identities, parameters, and prior derived objects. It should survive lowering and optimization.",
 "A gouge diagnostic on one pocket contour points back to the pocket operation, its finishing allowance, the selected tool, and the planner version.",
 "A modal mismatch in emitted G-code points back to the Controller IR operation and postprocessor rule that generated the block.",
 "Do not confuse provenance with a log message. Provenance is machine-readable data that supports navigation, caching, and certificate dependencies."),
("Content address",
 "Filenames and object identities can be reused, so they are weak foundations for certificates and caches.",
 "A content address is an identifier derived from canonical bytes, usually a cryptographic hash. If content changes, its address changes. References to exact artifacts can therefore be stable across processes and storage locations.",
 "The certificate refers to the SHA-256 of the exact G-code bytes, not merely `pocket.nc`.",
 "The tool model, holder model, machine profile, and work-offset record each have their own content addresses.",
 "Do not confuse a hash with a proof of correctness. It establishes identity and integrity, not semantics."),
("Reproducibility",
 "A certificate is difficult to investigate if the same inputs can silently produce different outputs.",
 "A compilation is reproducible when declared inputs, pass versions, and configuration determine the resulting artifacts. Sources of time, randomness, locale, unordered iteration, network state, or mutable globals must be eliminated or recorded.",
 "Recompiling the pocket with the same source, tool library, machine profile, and compiler version yields the same Plan IR and byte hash.",
 "A randomized optimizer can remain reproducible by recording its seed and solver configuration as inputs.",
 "Do not confuse reproducibility with correctness. A deterministic compiler can reproduce the same bug perfectly."),
("API boundary",
 "An extensible system needs plugins without allowing every plugin to mutate every representation or bypass checkers.",
 "An API boundary is a deliberately narrow interface between components, defined by accepted artifacts, returned artifacts, diagnostics, effects, and versioned semantics. Stable concepts belong in the core; strategies and backends plug in through explicit contracts.",
 "A pocket strategy receives Intent IR and planning context and returns Toolpath IR plus a witness; it does not write directly to the controller.",
 "A viewer receives immutable artifacts and derived render data; it cannot mutate the certified Machine IR.",
 "Do not confuse module boundaries with assurance boundaries. If two packages share mutable objects or privileged host capabilities, the boundary is nominal."),
],
"5. A compiler pass is a claim about two artifacts": [
("Compiler pass",
 "The phrase 'then we transform it' hides the central correctness question: what relationship must hold after the transformation?",
 "A compiler pass is a stage that consumes one or more artifacts and produces new artifacts, diagnostics, and optionally evidence. Its specification includes the semantic relation promised between input and output.",
 "An arc-linearization pass consumes a curve program and emits line segments.",
 "A modal-compression pass consumes explicit Controller IR and omits redundant G-code words.",
 "Do not confuse a pass with a file or function. Several functions may implement one pass, and one function that performs unrelated transformations should be split into separate pass contracts."),
("Pass contract",
 "Without an explicit contract, tests can verify examples but cannot say what the pass is intended to preserve.",
 "A pass contract states legal inputs, produced outputs, the semantic relation, allowed approximation, assumptions, failure behavior, provenance rules, witness format, and independent checker.",
 "The arc pass contract states endpoint preservation, orientation preservation, and a maximum Hausdorff or chordal error.",
 "The serialization contract states deterministic formatting and semantic equivalence after parsing the emitted bytes from a declared initial modal state.",
 "Do not confuse a pass contract with a TypeScript signature. The signature rarely expresses semantic preservation or quantitative error."),
("Witness",
 "A checker may be able to validate a result much more cheaply than it could discover that result from scratch.",
 "A witness is auxiliary data supplied by a producer to help establish a proposition. It can contain correspondences, partitions, solver assignments, interval bounds, or proof steps. The checker validates the witness rather than trusting it.",
 "A pocket planner supplies offset regions and coverage cells showing how its passes cover required-removal areas.",
 "A schedule optimizer supplies operation order, selected orientations, and a lower bound used to report an optimality gap.",
 "Do not confuse a witness with self-asserted metadata. Evidence becomes useful only through a checker whose soundness argument is understood."),
("Translation validation",
 "Proving an entire evolving TypeScript compiler correct may be impractical, but checking each produced result can still be feasible.",
 "Translation validation independently checks a particular pass execution: given input, output, and optional witness, it establishes the required semantic relation for that pair. The pass implementation may remain untrusted.",
 "After arc fitting, a validator proves that each fitted arc stays within the allowed deviation from the original polyline.",
 "After modal compression, a validator interprets both representations and compares canonical traces.",
 "Do not confuse translation validation with running the same algorithm twice. Independence requires a checker with simpler logic or a different method."),
("Checker",
 "The system needs a small component whose acceptance result has a clear meaning.",
 "A checker is a program that validates a structured proposition from artifacts and evidence. Its trusted code and numerical dependencies should be substantially smaller and simpler than the producer it checks.",
 "The pocket-coverage checker validates required-removal cells and protected-region separation.",
 "The runtime checker validates machine identity, firmware profile, work offset, tool, and uploaded byte hash before authorizing execution.",
 "Do not confuse a checker result with unconditional safety. Its theorem is conditional on the proposition, assumptions, and checker model."),
],
"6. Lowering to a machine, a controller, and exact bytes": [
("Machine profile",
 "A machine-independent action cannot be accepted until target limits and capabilities are known.",
 "A machine profile is a versioned artifact describing kinematics, travel, speed and acceleration limits, spindle and tool capabilities, controller dialect, and relevant machine-specific semantics.",
 "The pocket's work-frame path is transformed and checked against the Z1 profile's admissible travel envelope.",
 "A profile for another mill may support canned cycles or a rotary axis and therefore lower the same intent differently.",
 "Do not confuse a profile with marketing specifications. Assurance requires precise units, versions, semantics, and uncertainty where applicable."),
("Modal state",
 "Many G-code words remain active after the block that introduced them.",
 "Modal state is persistent controller interpreter state, such as distance mode, units, active plane, motion mode, feed, spindle speed, and work offset. The meaning of a block depends on both its words and the incoming modal state.",
 "A missing `G90` before the pocket can turn absolute coordinates into incremental moves if stale `G91` is active.",
 "Omitting a repeated feed word is safe only if the intended feed is already active and no intervening block changes it.",
 "Do not confuse source-code locality with modal locality. A harmless-looking block can depend on a command many lines earlier."),
("Postprocessor",
 "Machine IR is still not the byte language accepted by one controller.",
 "A postprocessor is the target-specific compiler backend that lowers machine or canonical operations into a controller dialect and exact serialized bytes. It is responsible for modality, supported interpolation, numeric format, preamble, epilogue, and controller quirks.",
 "The Z1 postprocessor decides how to express pocket arcs, feed values, spindle commands, and safe shutdown.",
 "A GRBL backend may choose different probing and file-execution mechanisms while consuming the same Machine IR.",
 "Do not confuse a postprocessor with a pretty-printer. It performs semantic lowering and must be validated as such."),
("Serialization",
 "The last step from structured blocks to bytes can change numbers, inject text, or reorder content.",
 "Serialization is the deterministic encoding of a structured artifact into exact bytes. It includes numeric rounding, line endings, comments, identifiers, and character encoding; therefore it is a compiler pass with a semantic contract.",
 "The pocket coordinates are rounded and formatted into ASCII blocks whose complete byte sequence receives a content hash.",
 "A JSON job manifest is canonically serialized so key order does not change its content address.",
 "Do not confuse a displayed string with the uploaded bytes. Encoding and line-ending conversion can produce a different artifact."),
("Parse-back validation",
 "The safest way to catch backend mistakes is to interpret what was actually emitted.",
 "Parse-back validation parses serialized controller bytes into a structured representation and compares their interpreted semantics with the pre-serialization artifact under a declared controller model and initial state.",
 "The emitted pocket file is reparsed, and its canonical motion trace is compared with Controller IR.",
 "A comment containing unexpected delimiters is rejected if it changes block structure or parser interpretation.",
 "Do not confuse syntactic round-trip equality with semantic equivalence. Formatting may differ while meaning remains equal, and identical text can mean different things under a different initial state."),
],
"1. Assertions and invariants begin with ordinary questions": [
("Assertion",
 "Engineering reviews contain many statements such as 'the spindle is off here.' They should become explicit propositions.",
 "An assertion is a logical proposition about a program point, artifact, or state. It may be checked statically, at runtime, or used as an assumption in a proof.",
 "Immediately before tool change, assert `spindle = off` and `motion = stopped`.",
 "Before authorizing the pocket, assert that the live work-offset hash equals the certified offset hash.",
 "Do not confuse an assertion with evidence. Writing `assert(safe)` does not establish why `safe` is true."),
("Precondition",
 "A command is meaningful or safe only in certain incoming states.",
 "A precondition is a proposition that must hold before an operation is executed or a theorem is applied. A caller or prior proof is responsible for establishing it.",
 "The pocket cut requires homed axes, a known work transform, the intended tool, a running spindle, and a safe entry state.",
 "A resume command requires a controller state in which a paused job still has a well-defined continuation.",
 "Do not confuse a precondition with a UI checkbox. The proposition must be tied to measured or derived state."),
("Postcondition",
 "After an operation, later reasoning needs to know what changed and what remains true.",
 "A postcondition is a proposition guaranteed after normal termination when the precondition held. It describes state updates and preserved properties.",
 "After one pocket contour, the pose is at the contour end and the stock is the prior stock minus the cutting sweep.",
 "After a successful probe, a measurement value exists within a stated uncertainty interval and may update a frame estimate.",
 "Do not confuse a postcondition with a prediction under failure. Alarm and timeout outcomes need separate branches."),
("Invariant",
 "Some properties must remain true through every command or every iteration, not merely at one endpoint.",
 "An invariant is a proposition true initially and preserved by every relevant transition. Induction proves it by checking the initial state and one preservation step.",
 "Throughout execution, machine pose remains inside the admissible envelope and protected fixtures remain uncut.",
 "Throughout a compiler pipeline, every derived segment retains provenance to at least one source operation.",
 "Do not confuse an invariant with a frequent observation. Preservation must cover all allowed transitions."),
("Weakest precondition",
 "Manually assembling all requirements for a long sequence is error-prone.",
 "The weakest precondition `wp(c, Q)` is the least restrictive proposition that must hold before command `c` to guarantee postcondition `Q` after normal termination. Sequential programs are handled backward: `wp(c1;c2,Q)=wp(c1,wp(c2,Q))`.",
 "Working backward from 'spindle stopped and pose at safe park' derives requirements for the final retract and spindle-stop sequence.",
 "Working backward through a probe-dependent offset update reveals that contact and uncertainty bounds are prerequisites for later cuts.",
 "Do not confuse weakest with easiest to check. The mathematically weakest condition may require sophisticated analysis."),
],
"2. Analyze all possible states, not one simulation": [
("Abstract interpretation",
 "A simulator follows one concrete execution, while a verifier must account for every state allowed by uncertain values and branches.",
 "Abstract interpretation is a framework for soundly executing a program over abstract values that represent sets of concrete states. Transfer functions over-approximate every concrete transition, allowing invariants to be computed without enumerating all executions.",
 "The pocket travel analysis propagates interval boxes for position through every move and proves all possible coordinates remain within limits.",
 "A modal analysis tracks sets of possible distance modes after conditionals or raw commands.",
 "Do not confuse an abstract interpreter with a low-precision simulator. Its purpose is conservative coverage; precision is a secondary engineering choice."),
("Abstract domain",
 "The analyzer needs a chosen vocabulary for uncertainty, such as intervals or finite state sets.",
 "An abstract domain is a structured set of abstract values together with an information order, join operation, and transfer functions. It determines which properties the analysis can express and how much precision it retains.",
 "Position may use axis-aligned intervals, spindle state a finite set `{off,on,unknown}`, and active tool an exact ID or top value.",
 "Stock may use a conservative dexel grid while protocol state uses a finite-state automaton.",
 "Do not confuse one abstract domain with the whole analyzer. Useful analyses often combine several domains in a reduced product."),
("Soundness",
 "A verifier is dangerous if it reports success after silently excluding a possible concrete behavior.",
 "An analysis is sound for a property when every concrete behavior represented by the inputs is contained in the concretization of the computed abstract result. Soundness permits false alarms but forbids false proofs relative to the model.",
 "If abstract position is proven inside travel limits, every concrete position represented by that abstraction is also inside.",
 "If a raw command has unknown modal effects, sound analysis sets affected modal components to unknown rather than assuming no change.",
 "Do not confuse soundness with completeness. A sound analyzer may return unknown for a safe job when its abstraction is too coarse."),
("Join",
 "When control-flow paths merge, the analyzer needs one value representing both possibilities.",
 "A join is the least abstract value that safely contains the information from two predecessor states under the domain's order. It trades precision for a single conservative result.",
 "If one branch selects tool T1 and another T2, the join records `{T1,T2}` or unknown rather than choosing one.",
 "If one path leaves X in `[0,10]` and another in `[8,20]`, an interval join yields `[0,20]`.",
 "Do not confuse join with arithmetic addition. It combines information from alternatives, not physical quantities."),
("Fixed point",
 "Loops, subprograms, retries, and protocol cycles can revisit a state, so analysis must stabilize.",
 "A fixed point of transfer function `F` is a value `x` with `F(x)=x`. Iterative static analysis computes an invariant that is stable under another traversal of the loop or transition system, often using widening to guarantee termination.",
 "A repeated pocket subprogram reaches a fixed abstract modal state after enough iterations.",
 "The upload-retry protocol analysis computes the set of reachable states under any number of retries.",
 "Do not confuse a fixed point of the analysis with a physical equilibrium. It is stability of abstract information under repeated transfer."),
],
"3. Geometry must remain correct near degeneracy": [
("Robust predicate",
 "Topological decisions such as left/right orientation or intersection can flip under tiny floating-point error and corrupt whole contours.",
 "A robust predicate returns the mathematically correct discrete decision for the chosen input model, using filtering, adaptive precision, exact arithmetic, or conservative intervals as needed.",
 "Contour stitching uses robust endpoint and orientation decisions rather than a lossy packed integer key.",
 "Triangle-tool intersection near tangency uses a robust sign test so a nearly touching fixture is not classified inconsistently.",
 "Do not confuse robust predicates with high-precision coordinates everywhere. Often only the discrete sign decision needs exactness."),
("Interval arithmetic",
 "Numerical calculations need a way to carry guaranteed bounds instead of only nominal floating-point values.",
 "Interval arithmetic computes with lower and upper bounds using outward rounding, so the exact real result is enclosed. It is useful for transforms, curve extrema, root isolation, and conservative geometric tests.",
 "An uncertain work transform maps the pocket corner to an interval box checked against machine travel.",
 "An interval evaluation of a spline segment proves its entire coordinate range lies above a fixture plane.",
 "Do not confuse a confidence interval with an arithmetic interval. Interval arithmetic expresses guaranteed enclosure under stated input bounds, not statistical probability."),
("Swept volume",
 "Checking only path points ignores the physical volume occupied by the moving tool and holder between samples.",
 "The swept volume of a solid moving along a trajectory is the union of every transformed placement of that solid over time. Cutting sweeps model material removal; tool-plus-holder sweeps model collision.",
 "The pocket cut removes the sweep of the flute geometry, while the holder sweep must stay disjoint from the stock top and clamps.",
 "A rapid link is safe only when its entire tool-holder sweep avoids current stock and fixtures.",
 "Do not confuse the tool-center curve with the swept volume. A collision can occur even when the centerline is clear."),
("Inner approximation",
 "To prove that material was definitely removed, the model must not claim more removal than the real process guarantees.",
 "An inner approximation is a set known to lie inside the true set. An inner cutting sweep supports required-removal claims because every point in it is guaranteed to have been swept under the model.",
 "The pocket coverage checker subtracts an inner removal estimate from an outer stock estimate to obtain conservative residual stock.",
 "A probe-contact region may have an inner set of positions guaranteed to cause contact.",
 "Do not confuse an inner approximation with a coarse sample. A sample is not guaranteed to fill the space between sampled points."),
("Outer approximation",
 "To prove absence of collision or gouge, the model must conservatively include every place the real object might occupy.",
 "An outer approximation is a set known to contain the true set. Outer tool sweeps, obstacles, and uncertainty regions support safe-separation claims when their intersection is empty.",
 "The pocket no-gouge checker uses an outer tool sweep against the protected target core.",
 "The holder model is dilated by pose and calibration uncertainty before fixture-clearance checking.",
 "Do not confuse an outer approximation with deliberate machining allowance. One bounds model uncertainty; the other is part of manufacturing intent."),
("Configuration space",
 "Motion planning becomes simpler when collision of extended bodies is converted into forbidden positions of a reference point.",
 "Configuration space is the space of machine configurations. Obstacles can be expanded by the reflected moving body so that collision-free motion of a tool assembly becomes point motion avoiding forbidden configuration regions.",
 "For fixed-orientation three-axis linking, fixtures and stock are expanded by the tool-holder shape, and the tool-center path must avoid the result.",
 "With a rotary axis, configuration space includes orientation and may have coupled joint limits.",
 "Do not confuse workspace clearance with configuration-space feasibility. A Cartesian point may be clear while the machine's joints or holder collide."),
],
"4. Approximation needs a quantitative budget": [
("Error bound",
 "A statement that an algorithm is 'accurate' is not composable across passes.",
 "An error bound is a proven upper limit on deviation under a named metric, frame, subject, and set of assumptions. It belongs to a particular transformation or physical uncertainty source.",
 "Arc linearization contributes at most 0.01 mm Hausdorff path error in the work frame.",
 "The tool-radius calibration contributes a separate radial geometry uncertainty of 0.005 mm.",
 "Do not confuse a requested tolerance with an achieved error bound. The bound is evidence about the implementation; the tolerance is a requirement."),
("Error budget",
 "Several individually small errors can combine into an unacceptable final deviation.",
 "An error budget is a structured allocation and composition of error bounds along a claim dependency path. It records compatible metrics, transformations, amplification factors, correlations, and remaining margin.",
 "The pocket wall budget combines CAD approximation, planner offset error, postprocessor rounding, frame uncertainty, tool-radius uncertainty, and following error.",
 "A protocol timing budget combines detection latency, network delay, controller response, and mechanical stopping time for a runtime-assurance monitor.",
 "Do not confuse a budget with a simple sum unless all quantities share a compatible metric and the sum is a justified worst-case composition."),
("Lipschitz bound",
 "A small input error can be amplified by a transformation, so later stages need a way to quantify that amplification.",
 "A Lipschitz bound `L` satisfies `d(f(x),f(y)) <= L d(x,y)`. It allows an incoming uncertainty to be propagated through a transformation and combined with the transformation's own approximation.",
 "A rigid translation has positional amplification 1; a scaled visualization transform may not be relevant to physical geometry at all.",
 "A nonlinear surface parameterization can amplify parameter error near singular regions, requiring a local bound or subdivision.",
 "Do not confuse a Lipschitz constant with a feed rate. It bounds sensitivity of a mapping, not motion speed."),
("Residual bound",
 "After composing all known errors, the system needs to know how much tolerance remains for later stages and physical variation.",
 "A residual bound is the unallocated or unconsumed margin between a requirement and the conservative composed error. A negative residual means the claim cannot be established with the current plan and models.",
 "If the pocket wall tolerance is 0.03 mm and certified compiler plus setup errors total 0.021 mm, 0.009 mm remains for additional bounded effects.",
 "A schedule may reserve runtime timing margin for controller jitter after accounting for planned acceleration limits.",
 "Do not confuse residual margin with evidence that unmodeled effects are small. Unknown effects must be bounded or the claim remains conditional or unknown."),
],
"5. Claims, evidence, checkers, and proof graphs": [
("Claim",
 "Labels such as 'gouge checked' hide the exact proposition and subject.",
 "A claim is a precise proposition about a specific artifact, model, state, or trace. It identifies the subject, property, result status, assumptions, method, evidence, checker, and quantitative bound where applicable.",
 "One claim states that the pocket tool sweep does not penetrate a particular protected-target artifact beyond 0.02 mm.",
 "Another claim states that reparsing the exact byte hash yields a canonical trace equivalent to Controller IR under a named initial modal state.",
 "Do not confuse a claim category with a proposition. 'Travel' or 'gouge' alone is not enough to check or interpret."),
("Evidence",
 "A claim needs supporting data that can be checked independently.",
 "Evidence is structured data used by a checker to establish a claim: interval enclosures, abstract invariants, spatial partitions, path correspondences, solver assignments, proof terms, parse-back traces, or calibration records.",
 "The pocket no-gouge evidence contains conservative spatial cells and separation bounds.",
 "The schedule evidence contains the selected order and verifies every precedence edge and transition cost.",
 "Do not confuse evidence with producer confidence. A heuristic score has meaning only if the claim and checker define how it supports acceptance."),
("Certificate",
 "A complete job depends on many claims and assumptions that must remain connected when artifacts change.",
 "A certificate is a machine-checkable graph of claims, evidence, assumptions, artifact identities, dependencies, and checker identities. It records what is proved, bounded, assumed, simulated, unknown, or refuted.",
 "The pocket bundle certificate links intent coverage, no-gouge, travel, modal equivalence, byte identity, and runtime setup claims.",
 "A probe certificate links measurement uncertainty to the updated frame artifact and every later operation that consumes it.",
 "Do not confuse a certificate with a digital signature. A signature authenticates origin and integrity; the certificate's checkers establish semantic propositions."),
("Trusted computing base",
 "The assurance argument is only as strong as the code and assumptions that must be trusted without further checking.",
 "The trusted computing base, or TCB, is the minimal set of implementations, semantic definitions, numerical kernels, and runtime mechanisms whose correctness is assumed by the assurance claim. The design goal is to keep it small and reviewable.",
 "The pocket planner can remain outside the TCB if a small coverage and collision checker validates its output.",
 "The exact-byte parser, modal interpreter, hash implementation, and runtime authorization monitor may belong to the TCB.",
 "Do not confuse small code size with a small conceptual TCB. External libraries, firmware semantics, and hardware assumptions also count."),
("Proof-carrying CAM",
 "Complex planners are difficult to trust, but their results can carry compact evidence checked by simpler code.",
 "Proof-carrying CAM is the architecture in which an untrusted producer emits a machining artifact together with evidence that it satisfies a defined policy, and an independent consumer-side checker accepts or rejects it.",
 "The pocket planner emits toolpaths plus coverage and clearance witnesses; the job is admitted only if the checker validates them.",
 "A remote optimization service can propose a faster schedule without receiving authority to execute it; the local checker validates feasibility before use.",
 "Do not confuse proof-carrying with theorem-prover-only workflows. Evidence may be intervals, finite checks, or translation-validation witnesses rather than formal proof terms."),
],
"6. The controller protocol is part of the proof": [
("Safety property",
 "Some protocol failures are unacceptable regardless of how long the system runs.",
 "A safety property states that a bad event never occurs. Any violation has a finite counterexample prefix that shows the first point where the property became false.",
 "The controller never begins motion unless the job hash is authorized and the machine is homed.",
 "A tool change never occurs while the spindle is running.",
 "Do not confuse safety with eventual progress. A controller that never moves satisfies many safety properties while being useless."),
("Liveness property",
 "A safe protocol can still deadlock forever after hold, abort, upload, or reconnect.",
 "A liveness property states that some desired event eventually occurs under stated fairness and environment assumptions. It rules out infinite stalling that never violates a local safety condition.",
 "After an accepted abort request, the machine eventually reaches stopped or faulted.",
 "After a valid upload and stable connection, the controller eventually acknowledges success or reports a terminal error.",
 "Do not confuse liveness with a time bound. Real-time deadlines require timed or hybrid models."),
("Model checking",
 "Concurrent protocol state spaces contain interleavings that are easy to miss in manual review.",
 "Model checking exhaustively or symbolically explores a finite or finitely abstracted transition system to establish temporal properties or produce counterexample traces.",
 "A model checker explores upload, timeout, retry, reconnect, authorize, and start interleavings for the pocket job.",
 "It also checks that pause, resume, abort, alarm, and disconnect transitions cannot enter an undefined execution state.",
 "Do not confuse the checked model with the implementation. Conformance between code, firmware, and the model remains a separate obligation."),
("Runtime assurance",
 "Compile-time proofs cannot prevent live state from changing between certification and execution.",
 "Runtime assurance uses a small trusted monitor to check live assumptions and intervene or refuse execution before a safety envelope can be violated. It often supervises a more capable but less trusted component.",
 "Before starting the pocket, the monitor checks machine identity, firmware profile, tool, work offset, alarms, and uploaded hash.",
 "During host-controlled jogging, a monitor can reject commands outside a conservative position and velocity envelope.",
 "Do not confuse monitoring with instantaneous stopping. Detection, communication, controller response, and braking distance must be included."),
("Hash-bound execution",
 "Certifying one file is insufficient if a controller may execute another file with the same name or a modified upload.",
 "Hash-bound execution is a protocol in which authorization and execution refer to the cryptographic identity of exact stored job bytes and relevant configuration artifacts. The controller or trusted bridge confirms that the authorized hash is the executed hash.",
 "The pocket certificate names hash `H`; upload acknowledgement reports `H`; the start command authorizes exactly `H`.",
 "A resume after reconnect verifies that the controller's current job instance still refers to the same hash and state snapshot.",
 "Do not confuse a host-computed hash with end-to-end binding. The storage and execution endpoint must attest to the bytes it will run."),
],
"1. Planning creates candidates; scheduling creates a job": [
("Planner",
 "Intent describes acceptable results but does not select paths.",
 "A planner is a producer that synthesizes one or more candidate geometric or process implementations of an intent. It may be heuristic, search-based, numerical, or learned, but its output remains subject to independent checks.",
 "The pocket planner chooses offset loops, stepdowns, stepover, and entry geometry.",
 "A probing planner chooses approach direction and repeated contacts based on expected fixture geometry.",
 "Do not confuse the planner's success return with proof that the intent is satisfied."),
("Scheduler",
 "A collection of individually valid cuts is not yet an executable job.",
 "A scheduler orders operations and selects orientations, entries, links, tool changes, spindle transitions, and other resource decisions while respecting dependencies and evolving state.",
 "The pocket scheduler orders roughing levels before the finishing wall and floor passes, then inserts links and retracts.",
 "For several holes and pockets, it may group operations by tool while preserving probe-before-cut dependencies.",
 "Do not confuse scheduling with path sorting by nearest endpoint. Stock, precedence, tools, and process state make the problem richer."),
("Entry strategy",
 "A cutting path may be valid after engagement but impossible or unsafe to enter directly.",
 "An entry strategy is the motion and process policy that transitions from free space into a cutting path, such as plunge, ramp, helix, predrilled entry, or edge approach. It has its own feasibility and clearance contract.",
 "The pocket uses a helix whose diameter fits inside current uncut stock and whose ramp angle respects the tool model.",
 "A thin-wall finishing pass may require an edge lead-in to avoid a witness mark.",
 "Do not confuse an entry point with an entry strategy. The approach path and process constraints matter."),
("Evolving stock state",
 "Whether a link or entry is safe depends on material already removed by prior operations.",
 "Evolving stock state is the sequence of conservative stock models after each material-removal operation. Scheduling and collision checking must use the stock corresponding to that point in the job.",
 "A low link across the pocket may be unsafe before roughing but safe after the cavity has been cleared.",
 "Removing the outer profile too early may eliminate support needed for later internal features.",
 "Do not confuse final stock with intermediate stock. Operations that commute as set difference may still differ in process feasibility and workholding."),
],
"2. Feasibility comes before optimization": [
("Feasible set",
 "An optimizer needs to know which candidates are acceptable before it can compare their speed.",
 "The feasible set is the collection of decision assignments satisfying every hard geometric, process, machine, protocol, and precedence constraint. Optimization searches only inside this set.",
 "Pocket schedules are feasible only if roughing precedes finishing, every link is clear in the corresponding stock state, and machine limits are respected.",
 "A feed schedule is feasible only if velocity, acceleration, jerk, contour error, and process limits hold.",
 "Do not confuse a low penalty with feasibility. A safety violation cannot be traded for a slightly shorter cycle time."),
("Hard constraint",
 "Some requirements must never be violated, regardless of objective value.",
 "A hard constraint is a predicate every accepted candidate must satisfy. Violating it removes the candidate from the feasible set rather than merely increasing cost.",
 "Fixture collision, target gouge beyond tolerance, and unsupported controller commands are hard constraints.",
 "A due-date requirement can also be hard in production scheduling, while energy use may remain an objective.",
 "Do not confuse a large penalty coefficient with a hard constraint; finite penalties can still be outweighed."),
("Objective",
 "Several feasible plans may differ in time, tool wear, retract distance, or robustness.",
 "An objective is a numerical or ordered criterion used to rank feasible candidates, such as cycle time, rapid distance, tool changes, predicted wear, or remaining safety margin.",
 "The pocket scheduler minimizes estimated cycle time after feasibility has been established.",
 "A robust planner may lexicographically maximize clearance margin before minimizing distance.",
 "Do not confuse the objective model with measured physical performance. Its accuracy and assumptions need validation."),
("Optimality gap",
 "A solver may find a good plan without proving it is the best possible.",
 "An optimality gap compares a candidate objective value with a valid lower bound on the optimum. It quantifies how far the solution could still be from optimal under the model.",
 "A pocket schedule costing 102 s with a 98 s lower bound has a reported gap of about 4.1 percent.",
 "A heuristic without a lower bound can report feasibility and cost but not a certified optimality gap.",
 "Do not confuse a small model gap with real-world optimality if the cycle-time model omits controller dynamics or process effects."),
("Precedence graph",
 "Many operations must occur in a partial order even when their exact sequence remains free.",
 "A precedence graph is a directed acyclic graph whose edges state that one operation must complete before another begins. It defines legal schedules without forcing a total order.",
 "Pocket roughing precedes wall finishing; probing the datum precedes every cut that uses the resulting frame.",
 "Internal features may precede an outer profile so the workpiece remains supported.",
 "Do not confuse precedence with proximity. The nearest operation may be illegal to execute next."),
],
"3. Linking and feed scheduling are constrained motion problems": [
("Link",
 "Separate cutting paths must be connected by motions that are safe and efficient.",
 "A link is a non-cutting or transition motion between operations or path components. Its specification includes clearance of the tool assembly, machine feasibility, controller semantics, and the stock state at that point.",
 "Between pocket loops, the scheduler may choose a low link through already cleared space or a conservative retract to the safe plane.",
 "Between fixtures, a link planner may route around clamp configuration obstacles.",
 "Do not confuse a rapid command with a link. `G0` is one controller encoding and may have controller-specific geometry."),
("Path parameterization",
 "A geometric path does not determine how fast the machine traverses each point.",
 "Path parameterization is a monotone mapping from time to path progress. It converts a geometric curve into a trajectory and is the variable optimized by time-optimal feed scheduling.",
 "The pocket contour slows near high-curvature corners while maintaining faster motion on long straight segments.",
 "A probe approach uses a low terminal speed near expected contact while moving faster farther away.",
 "Do not confuse parameterization of the curve's geometry with parameterization by physical time."),
("Feed schedule",
 "One programmed feed value can be infeasible or unnecessarily conservative along a complex path.",
 "A feed schedule assigns admissible speed or path-progress rate along a path, respecting axis velocity, acceleration, jerk, contour-error, spindle, engagement, and controller constraints.",
 "The pocket finish pass receives a slower schedule at corners to keep contour error within tolerance.",
 "A long free-space link may use a faster schedule limited by machine acceleration and stopping distance.",
 "Do not confuse commanded feed with achieved feed. Controller lookahead and servo dynamics affect the realized trajectory."),
("Optimal control",
 "Feed scheduling and some linking problems optimize a continuous trajectory under dynamic constraints.",
 "Optimal control chooses time-varying controls or state trajectories to minimize an objective subject to differential equations and state/control constraints. Time-optimal path parameterization is one specialized form.",
 "The pocket trajectory minimizes cycle time while respecting axis velocity, acceleration, jerk, and contour-error bounds.",
 "A runtime safe-stop controller minimizes stopping distance without exceeding machine deceleration limits.",
 "Do not confuse an optimal-control solution with guaranteed controller realization; the backend and machine model must be validated."),
("Robust optimization",
 "A plan optimized only for nominal geometry or timing can fail under small setup and model errors.",
 "Robust optimization searches for decisions that remain feasible over a specified uncertainty set, or explicitly trades nominal performance for margin and sensitivity.",
 "The pocket link is chosen with clearance remaining after tool, frame, and stock uncertainty are applied.",
 "A schedule may prefer a slightly longer route whose cycle time is less sensitive to controller acceleration variance.",
 "Do not confuse robust optimization with vague conservatism. The uncertainty set and robustness criterion must be explicit."),
],
"4. Package boundaries for a TypeScript implementation": [
("Package boundary",
 "The semantic layers should be visible in dependency rules rather than existing only in design documents.",
 "A package boundary is an enforced module interface that limits which representations and effects a component may access. Dependencies should generally point from applications and producers toward stable semantic kernels, not from checkers back into planners.",
 "`@cam/planners` may depend on Intent IR and geometry kernels; `@cam/checker-core` must not depend on planner implementation code.",
 "The Studio UI reads artifacts through a store API rather than importing postprocessor internals.",
 "Do not confuse a monorepo folder with an enforced boundary. Build rules, lint rules, and public APIs must prevent backdoor imports."),
("Trusted core",
 "Assurance becomes unmanageable when every UI, planner, and optimizer must be trusted.",
 "The trusted core is the deliberately small subset implementing semantic definitions, certificate validation, robust numerical primitives, exact parsing, hashing, and runtime admission. It is the software portion of the TCB.",
 "The pocket offset generator is outside the trusted core; its witness is checked by the coverage kernel.",
 "The final G-code parser and modal interpreter are inside or very near the trusted core.",
 "Do not confuse trusted with bug-free. Trusted code deserves stronger review, tests, simple design, and possibly mechanized proofs because errors have greater consequence."),
("Artifact store",
 "Workers, CLI tools, and the browser need to exchange exact immutable values without relying on mutable Redux objects or filenames.",
 "An artifact store is content-addressed storage for canonical bytes plus typed metadata and provenance. It supports deduplication, reproducible caching, dependency graphs, and exact certificate references.",
 "The pocket's source, Plan IR, toolpath, Machine IR, G-code, and certificate are stored as separate hashes linked by derivation records.",
 "A remote checker can fetch only the artifacts named in a claim and return new evidence artifacts.",
 "Do not confuse artifact storage with project-file UX. A project file is a manifest that references artifacts and editor state."),
("Worker boundary",
 "Geometry and checking may be computationally expensive or security-sensitive, especially in a browser application.",
 "A worker boundary separates execution contexts and communicates through serialized, validated messages. It can improve responsiveness and isolation, but only if privileged objects and mutable references do not cross implicitly.",
 "The JavaScript macro evaluator runs in an isolated worker and returns a validated AST artifact.",
 "The robust geometric checker runs in a separate worker or native service and returns evidence plus diagnostics, not direct UI mutations.",
 "Do not confuse a web worker with a complete security sandbox. Origin privileges, imports, resource limits, and message schemas still matter."),
],
"6. Testing and the Dropcut/Z1 counterexamples": [
("Property-based testing",
 "Example tests miss large families of geometric and state combinations.",
 "Property-based testing generates many inputs and checks a general invariant or algebraic law, shrinking failures to small counterexamples.",
 "For every generated path, reversing twice should preserve its chosen path equivalence and endpoint data.",
 "For every legal Controller IR program, serializing and parsing back should preserve interpreted canonical behavior.",
 "Do not confuse a frequently passing property test with proof. Generators and test counts sample the domain."),
("Metamorphic testing",
 "For many CAM problems the exact expected output is hard to compute, but known input transformations imply relations between outputs.",
 "Metamorphic testing applies a transformation with a known semantic effect and checks the corresponding relation between results.",
 "Translating the pocket and fixture together by a vector should translate the planned paths by the same vector without changing relative clearance.",
 "Changing source units from millimeters to equivalent inches should produce semantically equivalent Machine IR after elaboration.",
 "Do not confuse metamorphic relations with arbitrary output similarity. The expected relation must follow from semantics."),
("Differential testing",
 "Independent implementations can expose disagreements even when no hand-written oracle exists.",
 "Differential testing runs the same input through multiple implementations or semantic paths and compares results under a defined equivalence relation.",
 "The optimized modal interpreter is compared with a small reference interpreter on generated G-code.",
 "Two geometry kernels compare contour topology on adversarial nearly coincident inputs.",
 "Do not confuse agreement with correctness. Shared bugs or underspecified equivalence can make implementations agree incorrectly."),
("Fuzzing",
 "Parsers, protocol handlers, and geometry kernels fail on malformed or adversarial inputs that ordinary tests rarely cover.",
 "Fuzzing supplies automatically mutated or generated inputs to discover crashes, hangs, memory errors, invariant violations, or semantic inconsistencies. Coverage guidance helps explore new code paths.",
 "The G-code parser is fuzzed with comments, extreme numbers, modal combinations, and truncated uploads.",
 "The contour stitcher is fuzzed with coincident, nearly coincident, reversed, and very large coordinates.",
 "Do not confuse crash resistance with semantic safety. A parser can accept an unsafe program without crashing."),
("Counterexample",
 "A failed proof or test is most useful when it exposes the smallest trace or input that violates the intended property.",
 "A counterexample is a concrete artifact, state sequence, or geometric configuration demonstrating that a universal claim is false. Good tooling minimizes and preserves it as a regression test.",
 "Two unrelated endpoints separated by exactly the packed-key period form a contour-topology counterexample.",
 "A command line whose first token appears read-only but whose later token causes motion is an authorization counterexample.",
 "Do not confuse one counterexample with a complete diagnosis. It refutes the claim; root-cause analysis explains why."),
],
"7. A staged migration from prototype to assurance": [
("Operating mode",
 "A prototype may be acceptable for preview but not for unattended cutting, so acceptance must depend on context.",
 "An operating mode is a declared usage envelope with required checks, supervision, machine conditions, and permitted actions. Examples include preview, air cut, attended material cut, and unattended production.",
 "The pocket can be previewed with simulation-only geometry evidence, but attended cutting requires stronger final-byte and runtime checks.",
 "Manual jogging may have a separate mode with conservative speed and position envelopes.",
 "Do not confuse a UI toggle with a mode gate. The system must enforce the corresponding policy at command admission."),
("Assurance gate",
 "Capabilities should become available only after the evidence required for their risk level is present.",
 "An assurance gate is a policy that maps claims, assumptions, diagnostics, and runtime state to permitted actions. A missing or unknown critical claim blocks transition to a higher-risk mode.",
 "The Start button for the pocket remains disabled until byte identity, travel, tool, work offset, and controller-state gates pass.",
 "Unattended mode additionally requires liveness monitoring and a validated recovery policy.",
 "Do not confuse absence of errors with passing a gate. Required evidence must be positively present."),
("Migration invariant",
 "Incremental rewrites can accidentally remove existing safety checks while introducing new architecture.",
 "A migration invariant is a property that must remain true through every implementation phase, such as 'the controller cannot receive a command that bypasses authorization' or 'claims never become stronger without stronger evidence.'",
 "While replacing the pocket certificate schema, the system continues to downgrade sampled checks rather than labeling them exact.",
 "While moving controller code into a new package, every command still passes through one fail-closed semantic classifier.",
 "Do not confuse a roadmap milestone with an invariant. Milestones may be incomplete; invariants constrain every intermediate state."),
("Definition of done",
 "A feature can appear complete in the UI while lacking semantics, checking, failure handling, and reproducibility.",
 "A definition of done is an explicit acceptance checklist covering implementation, semantic contract, diagnostics, tests, evidence, documentation, versioning, and operating-mode policy.",
 "Arc fitting is done only when its pass contract, witness, checker, error accounting, property tests, and final-byte validation are integrated.",
 "A new controller command is done only when classification, protocol state, timeout behavior, runtime gating, and firmware compatibility are specified and tested.",
 "Do not confuse code merged with feature complete. Assurance work is part of the feature, not post-release polish."),
],
}
PY
python -m py_compile /mnt/data/z1_textbook_v2_work/term_cards.py
python - <<'PY'
import sys
sys.path.insert(0,'/mnt/data/z1_textbook_v2_work')
from term_cards import TERMS
print('groups',len(TERMS),'terms',sum(len(v) for v in TERMS.values()))
for k,v in TERMS.items(): print(len(v),k)
PY
```

<details><summary>💭 Thinking</summary>

**Audited and revised textbook chapter structure, references, and guided reading content**

</details>

```unknown
bash -lc cd /mnt/data/z1_textbook_v2_work && python /home/oai/skills/pdfs/scripts/md_to_pdf.py Building_a_Certificate_Carrying_CAM_Compiler.md -o Building_a_Certificate_Carrying_CAM_Compiler.pdf --pdf_engine xelatex
```

<details><summary>💭 Thinking</summary>

**Built, audited, corrected, and packaged the textbook PDF deliverables**

</details>

# Certificate-Carrying CAM Compilers — Four-Chapter Edition

The textbook has been rewritten around four large, cumulative chapters:

1. **Meaning Before Motion: What a CAM Compiler Is**
2. **A Language That Can Be Reasoned About**
3. **Passes, Proof Obligations, and Certificates**
4. **Execution, Optimization, and Engineering the Whole System**

The final manuscript contains:

- **47,732 words across 191 pages**
- **91 explicit definitions**
- **31 introductory examples**
- **67 CAM-specific examples**
- **34 extended worked-example sections**
- **15 student checkpoints**
- One pocket-and-probing example developed from intent through IR, compiler passes, certificates, controller execution, and optimization
- Reference IR schemas, checker algorithms, a temporal controller model, selected solutions, glossary, guided reading tracks, and primary references

The second pedagogical pass corrected first-use terminology, expanded acronyms in context, separated concepts that were previously introduced in pairs, added side-by-side semantic and IR examples, distinguished assertion/invariant/assumption/claim categories, and added complete walkthroughs for translation validation, conservative geometry, certificate construction, and runtime identity binding.

The PDF was rendered across all 191 pages. Automated blank-page and edge-clipping checks passed, followed by visual inspection of the front matter, table of contents, chapter openings, equations, code listings, figures, tables, appendices, glossary, and references.

- [Markdown textbook](sandbox:/mnt/data/z1_textbook_v2_deliverables/Certificate_Carrying_CAM_Compilers_Four_Chapter.md)
- [191-page PDF textbook](sandbox:/mnt/data/z1_textbook_v2_deliverables/Certificate_Carrying_CAM_Compilers_Four_Chapter.pdf)
- [Self-contained source bundle with figures and build instructions](sandbox:/mnt/data/z1_textbook_v2_deliverables/Certificate_Carrying_CAM_Compilers_Four_Chapter_Source.zip)
- [SHA-256 checksums](sandbox:/mnt/data/z1_textbook_v2_deliverables/SHA256SUMS.txt)

