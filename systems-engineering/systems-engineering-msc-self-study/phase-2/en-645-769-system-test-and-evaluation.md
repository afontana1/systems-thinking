# EN.645.769 — System Test & Evaluation

**Credits:** 3  
**Recommended self-study duration:** 12 weeks  
**Nominal effort:** 10–13 hours per week  
**Primary phase:** Phase 2 — Core systems-development lifecycle  
**Primary program competencies:** C2, C4, C6, C7, C8, C9, C10, C11, C12

## 1. Course purpose and professional context

Test and evaluation is the disciplined production and interpretation of evidence for decisions. It is not the final activity performed after engineering is complete, and it is not equivalent to running test cases. A systems T&E engineer connects stakeholder intent and requirements to test objectives, articles, configurations, environments, instrumentation, statistics, execution paths, discrepancy processes, analysis, limitations, and readiness recommendations.

This course develops the ability to plan and evaluate evidence for system elements and the total system. The learner receives the controlled design and integration baseline from EN.645.768, audits its testability, creates an integrated T&E strategy, defines critical test parameters and environments, constructs efficient integration and formal test paths, applies statistical methods, uses SIL/HIL and model-based evidence appropriately, executes representative test campaigns using physical, simulated, or supplied data, analyzes discrepancies and corrective actions, plans environmental and operational evaluation, and makes a defensible acceptance and operational-readiness recommendation.

The governing principle is that a test event does not verify a requirement by itself. Verification or validation requires an authoritative claim, an appropriate method, a known article and configuration, a representative or explicitly bounded environment, trustworthy measurement, predefined success criteria, evaluated results, and a conclusion whose uncertainty and limitations are visible.

## 2. Source description and self-study scope

The current Johns Hopkins course description emphasizes test requirements, critical test parameters, analysis of results, remedial action, verification and validation, hardware and software testing, tools and procedures, hardware-software integration, quality assurance, environmental testing, and operational T&E. The Fall 2026 abridged syllabus adds requirements traceability, test objectives/concepts/environments, MBSE and architecture for T&E, statistical techniques, SIL capabilities, informal and formal testing, operational evaluation, deployed systems and systems of systems, and AI and T&E. [JHU-769-COURSE] [JHU-769-SYLLABUS]

This self-study version preserves that scope while making six adaptations:

1. the source group project becomes a controlled end-to-end T&E program with optional peer teamwork and mandatory independent review roles;
2. the five source modules become 12 weeks to support sequential planning, design, execution, analysis, and review;
3. the learner must generate or analyze actual data through a small physical test, software test, simulation, or supplied reference dataset;
4. statistical claims must include assumptions, uncertainty, sample rationale, and analysis source;
5. AI/autonomy and system-of-systems topics are treated as extensions of sound T&E fundamentals, not as substitutes for them;
6. the final output is an evidence-based recommendation, not a binder of procedures.

The course is domain-neutral. DoD T&E guidance is used as a useful public reference for integrated developmental and operational evaluation, but learners should tailor terminology and authority to their own industry.

## 3. Relationship to the curriculum

### Imports from EN.645.768

The course receives:

* system and component specifications;
* stakeholder needs, ConOps, validation scenarios, and mission threads;
* physical architecture, functions, modes, states, and interface definitions;
* technical budgets, margins, uncertainty, and TPMs;
* prototype evidence and technology/risk decisions;
* RAM, HSI, safety, security, resilience, supportability, production, and disposal analyses;
* integration architecture, build sequence, enabling products, and discrepancy workflow;
* V&V plan, verification cross-reference matrix, validation matrix, and planned methods;
* PDR/CDR-style actions, waivers, dissent, residual risks, and configuration manifest.

### New contribution of this course

The course produces:

* a T&E receiving-review and testability audit;
* an integrated T&E strategy or lightweight TEMP;
* a requirement/need-to-objective-to-method-to-event trace model;
* critical test parameter definitions and measurement plans;
* a test architecture containing articles, SIL/HIL, simulations, facilities, instrumentation, data systems, personnel, and environments;
* statistically defensible experiment and sample plans;
* integration, informal, formal, qualification, environmental, reliability, maintainability, cybersecurity, and operational test products;
* test procedures, dry-run evidence, and Test Readiness Review records;
* executed or simulated test data with reproducible analysis;
* discrepancy, root-cause, corrective-action, retest, and closure evidence;
* verification and validation status with uncertainty and limitations;
* an operational effectiveness, suitability, survivability/resilience, and readiness recommendation;
* a final T&E evidence baseline suitable for a professional portfolio.

## 4. Prerequisites and readiness assessment

### Required prior competencies

Before Week 1, the learner should be able to:

* identify the authoritative system/design configuration and trace requirements to architecture and planned evidence;
* distinguish verification, validation, qualification, acceptance, certification, and operational evaluation;
* interpret system modes, interfaces, hazards, failure modes, technical budgets, and integration dependencies;
* use a spreadsheet and Python, R, MATLAB, or equivalent for descriptive statistics and plots;
* reason about distributions, confidence intervals, measurement error, randomization, and sample size at an introductory level;
* write controlled procedures and record objective observations;
* manage discrepancies, actions, risks, and configuration changes;
* communicate technical limitations without converting uncertainty into an unsupported pass/fail claim.

### Readiness diagnostic — 120 minutes

**Part A — evidence audit**

Using the EN.645.768 handoff:

1. identify two requirements with weak or infeasible verification methods;
2. identify two stakeholder expectations with nonrepresentative validation environments;
3. identify one critical interface absent from the integration test sequence;
4. identify one technical budget whose measurement method is undefined;
5. identify one hazard control that requires off-nominal testing;
6. identify one requirement for which analysis should supplement or replace test;
7. identify the authoritative article/build and one configuration ambiguity.

**Part B — statistical task**

Using a supplied sample of response-time data:

* calculate summary statistics and a confidence interval or bootstrap interval;
* identify an outlier and assess whether it is error or valid behavior;
* compare the result with a percentile-based requirement;
* explain why the sample may or may not support a compliance claim.

**Part C — procedure review**

Audit a one-page test procedure for missing prerequisites, configuration, instrumentation, expected results, safety controls, data capture, and discrepancy handling.

### Passing standard and recovery path

Pass with at least 80%, no missed safety-critical issue, and a statistically defensible interpretation. Learners below standard should complete a bridge on V&V distinctions, testability, measurement systems, descriptive statistics, confidence, procedure writing, and configuration-controlled evidence.

## 5. Course learning outcomes

| ID | Measurable course learning outcome | Program competency | Level | Primary evidence |
|---|---|---|:---:|---|
| CLO-1 | Describe and tailor an integrated T&E lifecycle that reduces technical and operational decision risk | C6, C10 | A | T&E strategy |
| CLO-2 | Define test objectives, concepts, critical parameters, methods, and events traceable to requirements and stakeholder expectations | C2, C6 | A | Trace and CTP package |
| CLO-3 | Design a T&E architecture containing articles, models, facilities, SIL/HIL, instrumentation, data, personnel, and environments | C4, C6, C10 | A | T&E architecture |
| CLO-4 | Apply statistical and measurement principles to experiment design, sample rationale, uncertainty, and analysis | C7, C8 | A | Statistical design package |
| CLO-5 | Construct risk-efficient integration execution paths and informal/formal test cases | C4, C6, C9 | A | Integration and test approach |
| CLO-6 | Write and dry-run controlled test procedures with objective success, safety, security, and discrepancy criteria | C6, C10 | A | TRR package |
| CLO-7 | Plan and evaluate hardware, software, hardware-software, cybersecurity, environmental, quality, RAM, and maintainability testing | C5, C6, C9, C11 | A | Specialty T&E package |
| CLO-8 | Execute or simulate tests and maintain trustworthy article, configuration, measurement, and data provenance | C6, C7, C10 | A | Test execution record |
| CLO-9 | Analyze results, discrepancies, root causes, corrective actions, retest, and evidence sufficiency | C6, C7, C9 | A | Analysis and corrective-action report |
| CLO-10 | Develop operational scenarios and evaluate effectiveness, suitability, resilience/survivability, and human-system performance | C6, C9, C11 | A | Operational evaluation |
| CLO-11 | Address T&E challenges for deployed, evolving, system-of-systems, AI-enabled, and autonomous capabilities | C6, C8, C11 | D/A | Advanced T&E supplement |
| CLO-12 | Make and defend an acceptance and operational-readiness recommendation with explicit residual risk and limitations | C10, C12 | A | Final evidence review and oral defense |

## 6. Essential questions

* What decision is each test intended to inform?
* Which claims require test, analysis, inspection, demonstration, simulation, or combined evidence?
* What is a critical test parameter, and why is it critical?
* How representative must the article, software build, operator, environment, load, data, and threat be?
* How do measurement uncertainty, sampling, variability, dependence, and missing data affect conclusions?
* What makes a test path efficient without sacrificing coverage or realism?
* How should informal exploratory testing and formal qualification evidence interact?
* When is a discrepancy a product defect, procedure error, instrumentation issue, requirement ambiguity, or environment mismatch?
* How much evidence is enough to claim compliance or operational fitness?
* How should T&E address evolving software, AI, autonomy, external systems, and operational learning?
* When should a readiness recommendation be conditional, and how should residual risk be communicated?

## 7. Running case and T&E rules

### Case — Autonomous Campus Mobility 2030: Evidence and Readiness

The learner receives the design selected and matured in the prior courses. Worked examples use the reference mixed-fleet architecture, but the learner must test the actual imported design baseline.

### Reference test assets

The course assumes access, physically or virtually, to some combination of:

* a system model and requirements repository;
* dispatch and rider-interface software or executable mock service;
* a vehicle/gateway emulator;
* an operations-console prototype;
* a SIL that can inject timing, network, sensor, state, and failure conditions;
* a small hardware or microcontroller test article, where available;
* environmental and reliability datasets supplied by the course;
* representative operator and rider scenarios;
* Python/R/spreadsheet tools for data generation and analysis.

A learner without physical hardware may use simulation and supplied datasets, but must state which conclusions are limited by article or environment fidelity.

### Controlled fictional thresholds and data rules

* rider request-to-confirmation: no more than 8 seconds at the 95th percentile under the defined peak profile;
* dispatch service availability during service hours: at least 0.995;
* fleet mission availability: at least 0.97;
* accessible boarding: at least 95% of qualified events within 4 minutes;
* degraded mobility service available within 15 minutes of a single-point disruption;
* end-of-route energy reserve: at least 20% under the defined worst credible profile;
* safety- and accessibility-critical discrepancies are never closed solely because they are rare;
* all generated data must include source, seed where applicable, schema, units, time base, missing-data rule, and configuration identifier;
* the learner may not delete adverse runs without documented data-quality rationale.

### Independent review roles

Major products require separate passes from:

1. systems T&E lead;
2. design authority;
3. operator/maintainer and human-factors representative;
4. safety/security/quality representative;
5. statistical or measurement reviewer;
6. independent operational evaluator or customer authority.

### Repository structure

Maintain at minimum:

* `/00-receiving-and-strategy`
* `/01-trace-and-test-objectives`
* `/02-test-architecture-and-environments`
* `/03-statistics-and-measurement`
* `/04-integration-and-procedures`
* `/05-execution-and-data`
* `/06-discrepancies-and-corrective-action`
* `/07-operational-evaluation`
* `/08-evidence-and-reviews`
* `/09-final-recommendation`

## 8. Resource architecture

### Required open-access backbone

* JHU course page and Fall 2026 abridged syllabus. [JHU-769-COURSE] [JHU-769-SYLLABUS]
* NASA Systems Engineering Handbook product integration, product verification, product validation, technical assessment, configuration, and review guidance. [NASA-SEH] [NASA-INTEGRATION] [NASA-VERIFICATION] [NASA-VALIDATION] [NASA-ASSESSMENT] [NASA-CM]
* NASA V&V Plan outline. [NASA-VV-PLAN]
* NIST/SEMATECH Engineering Statistics Handbook for measurement, exploratory analysis, experimental design, process characterization, reliability, and uncertainty. [NIST-ESH]
* DoD Systems Engineering Guidebook and public T&E/TEMP resources for integrated developmental and operational planning. [DOD-SE] [DAU-TEMP]
* NASA Software Engineering and Assurance Handbook testing guidance. [NASA-SWE-TEST]
* DoD guidebooks for cyber DT&E, AI-enabled systems, autonomy, and modeling/simulation in T&E as advanced supplements. [DOD-CYBER-TE] [DOD-AI-TE] [DOD-AUTONOMY-TE] [DOD-MS-TE]

### Resource-use rule

Public guidance supplies methods and examples, not automatic authority. Identify which organization owns acceptance, certification, operational, safety, or security decisions in the learner's domain.

## 9. Tools and working environment

Required capabilities:

* requirements and evidence traceability;
* procedure and test-case control;
* model/SIL or executable system behavior;
* data acquisition or generated test data;
* scripting or statistical analysis;
* plots, tables, and reproducible reports;
* issue/discrepancy/corrective-action tracking;
* article/build/configuration identification;
* presentation and oral-review capture.

Recommended: Git, Python/Jupyter with pandas/scipy/statsmodels or R, spreadsheet software, a requirements/modeling tool, a test framework, and a lightweight issue tracker. Automated tests should preserve logs and machine-readable results rather than only screenshots.

## 10. Assessment and grading model

| Assessment | Weight |
|---|---:|
| Weekly retrieval checks and knowledge tests | 8% |
| Weekly T&E products and quantitative exercises | 27% |
| T&E Strategy and Statistical Design Review | 15% |
| Test Readiness Review and procedure package | 15% |
| Execution, analysis, discrepancy, and operational-evaluation evidence | 20% |
| Final report, readiness recommendation, and oral defense | 15% |

Assignments below 82% should be revised. A revised score may demonstrate mastery even when a historical grade is retained separately.

## 11. Twelve-week course map

| Week | Focus | Primary controlled output | Review or decision |
|---:|---|---|---|
| 1 | Receiving review and integrated T&E strategy | Testability audit and T&E strategy | T&E Receiving Review |
| 2 | Requirements traceability and critical test parameters | Objective/method/CTP trace model | Coverage decision |
| 3 | Test concepts, environments, architecture, and M&S | T&E architecture and environment matrix | Architecture review |
| 4 | Measurement systems, statistics, DOE, and sample rationale | Statistical design package | Statistical Design Review |
| 5 | Integration approach, SIL/HIL, and informal testing | Integration execution path and exploratory cases | Integration-test decision |
| 6 | Formal qualification procedures and readiness | Controlled procedure set | Test Readiness Review |
| 7 | Hardware, software, cyber, automation, and tool evidence | Integrated technical test package | Method/tool qualification decision |
| 8 | Environmental, quality, reliability, maintainability, and safety testing | Specialty T&E package | Qualification coverage review |
| 9 | Test execution, data integrity, discrepancies, and corrective action | Executed campaign and discrepancy baseline | Continue/stop/retest decision |
| 10 | Result analysis, evidence sufficiency, and remedial action | Verification/validation evidence review | Compliance/limitation decision |
| 11 | Operational, deployed, SoS, AI, and autonomy evaluation | Operational evaluation and advanced supplement | Operational suitability decision |
| 12 | Final evidence review and readiness recommendation | Final T&E baseline and oral defense | Proceed/conditional/rework/stop |

## 12. Major assignments and review products

### A. T&E Receiving Review and Strategy

Audit testability, evidence feasibility, article and environment availability, configuration, risks, and decision authorities. Produce an integrated T&E strategy or lightweight TEMP.

### B. Statistical Design Review

Defend measures, instrumentation, uncertainty, data quality, sample rationale, experiment design, analysis method, and decision boundaries before formal procedure development.

### C. Test Readiness Review

Demonstrate that articles, builds, interfaces, facilities, environments, instrumentation, data systems, personnel, procedures, safety/security controls, dry runs, and discrepancy processes are ready.

### D. Verification/Validation Evidence Review

Evaluate whether executed and inherited evidence supports each claim, with uncertainty, anomalies, limitations, waivers, and retest needs.

### E. Final Operational Readiness Recommendation

Integrate technical compliance, stakeholder validation, operational effectiveness, suitability, resilience, safety, security, support, residual risk, and evidence limitations into a decision recommendation.

## 13. Common analytic rubric

| Dimension | Weight | Graduate-level evidence |
|---|---:|---|
| Claim-to-evidence traceability | 20% | Requirements and expectations map to objectives, methods, events, results, and conclusions. |
| Test design and representativeness | 20% | Article, configuration, environment, operators, loads, and threats fit the claim or limitations are explicit. |
| Statistical and measurement rigor | 20% | Measures, uncertainty, samples, assumptions, analysis, and decision rules are defensible. |
| Execution and data integrity | 15% | Procedures, configuration, logs, provenance, anomalies, and deviations are controlled. |
| Discrepancy and corrective-action quality | 10% | Root cause, impact, correction, regression, retest, and closure are evidence based. |
| Evaluation and recommendation | 10% | Conclusions distinguish pass, fail, inconclusive, limitation, waiver, and residual risk. |
| Communication and reproducibility | 5% | Another reviewer can reproduce the analysis and understand the decision.

## 14. Critical mastery criteria

The course cannot be passed if any of the following remains true:

* a safety-, accessibility-, security-, or mission-critical claim lacks an executable evidence path;
* the tested article/build/configuration cannot be identified;
* acceptance criteria are created or changed after results without controlled justification;
* measurement uncertainty or known data-quality defects are hidden;
* adverse or anomalous runs are deleted without traceable rationale;
* formal testing begins without approved readiness, safety, and discrepancy controls;
* a requirement is marked verified merely because a test was executed;
* validation uses a nonrepresentative environment without disclosing the limitation;
* a critical discrepancy is closed without root-cause and retest evidence or authorized risk acceptance;
* statistical conclusions exceed what the sample and design support;
* the final readiness recommendation hides residual risk, waiver, or inconclusive evidence;
* the learner cannot reproduce a key result during oral defense.

## 15. Final capstone and oral defense

The capstone contains:

1. receiving-review and testability audit;
2. T&E strategy/TEMP and governance;
3. traceability model and critical test parameters;
4. article, environment, facility, SIL/HIL, instrumentation, and data architecture;
5. statistical and measurement design;
6. integration and formal procedure set;
7. TRR evidence and actions;
8. executed or simulated data, logs, code, and plots;
9. discrepancies, corrective actions, regression and retest evidence;
10. verification and validation status by claim;
11. environmental, RAM, cybersecurity, human, and operational evaluation;
12. deployed/SoS/AI/autonomy considerations where applicable;
13. final report and readiness recommendation;
14. limitations, waivers, residual risks, and follow-on test plan.

The 25–35 minute oral defense includes a live trace, a data reanalysis, an anomaly challenge, a configuration question, and a request to revise the recommendation after a supplied new fact.

## 16. Portfolio and completion requirements

A professional portfolio should include redacted examples of:

* T&E strategy and TEMP-style content;
* VCRM/evidence matrix and critical parameter definitions;
* statistical design and reproducible notebook;
* SIL/HIL or integration execution path;
* controlled formal procedure and TRR checklist;
* test log, dataset, analysis, discrepancy, and corrective-action record;
* operational scenario and suitability evaluation;
* final evidence report and readiness recommendation;
* oral-defense or review record.

Phase 2 is complete when the learner can connect the original problem and concept decision through design, integration, executed evidence, and an honest readiness recommendation.

## 17. Course maintenance record

Record annually:

* JHU source syllabus date and topic changes;
* NASA, NIST, DoD, and domain-specific guidance versions;
* statistical-library and test-tool versions;
* case data and simulation changes;
* reference-dataset provenance;
* recurring test-design and interpretation errors;
* changes in AI/autonomy/cyber T&E guidance;
* downstream feedback from Phase 3 modeling and analytics work.

---
## Week 1 — Receive the design baseline and create the integrated T&E strategy

**Primary competency emphasis:** C4, C6, C10, C12

### Professional context and essential question

T&E begins by auditing claims, articles, environments, resources, and decision authorities—not by writing procedures. **Essential question:** Is the design baseline testable, and what integrated evidence strategy will reduce the most consequential decision risks?

### Weekly learning outcomes

By the end of the week, the learner will be able to:

* classify imported V&V plans and evidence by authority and maturity
* identify untestable requirements, missing environments, unavailable resources, and configuration ambiguity
* distinguish developmental, qualification, acceptance, operational, and continuous evaluation
* define T&E governance, independence, risk priorities, events, and decision points
* baseline an integrated T&E strategy or lightweight TEMP

### Retrieval and readiness check

1. Identify the authoritative design/build revision.
2. Name one verification and one validation objective.
3. Explain why T&E should begin before implementation is complete.
4. List four reasons a planned test may be infeasible.

### Required study

* **JHU Fall 2026 syllabus** — description, topics, CLOs, and coursework. **Purpose:** Anchor scope and expected outcomes. **Guiding questions:** Which topics extend beyond conventional verification testing?

* **NASA Product Realization** — integration, verification, validation, transition. **Purpose:** Position T&E in the lifecycle. **Guiding questions:** How do evidence products flow between processes?

* **DAU TEMP resource** — purpose and major planning elements. **Purpose:** Structure integrated T&E planning. **Guiding questions:** What decisions, events, resources, and responsibilities should the strategy connect?

### Instructor-style lesson notes

A receiving review verifies that T&E has a stable claim set, known articles, available environments, credible methods, and clear decision authority. It should challenge the design team's assumptions rather than merely accept its V&V matrix.


An integrated strategy sequences evidence from inexpensive and controlled to increasingly representative and operational. It should use analysis, simulation, inspection, demonstration, test, and operational observation where each provides decision value.


Developmental testing informs design and technical risk. Qualification establishes that a design or item can meet defined conditions. Acceptance supports a customer or authority decision about a delivered item. Operational evaluation addresses effectiveness, suitability, and use in realistic contexts.


T&E independence is a matter of decision role and conflict of interest, not organizational labels alone. Define who designs, witnesses, analyzes, approves, and accepts evidence.


### Worked example

The design VCRM proposes a 30-day field trial to prove 0.995 annual availability, but no production-representative fleet or data-retention approval exists. The T&E receiving review marks the method infeasible, creates a combined reliability model/fault-injection/limited field evidence strategy, and identifies the remaining confidence limitation for the acceptance authority.

### Guided practice

1. Classify 15 inherited evidence items as planned, executable, executed, limited, obsolete, or rejected.
2. Identify the top five T&E decision risks.
3. Draft an event sequence from component evidence through operational evaluation.
4. Create a RACI for test design, execution, analysis, approval, and acceptance.

### Independent exercises

* **Foundation:** Classify common T&E activities by purpose and decision authority.

* **Application:** Perform the receiving review on the EN.645.768 handoff.

* **Analysis:** Analyze feasibility and dependency for every critical evidence path.

* **Synthesis:** Create the integrated T&E strategy and review calendar.

* **Stretch:** Build a query listing critical claims with no executable article/environment/method combination.

### Weekly deliverable

Submit the T&E receiving-review report, testability audit, evidence-feasibility register, integrated strategy/TEMP v1, event roadmap, governance/RACI, risk priorities, and controlled baseline manifest.

### Analytic rubric

| Criterion | Weight | Evidence of mastery |
|---|---:|---|

| Testability audit | 30% | Critical gaps in claims, articles, configurations, environments, and resources are found. |

| Strategy integration | 30% | Events, methods, risks, decisions, and lifecycle stages form a coherent sequence. |

| Governance and independence | 20% | Roles and authorities are unambiguous. |

| Configuration and communication | 20% | The baseline and recommendation are controlled and usable. |


### Critical failures

* Critical article/build identity is ambiguous.
* Safety-critical evidence path is infeasible and unflagged.
* Strategy is a list of tests with no decision logic.
* Acceptance authority is undefined.

### Knowledge check

1. How does developmental test differ from operational evaluation?
2. What makes an evidence path executable?
3. Why perform a T&E receiving review?
4. What belongs in a TEMP-style strategy?
5. When is independent evaluation necessary?

### Revision and mastery gate

No critical claim may remain without an executable or explicitly deferred evidence strategy. Deferred claims require decision limits and authority approval.

### Suggested workload

| Activity | Hours |
|---|---:|

| Study | 2.5 |

| Audit | 3.5 |

| Strategy | 3.5 |

| Review/revision | 2.0 |


---

## Week 2 — Trace requirements and stakeholder expectations to objectives, methods, and critical test parameters

**Primary competency emphasis:** C2, C6

### Professional context and essential question

Testing everything is impossible. Critical test parameters focus resources on the measures that drive mission, safety, suitability, and decision risk. **Essential question:** Which parameters and evidence chains are necessary to support each important claim?

### Weekly learning outcomes

By the end of the week, the learner will be able to:

* validate requirement and stakeholder claim testability
* define test objectives, concepts, measures, thresholds, and decision rules
* identify critical test parameters and justify criticality
* map requirements and needs to methods, events, articles, environments, and reports
* detect coverage gaps, duplicate evidence, and weak proxies

### Retrieval and readiness check

1. Distinguish a requirement, test objective, measure, and test case.
2. What makes a parameter critical?
3. Give an example of a weak proxy measure.
4. Why can one event support multiple claims but still need separate criteria?

### Required study

* **NASA Product Verification** — method selection and evidence planning. **Purpose:** Create requirement compliance paths. **Guiding questions:** What inputs and outputs are required for verification?

* **NASA Product Validation** — stakeholder expectations and intended environment. **Purpose:** Create fitness-for-use paths. **Guiding questions:** How should operational scenarios shape validation?

* **NASA V&V Plan Outline** — objectives, methods, articles, environments, responsibilities, and reports. **Purpose:** Structure traceability. **Guiding questions:** Which plan elements make an objective executable?

### Instructor-style lesson notes

A test objective states the decision-relevant purpose, not the activity. 'Measure request latency under peak load to determine compliance with SYS-PERF-014' is better than 'perform a load test.'


A CTP may represent performance, safety, reliability, interoperability, human performance, cybersecurity, or suitability. Criticality should be tied to mission consequence, threshold sensitivity, uncertainty, risk, or lack of alternative evidence.


Every measure needs an operational definition: unit, time base, population, exclusions, aggregation, percentile or probability, data source, and uncertainty treatment.


Coverage tools should distinguish planned evidence, available evidence, evaluated evidence, and accepted evidence. A linked test case does not prove that the requirement has passed.


### Worked example

For accessible boarding, the CTP is elapsed time from a qualified boarding attempt to safe securement and ready-to-move state. The plan defines eligible events, pauses, operator intervention, environmental strata, and a 4-minute threshold for 95% of events. A satisfaction survey is retained as validation evidence but rejected as a proxy for the timing requirement.

### Guided practice

1. Rewrite five activity-style statements as test objectives.
2. Define operational measures for latency, availability, boarding, and degraded recovery.
3. Build a claim-to-objective-to-method trace for one mission thread.
4. Run coverage and weak-proxy queries.

### Independent exercises

* **Foundation:** Classify 20 measures as direct, derived, proxy, leading, or invalid.

* **Application:** Develop the complete objectives and CTP register.

* **Analysis:** Analyze whether thresholds and decision rules match the requirement semantics.

* **Synthesis:** Prioritize test objectives under a 25% resource reduction.

* **Stretch:** Generate an automated coverage heat map by criticality and evidence status.

### Weekly deliverable

Submit requirement/expectation quality findings, test-objective register, CTP definitions, measures dictionary, evidence trace model, coverage report, and prioritization rationale.

### Analytic rubric

| Criterion | Weight | Evidence of mastery |
|---|---:|---|

| Objective and measure quality | 30% | Objectives are decision linked and measures are operationally defined. |

| CTP justification | 25% | Criticality reflects mission, safety, uncertainty, and risk. |

| Traceability and coverage | 30% | Claims connect to methods, events, and evaluated evidence without false completion. |

| Prioritization | 15% | Resource choices preserve critical decision value. |


### Critical failures

* Critical claim uses an undefined measure.
* A proxy is treated as direct compliance evidence.
* Coverage status equates planned test with verified requirement.
* Safety-critical objective is deprioritized without authority.

### Knowledge check

1. What makes a test objective useful?
2. How is a CTP selected?
3. Why define the population for a percentile requirement?
4. What is a proxy measure?
5. How should evidence status be represented?

### Revision and mastery gate

Every critical requirement and expectation must have an objective, method, decision rule, owner, and planned event. Any exception requires explicit disposition.

### Suggested workload

| Activity | Hours |
|---|---:|

| Study | 2.5 |

| Measure/CTP design | 3.5 |

| Trace modeling | 3.5 |

| Review | 2.0 |


---

## Week 3 — Design test concepts, environments, architecture, and model-based evidence

**Primary competency emphasis:** C4, C6, C10

### Professional context and essential question

Testability depends on an architecture of articles, models, facilities, instrumentation, data, people, and environments. **Essential question:** What combination of real and synthetic assets can produce credible evidence at acceptable risk and cost?

### Weekly learning outcomes

By the end of the week, the learner will be able to:

* define test concepts for component, subsystem, system, and operational levels
* specify article, build, environment, operator, load, threat, and data fidelity
* design SIL, HIL, simulation, range, field, and laboratory roles
* identify instrumentation, synchronization, calibration, data, and observability requirements
* plan verification, validation, and accreditation of models used as evidence

### Retrieval and readiness check

1. What is the difference between SIL and HIL?
2. Name four fidelity dimensions.
3. Why is instrumentation part of the test architecture?
4. When can a simulation support verification?

### Required study

* **NASA Product Integration** — enabling products, simulators, emulators, and integration preparation. **Purpose:** Connect test architecture to system build-up. **Guiding questions:** Which assets must be ready before integration?

* **NASA Systems Modeling Handbook** — model support to requirements and V&V. **Purpose:** Use MBSE as T&E source and evidence map. **Guiding questions:** Which model elements should generate or constrain test cases?

* **DoD M&S for T&E Guidebook** — model use, validation, accreditation, and test support. **Purpose:** Bound model-based evidence. **Guiding questions:** What must be known before a model informs a decision?

### Instructor-style lesson notes

A test concept describes the objective, article, environment, stimulus, response, measurement, method, and decision use at a useful level before detailed procedure writing.


Fidelity is multidimensional: functional behavior, timing, interfaces, physical environment, workload, data distribution, threats, operators, and failure behavior. A high-fidelity vehicle model may have low-fidelity operator workload.


Instrumentation can alter the system and create timing or resource effects. Define sensor range, rate, resolution, accuracy, uncertainty, synchronization, storage, health, and calibration.


A model used for decision evidence needs a stated context of use, verification that it was implemented correctly, validation against relevant reality, uncertainty, limitations, and approval by the decision authority.


### Worked example

The SIL accurately emulates dispatch logic and packet delay but omits clock drift and operator workload. It is accepted for interface sequencing and load experiments, conditionally accepted for latency prediction with a correction factor, and rejected for human response and field reliability claims. The accreditation statement names these limits.

### Guided practice

1. Map each CTP to required article and environment fidelity.
2. Sketch the T&E architecture and data flows.
3. Define instrumentation for one timing and one human-performance measure.
4. Write a context-of-use statement for a simulation.

### Independent exercises

* **Foundation:** Compare lab, SIL, HIL, closed-course, and field concepts for five claims.

* **Application:** Develop the T&E architecture and environment matrix.

* **Analysis:** Analyze observability and synchronization gaps.

* **Synthesis:** Create a model VV&A/accreditation plan for one decision use.

* **Stretch:** Generate test skeletons from model states, transitions, requirements, and interfaces.

### Weekly deliverable

Submit T&E architecture, article/build matrix, environment/fidelity matrix, facility/SIL/HIL concept, instrumentation and data-flow design, model context-of-use and VV&A plan, and resource/risk analysis.

### Analytic rubric

| Criterion | Weight | Evidence of mastery |
|---|---:|---|

| Architecture completeness | 25% | Articles, facilities, models, people, data, and environments are integrated. |

| Fidelity and representativeness | 30% | Each claim has justified fidelity and explicit limitations. |

| Measurement/observability | 25% | Instrumentation, synchronization, calibration, and data are credible. |

| Model evidence governance | 20% | Context, VV&A, uncertainty, and accreditation are controlled. |


### Critical failures

* Critical claim assigned to a nonrepresentative asset without limitation.
* Instrumentation range/rate cannot measure the acceptance boundary.
* Simulation result used without context of use or validation.
* Article configuration is not traceable.

### Knowledge check

1. What is test-concept architecture?
2. How do SIL and HIL differ?
3. What is context of use?
4. Why is time synchronization important?
5. Who accredits a model for a decision?

### Revision and mastery gate

No critical test objective may proceed without adequate article, environment, measurement, and data architecture or an approved combined-evidence alternative.

### Suggested workload

| Activity | Hours |
|---|---:|

| Study | 2.5 |

| Architecture design | 4.0 |

| Fidelity/VV&A analysis | 3.0 |

| Review | 2.0 |


---

## Week 4 — Apply measurement science, statistics, DOE, and sample rationale

**Primary competency emphasis:** C7, C8

### Professional context and essential question

Good procedures cannot rescue weak measurement or experimental design. **Essential question:** What data and analysis are required to distinguish compliance, failure, variability, and uncertainty?

### Weekly learning outcomes

By the end of the week, the learner will be able to:

* characterize measurement range, resolution, bias, repeatability, reproducibility, and uncertainty
* select populations, samples, randomization, blocking, replication, and controls
* choose descriptive, interval, hypothesis, regression, DOE, reliability, or nonparametric methods
* develop sample-size or precision rationale
* predeclare data-quality, missing-data, outlier, stopping, and decision rules

### Retrieval and readiness check

1. Distinguish accuracy and precision.
2. Why randomize test order?
3. What is statistical power?
4. Why is a confidence interval not the probability that the true value lies in the observed interval?

### Required study

* **NIST Engineering Statistics Handbook** — measurement process characterization and uncertainty. **Purpose:** Assess whether the measurement can support the decision. **Guiding questions:** Which sources dominate uncertainty?

* **NIST DOE** — experimental objectives, factors, responses, randomization, blocking, and sequential experimentation. **Purpose:** Design efficient tests. **Guiding questions:** What threats are controlled by randomization and blocking?

* **NIST Exploratory Data Analysis** — graphical and assumption-checking methods. **Purpose:** Detect structure and anomalies before formal claims. **Guiding questions:** Which plots reveal distribution, drift, and outliers?

### Instructor-style lesson notes

Start with the estimand: the quantity the decision needs. Define population, conditions, aggregation, and acceptable precision before selecting a statistical test.


Measurement-system analysis separates system variation from instrument, operator, calibration, and process variation. If measurement uncertainty is large relative to margin, improve measurement or change the decision rule.


Sample size can be justified by desired interval width, detectable effect, reliability demonstration, percentile precision, or resource-constrained risk analysis. Avoid ritual numbers such as 30 without rationale.


Preanalysis rules protect credibility. Define exclusions, outlier investigation, missing data, transformations, multiple comparisons, interim looks, and stop criteria before execution.


### Worked example

For the 95th-percentile latency threshold, 20 nominal runs are inadequate to characterize the tail. The learner uses pilot data and bootstrap simulation to compare sample sizes, blocks by network condition, randomizes load order, and sets a target interval around the percentile. A separate extreme-condition test addresses worst credible behavior rather than mixing it into the nominal population.

### Guided practice

1. Audit the measurement capability for one CTP.
2. Use pilot data to create EDA plots and identify drift or outliers.
3. Design a small factorial or blocked experiment.
4. Write a sample and analysis rationale.

### Independent exercises

* **Foundation:** Calculate measurement uncertainty for a supplied chain.

* **Application:** Develop the statistical design for three critical objectives.

* **Analysis:** Compare parametric, nonparametric, bootstrap, and simulation approaches.

* **Synthesis:** Pre-register the analysis and decision rules.

* **Stretch:** Run a simulation study showing false-pass/false-fail risk under candidate sample plans.

### Weekly deliverable

Submit measurement-system assessment, data dictionary, statistical analysis plan, DOE/sample rationale, preanalysis rules, pilot-data EDA, code/notebook, and Statistical Design Review record.

### Analytic rubric

| Criterion | Weight | Evidence of mastery |
|---|---:|---|

| Measurement adequacy | 25% | Range, resolution, calibration, repeatability, bias, and uncertainty support the claim. |

| Experimental design | 30% | Population, factors, randomization, blocking, replication, and controls are justified. |

| Statistical method | 25% | Method and assumptions fit the estimand and data. |

| Reproducibility/decision rules | 20% | Code, preanalysis, and error risks are explicit. |


### Critical failures

* Measurement uncertainty exceeds decision margin and is ignored.
* Sample size has no rationale.
* Outlier/exclusion rule invented after results.
* Dependent observations analyzed as independent.

### Knowledge check

1. What is an estimand?
2. Why use blocking?
3. How is measurement uncertainty different from system variability?
4. What is a false pass?
5. When is a nonparametric or bootstrap method useful?

### Revision and mastery gate

The statistical design must be approved before formal execution. Any post hoc change is recorded, justified, and analyzed for impact.

### Suggested workload

| Activity | Hours |
|---|---:|

| Study | 3.0 |

| Measurement/EDA | 3.0 |

| DOE/sample design | 3.5 |

| Review/revision | 2.0 |


---

## Week 5 — Construct the integration test approach, SIL/HIL paths, and informal tests

**Primary competency emphasis:** C4, C6, C9

### Professional context and essential question

Informal and integration testing should expose defects early, cheaply, and diagnostically while preserving the path to formal evidence. **Essential question:** How should the system be built and exercised so that interface and behavior defects are localized before qualification?

### Weekly learning outcomes

By the end of the week, the learner will be able to:

* construct integration execution paths from architecture and dependencies
* select risk-first, thread-based, incremental, bottom-up, or hybrid sequencing
* write interface, state, negative, boundary, fault-injection, and exploratory test cases
* use SIL/HIL, stubs, drivers, emulators, and observability to localize defects
* define promotion criteria from informal to formal evidence

### Retrieval and readiness check

1. What is the purpose of informal testing?
2. How does an integration test differ from a component test?
3. What is a test oracle?
4. Why preserve failed exploratory tests?

### Required study

* **NASA Product Integration** — sequence, interface checks, enabling products, and outputs. **Purpose:** Construct the integration approach. **Guiding questions:** How are discrepancies reported and resolved?

* **NASA Software testing guidance** — dynamic testing, simulated and actual hardware, safety functions, and coverage. **Purpose:** Integrate software and system evidence. **Guiding questions:** Which failures and recovery mechanisms should be prioritized?

* **JHU syllabus topics** — SIL, informal/formal testing, and execution paths. **Purpose:** Maintain source alignment. **Guiding questions:** What changes when evidence becomes formal?

### Instructor-style lesson notes

Integration tests evaluate interactions, assumptions, timing, states, data semantics, error handling, and recovery. A component can be correct in isolation and wrong in system context.


Exploratory testing is structured learning, not random clicking. Use charters tied to risks, record configurations and observations, and convert consequential discoveries into repeatable regression cases.


A test oracle defines expected behavior. It may come from a requirement, reference model, invariant, independent implementation, manual calculation, or approved operational rule. An oracle that duplicates the same defect can create false confidence.


Promotion to formal testing requires stable configuration, reviewed expected result, adequate instrumentation, controlled procedure, and resolved blockers. Informal success alone is not qualification evidence.


### Worked example

A state-transition explorer injects duplicate assignments, delayed vehicle acknowledgment, network partition, and operator override. It finds a race condition that creates two active assignments. The defect becomes a formal regression test, the interface/state model is corrected, and the build cannot advance until repeated evidence passes.

### Guided practice

1. Build an integration dependency and execution graph.
2. Write positive, negative, boundary, and fault-injection cases for one interface.
3. Run a short exploratory charter in the SIL.
4. Convert one finding into a controlled regression test.

### Independent exercises

* **Foundation:** Classify 20 tests by level, purpose, and evidence status.

* **Application:** Develop integration paths and informal test catalog.

* **Analysis:** Analyze observability and fault-localization quality.

* **Synthesis:** Define promotion and regression criteria.

* **Stretch:** Automate execution of one mission-thread suite with machine-readable logs.

### Weekly deliverable

Submit integration test approach, execution paths, SIL/HIL configuration, exploratory charters and logs, informal test cases, defect/regression evidence, promotion criteria, and updated risk/traceability.

### Analytic rubric

| Criterion | Weight | Evidence of mastery |
|---|---:|---|

| Integration logic | 30% | Paths follow dependencies, mission threads, and risk. |

| Test-case quality | 25% | Cases cover normal, boundary, negative, interface, and recovery behavior. |

| Diagnostic value | 25% | Oracles, observability, and fault localization are strong. |

| Evidence promotion | 20% | Informal findings become controlled regression and formal readiness evidence. |


### Critical failures

* Critical interface absent from integration path.
* Expected result has no authoritative oracle.
* Exploratory failure is discarded.
* Informal result is labeled qualification evidence.

### Knowledge check

1. What is a test oracle?
2. Why use negative testing?
3. What is exploratory testing?
4. When should a test be automated?
5. What is required to promote evidence to formal status?

### Revision and mastery gate

All critical interface and state paths must have at least one controlled integration test and discrepancy route before formal qualification planning proceeds.

### Suggested workload

| Activity | Hours |
|---|---:|

| Study | 2.5 |

| Path/case design | 3.5 |

| Execution | 3.0 |

| Regression/revision | 2.0 |


---

## Week 6 — Write formal qualification procedures and conduct the Test Readiness Review

**Primary competency emphasis:** C6, C10, C12

### Professional context and essential question

Formal tests require controlled articles, procedures, environments, measurements, safety, and decision rules. **Essential question:** Is the test system ready to produce trustworthy evidence without unacceptable risk?

### Weekly learning outcomes

By the end of the week, the learner will be able to:

* write controlled procedures with prerequisites, steps, expected results, data, and stop criteria
* define test article/build, environment, instrumentation, calibration, personnel, and safety/security controls
* conduct dry runs and procedure validation
* prepare entrance/success criteria and evidence for TRR
* record actions, waivers, deviations, and readiness decisions

### Retrieval and readiness check

1. What makes a procedure repeatable?
2. Distinguish a test step from an acceptance criterion.
3. Why perform a dry run?
4. What conditions require stopping a test?

### Required study

* **NASA V&V Plan Outline** — procedure, environment, responsibility, data, and reporting content. **Purpose:** Translate plans into execution. **Guiding questions:** What must be controlled before a test?

* **NASA review guidance** — TRR purpose and readiness evidence. **Purpose:** Prepare the review. **Guiding questions:** Which safety, configuration, and facility questions should the board ask?

* **NASA configuration management** — article and evidence baseline integrity. **Purpose:** Prevent configuration ambiguity. **Guiding questions:** How are deviations and as-run status recorded?

### Instructor-style lesson notes

A formal procedure should identify objective, references, article/build, prerequisites, environment, equipment, calibration, safety/security, roles, setup, step/action, expected result, data capture, pass/fail logic, anomalies, stop/abort, restoration, and approvals.


Procedure validation is a test of the test. Dry runs reveal ambiguity, unsafe sequencing, unavailable data, unrealistic timing, and operator interpretation before valuable articles or formal evidence are at risk.


TRR does not certify that the system will pass. It decides whether the test is ready and worthwhile. The board may approve, conditionally approve with limits, defer, or reject.


As-run records matter more than planned procedures when results are evaluated. Record deviations, timestamps, configurations, calibrations, personnel, environmental conditions, and anomalies.


### Worked example

A failover procedure initially commands a service shutdown before confirming that the backup has current state. The dry run exposes potential data loss. The procedure and design are revised to establish synchronization, verify readiness, transfer authority, and then isolate the primary. The TRR action remains open until the sequence passes three dry runs.

### Guided practice

1. Annotate a defective procedure.
2. Write one formal procedure and data sheet.
3. Conduct a tabletop or executable dry run.
4. Build and present the TRR evidence matrix.

### Independent exercises

* **Foundation:** Correct a supplied unsafe and ambiguous procedure.

* **Application:** Develop formal procedures for three critical objectives.

* **Analysis:** Analyze human error and measurement risks in the procedures.

* **Synthesis:** Conduct the TRR and disposition findings.

* **Stretch:** Generate an as-run record template from procedure source.

### Weekly deliverable

Submit controlled procedure set, data sheets, dry-run records, safety/security assessment, equipment/calibration status, personnel qualifications, TRR evidence matrix, review minutes/actions, and readiness decision.

### Analytic rubric

| Criterion | Weight | Evidence of mastery |
|---|---:|---|

| Procedure completeness | 30% | Steps, expected results, data, criteria, and controls are executable. |

| Safety/configuration/readiness | 30% | Articles, environments, equipment, people, and hazards are controlled. |

| Dry-run evidence | 20% | Procedure defects are found and corrected. |

| Review quality | 20% | TRR decision and actions are evidence based. |


### Critical failures

* Formal test starts without approved article/configuration.
* Stop/abort criteria absent for hazardous test.
* Calibration or synchronization status unknown.
* TRR action closed without evidence.

### Knowledge check

1. What is the purpose of TRR?
2. Why validate the procedure?
3. What belongs in an as-run record?
4. How should a test deviation be handled?
5. When is conditional readiness appropriate?

### Revision and mastery gate

No formal execution may begin until all red TRR criteria are closed or an authorized conditional limit is documented. Procedures and configuration are baselined after review.

### Suggested workload

| Activity | Hours |
|---|---:|

| Study | 2.5 |

| Procedure writing | 4.0 |

| Dry run | 2.5 |

| TRR/revision | 2.5 |


---

## Week 7 — Integrate hardware, software, cybersecurity, automation, and test-tool evidence

**Primary competency emphasis:** C5, C6, C9, C11

### Professional context and essential question

Different system elements fail and reveal defects differently, but their evidence must support one system claim. **Essential question:** How should hardware, software, cyber, and automated test methods combine without creating blind spots or false confidence?

### Weekly learning outcomes

By the end of the week, the learner will be able to:

* distinguish hardware and software failure/test characteristics
* plan unit, component, interface, integration, system, regression, stress, and fault-injection evidence
* evaluate test automation, tool qualification, coverage, and oracle risk
* integrate cybersecurity test objectives with mission and resilience consequences
* combine evidence across hardware, software, humans, and operations

### Retrieval and readiness check

1. Why does software not wear out like hardware?
2. What is regression testing?
3. What risk is introduced by test automation?
4. How is a cyber test objective linked to mission impact?

### Required study

* **NASA Software Engineering and Assurance Handbook** — testing, simulated/actual hardware, safety functions, and coverage. **Purpose:** Plan software and system tests. **Guiding questions:** Which tests address nominal and off-nominal behavior?

* **DoD Cyber DT&E Guidebook** — mission-based cyber test and evaluation. **Purpose:** Integrate cyber threats and system consequences. **Guiding questions:** How should cyber events influence technical and operational tests?

* **NASA Product Verification** — combined methods and evidence evaluation. **Purpose:** Integrate evidence types. **Guiding questions:** When can one event support multiple verification methods?

### Instructor-style lesson notes

Hardware tests often characterize physical variability, stress, degradation, tolerances, and failure. Software tests explore enormous state/input spaces, logic, concurrency, interfaces, configuration, and change. System tests must address interactions and emergent behavior.


Automation improves repeatability and coverage but can automate wrong expectations, conceal environment differences, create flaky results, and depend on unqualified tools. Validate the harness and preserve raw evidence.


Coverage is evidence about exercised structure or behavior, not proof of correctness. Requirement, state, path, interface, hazard, and code coverage answer different questions.


Cyber T&E should connect threat actions to mission effects, detection, response, recovery, and residual risk. Vulnerability discovery alone does not evaluate operational resilience.


### Worked example

An automated suite reports 100% pass after an interface schema change because the test harness silently ignores unknown fields. A manual packet inspection reveals missing accessibility-status data. The harness is corrected to fail on schema drift, prior results are invalidated, and interface regression coverage is expanded.

### Guided practice

1. Map hardware and software evidence for one system requirement.
2. Audit an automated test oracle and harness.
3. Create a cyber mission-thread test objective.
4. Define regression selection after an interface change.

### Independent exercises

* **Foundation:** Classify tests by element, level, and failure mechanism.

* **Application:** Build an integrated technical test package for the case.

* **Analysis:** Analyze tool/oracle qualification and flaky-test risk.

* **Synthesis:** Conduct a cyber-resilience tabletop or controlled fault injection.

* **Stretch:** Create a coverage model linking requirements, states, hazards, interfaces, and automated tests.

### Weekly deliverable

Submit hardware/software test comparison, automated suite or detailed design, tool/oracle validation, coverage report, cyber mission-based test plan/results, regression strategy, and integrated evidence map.

### Analytic rubric

| Criterion | Weight | Evidence of mastery |
|---|---:|---|

| Cross-domain test design | 25% | Hardware, software, interfaces, humans, and mission behavior are coordinated. |

| Automation/tool credibility | 25% | Harnesses, oracles, versions, and limitations are validated. |

| Cyber mission relevance | 25% | Threats connect to mission effect, resilience, and evidence. |

| Coverage and regression | 25% | Coverage is multidimensional and changes trigger appropriate retest. |


### Critical failures

* Automated results accepted without validating the harness.
* Cyber test has no mission consequence or recovery objective.
* Coverage metric is treated as proof of correctness.
* Configuration change receives no regression impact analysis.

### Knowledge check

1. How do hardware and software testing differ?
2. What is an oracle problem?
3. Why can automation create false confidence?
4. What does coverage measure?
5. How is cyber T&E mission based?

### Revision and mastery gate

All critical automated evidence requires a validated oracle/harness and retained raw logs. Critical changes must trigger documented regression selection.

### Suggested workload

| Activity | Hours |
|---|---:|

| Study | 2.5 |

| Test/tool design | 3.5 |

| Execution/tabletop | 3.0 |

| Analysis/revision | 2.0 |


---

## Week 8 — Plan environmental, quality, reliability, maintainability, safety, and acceptance testing

**Primary competency emphasis:** C6, C9, C11

### Professional context and essential question

Qualification must show that the system can withstand and be supported in its intended conditions, not merely operate in a comfortable lab. **Essential question:** Which stresses, durations, sequences, maintenance tasks, and quality controls are necessary to support lifecycle confidence?

### Weekly learning outcomes

By the end of the week, the learner will be able to:

* derive environmental and stress profiles from intended use and transportation/storage
* plan qualification, acceptance, screening, reliability growth/demonstration, and maintainability tests
* define safety and quality-assurance witnesses, controls, and records
* address combined environments, sequencing, cumulative damage, and representativeness
* integrate failures into FRACAS and design/test updates

### Retrieval and readiness check

1. Distinguish qualification and acceptance testing.
2. What is reliability growth?
3. Why can combined environments matter?
4. What makes a maintainability demonstration representative?

### Required study

* **NASA Reliability and Maintainability** — R&M planning, FMEA, maintainability, supportability, and demonstrations. **Purpose:** Plan RAM evidence. **Guiding questions:** How should failures drive corrective action and growth?

* **NASA SE Handbook** — environmental, quality, supportability, and product realization references. **Purpose:** Connect lifecycle conditions to evidence. **Guiding questions:** Which enabling systems and controls are needed?

* **DoD Engineering of Defense Systems Guidebook** — R&M test, demonstration, FRACAS, and integrated planning sections. **Purpose:** Use a public lifecycle example. **Guiding questions:** How are R&M tests coordinated with other evidence?

### Instructor-style lesson notes

Environmental requirements should derive from operational, storage, transport, maintenance, cleaning, weather, electromagnetic, network, and human-use profiles. Define levels, durations, rates, combinations, sequence, margins, and article representativeness.


Qualification generally establishes that the design can withstand specified conditions; acceptance checks delivered items for workmanship or required characteristics. Screening and process control have different purposes and decision risks.


Reliability evidence may combine growth testing, demonstration, field data, similarity, analysis, and fault injection. Maintainability tests use representative personnel, tools, procedures, access, faults, and restoration verification.


FRACAS connects failures to analysis, corrective action, effectiveness verification, and recurrence prevention. Closing a ticket is not closing a failure mode.


### Worked example

A rain test passes water ingress but reveals that wet-glove interaction doubles operator recovery time. The result affects environmental, usability, and maintainability claims. The interface and procedure are revised, the environmental test is repeated with human tasks, and the combined evidence replaces the narrow pass statement.

### Guided practice

1. Create an environment profile and test matrix.
2. Plan one reliability and one maintainability demonstration.
3. Define qualification versus acceptance criteria for one item.
4. Trace a failure through FRACAS and retest.

### Independent exercises

* **Foundation:** Match stress/test types to lifecycle conditions.

* **Application:** Develop the specialty T&E package for the case.

* **Analysis:** Analyze sample, duration, combined-environment, and article choices.

* **Synthesis:** Design quality witness and FRACAS processes.

* **Stretch:** Integrate environmental, RAM, human, and cyber events to reduce duplicate testing.

### Weekly deliverable

Submit environmental profile and test matrix, qualification/acceptance strategy, reliability and maintainability test plans, safety/quality controls, FRACAS workflow, integrated-event rationale, and residual evidence limits.

### Analytic rubric

| Criterion | Weight | Evidence of mastery |
|---|---:|---|

| Environment derivation | 25% | Profiles trace to intended use, storage, transport, and credible stress. |

| RAM/maintainability rigor | 25% | Objectives, duration/sample, faults, people, tools, and recovery are credible. |

| Qualification/quality control | 25% | Purpose, article, witness, and acceptance distinctions are correct. |

| Integration and corrective action | 25% | Events share evidence appropriately and failures drive controlled correction/retest. |


### Critical failures

* Critical environment omitted.
* Qualification and acceptance purposes conflated.
* Reliability claim has no time/profile or sample rationale.
* Failure closed without corrective-action verification.

### Knowledge check

1. How do qualification and acceptance differ?
2. What is FRACAS?
3. Why test combined environments?
4. What is reliability growth?
5. What makes a maintenance test valid?

### Revision and mastery gate

All design-driving environments and critical maintenance/reliability claims require a planned evidence path. Known combined effects must be addressed or explicitly accepted as limitations.

### Suggested workload

| Activity | Hours |
|---|---:|

| Study | 2.5 |

| Specialty plans | 4.0 |

| Integration/FRACAS | 3.0 |

| Review | 2.0 |


---

## Week 9 — Execute tests and control data, deviations, discrepancies, and corrective action

**Primary competency emphasis:** C6, C7, C9, C10

### Professional context and essential question

Execution converts plans into evidence, but only if as-run conditions and anomalies are preserved. **Essential question:** How will the team know exactly what happened, whether the data are trustworthy, and what action is required?

### Weekly learning outcomes

By the end of the week, the learner will be able to:

* execute controlled procedures or realistic simulations
* record article, build, environment, instrument, personnel, time, and deviations
* protect data provenance, integrity, retention, and access
* classify discrepancies and determine immediate continue/stop/retest action
* perform root-cause analysis and manage corrective action and regression

### Retrieval and readiness check

1. What is the difference between an anomaly and a discrepancy?
2. Why preserve raw data?
3. When should a test stop?
4. What information is needed to reproduce an as-run configuration?

### Required study

* **NASA Product Verification** — execution, data collection, analysis, and reporting. **Purpose:** Control formal evidence. **Guiding questions:** How are deviations and results evaluated?

* **NASA Configuration Management** — as-built/as-tested identity and change control. **Purpose:** Preserve test article integrity. **Guiding questions:** What records establish the tested configuration?

* **NIST Exploratory Data Analysis** — plots and diagnostics. **Purpose:** Detect drift, outliers, and structure during execution. **Guiding questions:** Which plots should be reviewed before accepting a run?

### Instructor-style lesson notes

Execution discipline requires a contemporaneous record. Record planned step, actual action, actual result, timestamps, deviations, environmental conditions, configuration, operator, instrument health, and data identifiers.


Data integrity includes provenance, immutable raw data, controlled transformations, schema, units, time base, calibration, missingness, access, retention, and reproducible analysis. Derived datasets should never replace raw source.


Immediate discrepancy triage distinguishes safety stop, test-setup error, instrument failure, procedure defect, requirement ambiguity, product defect, environment mismatch, and expected variability. The initial classification may change after analysis.


Corrective action requires containment, root cause, impact scope, correction, verification of correction, regression, and closure authority. A retest of the same step may be insufficient if the defect affected prior evidence.


### Worked example

During latency testing, three extreme values coincide with time-synchronization loss. Raw logs reveal that the system still responded quickly but the measurement clocks diverged. The runs are invalid for latency compliance, valid as evidence of instrumentation weakness, and trigger correction and a repeat. They are not deleted from the record.

### Guided practice

1. Execute or simulate one formal procedure.
2. Create the as-run log and data manifest.
3. Triage three injected anomalies.
4. Perform a root-cause and regression-impact analysis.

### Independent exercises

* **Foundation:** Practice continue/stop decisions on ten scenarios.

* **Application:** Execute at least three controlled test campaigns or supplied-data analyses.

* **Analysis:** Analyze data integrity and configuration provenance.

* **Synthesis:** Open, investigate, correct, retest, and close one discrepancy.

* **Stretch:** Automate a test-to-data-to-analysis-to-discrepancy provenance report.

### Weekly deliverable

Submit as-run procedures, configuration records, raw/derived data manifests, execution logs, EDA, anomaly/discrepancy records, root-cause and corrective-action evidence, regression/retest results, and updated trace status.

### Analytic rubric

| Criterion | Weight | Evidence of mastery |
|---|---:|---|

| Execution discipline | 25% | As-run conditions, deviations, and observations are complete. |

| Data integrity | 25% | Raw and derived data are traceable, controlled, and reproducible. |

| Discrepancy analysis | 25% | Classification, root cause, scope, and action are evidence based. |

| Corrective action/retest | 25% | Correction and regression are verified before closure. |


### Critical failures

* Adverse run deleted or overwritten.
* Test article/configuration cannot be reconstructed.
* Safety stop criterion ignored.
* Critical discrepancy closed without root cause or retest.

### Knowledge check

1. What belongs in an as-run record?
2. Why keep invalid runs?
3. How does anomaly differ from discrepancy?
4. What is containment?
5. When must earlier evidence be invalidated?

### Revision and mastery gate

At least one executed campaign must be independently reproducible. Critical discrepancies remain open until closure evidence or authorized risk acceptance exists.

### Suggested workload

| Activity | Hours |
|---|---:|

| Execution | 3.5 |

| Data/EDA | 3.0 |

| Discrepancy/corrective action | 3.0 |

| Review | 2.0 |


---

## Week 10 — Analyze results, determine evidence sufficiency, and recommend remedial action

**Primary competency emphasis:** C6, C7, C9, C12

### Professional context and essential question

A pass/fail table hides uncertainty, data quality, limitations, and interaction among evidence sources. **Essential question:** What conclusions are actually supported, and what action follows when evidence is adverse or inconclusive?

### Weekly learning outcomes

By the end of the week, the learner will be able to:

* apply the predeclared analysis and assess assumptions
* estimate performance, uncertainty, confidence, and practical significance
* combine test, analysis, inspection, demonstration, simulation, and prior evidence
* distinguish pass, fail, inconclusive, limited, waived, and not tested
* recommend correction, redesign, requirement clarification, added evidence, or risk acceptance

### Retrieval and readiness check

1. What is practical significance?
2. Why can failing to reject a hypothesis not prove compliance?
3. What is an inconclusive result?
4. How should multiple evidence sources be combined?

### Required study

* **NIST Engineering Statistics Handbook** — EDA, intervals, regression, DOE analysis, reliability, and uncertainty. **Purpose:** Analyze data defensibly. **Guiding questions:** Which assumptions and diagnostics matter?

* **NASA Product Verification** — result analysis and verification reports. **Purpose:** Convert evidence into compliance conclusions. **Guiding questions:** What should be included in the verification report?

* **NASA Product Validation** — evaluation against intended use and stakeholder expectations. **Purpose:** Separate technical compliance from operational fitness. **Guiding questions:** How are limitations communicated?

### Instructor-style lesson notes

Analysis begins with data and configuration validity, then assumption checks, then estimation and comparison with decision boundaries. Avoid choosing the method after seeing the preferred outcome.


Compliance may require demonstrating that a bound lies on the acceptable side of a threshold, not merely that the sample average passes. Tail and reliability requirements often need specialized methods or combined evidence.


Evidence synthesis should identify independence, overlap, common assumptions, and credibility. Two analyses based on the same flawed model are not independent corroboration.


A remedial action should match the cause: redesign for product deficiency, procedure change for test deficiency, calibration for measurement deficiency, requirement clarification for ambiguity, additional testing for insufficient precision, or authorized risk acceptance for known residual exposure.


### Worked example

Latency data have a sample 95th percentile of 7.7 s, below the 8.0 s threshold, but the bootstrap upper interval is 8.4 s and the worst network stratum is underrepresented. The result is classified inconclusive rather than pass. The plan adds targeted runs in the worst stratum and a network design mitigation; no requirement status is changed until evidence improves.

### Guided practice

1. Reproduce one analysis from raw data.
2. Check assumptions and compare alternative methods.
3. Create a claim-evidence argument for one requirement and one stakeholder expectation.
4. Recommend action for pass, fail, and inconclusive cases.

### Independent exercises

* **Foundation:** Interpret ten misleading result summaries.

* **Application:** Analyze all executed campaign data using predeclared methods.

* **Analysis:** Quantify uncertainty and false-pass/false-fail risk.

* **Synthesis:** Conduct the Verification/Validation Evidence Review.

* **Stretch:** Generate an evidence dashboard that separates planned, executed, valid, evaluated, and accepted status.

### Weekly deliverable

Submit reproducible analysis notebooks, diagnostics, result tables/plots, evidence arguments, requirement and validation status, limitation/waiver register, remedial-action recommendations, and Evidence Review record.

### Analytic rubric

| Criterion | Weight | Evidence of mastery |
|---|---:|---|

| Analysis correctness | 30% | Methods, assumptions, uncertainty, and diagnostics are defensible. |

| Evidence synthesis | 25% | Sources are combined without double counting or hidden dependence. |

| Status classification | 25% | Pass/fail/inconclusive/limited/waived conclusions match evidence. |

| Action and communication | 20% | Remedial actions and limitations are decision useful. |


### Critical failures

* Requirement marked pass from insufficient or invalid evidence.
* Known uncertainty omitted.
* Analysis method changed to obtain preferred result without disclosure.
* Inconclusive evidence presented as operational validation.

### Knowledge check

1. What is practical significance?
2. When is a result inconclusive?
3. Why use intervals rather than only point estimates?
4. How can evidence be dependent?
5. What remedial actions fit different root causes?

### Revision and mastery gate

Every critical conclusion must be reproducible and reviewed. Inconclusive critical claims require a follow-on plan or explicit decision restriction.

### Suggested workload

| Activity | Hours |
|---|---:|

| Study | 2.5 |

| Analysis | 4.0 |

| Evidence synthesis | 3.0 |

| Review/revision | 2.0 |


---

## Week 11 — Evaluate operational use, deployed systems, systems of systems, AI, and autonomy

**Primary competency emphasis:** C6, C8, C9, C11

### Professional context and essential question

Operational success depends on mission context, people, support, external systems, adaptation, and behavior that may change after deployment. **Essential question:** Will the capability be effective, suitable, resilient, and trustworthy in realistic operations and across evolving dependencies?

### Weekly learning outcomes

By the end of the week, the learner will be able to:

* design operational scenarios, field trials, and acceptance criteria
* evaluate effectiveness, suitability, availability, supportability, usability, training, and resilience
* address external organizations, interoperability, data, and SoS dependencies
* plan continuous evaluation for evolving software and deployed updates
* identify AI/autonomy-specific data, model, behavior, human, uncertainty, and distribution-shift concerns

### Retrieval and readiness check

1. Distinguish operational effectiveness and suitability.
2. Why can a system pass qualification but fail operational evaluation?
3. What is distribution shift?
4. Why are SoS test boundaries difficult?

### Required study

* **JHU syllabus** — operational, deployed, SoS, and AI topics. **Purpose:** Preserve source breadth. **Guiding questions:** Which late-lifecycle concerns change test strategy?

* **DoD AI-enabled systems T&E guidebook** — datasets, models, system context, uncertainty, and iterative evaluation. **Purpose:** Address AI-specific challenges. **Guiding questions:** What should be tested beyond model accuracy?

* **DoD autonomy T&E guidebook** — end-to-end, mission-based, human-autonomy, M&S, and continuous evidence concepts. **Purpose:** Address autonomous behavior. **Guiding questions:** How does autonomy change scenario and assurance design?

* **NIST SP 800-160 Vol. 2 Rev. 1** — anticipate, withstand, recover, adapt. **Purpose:** Evaluate operational resilience. **Guiding questions:** Which measures show degraded mission capability and recovery?

### Instructor-style lesson notes

Operational effectiveness asks whether the system accomplishes the mission. Suitability asks whether it can be used and sustained by intended people and organizations, including reliability, availability, maintainability, support, training, interoperability, safety, and workload.


Operational scenarios should include realistic routes, weather, demand, mixed traffic, accessibility, events, degraded communications, maintenance, staffing, cyber disruption, external transit dependencies, and public response.


SoS evidence is difficult because constituent systems have independent owners, evolution, data rights, schedules, and objectives. Define boundary, participating configuration, assumptions, unavailable control, and monitoring.


AI/autonomy T&E must address dataset provenance and coverage, model and system performance, calibration, uncertainty, robustness, distribution shift, human-autonomy interaction, unsafe generalization, monitoring, fallback, update control, and post-deployment learning. Accuracy alone is insufficient.


### Worked example

The perception subsystem performs well on the development dataset but boarding assistance degrades in heavy rain and at temporary construction zones. Operational evaluation stratifies environments, measures confidence and human takeover, detects distribution shift, and triggers a bounded operating-domain restriction plus new data collection and retraining/reverification rules.

### Guided practice

1. Define operational effectiveness and suitability measures.
2. Create one SoS dependency and monitoring map.
3. Audit an AI/autonomy claim for dataset and context gaps.
4. Plan a field or synthetic operational scenario with stop rules.

### Independent exercises

* **Foundation:** Classify measures as effectiveness, suitability, survivability/resilience, or technical performance.

* **Application:** Develop the operational test and evaluation plan.

* **Analysis:** Analyze external-system and organizational dependencies.

* **Synthesis:** Create an AI/autonomy/deployed-change supplement applicable to the learner's design.

* **Stretch:** Design continuous evidence monitoring with thresholds for rollback or reevaluation.

### Weekly deliverable

Submit operational scenarios and field-test plan, effectiveness/suitability measures, operator/maintainer/accessibility evaluation, SoS dependency map, resilience events, AI/autonomy or evolving-software supplement, continuous-monitoring plan, and operational limitations.

### Analytic rubric

| Criterion | Weight | Evidence of mastery |
|---|---:|---|

| Operational realism | 25% | Scenarios, users, environments, threats, and dependencies are representative. |

| Effectiveness/suitability | 25% | Measures cover mission and sustainable use. |

| SoS/deployed evolution | 20% | External authority, configuration, monitoring, and change are addressed. |

| AI/autonomy rigor | 20% | Data, uncertainty, shift, human interaction, fallback, and updates are treated where applicable. |

| Decision limits | 10% | Restrictions and continuous-evidence triggers are explicit. |


### Critical failures

* Operational evaluation repeats lab conditions without disclosure.
* Suitability and support are omitted.
* AI claim relies only on average accuracy.
* External-system configuration or authority is ignored.

### Knowledge check

1. How do effectiveness and suitability differ?
2. What makes an operational environment representative?
3. Why is SoS T&E difficult?
4. What is distribution shift?
5. What evidence is needed after a deployed update?

### Revision and mastery gate

Operational conclusions must state population, environment, configuration, and limitations. AI/autonomy or evolving-software capability requires monitoring and change-triggered reevaluation.

### Suggested workload

| Activity | Hours |
|---|---:|

| Study | 3.0 |

| Operational plan | 3.5 |

| Advanced supplement | 3.0 |

| Review | 2.0 |


---

## Week 12 — Conduct the final evidence review and make the operational-readiness recommendation

**Primary competency emphasis:** C6, C9, C10, C12

### Professional context and essential question

The final obligation is not to declare success but to tell decision makers what the evidence supports, what it does not, and what risk remains. **Essential question:** Should the system proceed, proceed under conditions, return for rework, or stop?

### Weekly learning outcomes

By the end of the week, the learner will be able to:

* integrate requirement verification, stakeholder validation, operational evaluation, discrepancies, and residual risk
* demonstrate live provenance from claim to article, data, analysis, and conclusion
* evaluate evidence sufficiency, limitations, waivers, and unresolved actions
* make a clear acceptance and readiness recommendation with conditions
* define follow-on, production, deployment, monitoring, and regression evidence

### Retrieval and readiness check

1. State the highest-risk unresolved claim.
2. Identify the authoritative test article/build.
3. Name one verified requirement that is not yet operationally validated.
4. State one condition that would reverse the recommendation.

### Required study

* **NASA verification and validation** — reporting and decision evidence. **Purpose:** Synthesize compliance and intended use. **Guiding questions:** What objective evidence and limitations belong in final reports?

* **Phase 2 README** — continuous evidence chain and exit criteria. **Purpose:** Close the phase. **Guiding questions:** Can every major claim be traced upstream and downstream?

* **JHU source syllabus** — CLOs and topic breadth. **Purpose:** Check source completeness. **Guiding questions:** Which capstone element demonstrates each CLO?

### Instructor-style lesson notes

A final evidence review should separate product compliance, stakeholder validation, operational effectiveness, suitability, safety/security, support, and readiness. These may produce different statuses.


Use an evidence status vocabulary such as verified, failed, inconclusive, limited, waived, not tested, invalidated, or superseded. State authority and date for acceptance decisions.


Conditional readiness requires enforceable conditions: operating-domain limits, monitoring, training, staffing, maintenance, update restrictions, corrective actions, deadlines, and stop/rollback triggers.


The oral defense checks provenance and judgment. The learner should be able to re-run analysis, explain an anomaly, identify configuration, and update the recommendation after new evidence.


### Worked example

The system meets latency and accessibility thresholds in tested conditions but has inconclusive availability evidence and one open severe-weather autonomy discrepancy. The recommendation is a bounded human-driven and low-speed autonomous pilot under weather restrictions, enhanced monitoring, mandatory failover staffing, and a defined evidence campaign before expansion. The report does not label the entire system simply 'passed.'

### Guided practice

1. Run a portfolio consistency and evidence-status audit.
2. Practice a live claim-to-data-to-analysis trace.
3. Reanalyze one dataset after a supplied exclusion or calibration change.
4. Conduct the final board and receiving-authority challenge.

### Independent exercises

* **Foundation:** Complete a closed-book T&E reasoning assessment.

* **Application:** Assemble and baseline the final T&E portfolio.

* **Analysis:** Develop the integrated readiness argument and conditions.

* **Synthesis:** Conduct and record the final oral defense.

* **Stretch:** Publish a machine-readable evidence manifest and monitoring/retest backlog.

### Weekly deliverable

Submit final T&E report, evidence matrix, verification/validation/operational status, discrepancy and waiver summary, residual-risk assessment, readiness recommendation, review deck, oral-defense record, and follow-on evidence plan.

### Analytic rubric

| Criterion | Weight | Evidence of mastery |
|---|---:|---|

| Evidence coherence | 30% | Claims, articles, data, analysis, discrepancies, and conclusions trace and agree. |

| Technical/statistical judgment | 25% | Uncertainty, limits, and sufficiency are correctly interpreted. |

| Readiness recommendation | 25% | Decision, conditions, residual risk, and follow-on work are clear and proportionate. |

| Defense/reproducibility | 20% | Key evidence is reproduced and defended live. |


### Critical failures

* Final recommendation hides a critical limitation or waiver.
* Evidence provenance cannot be demonstrated.
* Inconclusive claim is reported as pass.
* Conditional recommendation lacks enforceable conditions or triggers.

### Knowledge check

1. What belongs in a final T&E report?
2. How does acceptance differ from operational readiness?
3. What makes a condition enforceable?
4. When should evidence be invalidated?
5. What should trigger post-deployment reevaluation?

### Revision and mastery gate

Pass only when all critical mastery criteria are satisfied, the integrated evidence is reproducible, and the recommendation is accepted or conditionally accepted by the simulated authority with documented actions.

### Suggested workload

| Activity | Hours |
|---|---:|

| Audit and study | 2.0 |

| Final analysis/report | 4.5 |

| Board/defense | 3.0 |

| Revision/monitoring plan | 2.0 |


---

## Solution and instructor-material package

Maintain a separate solution and mentor package containing:

* readiness-diagnostic answer guide;
* defective VCRM, test concept, procedure, and analysis examples;
* reference T&E architecture and critical parameter register;
* reference measurement uncertainty and DOE/sample calculations;
* supplied SIL, integration, latency, availability, boarding, environmental, and anomaly datasets;
* validated analysis notebooks and expected result ranges;
* reference discrepancy, root-cause, corrective-action, and retest records;
* TRR and evidence-review board scoring notes;
* operational/SoS/AI scenario prompts;
* knowledge-check answers and rationales;
* oral-defense injects and model responses;
* common errors, recovery work, and exemplar limitation statements.

The learner-facing repository should include data and problem statements but should not expose complete diagnostic answers before work is submitted.

## References

[JHU-769-COURSE]: https://ep.jhu.edu/courses/645769-system-test-evaluation/ "JHU — System Test & Evaluation"
[JHU-769-SYLLABUS]: https://apps.ep.jhu.edu/syllabus/fall-2026/645.769.81 "JHU Fall 2026 abridged syllabus — System Test & Evaluation"
[NASA-SEH]: https://www.nasa.gov/reference/systems-engineering-handbook/ "NASA Systems Engineering Handbook"
[NASA-INTEGRATION]: https://www.nasa.gov/reference/5-2-product-integration/ "NASA SE Handbook — Product Integration"
[NASA-VERIFICATION]: https://www.nasa.gov/reference/5-3-product-verification/ "NASA SE Handbook — Product Verification"
[NASA-VALIDATION]: https://www.nasa.gov/reference/5-4-product-validation/ "NASA SE Handbook — Product Validation"
[NASA-ASSESSMENT]: https://www.nasa.gov/reference/6-7-technical-assessment/ "NASA SE Handbook — Technical Assessment"
[NASA-CM]: https://www.nasa.gov/reference/6-5-configuration-management/ "NASA SE Handbook — Configuration Management"
[NASA-VV-PLAN]: https://www.nasa.gov/reference/appendix-i-verification-and-validation-plan-outline/ "NASA SE Handbook — V&V Plan Outline"
[NIST-ESH]: https://www.nist.gov/programs-projects/nistsematech-engineering-statistics-handbook "NIST/SEMATECH Engineering Statistics Handbook"
[NIST-EDA]: https://www.itl.nist.gov/div898/handbook/eda/eda.htm "NIST/SEMATECH e-Handbook — Exploratory Data Analysis"
[NIST-DOE]: https://www.itl.nist.gov/div898/handbook/pri/pri.htm "NIST/SEMATECH e-Handbook — Process Improvement and DOE"
[DOD-SE]: https://ac.cto.mil/wp-content/uploads/2022/08/Systems-Eng-Guidebook_Feb2022-Cleared.pdf "DoD Systems Engineering Guidebook"
[DAU-TEMP]: https://aaf.dau.edu/aaf/mca/temp/ "DAU — Test and Evaluation Master Plan"
[NASA-SWE-TEST]: https://swehb.nasa.gov/spaces/SWEHBVD/pages/102695449/SWE-066+-+Perform+Testing "NASA Software Engineering and Assurance Handbook — Perform Testing"
[DOD-CYBER-TE]: https://aaf.dau.edu/storage/2025/07/Cyber-DTE-Guidebook-V3-June2025Update_Final-OFF.pdf "DoD Cyber Developmental Test and Evaluation Guidebook, Version 3"
[DOD-AI-TE]: https://www.cto.mil/wp-content/uploads/2025/02/TE_of_AIES_Guidebook_Final_26Feb25.pdf "DoD Developmental T&E of AI-Enabled Systems Guidebook"
[DOD-AUTONOMY-TE]: https://www.cto.mil/wp-content/uploads/2025/10/DTE-of-AS-GB.pdf "DoD Developmental T&E of Autonomous Systems Guidebook"
[DOD-MS-TE]: https://aaf.dau.edu/storage/2025/05/MS-TE-Guidebook-Final.pdf "DoD Modeling and Simulation for Test and Evaluation Guidebook"
[NIST-RESILIENCE]: https://csrc.nist.gov/pubs/sp/800/160/v2/r1/final "NIST SP 800-160 Vol. 2 Rev. 1 — Developing Cyber-Resilient Systems"
[NASA-RM]: https://sma.nasa.gov/sma-disciplines/reliability-and-maintainability "NASA Reliability and Maintainability"
[DOD-ENGINEERING]: https://www.cto.mil/wp-content/uploads/2024/08/Eng-Def-Sys-Change1-July2024.pdf "DoD Engineering of Defense Systems Guidebook"

[Back to Phase 2 README](README.md)  
[Back to program README](../README.md)
