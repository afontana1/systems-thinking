# EN.645.756 — Metrics, Modeling, and Simulation for Systems Engineering

**Credits:** 3  
**Phase:** 3 — Quantitative analysis and model-driven decision support  
**Prerequisites:** EN.645.662 Introduction to Systems Engineering, EN.645.667 Management of Systems Projects, and EN.645.767 System Conceptual Design, or equivalent preparation  
**Recommended preparation:** EN.645.757 Foundations of Modeling and Simulation, basic Python or R, algebra, and introductory probability

[Back to Phase 3 README](README.md) · [Back to program README](../README.md)

---

## 1. Course purpose

This course develops the quantitative measurement and statistical-modeling capability required to make and defend systems-engineering decisions across the lifecycle. The learner will define technical measures; characterize stochastic performance; design defensible data-collection and experimentation plans; build statistical and analytic simulation models that relate system performance to use and environment; quantify uncertainty, reliability, and margin; and use the resulting evidence to support requirements, design, upgrade, replacement, and retirement decisions.

The course is not a generic statistics survey. Every method must answer a systems-engineering question, preserve the measurement and data provenance needed for review, and state the conditions under which the conclusion may fail. A precise calculation attached to the wrong measure, biased sample, invalid model, or misunderstood decision is not acceptable evidence.

## 2. Source scope and self-study adaptation

The public JHU course description emphasizes an integrated treatment of foundational statistics, system-level key performance parameters, stochastic characterization, experimental design, data collection, performance modeling as a function of use and environment, analytic simulation, and lifecycle decisions from conceptualization through retirement. The currently linked public syllabus is an abridged Fall 2024 syllabus and does not expose the complete Canvas module sequence. This self-study course therefore preserves the publicly stated scope while organizing it into a transparent 12-week progression and making the required evidence, reviews, and mastery gates explicit. [JHU-756-COURSE] [JHU-756-SYLLABUS]

The NIST/SEMATECH e-Handbook supplies the main statistical backbone because it is written for scientists and engineers who must design experiments, build process models, analyze data, and assess reliability. NASA systems-engineering guidance supplies the lifecycle and technical-measurement context. INCOSE's Technical Measurement Guide supplies a disciplined measurement process. The JCGM Guide to the Expression of Uncertainty in Measurement supplies the measurement-uncertainty framework. [NIST-EHANDBOOK] [NASA-SEH] [NASA-APPENDIX] [INCOSE-TECH-MEAS] [JCGM-GUM]

## 3. Relationship to adjacent courses

### Inputs from earlier courses

The learner should import:

* the Phase 2 stakeholder, requirements, architecture, interface, risk, verification, and test baselines;
* the concept-selection assumptions, measures, thresholds, and unresolved uncertainties;
* the EN.645.757 model-purpose, conceptual-model, input-data, verification, validation, and reproducibility practices;
* the EN.645.784 objectives, value structure, decision record, Pareto analysis, and robustness questions;
* the Phase 3 repository conventions and controlled Autonomous Campus Mobility 2030 case.

### Outputs to later Phase 3 courses

This course produces:

* a governed hierarchy of KPPs, KSAs, MOEs, MOPs, TPMs, leading indicators, and diagnostic measures;
* a measurement dictionary with operational definitions, units, scales, thresholds, provenance, quality, and uncertainty;
* reproducible data-quality, exploratory, inference, DOE, regression, reliability, and Monte Carlo notebooks;
* calibrated performance models that connect use and environment to system outcomes;
* requirement-compliance, margin, reliability, upgrade, replacement, and retirement analyses;
* analytic artifacts and trace relationships suitable for EN.645.632 Applied Analytics for MBSE;
* statistical components, uncertainty models, and lifecycle evidence reusable in EN.645.758 Advanced Systems Modeling and Simulation.

## 4. Prerequisites and readiness diagnostic

Complete the following without outside help:

1. Distinguish a stakeholder objective, requirement, MOE, MOP, TPM, KPP, observation, estimate, model output, and decision criterion.
2. Compute a mean, standard deviation, percentile, probability, and confidence interval for a small dataset.
3. Explain why correlation does not establish causation and why statistical significance does not establish engineering significance.
4. Interpret a histogram, empirical cumulative distribution, scatterplot, residual plot, and confidence interval.
5. Explain randomization, replication, blocking, confounding, and interaction in an experiment.
6. Fit or interpret a basic linear model with one predictor and identify at least two assumptions.
7. Explain the difference between aleatory variability, epistemic uncertainty, measurement uncertainty, and stakeholder disagreement.
8. Use a spreadsheet, Python, or R to import a CSV file, check types and missing values, calculate grouped summaries, and produce a reproducible plot.
9. State why a point estimate cannot demonstrate probability of meeting a requirement.
10. Identify three ways lifecycle or operational data can be biased by selection, censoring, changing configuration, or inconsistent measurement.

A learner below the standard should complete a one- to two-week bridge covering descriptive statistics, probability distributions, confidence intervals, basic regression, experiment terminology, Python or R data handling, and the distinction among measures, requirements, and decisions.

## 5. Course learning outcomes

| ID | Measurable course learning outcome | Program competency | Level | Primary evidence |
|---|---|---|:---:|---|
| CLO-1 | Define a lifecycle technical-measurement strategy linking stakeholder outcomes, requirements, architecture, risks, and decisions | C2, C3, C8, C9 | D | Technical Measurement Strategy Review |
| CLO-2 | Construct operationally precise KPP, KSA, MOE, MOP, TPM, leading-indicator, and diagnostic-measure definitions | C2, C8 | A | Controlled measure dictionary |
| CLO-3 | Characterize univariate and multivariate stochastic performance, including distributions, dependence, tails, and uncertainty sources | C7, C8 | A | Stochastic characterization package |
| CLO-4 | Assess data provenance, sampling, missingness, censoring, measurement error, configuration consistency, and fitness for intended analysis | C7, C8, C12 | A | Data Readiness Review |
| CLO-5 | Apply estimation, confidence intervals, hypothesis, equivalence, and practical-significance reasoning to engineering evidence | C8, C9 | A | Inference notebook and decision memo |
| CLO-6 | Design and analyze randomized, replicated, blocked, and factorial experiments that expose interactions and support a stated decision | C7, C8, C9 | A | DOE and Experiment Analysis Review |
| CLO-7 | Build, diagnose, validate, and communicate statistical response models relating performance to use, design, and environment | C7, C8 | A | Performance response model |
| CLO-8 | Analyze reliability, availability, maintainability, degradation, censoring, and rare-event evidence without overstating precision | C6, C7, C8 | D/A | RAM and degradation analysis |
| CLO-9 | Implement analytic Monte Carlo simulation and uncertainty propagation with reproducible input models and convergence checks | C7, C8 | A | Stochastic performance simulation |
| CLO-10 | Quantify requirement-compliance probability, margin, allocation risk, and sensitivity across operational conditions | C2, C3, C8, C9 | A | Requirements and design margin review |
| CLO-11 | Update evidence over time and analyze upgrade, replacement, retirement, and additional-information choices | C1, C8, C9, C10 | A | Lifecycle decision package |
| CLO-12 | Defend a bounded recommendation with traceable data, models, uncertainty, limitations, and reproducible results | C7, C8, C9, C12 | A | Final Lifecycle Analytics Review |

## 6. Essential questions

* Which measures reveal mission effectiveness, and which merely describe internal activity?
* What exactly is being measured, under what configuration, use, environment, and time basis?
* Which variation is natural, which is due to incomplete knowledge, and which is measurement error?
* What data are missing because the system or organization did not observe them?
* When is a sample representative enough for the stated decision?
* What is the engineering consequence of an interval estimate or a tail probability?
* Which factors interact, and what decisions would be wrong if interaction were ignored?
* When is a fitted statistical relationship useful for prediction, explanation, or control?
* What evidence supports extrapolation beyond observed use or environmental conditions?
* How should reliability and degradation evidence be interpreted when failures are rare or observations are censored?
* What is the probability of meeting a requirement, and how much margin exists under realistic uncertainty?
* When does a system need improvement, replacement, retirement, or more information rather than another model?

## 7. Running case and controlled analytic data

### Case — Campus Mobility Performance and Lifecycle Analytics Program

The Autonomous Campus Mobility 2030 program has completed concept, design, integration, and initial test work. Leadership now needs a quantitative technical-measurement and analytic capability that can support pilot acceptance, operational tuning, scale-up, winter-weather design changes, charging-system upgrades, fleet replacement, and eventual retirement decisions.

The learner serves as the independent lifecycle analytics lead. Earlier requirements and models are treated as controlled inputs, not unquestionable truth. All numerical data are synthetic course data.

### Decision questions

The course must answer at least these questions:

1. Which measures provide early warning that mission or technical performance will miss thresholds?
2. How do demand, temperature, precipitation, route grade, passenger accessibility needs, battery age, and dispatch policy affect wait time, trip completion, energy use, and availability?
3. Which design or operating factors have important interactions?
4. What is the probability that the pilot meets wait-time, accessible-service, availability, safety, and energy requirements?
5. What uncertainty or data limitation dominates each conclusion?
6. Which upgrade is justified, and under what operating conditions?
7. When should a vehicle, charger, subsystem, or operational concept be replaced or retired?

### Controlled starting measures

| Measure | Current threshold or objective | Initial synthetic evidence | Known concern |
|---|---|---|---|
| 90th-percentile passenger wait | ≤ 12 min threshold; ≤ 8 min objective | 11.4 min overall; 17.8 min during high-demand rain | Tail and subgroup behavior hidden by overall average |
| Accessible-trip fulfillment | ≥ 0.98 | 0.972 overall; 0.941 during two-vehicle outage | Sparse but consequential failures |
| Mission availability | ≥ 0.95 | 0.956 estimated | Configuration and maintenance-state definitions vary |
| Trip completion without service interruption | ≥ 0.995 | 0.9915 | Rare events and reporting censoring |
| Fleet energy intensity | ≤ 0.82 kWh/passenger-km | 0.79 average | Strong temperature and load dependence |
| Critical safety event rate | no unacceptable event; monitor precursor rate | zero critical events in 28,000 trips | Zero observed events does not prove zero risk |
| Charging turnaround | ≤ 42 min at defined conditions | 39 min median; 58 min 95th percentile | Battery age and cold-weather interaction |
| Maintenance labor | ≤ 1.8 labor-hours/100 vehicle-hours | 2.1 | Learning, supplier, and configuration effects |

### Synthetic data package to create

The learner creates and controls a reproducible synthetic dataset with at least:

* 20,000–30,000 trip-level observations;
* 12–20 vehicles and 4–8 chargers;
* weather, route, demand, accessibility, load, battery age, dispatch, maintenance, and configuration variables;
* deliberate missingness, censoring, sensor bias, duplicate records, inconsistent units, and configuration changes;
* at least one planned factorial experiment and one observational operating dataset;
* event and exposure data suitable for reliability and availability analysis;
* a data-generation script so the complete dataset can be regenerated from a documented seed.

### Multi-role review protocol

For each major review, assess the work from at least four roles:

* **decision authority** — asks whether the result changes an action;
* **chief engineer** — challenges requirements, architecture, margins, and extrapolation;
* **test/statistics reviewer** — challenges data, design, assumptions, and inference;
* **operator or maintainer** — challenges definitions, feasibility, subgroup effects, and operational relevance.

## 8. Resource architecture

### Required backbone

* **JHU course description and public syllabus** — authoritative source-course scope. [JHU-756-COURSE] [JHU-756-SYLLABUS]
* **NIST/SEMATECH e-Handbook of Statistical Methods** — exploratory analysis, process modeling, DOE, uncertainty, and reliability. [NIST-EHANDBOOK]
* **NASA Systems Engineering Handbook and appendix** — lifecycle decisions, technical measures, margins, verification, and system analysis. [NASA-SEH] [NASA-APPENDIX]
* **INCOSE Technical Measurement Guide** — measure selection, planning, collection, analysis, reporting, and improvement. [INCOSE-TECH-MEAS]
* **JCGM Guide to the Expression of Uncertainty in Measurement** — measurement models and uncertainty components. [JCGM-GUM]

### Statistical and computational resources

* NIST exploratory data analysis, process modeling, DOE, and reliability chapters. [NIST-EDA] [NIST-PROCESS] [NIST-DOE] [NIST-RELIABILITY]
* SciPy statistical functions and distributions. [SCIPY-STATS]
* statsmodels regression, ANOVA, diagnostics, and time-series tools. [STATSMODELS]
* SALib global sensitivity-analysis methods. [SALIB]
* pandas and Jupyter for reproducible data work. [PANDAS] [JUPYTER]

### Recommended books

Use one engineering-statistics text and one reliability or uncertainty reference available to you. Suitable choices include a standard text on probability and statistics for engineering, Montgomery's *Design and Analysis of Experiments*, and Meeker, Escobar, and Pascual's *Statistical Methods for Reliability Data*. These are recommended rather than required because editions and access differ.

## 9. Tools and working environment

### Required open track

* Python 3.11 or later;
* JupyterLab or VS Code notebooks;
* pandas, NumPy, SciPy, statsmodels, matplotlib, and SALib;
* a version-controlled repository;
* a `requirements.txt`, lock file, or exported environment;
* a test runner such as `pytest` for data and model checks.

### Optional tracks

* R with tidyverse, `lm`, `aov`, reliability/survival packages, and Quarto;
* JMP, Minitab, MATLAB, or another approved engineering-statistics environment;
* spreadsheet work for hand checks, never as the sole source for the final reproducible analysis.

### Common requirements

Every notebook or script must:

* identify input files and configuration versions;
* validate units, ranges, identifiers, missingness, and duplicates;
* separate data preparation from analysis;
* preserve random seeds and sampling design;
* state model assumptions and diagnostics;
* regenerate every submitted table and figure;
* export machine-readable results as well as human-readable reports;
* record the decision and intended use supported by each result.

## 10. Assessment and grading model

| Assessment | Weight |
|---|---:|
| Weekly retrieval checks, hand calculations, and short labs | 15% |
| Technical measurement strategy and controlled measure dictionary | 10% |
| Data readiness, uncertainty, and statistical inference package | 12% |
| DOE plan, execution, and analysis review | 15% |
| Performance response and RAM model package | 15% |
| Monte Carlo requirements and design-margin review | 13% |
| Lifecycle upgrade/replacement/retirement capstone and oral defense | 20% |
| **Total** | **100%** |

All major reviews require revision. A technically polished report with untraceable data, invalid inference, or a recommendation beyond the evidence cannot receive a passing mark.

## 11. Twelve-week course map

| Week | Theme | Primary evidence | Review or gate |
|---|---|---|---|
| 1 | Lifecycle technical measurement and decision framing | Measurement strategy and decision map | Technical Measurement Strategy Review |
| 2 | Probability, distributions, dependence, and stochastic characterization | Input and performance characterization | Stochastic Assumptions Gate |
| 3 | Data provenance, sampling, EDA, and measurement uncertainty | Data-quality and uncertainty package | Data Readiness Review |
| 4 | Estimation, intervals, tests, equivalence, and engineering significance | Statistical inference decision memo | Inference Adequacy Gate |
| 5 | Experiment objectives, factors, responses, power, randomization, and blocking | Experiment protocol | Experiment Readiness Review |
| 6 | Factorial experiments, ANOVA, interactions, diagnostics, and confirmation | DOE analysis and confirmation plan | Experiment Analysis Review |
| 7 | Regression, response surfaces, use/environment models, and prediction | Performance response model | Model Form Review |
| 8 | Reliability, availability, maintainability, degradation, and censoring | RAM and degradation package | Performance Model Review |
| 9 | Monte Carlo analytic simulation and uncertainty propagation | Stochastic performance simulation | Computational Evidence Review |
| 10 | Requirements probability, margins, allocation risk, and design decisions | Requirement and design-margin package | Lifecycle Analytics Review I |
| 11 | Monitoring, updating, upgrade, replacement, retirement, and value of information | Lifecycle option analysis | Lifecycle Analytics Review II |
| 12 | Integrated capstone, live challenge, oral defense, and downstream handoff | Final decision record and reproducible repository | Final Lifecycle Analytics Review |

## 12. Major assignments and review products

### A. Technical Measurement Strategy Review

Define the decisions, stakeholders, requirements, risks, measures, operational definitions, thresholds, collection plans, reporting cadence, ownership, and action rules. Demonstrate that each critical measure has a decision use and that no critical decision relies on an undefined metric.

### B. Data Readiness and Inference Package

Create the synthetic dataset and generation script; identify provenance, missingness, censoring, selection mechanisms, measurement uncertainty, unit and configuration defects; conduct exploratory analysis; and issue a bounded statement about which analyses are and are not currently supportable.

### C. DOE and Experiment Analysis Review

Design, execute, and analyze a controlled experiment involving at least four factors, one blocking variable, two responses, and one expected interaction. Include randomization, replication, power or precision reasoning, model diagnostics, confirmation runs, and a decision recommendation.

### D. Performance Response and RAM Package

Build statistical models that relate wait time, energy, charging turnaround, availability, and maintenance behavior to use, environment, design, and age. Include alternative model forms, diagnostics, validation, subgroup analysis, extrapolation limits, and reliability or degradation evidence.

### E. Monte Carlo Requirements and Design-Margin Review

Propagate uncertainty through an analytic performance model; estimate probability of meeting critical requirements; analyze tails, margins, allocation risk, and global sensitivity; and compare at least three improvement options without hiding common inputs or dependence.

### F. Lifecycle Decision Capstone

Recommend an upgrade, replacement, retirement, or information-collection action. Integrate technical measures, field and experiment data, performance and reliability models, uncertainty, cost/schedule context, residual risk, implementation conditions, and revisit triggers. Distinguish technical evidence from organizational preference and decision authority.

## 13. Common analytic rubric

| Criterion | Weight | Evidence of mastery |
|---|---:|---|
| Decision and measure validity | 15% | Measures are operationally defined, traceable, decision-relevant, and not redundant or easily gamed. |
| Data and experiment quality | 20% | Provenance, sampling, missingness, uncertainty, randomization, blocking, replication, and power are addressed. |
| Statistical and computational rigor | 25% | Methods fit the data and decision; assumptions, diagnostics, convergence, and alternatives are examined. |
| Systems-engineering interpretation | 20% | Results connect to requirements, architecture, risk, lifecycle, margins, and actions. |
| Uncertainty, limitations, and ethics | 10% | Tail risk, subgroup effects, uncertainty sources, extrapolation, and misuse risks are explicit. |
| Reproducibility and communication | 10% | Data, code, figures, calculations, decisions, and revisions can be independently reproduced and reviewed. |

## 14. Critical mastery criteria

The course cannot be passed if any of the following remains true:

* a critical measure lacks an operational definition, unit, population, time basis, or decision use;
* an average is used to represent a tail, reliability, accessibility, or safety requirement without justification;
* observational and experimental evidence are mixed without identifying the different causal claims each supports;
* missing, censored, duplicated, or configuration-inconsistent data are silently removed or combined;
* statistical significance is presented as sufficient engineering significance;
* a hypothesis test is used to claim equivalence or acceptable performance without a justified equivalence or acceptance region;
* a factorial experiment is analyzed only through main effects when interaction is plausible or visible;
* a response model is used outside its validated domain without an explicit extrapolation argument and uncertainty treatment;
* reliability is reported without exposure, population, censoring, or confidence/credibility bounds;
* correlated inputs are sampled as independent when dependence materially changes the result;
* Monte Carlo output is reported without seed policy, convergence or precision evidence, and input provenance;
* requirement compliance is asserted from a mean prediction rather than a distribution and defined operating conditions;
* upgrade, replacement, or retirement is recommended without alternatives, residual risk, and reversal conditions;
* the learner cannot regenerate a key result or explain how the result changes under a challenged assumption.

## 15. Final capstone and oral defense

The final capstone is the **Campus Mobility Lifecycle Performance and Upgrade Decision Record**. It must contain:

1. decision charter and authority;
2. technical-measurement strategy and measure dictionary;
3. data-generation, provenance, quality, and uncertainty records;
4. exploratory and inferential analysis;
5. experiment protocol, analysis, confirmation, and lessons;
6. performance response models and validated domains;
7. reliability, availability, maintainability, and degradation assessment;
8. analytic Monte Carlo model and input dependence;
9. requirement-compliance probabilities, margins, and sensitivity;
10. upgrade, replace, retire, defer, and collect-more-information alternatives;
11. cost, schedule, operational, accessibility, safety, and residual-risk implications;
12. recommendation, limitations, implementation conditions, and revisit triggers;
13. reproducible source, environment, data, tests, outputs, and review history.

The oral defense must answer at least these questions:

* Which decision is supported, and which adjacent decision remains unsupported?
* Why is each top-level measure necessary, and how could it be gamed?
* What data defect most threatens the conclusion?
* Which uncertainty is measurement uncertainty, and which is natural variability?
* What causal claim can the experiment support that the observational data cannot?
* Which interaction changes the engineering recommendation?
* What evidence shows the response model is valid in the recommended operating region?
* How were censored or zero-failure observations handled?
* What is the probability of meeting the most important requirement, under what conditions?
* Which input or assumption dominates decision reversal risk?
* Why act now rather than collect more information?
* What evidence or condition would trigger upgrade, replacement, retirement, or reopening of the decision?

## 16. Portfolio and completion requirements

Retain:

* measure dictionary and technical-measurement strategy;
* controlled synthetic data and generation script;
* data-quality, uncertainty, EDA, inference, DOE, regression, RAM, Monte Carlo, and sensitivity notebooks;
* review packages, findings, dispositions, and revised baselines;
* executive and technical decision records;
* environment, tests, run instructions, and portfolio manifest;
* a one-page reflection identifying the most consequential analytic mistake corrected during the course.

Completion requires:

* at least 80% overall;
* at least 80% on the final capstone;
* no unresolved critical mastery failure;
* successful reproduction of one DOE result, one reliability or performance-model result, and one Monte Carlo result during the oral defense;
* a controlled handoff to EN.645.632.

## 17. Course maintenance record

Review annually:

* the JHU course description and any newly public syllabus;
* NIST handbook availability and links;
* NASA and INCOSE measurement guidance;
* JCGM uncertainty publications and amendments;
* Python, SciPy, statsmodels, pandas, SALib, and Jupyter versions;
* reproducibility of synthetic data and notebooks;
* whether methods have drifted into EN.645.784 decision science or EN.645.758 advanced simulation without adding distinct measurement/statistical depth.

## Week 1 — Define the lifecycle technical-measurement strategy and decision chain

**Primary competency emphasis:** C2, C3, C8, C9

### Professional context and essential question

Programs collect many numbers and still discover too late that the decisive question was never measured. **Essential question:** Which measures and reporting actions will reveal whether the system is achieving stakeholder outcomes and whether intervention is required?

### Weekly learning outcomes

By the end of the week, the learner will be able to:

* distinguish KPPs, KSAs, MOEs, MOPs, TPMs, leading indicators, diagnostic measures, and management metrics
* trace measures to stakeholder outcomes, requirements, architecture elements, risks, and lifecycle decisions
* write complete operational definitions with population, event, unit, time basis, aggregation, and configuration
* define thresholds, objectives, control limits, warning bands, and action rules without mixing their purposes
* identify metric-gaming, aggregation, subgroup, and perverse-incentive risks
* conduct a Technical Measurement Strategy Review

### Retrieval and readiness check

1. What is the difference between a MOE and a MOP?
2. What information makes a measure operationally reproducible?
3. Why can a good measure become harmful when tied to incentives?
4. What decision should a TPM support?

### Required study

* **JHU course description and syllabus** — course scope, KPPs, stochastic characterization, data, and lifecycle decisions. **Purpose:** establish the intended quantitative systems-engineering role. **Guiding question:** Which decisions require more than deterministic performance values? [JHU-756-COURSE] [JHU-756-SYLLABUS]
* **INCOSE Technical Measurement Guide** — technical-measurement process, information needs, measures, analysis, and reporting. **Purpose:** establish a disciplined measurement strategy. **Guiding question:** How does a measure lead to an action? [INCOSE-TECH-MEAS]
* **NASA Systems Engineering Handbook appendix** — MOE, MOP, TPM, metric, margin, and technical-measure definitions. **Purpose:** normalize terminology. **Guiding question:** Which measure belongs at which level? [NASA-APPENDIX]

### Instructor-style lesson notes

Begin with the decision, not the available sensor. A measurement program exists to reduce uncertainty about an action, threshold, risk, or trend.

A MOE expresses operational success from a stakeholder or mission perspective. A MOP characterizes system performance that contributes to effectiveness. A TPM tracks a critical technical characteristic or margin during realization. KPP and KSA labels are governance classifications, not replacements for precise operational definitions.

Every measure needs a numerator, denominator where applicable, event or population, inclusion and exclusion rules, unit, time basis, aggregation rule, configuration, source, uncertainty, owner, reporting cadence, and action rule.

Thresholds define minimum acceptability; objectives express desired performance; control limits describe process behavior; warning bands trigger investigation. Treating them as interchangeable creates false alarms or missed failures.

Measurement changes behavior. Audit whether a metric encourages queue manipulation, exclusion of difficult trips, deferred maintenance, or averaging that hides accessibility or safety problems.

### Worked example

The draft program reports 'average wait time = 7.2 minutes' and concludes that the 12-minute requirement is met. The requirement actually applies to the 90th percentile by service zone and accessibility class during defined operating hours. The revised operational definition specifies the request-to-board interval, valid request population, cancellations, time zone, aggregation period, subgroup reporting, vehicle configuration, data source, and action rule. The same raw data now reveal one zone with a 16.9-minute 90th percentile and an accessibility subgroup with insufficient sample size.

### Guided practice

1. Map five Phase 2 decisions to the information needed to act.
2. Draft operational definitions for wait time, availability, accessible-trip fulfillment, energy intensity, and maintenance labor.
3. Build a measure hierarchy and trace it to requirements, architecture, risks, and verification evidence.
4. Run a metric-gaming pre-mortem and revise the measure set.

### Independent exercises

* **Foundation:** Classify 25 candidate statements as objective, requirement, MOE, MOP, TPM, leading indicator, diagnostic measure, or management metric.
* **Application:** Create the controlled measure dictionary and technical-measurement strategy for the campus mobility case.
* **Analysis:** Identify redundant, lagging, unmeasurable, or easily gamed measures and justify removal or redesign.
* **Synthesis:** Conduct the Technical Measurement Strategy Review with the four-role protocol and disposition every finding.
* **Stretch:** Implement a schema and automated validation that rejects measure definitions missing units, population, time basis, source, or action rule.

### Weekly deliverable

Submit the decision-to-measure map, measure hierarchy, operational-definition dictionary, thresholds/objectives/action rules, reporting cadence, ownership map, metric-gaming analysis, review record, and revised baseline.

### Analytic rubric

| Criterion | Weight | Evidence of mastery |
|---|---:|---|
| Decision trace | 30% | Every critical measure supports a named decision, requirement, risk, or technical-control need. |
| Operational definitions | 30% | Definitions are reproducible across people, tools, time, and configuration. |
| Measure quality | 20% | Measures are necessary, nonredundant, sensitive, interpretable, and resistant to gaming. |
| Review and governance | 20% | Owners, cadence, actions, findings, and revisions are controlled. |

### Critical failures

* A critical decision has no associated measure or evidence source.
* Wait time, availability, or safety is defined only by an informal label.
* A threshold, objective, warning band, and control limit are treated as the same concept.
* Subgroup or metric-gaming risk is known but hidden.

### Knowledge check and answer guidance

1. **What makes a measure decision-relevant?**  
   *Answer guidance:* It provides information that can change, confirm, time, or bound a named action.
2. **What is an operational definition?**  
   *Answer guidance:* A complete rule for what is measured, for whom or what, when, under which configuration, in what units, and how it is calculated.
3. **Why is a TPM not automatically a MOE?**  
   *Answer guidance:* A TPM is a technical characteristic or margin; a MOE concerns operational or stakeholder effectiveness.
4. **What is a leading indicator?**  
   *Answer guidance:* A measure that may provide early evidence of a future outcome or problem, with a justified relationship to that outcome.
5. **What is metric gaming?**  
   *Answer guidance:* Behavior that improves the reported number without improving, or while harming, the intended outcome.

### Revision and mastery gate

Every critical lifecycle decision must trace to one or more fully defined measures and every critical measure must have an owner, source, uncertainty statement, reporting cadence, and action rule. Resolve all review findings before Week 2.

### Suggested workload

| Activity | Hours |
|---|---:|
| Study and retrieval | 2.0 |
| Measurement design | 3.5 |
| Trace and gaming analysis | 2.5 |
| Review and revision | 2.0 |
| **Total** | **10.0** |

### Configuration and portfolio update

Commit source data, data dictionary, code/notebooks, environment, tests, figures, machine-readable results, review comments, and revisions. Update the measure, assumption, uncertainty, data-quality, model-risk, and decision registers.

---
## Week 2 — Characterize probability distributions, tails, dependence, and stochastic performance

**Primary competency emphasis:** C7, C8

### Professional context and essential question

A system is used across variable demand, weather, human behavior, component condition, and mission scenarios. **Essential question:** What probability model represents performance and dependence well enough for the intended engineering decision?

### Weekly learning outcomes

By the end of the week, the learner will be able to:

* distinguish discrete and continuous random variables, parameters, statistics, and realizations
* select and critique candidate distributions using mechanism, support, data, and diagnostics
* characterize center, spread, skew, tails, percentiles, exceedance probability, and conditional performance
* identify dependence, common causes, mixtures, nonstationarity, and hierarchical variation
* separate aleatory variability, epistemic uncertainty, measurement uncertainty, and model-form uncertainty
* document a controlled stochastic-assumptions baseline

### Retrieval and readiness check

1. When is a probability distribution a model rather than a fact?
2. Why can two variables with zero correlation still be dependent?
3. What is a tail probability?
4. How does a mixture distribution arise in operations?

### Required study

* **NIST e-Handbook** — probability distributions and exploratory characterization. **Purpose:** connect mechanisms and observed data to candidate models. **Guiding question:** Which diagnostics reveal poor distribution fit? [NIST-EHANDBOOK] [NIST-EDA]
* **SciPy statistics documentation** — distribution objects, fitting, percentiles, and random variates. **Purpose:** implement reproducible distribution checks. **Guiding question:** Which quantities are parameters and which are estimates? [SCIPY-STATS]
* **JCGM GUM** — measurement models and uncertainty components. **Purpose:** keep measurement uncertainty distinct from operational variation. **Guiding question:** What uncertainty is associated with the measured value itself? [JCGM-GUM]

### Instructor-style lesson notes

Distribution choice begins with the generating process and support. Counts, proportions, positive durations, bounded capacities, and time-to-event observations require different candidate families.

Fit is not proved by one goodness-of-fit p-value. Use empirical distributions, Q-Q or P-P plots, tail behavior, parameter stability, mechanism, and intended-use consequences.

Mixtures appear when data combine zones, vehicle types, weather regimes, passenger classes, or configurations. A single fitted distribution can hide multimodality and subgroup failure.

Dependence matters in uncertainty propagation. Demand, precipitation, traffic, and charging delay may rise together. Independent sampling can materially understate extreme wait time or energy demand.

Create an uncertainty taxonomy. Aleatory variability may be irreducible for the decision horizon; epistemic uncertainty may be reduced; measurement uncertainty affects observed values; model-form uncertainty reflects alternative plausible representations.

### Worked example

Trip demand is initially modeled as Poisson and boarding time as lognormal. Diagnostics show strong overdispersion in counts and two boarding-time regimes associated with mobility-device use. Demand and precipitation are dependent. The revised model uses a negative-binomial demand model, a conditional boarding-time model, and a joint resampling or copula approach for demand and weather. The 95th-percentile wait estimate increases because the original independent, single-population model understated concurrent stress.

### Guided practice

1. Classify each baseline variable by support, mechanism, and candidate distribution family.
2. Generate empirical CDF, histogram, Q-Q, and tail plots for at least four variables.
3. Estimate and compare conditional distributions by weather, zone, accessibility, and vehicle age.
4. Create a dependence map and test the consequence of independent versus dependent sampling.

### Independent exercises

* **Foundation:** Compute mean, variance, quantiles, exceedance probabilities, and conditional probabilities by hand and code for a small dataset.
* **Application:** Fit and compare candidate distributions for demand, boarding time, charging duration, and failure exposure.
* **Analysis:** Diagnose mixtures, nonstationarity, common-cause dependence, and tail underfit.
* **Synthesis:** Issue a stochastic-assumptions baseline with selected models, alternatives, evidence, and use limits.
* **Stretch:** Implement a copula or stratified empirical resampling model and compare extreme-output behavior with independent sampling.

### Weekly deliverable

Submit the variable taxonomy, empirical and fitted distribution diagnostics, parameter estimates and intervals, subgroup and mixture analysis, dependence map, uncertainty taxonomy, independent-versus-dependent consequence study, and revised stochastic-assumptions register.

### Analytic rubric

| Criterion | Weight | Evidence of mastery |
|---|---:|---|
| Mechanism and support | 25% | Candidate models respect the physical or operational process and variable domain. |
| Distribution evidence | 25% | Graphical, numerical, tail, and stability evidence are considered together. |
| Dependence and mixtures | 30% | Common causes, conditional regimes, and dependence consequences are analyzed. |
| Uncertainty record | 20% | Variability and uncertainty types, alternatives, and use limits are explicit. |

### Critical failures

* A normal distribution assigns material probability to impossible negative values without treatment.
* A single distribution is fitted across known configurations or populations without checking mixtures.
* Inputs with a common driver are sampled independently despite consequential tail effects.
* Parameter estimates are reported as exact known constants.

### Knowledge check and answer guidance

1. **What is a random variable?**  
   *Answer guidance:* A numerical representation of an uncertain outcome defined on a probability space.
2. **What is a percentile?**  
   *Answer guidance:* A value below which a specified proportion of the modeled or observed population lies.
3. **What is overdispersion?**  
   *Answer guidance:* Variance greater than expected under a reference count model such as Poisson, often indicating heterogeneity or dependence.
4. **Why condition a distribution?**  
   *Answer guidance:* Performance may differ systematically by environment, use, subgroup, or configuration; conditioning avoids mixing distinct regimes.
5. **What is epistemic uncertainty?**  
   *Answer guidance:* Uncertainty due to incomplete knowledge that may be reduced through data, experiments, or improved modeling.

### Revision and mastery gate

Every stochastic input and critical performance measure must have a selected or bounded representation, provenance, parameter uncertainty, dependence treatment, and documented alternative. Demonstrate that the representation is adequate for the next decision, not universally true.

### Suggested workload

| Activity | Hours |
|---|---:|
| Study and hand calculations | 2.5 |
| Distribution analysis | 3.5 |
| Dependence and uncertainty | 3.0 |
| Review and revision | 1.5 |
| **Total** | **10.5** |

### Configuration and portfolio update

Commit source data, data dictionary, code/notebooks, environment, tests, figures, machine-readable results, review comments, and revisions. Update the measure, assumption, uncertainty, data-quality, model-risk, and decision registers.

---
## Week 3 — Establish data provenance, sampling validity, exploratory analysis, and measurement uncertainty

**Primary competency emphasis:** C7, C8, C12

### Professional context and essential question

Operational datasets are rarely designed for the analyst's later question. **Essential question:** Which data are fit for the intended analysis, and what bias or uncertainty remains after cleaning?

### Weekly learning outcomes

By the end of the week, the learner will be able to:

* construct a data-provenance and configuration lineage
* diagnose missingness, duplication, censoring, truncation, selection bias, survivorship, and inconsistent units
* design exploratory analysis that reveals structure without turning exploration into unreported hypothesis fishing
* develop a measurement model and uncertainty budget for selected variables
* distinguish data correction, exclusion, imputation, and sensitivity choices
* issue a Data Readiness Review recommendation

### Retrieval and readiness check

1. What is the difference between missing and censored data?
2. Why does configuration history matter to an operational dataset?
3. What is a measurement model?
4. When can imputation create false precision?

### Required study

* **NIST exploratory data analysis** — graphical and quantitative techniques for understanding data before formal modeling. **Purpose:** identify patterns, anomalies, and assumptions. **Guiding question:** What structure would a summary statistic conceal? [NIST-EDA]
* **JCGM GUM and publications** — measurement models, standard uncertainty, combined uncertainty, and reporting. **Purpose:** build a bounded uncertainty budget. **Guiding question:** Which inputs contribute to the measured result? [JCGM-GUM] [JCGM-PUBLICATIONS]
* **pandas documentation** — input, missing data, grouping, joining, and validation operations. **Purpose:** implement an auditable data pipeline. **Guiding question:** Which transformation could change the analysis population? [PANDAS]

### Instructor-style lesson notes

Data cleaning is an analytic decision. Preserve raw data, create immutable identifiers, and log every transformation, exclusion, unit conversion, merge, and imputation.

Missing completely at random, missing at random conditional on observed information, and missing not at random imply different risks. In engineering operations, missingness often reflects sensor dropout, maintenance, severe conditions, or human reporting behavior and is therefore informative.

Censoring records partial information: a component may still be operating at study end, or an event may be detected only above a threshold. Deleting censored records biases reliability and duration estimates.

Measurement uncertainty begins with a measurement model that relates the reported quantity to sensor, calibration, environmental, resolution, processing, and sampling contributions. Do not mix this uncertainty automatically with population variability.

Exploratory analysis should be reproducible and labeled exploratory. Pre-specify confirmatory analyses after exploration or validate them on held-out or new data.

### Worked example

A charger log records 41-minute median turnaround. Examination finds that failed sessions were excluded, cold-weather sessions have 18% sensor dropout, and two charger firmware versions use different end-of-charge definitions. A measurement model adds timestamp synchronization, current-sensor calibration, and event-detection uncertainty. Reconstructing failed sessions and stratifying by firmware changes the 95th percentile from 55 to 67 minutes and invalidates the original threshold claim.

### Guided practice

1. Create raw, staged, and analysis data layers with immutable record IDs.
2. Write automated checks for units, ranges, duplicates, impossible sequences, configuration consistency, and missingness patterns.
3. Build an EDA notebook with distributions, time order, subgroup, exposure, and missingness views.
4. Construct one measurement model and uncertainty budget, then propagate it to a reported result.

### Independent exercises

* **Foundation:** Classify 20 data defects as missingness, censoring, truncation, duplication, unit, configuration, selection, or measurement issues.
* **Application:** Generate the controlled synthetic dataset with deliberate defects and produce a data-quality report.
* **Analysis:** Compare complete-case, justified imputation, and sensitivity-bound results for one consequential measure.
* **Synthesis:** Conduct the Data Readiness Review and approve, constrain, or reject each planned analysis.
* **Stretch:** Create a machine-readable data contract and automated quality dashboard with failure thresholds.

### Weekly deliverable

Submit the data-generation script, raw/staged/analysis schemas, provenance map, configuration lineage, data contract, automated quality tests, EDA notebook, missingness and censoring analysis, measurement model and uncertainty budget, analysis-readiness matrix, review record, and revised data baseline.

### Analytic rubric

| Criterion | Weight | Evidence of mastery |
|---|---:|---|
| Provenance and controls | 25% | Raw data, transformations, configurations, and populations are traceable. |
| Defect and bias analysis | 30% | Missingness, censoring, selection, units, and configuration effects are diagnosed. |
| Measurement uncertainty | 25% | A justified measurement model and uncertainty budget support the reported quantity. |
| Readiness decision | 20% | Each planned analysis is approved, constrained, deferred, or rejected with rationale. |

### Critical failures

* Raw data are overwritten or transformations cannot be replayed.
* Failed sessions, censored lives, or difficult cases are deleted without bias analysis.
* Firmware or configuration changes are combined as if measurements were identical.
* An imputed dataset is reported without uncertainty or sensitivity analysis.

### Knowledge check and answer guidance

1. **What is censoring?**  
   *Answer guidance:* Partial observation of an outcome, such as knowing a component survived at least until study end.
2. **What is selection bias?**  
   *Answer guidance:* Systematic difference between observed and target populations caused by the observation or inclusion process.
3. **What is a measurement model?**  
   *Answer guidance:* A functional relationship linking the measurand to input quantities and corrections used to evaluate the reported value.
4. **Why preserve raw data?**  
   *Answer guidance:* To maintain auditability, permit reprocessing, and distinguish observations from analyst transformations.
5. **What is exploratory analysis for?**  
   *Answer guidance:* To reveal structure, anomalies, and plausible models while preserving the distinction from confirmatory evidence.

### Revision and mastery gate

No confirmatory model may begin until the intended population, provenance, configuration, defect handling, and measurement uncertainty are approved. Every exclusion and correction must be reproducible and sensitivity-tested when consequential.

### Suggested workload

| Activity | Hours |
|---|---:|
| Study and retrieval | 2.0 |
| Data engineering and tests | 3.5 |
| EDA and uncertainty budget | 3.5 |
| Review and revision | 2.0 |
| **Total** | **11.0** |

### Configuration and portfolio update

Commit source data, data dictionary, code/notebooks, environment, tests, figures, machine-readable results, review comments, and revisions. Update the measure, assumption, uncertainty, data-quality, model-risk, and decision registers.

---
## Week 4 — Use estimation, confidence intervals, hypothesis, equivalence, and engineering significance

**Primary competency emphasis:** C8, C9

### Professional context and essential question

Decision makers often ask whether performance is 'different,' 'good enough,' or 'within margin.' These are not the same question. **Essential question:** Which inferential claim matches the engineering decision, and what precision is required?

### Weekly learning outcomes

By the end of the week, the learner will be able to:

* select estimands that match the target population and engineering decision
* compute and interpret confidence intervals for means, proportions, quantiles, differences, and rates
* distinguish null-hypothesis tests, one-sided acceptance questions, equivalence, noninferiority, and estimation
* separate statistical significance from engineering and operational significance
* address multiplicity, optional stopping, subgroup exploration, and model assumptions
* issue an inference adequacy statement with bounded claims

### Retrieval and readiness check

1. What is an estimand?
2. Why does failing to reject a null not prove equivalence?
3. What is practical significance?
4. How does repeated testing inflate false-positive risk?

### Required study

* **NIST e-Handbook** — estimation, confidence intervals, tests, and engineering data analysis. **Purpose:** choose and interpret inferential methods. **Guiding question:** What quantity and population does the interval estimate? [NIST-EHANDBOOK]
* **SciPy statistics** — tests, confidence procedures, bootstrap, and distributions. **Purpose:** implement checks and compare methods. **Guiding question:** Which assumptions affect the result? [SCIPY-STATS]
* **statsmodels documentation** — statistical models and inference. **Purpose:** produce model-based intervals and diagnostics. **Guiding question:** What inferential statement follows from the fitted model? [STATSMODELS]

### Instructor-style lesson notes

Define the estimand before selecting the test. Examples include the difference in 90th-percentile wait under two policies, the accessible-trip success probability in winter, or the maintenance-rate ratio between configurations.

Confidence intervals quantify uncertainty under a sampling and model procedure; they do not assign a simple probability to a fixed parameter under the usual frequentist interpretation. Communicate the engineering range and decision consequence rather than ritual wording.

A superiority test asks whether a difference is supported. Equivalence asks whether performance lies within a predeclared region that is small enough to be operationally unimportant. Noninferiority asks whether a candidate is not worse by more than an accepted margin.

Large samples can make trivial differences statistically significant. Small samples can leave consequential differences uncertain. Always report effect size, interval, threshold or equivalence margin, and decision consequence.

Predeclare primary outcomes and subgroup analyses where possible. If exploration produces a promising claim, label it and seek confirmation rather than presenting it as prespecified evidence.

### Worked example

An upgraded dispatcher reduces mean wait by 0.4 minutes with p < 0.001 across 24,000 trips. The improvement is statistically clear but below the predeclared 1.0-minute practical threshold, while the 90th-percentile wait in the accessibility subgroup improves by 2.8 minutes with a wider interval. The engineering decision therefore depends on tail and subgroup estimands, not the overall mean p-value.

### Guided practice

1. Define estimands and decision thresholds for four course measures.
2. Calculate intervals using analytic and bootstrap methods and compare them.
3. Reframe one 'no difference' question as an equivalence or noninferiority question with a justified margin.
4. Perform a multiplicity and subgroup audit of the planned analysis.

### Independent exercises

* **Foundation:** Compute and interpret intervals for a mean, proportion, difference, and rate using a small dataset.
* **Application:** Analyze pilot-versus-baseline wait, accessibility, energy, and maintenance outcomes with appropriate estimands.
* **Analysis:** Compare conclusions from mean, percentile, subgroup, and rate analyses and explain why they differ.
* **Synthesis:** Issue a statistical inference decision memo that identifies supported, unsupported, and still-uncertain claims.
* **Stretch:** Use simulation to assess coverage, Type I error, power, or bootstrap performance under nonnormal and dependent data.

### Weekly deliverable

Submit the estimand registry, prespecified analysis plan, effect and interval results, assumption checks, equivalence/noninferiority rationale where applicable, multiplicity and subgroup analysis, engineering-significance table, decision memo, and revision record.

### Analytic rubric

| Criterion | Weight | Evidence of mastery |
|---|---:|---|
| Estimand and design fit | 25% | The quantity, population, condition, and comparison match the decision. |
| Inferential correctness | 30% | Intervals/tests and assumptions are appropriate and correctly interpreted. |
| Engineering interpretation | 30% | Effect, uncertainty, thresholds, tails, and subgroup consequences drive the conclusion. |
| Transparency | 15% | Multiplicity, exploratory work, exclusions, and unsupported claims are explicit. |

### Critical failures

* Failure to reject a difference is reported as proof of equivalence.
* A p-value is reported without effect size and interval.
* The overall average is allowed to override a critical subgroup or tail requirement.
* Exploratory subgroup findings are presented as prespecified confirmation.

### Knowledge check and answer guidance

1. **What is an estimand?**  
   *Answer guidance:* The precisely defined quantity the analysis seeks to estimate for a target population and condition.
2. **What does a confidence interval communicate?**  
   *Answer guidance:* The range produced by a procedure with stated long-run coverage under its assumptions, used to assess plausible engineering values and precision.
3. **Why is p < 0.05 insufficient?**  
   *Answer guidance:* It does not establish effect importance, model validity, requirement compliance, or decision value.
4. **What is equivalence testing?**  
   *Answer guidance:* Testing whether a difference lies inside a predeclared region of practical equivalence rather than merely failing to find a difference.
5. **What is multiplicity?**  
   *Answer guidance:* The increased opportunity for false findings when many outcomes, models, subgroups, or sequential looks are examined.

### Revision and mastery gate

Every inferential statement must name the estimand, population, conditions, method, assumptions, effect, interval, practical threshold, and decision implication. Unsupported or exploratory claims must be labeled and routed to additional evidence.

### Suggested workload

| Activity | Hours |
|---|---:|
| Study and hand calculations | 2.5 |
| Inference notebook | 3.5 |
| Engineering interpretation | 2.5 |
| Review and revision | 1.5 |
| **Total** | **10.0** |

### Configuration and portfolio update

Commit source data, data dictionary, code/notebooks, environment, tests, figures, machine-readable results, review comments, and revisions. Update the measure, assumption, uncertainty, data-quality, model-risk, and decision registers.

---
## Week 5 — Design efficient experiments with factors, responses, noise, power, randomization, and blocking

**Primary competency emphasis:** C7, C8, C9

### Professional context and essential question

Observational data can reveal association but often cannot separate configuration, environment, and operational causes. **Essential question:** What experiment will produce enough information to support the engineering decision without wasting runs or creating avoidable bias?

### Weekly learning outcomes

By the end of the week, the learner will be able to:

* translate an engineering question into experimental units, factors, levels, responses, and estimands
* distinguish control, noise, nuisance, blocking, covariate, and response variables
* choose randomization, replication, blocking, and run-order controls
* identify aliasing, confounding, carryover, interference, and operational constraints
* perform precision or power reasoning tied to an engineering effect size
* write an executable experiment protocol and readiness checklist

### Retrieval and readiness check

1. What is the experimental unit?
2. Why randomize run order?
3. What is the difference between replication and repeated measurement?
4. When should a factor be blocked rather than studied as a primary effect?

### Required study

* **NIST DOE chapter** — experiment objectives, designs, factors, responses, randomization, blocking, and analysis. **Purpose:** develop a defensible experiment. **Guiding question:** How does design structure protect the causal comparison? [NIST-DOE]
* **NIST process modeling** — models for relating inputs to responses. **Purpose:** connect planned design to eventual analysis. **Guiding question:** What model terms must the design estimate? [NIST-PROCESS]
* **statsmodels ANOVA documentation** — model and ANOVA implementation. **Purpose:** align the data structure and planned analysis. **Guiding question:** What degrees of freedom and error term will support each test? [STATSMODELS-ANOVA]

### Instructor-style lesson notes

Start with the decision and minimum consequential effect. A design should be able to estimate the effect or interaction that could change the decision, not merely fit within an arbitrary run budget.

The experimental unit is the smallest unit independently assigned to a treatment. Repeated sensor samples within one vehicle-run are not independent replicates of the operating policy.

Randomization protects against unknown time trends and assignment bias. Blocking removes known nuisance variation from the error term. Replication estimates variability and improves precision. These are design protections, not optional statistical decorations.

Interactions are central in systems engineering: temperature may change the benefit of preconditioning; passenger load may change the effect of dispatch policy; charger type may interact with battery age. Design for them explicitly.

Operational constraints may require split-plot, repeated-measures, or blocked designs. Document restrictions and use an analysis consistent with the randomization structure.

### Worked example

The team proposes comparing two dispatch policies on consecutive weeks. That design confounds policy with weather, demand, learning, and fleet condition. The revised experiment uses vehicle-day experimental units, randomizes policy within blocks defined by route and demand period, includes temperature and battery-age factors, repeats each combination, and predeclares wait-tail and energy responses. A simulation-based precision study shows the run count needed to detect a 1.5-minute 90th-percentile improvement.

### Guided practice

1. Write the experiment objective, decision, estimands, minimum consequential effects, and acceptance rules.
2. Identify experimental units, factors, levels, responses, blocks, covariates, and noise variables.
3. Create the randomization, replication, run-order, and contamination-control plan.
4. Perform a precision or power study and conduct the Experiment Readiness Review.

### Independent exercises

* **Foundation:** Diagnose pseudoreplication, confounding, and missing randomization in four proposed experiments.
* **Application:** Design a four-factor mobility experiment with at least one block and two responses.
* **Analysis:** Compare full factorial, fractional factorial, blocked, and split-plot options for cost and estimability.
* **Synthesis:** Issue an executable experiment protocol with data schema, analysis model, safety/operational constraints, and stop rules.
* **Stretch:** Simulate candidate designs under realistic noise and interaction effects to compare power, precision, and decision error.

### Weekly deliverable

Submit the experiment charter, causal rationale, experimental-unit definition, factors/levels/responses, effect-size thresholds, design matrix, alias or estimability assessment, randomization and blocking plan, run instructions, power/precision analysis, data contract, risk and stop rules, readiness checklist, review findings, and revised protocol.

### Analytic rubric

| Criterion | Weight | Evidence of mastery |
|---|---:|---|
| Decision and estimand | 20% | The experiment targets a consequential and precisely defined engineering effect. |
| Design validity | 35% | Experimental units, assignment, randomization, blocking, replication, and restrictions are correct. |
| Precision and feasibility | 25% | Run count and operational plan support required precision without hidden pseudoreplication. |
| Execution controls | 20% | Data, configuration, safety, contamination, stop, and review controls are executable. |

### Critical failures

* Repeated measurements are counted as independent treatment replicates.
* Policy is confounded with time, route, vehicle, or weather without mitigation.
* The design cannot estimate a decision-critical interaction.
* Run count is selected without an engineering effect size or precision target.

### Knowledge check and answer guidance

1. **What is an experimental unit?**  
   *Answer guidance:* The smallest unit independently assigned to a treatment or condition under the design.
2. **Why randomize?**  
   *Answer guidance:* To reduce assignment bias and distribute unknown nuisance effects, supporting valid causal comparisons.
3. **What does blocking do?**  
   *Answer guidance:* Groups similar experimental units or runs so known nuisance variability is separated from treatment comparison.
4. **What is pseudoreplication?**  
   *Answer guidance:* Treating nonindependent repeated observations as independent experimental units.
5. **What is an interaction?**  
   *Answer guidance:* A condition in which the effect of one factor depends on the level of another factor.

### Revision and mastery gate

The experiment may proceed only when treatment assignment, estimability, data capture, operational safety, precision, and analysis are coherent. A dry run must demonstrate that the data contract and run controls work before formal data collection.

### Suggested workload

| Activity | Hours |
|---|---:|
| Study and design diagnostics | 2.5 |
| Experiment design | 4.0 |
| Power and execution planning | 2.5 |
| Review and revision | 2.0 |
| **Total** | **11.0** |

### Configuration and portfolio update

Commit source data, data dictionary, code/notebooks, environment, tests, figures, machine-readable results, review comments, and revisions. Update the measure, assumption, uncertainty, data-quality, model-risk, and decision registers.

---
## Week 6 — Analyze factorial experiments, interactions, diagnostics, and confirmation evidence

**Primary competency emphasis:** C7, C8, C9

### Professional context and essential question

A factorial experiment is valuable because it reveals interactions and supports efficient learning, but only when its analysis respects the design. **Essential question:** Which factor combinations materially change performance, and how strong is the evidence?

### Weekly learning outcomes

By the end of the week, the learner will be able to:

* fit factorial and ANOVA models consistent with the design and randomization structure
* estimate and visualize main effects and interactions with uncertainty
* interpret aliasing and avoid claiming effects the design cannot separate
* diagnose residual, variance, dependence, influence, and model-form problems
* distinguish screening, estimation, optimization, and confirmation purposes
* design and analyze confirmation runs

### Retrieval and readiness check

1. Why can a small main effect coexist with an important interaction?
2. What does an ANOVA table not tell you by itself?
3. What is aliasing?
4. Why are confirmation runs needed?

### Required study

* **NIST DOE and process-modeling chapters** — factorial analysis, interactions, diagnostics, and interpretation. **Purpose:** analyze the Week 5 design correctly. **Guiding question:** Which model terms are estimable and meaningful? [NIST-DOE] [NIST-PROCESS]
* **statsmodels ANOVA** — factorial regression, ANOVA tables, contrasts, and diagnostics. **Purpose:** implement the planned model. **Guiding question:** Does the software formula reflect the actual design? [STATSMODELS-ANOVA]
* **NIST data analysis for process modeling** — model building and diagnostics. **Purpose:** prevent an attractive equation from hiding invalid assumptions. **Guiding question:** What residual behavior contradicts the fitted model? [NIST-PROCESS-ANALYSIS]

### Instructor-style lesson notes

Fit the planned model before searching many alternatives. Preserve factor coding, block terms, interaction hierarchy, and the correct experimental error structure.

Main effects average across other factors. When interaction is important, report conditional effects and engineering regions rather than one global main-effect statement.

ANOVA partitions variation under a model; it does not establish practical importance or prove assumptions. Pair it with effect estimates, intervals, plots, residual diagnostics, and decision thresholds.

For fractional designs, list the alias structure and avoid naming an effect as identified when it is confounded with another plausible term. Fold-over or follow-up runs may be necessary.

Confirmation runs should occur at selected and comparison settings, preferably under new time or operational conditions, and should test prediction rather than merely repeat the fitting data.

### Worked example

Analysis finds little average benefit from battery preconditioning, but a strong temperature-by-preconditioning interaction: negligible above 10°C and substantial below 0°C. Dispatch policy also interacts with passenger load. A main-effects-only recommendation would have rejected preconditioning. Diagnostics reveal increasing variance at high demand, so the analysis uses a transformed or heteroscedasticity-aware model and reports conditional prediction intervals. Confirmation runs in a later cold-weather block support the interaction within stated uncertainty.

### Guided practice

1. Execute or generate the controlled experiment data from the approved design.
2. Fit the prespecified factorial model and produce effects, intervals, interaction plots, and engineering comparisons.
3. Perform residual, influence, variance, block, run-order, and lack-of-fit diagnostics.
4. Plan and analyze confirmation runs, then conduct the Experiment Analysis Review.

### Independent exercises

* **Foundation:** Interpret a two-factor interaction table and explain why separate one-factor tests lose information.
* **Application:** Analyze the mobility experiment with factors, blocks, interactions, and two responses.
* **Analysis:** Compare conclusions under main-effects-only, full hierarchical, transformed, and robust-variance models.
* **Synthesis:** Issue a decision recommendation and confirmation plan that preserves conditional effects and uncertainty.
* **Stretch:** Analyze a fractional or split-plot variant and document aliasing or multiple error strata.

### Weekly deliverable

Submit the controlled experiment data, design verification, prespecified and sensitivity models, ANOVA/effect results, interaction and diagnostic figures, practical-significance table, confirmation design and results, decision memo, review findings, and revised experiment baseline.

### Analytic rubric

| Criterion | Weight | Evidence of mastery |
|---|---:|---|
| Design-consistent model | 25% | The formula, error structure, coding, blocks, and estimability match the experiment. |
| Effects and interactions | 30% | Conditional effects, intervals, thresholds, and interaction consequences are correctly interpreted. |
| Diagnostics and sensitivity | 25% | Residual, variance, influence, run-order, and model-form risks are tested. |
| Confirmation and decision | 20% | New evidence tests the recommendation and states residual uncertainty. |

### Critical failures

* A decision-critical interaction is omitted solely because its p-value or main effect is inconvenient.
* An aliased effect is described as uniquely identified.
* ANOVA p-values are reported without effect estimates, intervals, and diagnostics.
* Confirmation uses the same fitting data or conditions and is called independent evidence.

### Knowledge check and answer guidance

1. **What does a main effect represent?**  
   *Answer guidance:* The average change associated with a factor across the levels of other factors in the fitted design.
2. **Why preserve model hierarchy?**  
   *Answer guidance:* Including an interaction generally requires retaining its component main effects for coherent interpretation.
3. **What is aliasing?**  
   *Answer guidance:* Confounding of model terms such that the design cannot estimate them separately.
4. **What is lack of fit?**  
   *Answer guidance:* Evidence that the chosen model form does not adequately describe the response beyond pure experimental error.
5. **What is a confirmation run?**  
   *Answer guidance:* A planned observation at selected conditions used to test the model prediction and proposed setting after model development.

### Revision and mastery gate

The experiment analysis must reproduce from raw run data, respect the design, quantify interactions and practical effects, pass or bound diagnostics, and survive confirmation. Unsupported causal or global claims must be removed.

### Suggested workload

| Activity | Hours |
|---|---:|
| Study and model setup | 2.0 |
| Experiment analysis | 4.0 |
| Diagnostics and confirmation | 3.0 |
| Review and revision | 2.0 |
| **Total** | **11.0** |

### Configuration and portfolio update

Commit source data, data dictionary, code/notebooks, environment, tests, figures, machine-readable results, review comments, and revisions. Update the measure, assumption, uncertainty, data-quality, model-risk, and decision registers.

---
## Week 7 — Build and validate performance response models across use and environment

**Primary competency emphasis:** C7, C8

### Professional context and essential question

Systems engineers need models that predict performance under varying demand, weather, load, design, and condition. **Essential question:** What statistical response model is accurate, interpretable, and valid over the decision region?

### Weekly learning outcomes

By the end of the week, the learner will be able to:

* formulate linear, transformed, polynomial, generalized, and interaction response models
* separate prediction, explanation, interpolation, and extrapolation uses
* select variables and model forms using engineering structure as well as data
* diagnose residuals, leverage, collinearity, heteroscedasticity, dependence, and nonlinearity
* validate predictions using holdout, cross-validation, confirmation, and subgroup checks
* state the validated domain and prediction uncertainty

### Retrieval and readiness check

1. What is the difference between a confidence interval and a prediction interval?
2. Why is high R-squared insufficient?
3. What is extrapolation?
4. How can collinearity affect engineering interpretation?

### Required study

* **NIST process modeling** — model goals, regression, diagnostics, and use. **Purpose:** build engineering response models. **Guiding question:** Which model form supports the intended prediction or understanding? [NIST-PROCESS] [NIST-PROCESS-ANALYSIS]
* **statsmodels user guide** — regression, generalized models, diagnostics, and prediction. **Purpose:** implement multiple model forms. **Guiding question:** Which assumptions and output intervals apply? [STATSMODELS]
* **NIST model use and interpretation** — prediction and uncertainty. **Purpose:** prevent overreach. **Guiding question:** Where is the model supported and how uncertain is a new prediction? [NIST-PROCESS-USE]

### Instructor-style lesson notes

Choose the response distribution and link to match the data: continuous energy, positive skewed duration, binary completion, count failures, or proportions may require different models.

Engineering structure should guide variables and interactions. Blind stepwise selection can remove physically important terms, select noise, and understate model uncertainty.

Training fit is not predictive evidence. Reserve time blocks, vehicles, zones, or experimental conditions for validation, and test critical subgroups and tails.

Collinearity may allow good prediction while making individual coefficient interpretation unstable. Report this distinction and avoid causal language unless design supports it.

Publish a validated-domain table specifying ranges, configurations, populations, environments, and known gaps. Prediction beyond that domain is a separate model-use decision.

### Worked example

A model predicts charging time from temperature, state of charge, charger power, battery age, and their interactions. A simple linear model fits moderately but shows curved residuals and age-by-temperature interaction. A hierarchical polynomial or spline model improves validation error and interval calibration. The team refuses to predict below -12°C because no validation data exist there; instead it identifies an experiment or conservative bound.

### Guided practice

1. Define intended uses and target responses for wait, energy, charging, accessibility, and maintenance models.
2. Fit at least three defensible candidate forms and compare diagnostics and validation performance.
3. Evaluate subgroup, time, configuration, and tail calibration.
4. Create the validated-domain and extrapolation-risk record.

### Independent exercises

* **Foundation:** Interpret coefficients, interactions, residual plots, leverage, and prediction intervals for a small model.
* **Application:** Build a performance model as a function of use, environment, design, and age.
* **Analysis:** Compare mechanistic, linear, generalized, nonlinear, and flexible candidate forms with validation evidence.
* **Synthesis:** Conduct a Model Form Review and approve one model for specific uses while rejecting unsupported uses.
* **Stretch:** Use hierarchical or mixed-effects modeling to represent vehicle, route, day, or zone variation and compare with pooled analysis.

### Weekly deliverable

Submit the model-use statements, feature and response definitions, candidate models, training/validation design, coefficients or functional relationships, diagnostics, interval calibration, subgroup and tail checks, validated-domain table, extrapolation analysis, selected model rationale, review record, and reproducible notebook.

### Analytic rubric

| Criterion | Weight | Evidence of mastery |
|---|---:|---|
| Intended use and structure | 20% | The model target, variables, interactions, and form reflect the engineering process and decision. |
| Diagnostics | 25% | Residual, variance, dependence, influence, collinearity, and form risks are examined. |
| Validation | 35% | Predictions are tested on appropriate held-out conditions, subgroups, and tails with uncertainty. |
| Use bounds | 20% | Validated domain, extrapolation, limitations, and rejected uses are explicit. |

### Critical failures

* Training fit or R-squared is used as the only validation evidence.
* A model is extrapolated to an unobserved environmental or design region without warning or uncertainty treatment.
* Coefficient association is described as causal without experimental or causal-design support.
* Critical subgroup or tail calibration is ignored.

### Knowledge check and answer guidance

1. **What is a prediction interval?**  
   *Answer guidance:* An interval for a future observation that includes both model-estimation uncertainty and outcome variability under the model.
2. **What is extrapolation?**  
   *Answer guidance:* Using a model outside the input, configuration, population, or environmental region supported by development and validation evidence.
3. **Why is R-squared insufficient?**  
   *Answer guidance:* It does not establish correct form, unbiased prediction, valid assumptions, tail calibration, or external performance.
4. **What is collinearity?**  
   *Answer guidance:* Strong relationship among predictors that can make individual effects unstable even when combined prediction is useful.
5. **What is a validated domain?**  
   *Answer guidance:* The bounded set of conditions for which evidence supports the model's stated use and accuracy.

### Revision and mastery gate

The selected response model must have a stated use, reproducible training and validation, acceptable diagnostics or bounded corrections, calibrated uncertainty, and a controlled validated domain. Any planned Week 8–10 use outside that domain requires new evidence or explicit conservative treatment.

### Suggested workload

| Activity | Hours |
|---|---:|
| Study and model planning | 2.0 |
| Model development | 4.0 |
| Validation and diagnostics | 3.5 |
| Review and revision | 1.5 |
| **Total** | **11.0** |

### Configuration and portfolio update

Commit source data, data dictionary, code/notebooks, environment, tests, figures, machine-readable results, review comments, and revisions. Update the measure, assumption, uncertainty, data-quality, model-risk, and decision registers.

---
## Week 8 — Analyze reliability, availability, maintainability, degradation, and censored evidence

**Primary competency emphasis:** C6, C7, C8

### Professional context and essential question

Failures, repairs, degradation, and downtime often occur sparsely and under changing exposure. **Essential question:** What reliability and availability claims are supported by the event, exposure, censoring, and maintenance data?

### Weekly learning outcomes

By the end of the week, the learner will be able to:

* define reliability, failure rate, hazard, maintainability, availability, downtime, and exposure for the system context
* organize failure and repair data with configuration, cause, censoring, and recurrent-event information
* estimate and compare life, failure, repair, and availability models with uncertainty
* test model assumptions and identify competing risks, common causes, and informative censoring
* model degradation and reliability growth without confusing process improvement with changed reporting
* translate RAM evidence into operational and lifecycle decisions

### Retrieval and readiness check

1. What is the difference between reliability and availability?
2. What is right censoring?
3. Why is zero observed failures not zero failure probability?
4. What is a hazard function?

### Required study

* **NIST reliability chapter** — life data, reliability models, assumption checks, accelerated testing, and growth. **Purpose:** analyze sparse and censored engineering events. **Guiding question:** What exposure and censoring support the claim? [NIST-RELIABILITY]
* **NIST reliability assumption checks** — diagnostics for selected models. **Purpose:** prevent automatic distribution fitting. **Guiding question:** Which observed pattern contradicts the model? [NIST-RELIABILITY-CHECKS]
* **NASA Systems Engineering Handbook** — reliability, maintainability, margins, verification, and lifecycle integration. **Purpose:** connect RAM measures to architecture and decisions. **Guiding question:** Which design or support decision changes when RAM evidence changes? [NASA-SEH]

### Instructor-style lesson notes

Define the event and exposure. 'Failure rate' is meaningless without what counts as failure, the population, operating state, environment, configuration, and exposure unit.

Reliability concerns successful operation for a duration or mission; availability concerns readiness or uptime and includes restoration. High repairability can improve availability without improving reliability.

Right-censored units contribute survival information. Recurrent failures, repairable systems, and competing failure modes require structures different from simple first-failure life data.

Zero failures provide a bound dependent on exposure and confidence or credibility level, not proof of perfect reliability. Rare-event decisions often need precursor, physics, simulation, or structured prior evidence as well as direct events.

Reliability growth claims require stable definitions, configuration history, test intensity, and evidence that improvements—not reporting changes or easier conditions—explain the trend.

### Worked example

Twelve vehicles accumulate 18,000 operating hours with three propulsion interruptions and many censored vehicle histories. A naive estimate divides failures by calendar days. The corrected analysis uses operating exposure, configuration and temperature strata, recurrent-event records, and confidence bounds. Availability is analyzed separately using downtime duration and logistics delay. The evidence supports a charger-interface redesign and spares change but is insufficient to claim the propulsion requirement is met in severe cold.

### Guided practice

1. Create failure, repair, censoring, exposure, and configuration data structures.
2. Estimate reliability or event-rate measures with intervals and compare candidate models.
3. Analyze downtime by active repair, diagnostics, parts, logistics, and administrative delay.
4. Model one degradation indicator and evaluate a maintenance or replacement threshold.

### Independent exercises

* **Foundation:** Compute simple reliability, event-rate, MTBF, MTTR, and availability measures and identify their assumptions.
* **Application:** Analyze propulsion interruptions, charging failures, repairs, and censored vehicle histories.
* **Analysis:** Compare exponential, Weibull or alternative life/event models and test assumption sensitivity.
* **Synthesis:** Conduct the Performance Model Review and issue RAM design/support recommendations with bounds.
* **Stretch:** Analyze recurrent events, competing risks, Bayesian updating, accelerated-life data, or reliability growth with explicit assumptions.

### Weekly deliverable

Submit the RAM measure definitions, event/exposure/censoring dataset, configuration and cause taxonomy, reliability and repair analyses, model diagnostics, availability decomposition, degradation model, zero-failure or rare-event bounds, design/support recommendations, review findings, and revised model package.

### Analytic rubric

| Criterion | Weight | Evidence of mastery |
|---|---:|---|
| Event and exposure validity | 25% | Failures, missions, time, population, configuration, and censoring are correctly represented. |
| Model and uncertainty | 30% | Selected RAM/degradation models, diagnostics, intervals, and alternatives are defensible. |
| Availability and maintenance | 20% | Downtime and restoration drivers are decomposed into actionable contributors. |
| Lifecycle interpretation | 25% | Evidence leads to bounded design, support, monitoring, or replacement actions. |

### Critical failures

* Censored units are discarded or treated as failures at study end.
* Calendar time, operating exposure, missions, and fleet population are mixed without definition.
* Zero failures are described as zero risk or complete requirement compliance.
* Reliability and availability are treated as interchangeable.

### Knowledge check and answer guidance

1. **What is reliability?**  
   *Answer guidance:* The probability of performing required functions without failure for a specified time or mission under stated conditions.
2. **What is availability?**  
   *Answer guidance:* The probability or proportion of time a system is in an operable and committable state under stated support conditions.
3. **What is right censoring?**  
   *Answer guidance:* Knowing that an item survived at least to a time without observing its failure time.
4. **What is hazard?**  
   *Answer guidance:* The instantaneous failure tendency conditional on survival to that point.
5. **How should zero failures be interpreted?**  
   *Answer guidance:* As evidence that supports an upper bound or posterior estimate conditional on exposure and assumptions, not zero probability.

### Revision and mastery gate

RAM conclusions must preserve event definitions, exposure, censoring, configuration, model assumptions, and uncertainty. The learner must state which requirement or lifecycle decision is supported and which remains unresolved.

### Suggested workload

| Activity | Hours |
|---|---:|
| Study and hand calculations | 2.5 |
| RAM data and modeling | 4.0 |
| Degradation and decisions | 2.5 |
| Review and revision | 2.0 |
| **Total** | **11.0** |

### Configuration and portfolio update

Commit source data, data dictionary, code/notebooks, environment, tests, figures, machine-readable results, review comments, and revisions. Update the measure, assumption, uncertainty, data-quality, model-risk, and decision registers.

---
## Week 9 — Propagate uncertainty with analytic Monte Carlo simulation and sensitivity analysis

**Primary competency emphasis:** C7, C8, C9

### Professional context and essential question

Performance models combine uncertain demand, weather, component behavior, measurement, parameters, and future conditions. **Essential question:** What distribution of system outcomes follows from the controlled uncertainty model, and which inputs drive the result?

### Weekly learning outcomes

By the end of the week, the learner will be able to:

* construct an analytic simulation from traceable performance and reliability components
* represent input distributions, parameter uncertainty, scenarios, and dependence without double counting
* implement random sampling, seed policy, vectorized computation, and automated verification tests
* assess convergence and Monte Carlo precision for means, quantiles, probabilities, and rare outcomes
* perform local and global sensitivity analysis with correct interpretation
* distinguish uncertainty propagation, variability analysis, and optimization

### Retrieval and readiness check

1. What does Monte Carlo simulation estimate?
2. Why is a seed not sufficient evidence of reproducibility?
3. How can input dependence change tail outcomes?
4. What is the difference between local and global sensitivity?

### Required study

* **NIST uncertainty and process-modeling material** — propagation and model prediction uncertainty. **Purpose:** define the uncertainty model and output quantities. **Guiding question:** Which uncertainty components belong in the calculation? [NIST-EHANDBOOK] [NIST-PROCESS-USE]
* **JCGM GUM and publications** — measurement models and propagation. **Purpose:** maintain coherent uncertainty accounting. **Guiding question:** What is the measurand and how do inputs combine? [JCGM-GUM] [JCGM-PUBLICATIONS]
* **SALib documentation** — Morris, Sobol, and other global sensitivity methods. **Purpose:** identify influential inputs and interactions. **Guiding question:** Does the sampling design match the sensitivity estimator? [SALIB]
* **SciPy statistics** — random variables and quasi-Monte Carlo support. **Purpose:** implement controlled sampling and diagnostic comparisons. **Guiding question:** What evidence shows adequate numerical precision? [SCIPY-STATS]

### Instructor-style lesson notes

Write the analytic model as a traceable set of equations or functions before running it. Each input must map to a measure, model, source, unit, and uncertainty type.

Avoid double counting. Parameter uncertainty about a distribution, operational variability drawn from that distribution, and measurement error on observed data are distinct layers.

Model dependence explicitly through conditional models, common drivers, copulas, or empirical joint sampling. Verify that generated samples reproduce intended marginal and joint behavior.

Monte Carlo error is not system uncertainty. Quantify numerical precision with repeated batches, standard errors, interval estimates, or convergence plots for the actual output statistic, especially quantiles and small probabilities.

Local sensitivity asks how output changes near one point; global sensitivity apportions variation over an input space and can capture interactions. Sensitivity depends on the specified ranges and distributions and is not a universal property of the system.

### Worked example

The analytic model predicts 90th-percentile wait, energy use, availability, and accessible-trip fulfillment from demand, weather, fleet configuration, boarding distributions, charging behavior, and failure/repair models. Independent sampling estimates 4% probability of wait noncompliance; dependent weather-demand sampling raises it to 13%. Sobol analysis identifies demand-weather interaction and cold charging time as dominant, while vehicle-count uncertainty dominates only near the capacity threshold. Replicate batches show that 100,000 runs are adequate for the compliance probability but not for an extremely rare safety-event estimate.

### Guided practice

1. Create the input registry with source, type, distribution, parameter uncertainty, dependence, and validated range.
2. Implement the analytic simulation with unit tests and hand-check cases.
3. Run convergence and Monte Carlo precision studies for required output statistics.
4. Perform local and global sensitivity and explain dependence on the chosen uncertainty space.

### Independent exercises

* **Foundation:** Hand-check a small propagation model and compare analytic, linearized, and Monte Carlo results.
* **Application:** Build the campus mobility stochastic performance simulation.
* **Analysis:** Compare independent, conditional, and dependent input models and identify tail consequences.
* **Synthesis:** Conduct the Computational Evidence Review and approve output statistics for decision use.
* **Stretch:** Use variance reduction, quasi-Monte Carlo, importance sampling, or nested uncertainty to improve a difficult estimate.

### Weekly deliverable

Submit the analytic-model specification, input and dependence registry, code and tests, hand-check cases, seed and environment policy, convergence and numerical-precision evidence, output distributions and intervals, local/global sensitivity results, rare-event limitations, review findings, and revised simulation baseline.

### Analytic rubric

| Criterion | Weight | Evidence of mastery |
|---|---:|---|
| Model trace and verification | 25% | Equations/functions, units, inputs, outputs, and hand checks are coherent and tested. |
| Uncertainty representation | 30% | Variability, parameter, measurement, model-form, scenario, and dependence choices are controlled. |
| Numerical adequacy | 20% | Convergence and Monte Carlo precision are demonstrated for decision statistics. |
| Sensitivity and interpretation | 25% | Influential inputs, interactions, ranges, and action implications are correctly explained. |

### Critical failures

* Correlated inputs are sampled independently without consequence analysis.
* The same uncertainty is included twice under different names.
* A large run count is cited without precision or convergence evidence for the target statistic.
* Sensitivity indices are interpreted without stating input ranges and distributions.

### Knowledge check and answer guidance

1. **What does Monte Carlo simulation do?**  
   *Answer guidance:* It numerically propagates specified uncertain inputs through a model to estimate a distribution or statistic of outputs.
2. **What is Monte Carlo error?**  
   *Answer guidance:* Numerical sampling uncertainty in the estimated output statistic, distinct from modeled system uncertainty.
3. **Why model dependence?**  
   *Answer guidance:* Joint extremes and common causes can materially change output variance, tails, and compliance probability.
4. **What is global sensitivity?**  
   *Answer guidance:* Analysis of how output variation over a specified input space is associated with individual inputs and interactions.
5. **Why is a sensitivity ranking conditional?**  
   *Answer guidance:* It depends on the model, input distributions or ranges, dependence, output, and scenario.

### Revision and mastery gate

The simulation may support Week 10 decisions only if its trace, units, tests, input provenance, dependence, numerical precision, and sensitivity interpretation pass review. Unsupported rare-event or extrapolative claims must be removed or separately bounded.

### Suggested workload

| Activity | Hours |
|---|---:|
| Study and hand checks | 2.0 |
| Simulation implementation | 4.0 |
| Convergence and sensitivity | 3.5 |
| Review and revision | 2.0 |
| **Total** | **11.5** |

### Configuration and portfolio update

Commit source data, data dictionary, code/notebooks, environment, tests, figures, machine-readable results, review comments, and revisions. Update the measure, assumption, uncertainty, data-quality, model-risk, and decision registers.

---
## Week 10 — Quantify requirement compliance, technical margin, allocation risk, and design options

**Primary competency emphasis:** C2, C3, C8, C9

### Professional context and essential question

Requirements and budgets are often treated as deterministic lines even when performance and conditions are uncertain. **Essential question:** What is the probability of satisfying critical requirements, how much usable margin exists, and which design action most improves the evidence?

### Weekly learning outcomes

By the end of the week, the learner will be able to:

* translate requirements into measurable compliance events and operating-condition distributions
* estimate probability of compliance, conditional compliance, and confidence or credibility in the estimate
* distinguish design margin, statistical uncertainty, reserve, contingency, and tolerance
* analyze subsystem allocations and common-cause or covariance risk
* compare design and operating options using consistent measures and uncertainty
* issue a bounded requirements and design-margin recommendation

### Retrieval and readiness check

1. Why is mean performance not sufficient for a percentile requirement?
2. What is technical margin?
3. How can subsystem allocations appear safe while the system budget is unsafe?
4. What conditions define a valid compliance probability?

### Required study

* **NASA Systems Engineering Handbook and appendix** — requirements, margins, technical measures, and decision analysis. **Purpose:** connect statistical evidence to technical control. **Guiding question:** Which performance and margin information should trigger action? [NASA-SEH] [NASA-APPENDIX]
* **INCOSE Technical Measurement Guide** — status, trends, thresholds, and action. **Purpose:** define the measurement-to-control loop. **Guiding question:** How should a deteriorating margin be reported and acted upon? [INCOSE-TECH-MEAS]
* **NIST process-model use** — prediction and uncertainty. **Purpose:** calculate bounded compliance evidence. **Guiding question:** Does the prediction interval cover the requirement conditions? [NIST-PROCESS-USE]

### Instructor-style lesson notes

Convert requirement text into a measurable event with population, conditions, configuration, time basis, and method. A probability of compliance without these conditions is not reviewable.

Separate outcome variability from uncertainty in the estimated probability. Report both the estimated compliance probability and the precision or credibility of that estimate.

Margin is the difference between requirement limit and predicted or measured performance under a stated convention. Choose whether the comparison uses mean, percentile, confidence bound, worst credible case, or another approved basis and do not mix them.

Subsystem budgets are correlated through common environment, use, architecture, and measurement. Root-sum-square or simple addition is not automatically valid. Model covariance and shared drivers.

Compare options under the same input assumptions and decision measures. An option that improves average performance but worsens accessible-service tails or maintenance risk may not be preferred.

### Worked example

The wait-time requirement is the 90th percentile ≤ 12 minutes by zone and accessibility class during defined service hours. The simulation estimates 0.87 probability of compliance under the winter demand distribution, with wide uncertainty for one accessibility subgroup. Adding one vehicle raises compliance to 0.95 but increases cost and energy; a dispatch change raises it to 0.93 with lower cost but creates sensitivity to communication latency. The recommended staged option combines dispatch change, targeted vehicle reserve, and additional winter data, with a reopening trigger if subgroup compliance remains below 0.95.

### Guided practice

1. Create requirement-to-measurand definitions for five critical requirements.
2. Estimate unconditional and conditional compliance probabilities with intervals or credibility bounds.
3. Build a technical-margin and allocation-risk ledger with common dependencies.
4. Compare three improvement options and conduct Lifecycle Analytics Review I.

### Independent exercises

* **Foundation:** Calculate deterministic margin, probabilistic compliance, and uncertainty bounds for simple examples.
* **Application:** Analyze wait, accessibility, availability, energy, and charging requirements under realistic conditions.
* **Analysis:** Test sensitivity to operational distributions, dependence, subgroup definitions, and allocation assumptions.
* **Synthesis:** Issue a design and operations recommendation with action thresholds and residual risk.
* **Stretch:** Formulate chance constraints, reliability-based design, or probabilistic budget allocation for one critical requirement.

### Weekly deliverable

Submit the requirement-measure crosswalk, compliance event definitions, condition and population models, probability and interval results, subgroup analysis, technical-margin ledger, allocation/covariance model, option comparison, sensitivity and reversal analysis, decision memo, review findings, and revised requirements evidence baseline.

### Analytic rubric

| Criterion | Weight | Evidence of mastery |
|---|---:|---|
| Compliance definition | 25% | Requirements, populations, conditions, configurations, and events are measurable and traceable. |
| Probability and margin rigor | 30% | Compliance, uncertainty, margin basis, tails, and subgroup effects are correctly quantified. |
| Allocation and dependence | 20% | Common drivers, covariance, and subsystem-to-system risk are modeled. |
| Decision recommendation | 25% | Options, residual risk, actions, and reversal conditions follow from consistent evidence. |

### Critical failures

* Mean performance is used to claim a percentile, reliability, or subgroup requirement is met.
* A margin number is reported without defining its statistical and operating basis.
* Subsystem allocations are combined under an unjustified independence assumption.
* A critical subgroup is omitted because its sample or compliance is inconvenient.

### Knowledge check and answer guidance

1. **What is probability of compliance?**  
   *Answer guidance:* The modeled or estimated probability that a precisely defined requirement event is satisfied under stated populations, conditions, configurations, and uncertainty.
2. **What is technical margin?**  
   *Answer guidance:* A controlled difference between a performance estimate or bound and a requirement or allocation, under a specified calculation convention.
3. **Why report conditional compliance?**  
   *Answer guidance:* Overall compliance can hide failure in zones, weather, configurations, or protected/critical subgroups.
4. **What is allocation risk?**  
   *Answer guidance:* Risk that subsystem budgets, interactions, covariance, or growth cause the system-level requirement to be missed.
5. **What is a reversal condition?**  
   *Answer guidance:* A stated evidence, assumption, requirement, or context change that would alter or reopen the recommendation.

### Revision and mastery gate

Each critical requirement must have a measurable event, operating-condition model, compliance estimate with uncertainty, margin basis, and action decision. The learner must defend why the recommended option is preferable under both central and stressed assumptions.

### Suggested workload

| Activity | Hours |
|---|---:|
| Study and requirement formalization | 2.0 |
| Compliance and margin analysis | 4.0 |
| Options and sensitivity | 3.0 |
| Review and revision | 2.0 |
| **Total** | **11.0** |

### Configuration and portfolio update

Commit source data, data dictionary, code/notebooks, environment, tests, figures, machine-readable results, review comments, and revisions. Update the measure, assumption, uncertainty, data-quality, model-risk, and decision registers.

---
## Week 11 — Update lifecycle evidence and decide among upgrade, replacement, retirement, or more information

**Primary competency emphasis:** C1, C8, C9, C10

### Professional context and essential question

A system can remain operational while its margin, supportability, safety evidence, or mission relevance erodes. **Essential question:** When should the program improve, replace, retire, defer, or collect more evidence?

### Weekly learning outcomes

By the end of the week, the learner will be able to:

* construct time-indexed technical measures and detect meaningful trend, drift, degradation, and change points
* update performance and reliability evidence as new data arrive without hiding configuration change
* compare upgrade, replacement, retirement, defer, and collect-more-information alternatives
* integrate technical, cost, schedule, operational, safety, accessibility, and support evidence
* assess expected value or decision value of additional information at a practical level
* define implementation conditions, monitoring plans, and revisit triggers

### Retrieval and readiness check

1. What is the difference between process variation and degradation?
2. Why can a trend be caused by changing configuration or population?
3. What does value of information ask?
4. Why is retirement a systems-engineering decision rather than only an age threshold?

### Required study

* **NASA Systems Engineering Handbook** — operations, technical assessment, decision analysis, and retirement. **Purpose:** connect analytic evidence to lifecycle action. **Guiding question:** What technical evidence should reopen a baseline or end a system's service? [NASA-SEH]
* **INCOSE Technical Measurement Guide** — trending, thresholds, and corrective action. **Purpose:** establish a sustained technical-control loop. **Guiding question:** Which trend is actionable rather than noise? [INCOSE-TECH-MEAS]
* **NIST reliability and process modeling** — degradation, reliability growth, prediction, and uncertainty. **Purpose:** update lifecycle models. **Guiding question:** How does new evidence change the estimated future state? [NIST-RELIABILITY] [NIST-PROCESS]

### Instructor-style lesson notes

Trend analysis requires consistent definitions and configuration. A step change may reflect firmware, sensor, route, population, maintenance, or reporting changes rather than physical degradation.

Use control charts, regression with time and covariates, degradation models, survival or event models, and change-point logic as appropriate. Do not fit a line through every time series and call it a forecast.

Lifecycle alternatives include continue as-is, operational mitigation, targeted upgrade, major redesign, replacement, phased retirement, and collect more information. Preserve the do-nothing and staged options.

Technical evidence must be integrated with cost, schedule, supply, workforce, safety, accessibility, cybersecurity, mission demand, and transition risk. The statistical model informs but does not own these preferences or authorities.

Value of information asks whether reducing a specific uncertainty could change the decision enough to justify the cost, delay, and risk of obtaining that evidence. More data are not automatically valuable.

### Worked example

Battery energy intensity rises 2.2% per 1,000 equivalent cycles after controlling for temperature, route, and load; charger downtime also increases for one firmware/configuration. An immediate fleet replacement is not justified. A staged package—firmware correction, targeted battery replacement above a degradation threshold, cold-weather validation, and a two-quarter monitoring gate—has lower regret. Full replacement becomes preferred if projected winter availability falls below 0.95 or maintenance labor exceeds the defined threshold despite corrective action.

### Guided practice

1. Create time-indexed technical-measure views with configuration and uncertainty.
2. Test for trend, change points, degradation, and alternative explanations.
3. Define at least five lifecycle alternatives and the evidence required for each.
4. Estimate the decision value of one additional test or data-collection campaign and conduct Lifecycle Analytics Review II.

### Independent exercises

* **Foundation:** Diagnose trend, seasonality, step change, regression to the mean, and configuration effects in sample series.
* **Application:** Update the campus mobility performance and RAM models with sequential field data.
* **Analysis:** Compare continue, mitigate, upgrade, replace, retire, and information alternatives under multiple futures.
* **Synthesis:** Issue the lifecycle action recommendation, implementation conditions, monitoring plan, and revisit triggers.
* **Stretch:** Use Bayesian updating, state-space models, change-point methods, or real-options reasoning for one lifecycle uncertainty.

### Weekly deliverable

Submit the controlled time-series dataset, configuration timeline, trend/degradation models, diagnostics and alternative explanations, updated performance/RAM evidence, lifecycle alternative set, technical-cost-schedule-risk comparison, value-of-information analysis, monitoring and transition plan, decision record, review findings, and revised recommendation.

### Analytic rubric

| Criterion | Weight | Evidence of mastery |
|---|---:|---|
| Trend and update validity | 25% | Time, configuration, covariates, uncertainty, and alternative explanations are controlled. |
| Alternative completeness | 20% | Continue, staged, upgrade, replace, retire, and information options are considered. |
| Integrated lifecycle analysis | 30% | Technical, cost, schedule, operational, support, safety, and transition evidence are coherent. |
| Action and monitoring | 25% | Recommendation, conditions, indicators, thresholds, and revisit triggers are executable. |

### Critical failures

* A raw trend is attributed to degradation without controlling for configuration, environment, use, or population.
* Replacement is compared only against continued operation, omitting staged or targeted options.
* More data are recommended without identifying which uncertainty or decision could change.
* Retirement or upgrade conditions have no measurable trigger or transition plan.

### Knowledge check and answer guidance

1. **What is degradation?**  
   *Answer guidance:* A systematic loss of performance or condition over exposure or time, distinguished from reversible variation and measurement change.
2. **What is a change point?**  
   *Answer guidance:* A time at which the statistical behavior or governing process changes.
3. **What is value of information?**  
   *Answer guidance:* The expected decision benefit from reducing a specific uncertainty, compared with the cost and delay of obtaining information.
4. **Why preserve a configuration timeline?**  
   *Answer guidance:* Observed trends may reflect system, software, sensor, mission, maintenance, or reporting changes rather than aging.
5. **What is a revisit trigger?**  
   *Answer guidance:* A measurable condition or new evidence that requires the decision to be reviewed.

### Revision and mastery gate

The lifecycle recommendation must compare credible alternatives, quantify or bound key technical uncertainty, identify the value of additional evidence, and specify executable monitoring and reversal conditions. Review findings must be closed before final integration.

### Suggested workload

| Activity | Hours |
|---|---:|
| Study and trend diagnostics | 2.0 |
| Model update and alternatives | 4.0 |
| Value of information and planning | 3.0 |
| Review and revision | 2.0 |
| **Total** | **11.0** |

### Configuration and portfolio update

Commit source data, data dictionary, code/notebooks, environment, tests, figures, machine-readable results, review comments, and revisions. Update the measure, assumption, uncertainty, data-quality, model-risk, and decision registers.

---
## Week 12 — Integrate, reproduce, challenge, and defend the lifecycle analytics decision

**Primary competency emphasis:** C7, C8, C9, C12

### Professional context and essential question

A final report is useful only if the evidence chain can be reproduced, challenged, and revised. **Essential question:** What does the complete quantitative evidence support, what does it not support, and what would change the decision?

### Weekly learning outcomes

By the end of the week, the learner will be able to:

* integrate measures, data, experiments, statistical models, RAM, simulation, margins, and lifecycle options into one evidence chain
* create consistent executive, technical, and machine-readable products
* audit reproducibility, traceability, uncertainty, subgroup effects, and decision authority
* respond to a surprise data defect, requirement change, or environmental shift
* reproduce key calculations during an oral defense
* issue a controlled final decision and downstream MBSE-analytics handoff

### Retrieval and readiness check

1. What is the complete evidence chain?
2. Which conclusion has the weakest support?
3. What is the difference between an analytic recommendation and authorization to implement?
4. What must be handed to EN.645.632?

### Required study

* **JHU course description and syllabus** — integrated statistics, modeling, simulation, and lifecycle decision scope. **Purpose:** verify that the capstone demonstrates the source-course capability. **Guiding question:** Does the work support requirements, design, upgrade, and retirement decisions? [JHU-756-COURSE] [JHU-756-SYLLABUS]
* **NASA Systems Engineering Handbook** — technical assessment, decision analysis, configuration, operations, and retirement. **Purpose:** close the lifecycle evidence chain. **Guiding question:** Which authority and next process receives the recommendation? [NASA-SEH]
* **Phase 3 README and EN.645.632 course file** — analytic traceability and MBSE handoff. **Purpose:** prepare reusable model, metric, and evidence interfaces. **Guiding question:** Which elements must become queryable and connected to the authoritative system model?

### Instructor-style lesson notes

Build the evidence chain explicitly: decision → stakeholder outcomes and requirements → measures → data and experiment design → statistical and reliability models → uncertainty propagation → compliance and margins → lifecycle alternatives → recommendation → implementation conditions and monitoring.

Create an executive decision record, a technical report, reproducible notebooks/scripts, machine-readable measure and result tables, and a review history. They serve different audiences but must agree.

Run a red-team audit for hidden exclusions, subgroup harm, unjustified independence, invalid extrapolation, model-form sensitivity, threshold manipulation, and recommendations beyond the authority or evidence.

The live challenge changes one consequential element: a sensor calibration defect, a new accessibility requirement, a harsher winter distribution, a supplier discontinuation, or a revised cost/schedule constraint. Revise the analysis rather than defending the original answer reflexively.

The oral defense tests understanding and reproducibility. The learner must regenerate one experiment result, one RAM or response-model result, and one Monte Carlo compliance result from controlled source.

### Worked example

The integrated recommendation is a staged charging and dispatch upgrade with targeted battery replacement, conditional on winter confirmation and accessibility subgroup monitoring. During the defense, a timestamp calibration defect increases charging-duration uncertainty and weakens the upgrade's predicted benefit. The learner revises the input model, reruns the Monte Carlo and option comparison, retains the staged recommendation but moves the winter test ahead of fleet-scale purchase and tightens the revisit trigger.

### Guided practice

1. Create the complete evidence-chain and traceability maps.
2. Regenerate all final figures and tables from a clean environment using the run book.
3. Conduct an independent red-team review and disposition findings.
4. Perform the live challenge, oral defense, revision, and controlled downstream handoff.

### Independent exercises

* **Foundation:** Audit every course critical-mastery criterion and close or bound each issue.
* **Application:** Complete the lifecycle analytics capstone and repository.
* **Analysis:** Run sensitivity to model form, missing data, subgroup definitions, dependence, thresholds, and future scenarios.
* **Synthesis:** Conduct the Final Lifecycle Analytics Review and issue the final controlled decision record.
* **Stretch:** Create a one-command or workflow-based build that regenerates the synthetic data, analyses, figures, result tables, and final appendix.

### Weekly deliverable

Submit the final capstone report, executive decision record, evidence-chain and traceability maps, measure and result tables, complete controlled data/code/environment/test repository, run book, review and finding records, live-challenge analysis, oral-defense record, revised recommendation, portfolio manifest, and EN.645.632 handoff package.

### Analytic rubric

| Criterion | Weight | Evidence of mastery |
|---|---:|---|
| Integrated evidence chain | 30% | Measures, data, experiments, models, uncertainty, requirements, and lifecycle actions are coherent and traceable. |
| Technical rigor | 25% | Statistical, DOE, response, RAM, Monte Carlo, and sensitivity evidence is valid and bounded. |
| Reproducibility and review | 20% | A clean environment regenerates results and findings are controlled and dispositioned. |
| Defense and adaptability | 25% | The learner explains limits, reproduces results, and revises responsibly under challenge. |

### Critical failures

* Executive and technical products disagree on a result, condition, or recommendation.
* A key figure or decision result cannot be regenerated from controlled source.
* A surprise defect is dismissed or hidden to preserve the preferred answer.
* The recommendation exceeds the validated evidence, decision authority, or lifecycle gate.

### Knowledge check and answer guidance

1. **What is an evidence chain?**  
   *Answer guidance:* Traceable linkage from decision and requirements through measures, data, models, uncertainty, analysis, recommendation, and action conditions.
2. **Why separate recommendation from authorization?**  
   *Answer guidance:* Funding, safety, regulatory, contractual, validation, or governance gates may still control implementation.
3. **What is reproducibility?**  
   *Answer guidance:* The ability to regenerate results from controlled data, source, environment, parameters, and documented procedures.
4. **What belongs in the downstream handoff?**  
   *Answer guidance:* Queryable measures and definitions, data/model provenance, result and uncertainty records, traces to requirements/architecture/decisions, limitations, and update rules.
5. **What is the analyst's final obligation?**  
   *Answer guidance:* State what the evidence supports, what it does not, who owns the decision, residual risk, and what would change the conclusion.

### Revision and mastery gate

The learner must pass the oral defense, reproduce the required analyses, respond to the live challenge, close all critical findings, and issue a final decision record whose authority, limitations, conditions, monitoring, and reversal triggers are explicit.

### Suggested workload

| Activity | Hours |
|---|---:|
| Final integration | 3.5 |
| Reproducibility and red team | 3.0 |
| Defense and live challenge | 3.0 |
| Revision and handoff | 2.0 |
| **Total** | **11.5** |

### Configuration and portfolio update

Commit source data, data dictionary, code/notebooks, environment, tests, figures, machine-readable results, review comments, and revisions. Update the measure, assumption, uncertainty, data-quality, model-risk, and decision registers.

---
## References

[JHU-756-COURSE]: https://ep.jhu.edu/courses/645756-metrics-modeling-and-simulation-for-systems-engineering/ "Metrics, Modeling, and Simulation for Systems Engineering — Johns Hopkins Engineering for Professionals"
[JHU-756-SYLLABUS]: https://apps.ep.jhu.edu/syllabus/fall-2024/645.756.1130 "Fall 2024 public syllabus for EN.645.756"
[NASA-SEH]: https://www.nasa.gov/reference/systems-engineering-handbook/ "NASA Systems Engineering Handbook"
[NASA-APPENDIX]: https://www.nasa.gov/reference/system-engineering-handbook-appendix/ "NASA Systems Engineering Handbook Appendix — technical measures and definitions"
[INCOSE-TECH-MEAS]: https://www.incose.org/docs/default-source/ProductsPublications/technical-measurement-guide---dec-2005.pdf?sfvrsn=4&sfvrsn=4 "INCOSE Technical Measurement Guide"
[NIST-EHANDBOOK]: https://www.itl.nist.gov/div898/handbook/ "NIST/SEMATECH e-Handbook of Statistical Methods"
[NIST-EDA]: https://www.itl.nist.gov/div898/handbook/eda/eda.htm "NIST/SEMATECH e-Handbook — Exploratory Data Analysis"
[NIST-PROCESS]: https://www.itl.nist.gov/div898/handbook/pmd/pmd.htm "NIST/SEMATECH e-Handbook — Process Modeling"
[NIST-PROCESS-ANALYSIS]: https://www.itl.nist.gov/div898/handbook/pmd/section4/pmd4.htm "NIST/SEMATECH e-Handbook — Data Analysis for Process Modeling"
[NIST-PROCESS-USE]: https://www.itl.nist.gov/div898/handbook/pmd/section5/pmd5.htm "NIST/SEMATECH e-Handbook — Use and Interpretation of Process Models"
[NIST-DOE]: https://www.itl.nist.gov/div898/handbook/pri/pri.htm "NIST/SEMATECH e-Handbook — Process Improvement and Design of Experiments"
[NIST-RELIABILITY]: https://www.itl.nist.gov/div898/handbook/apr/apr.htm "NIST/SEMATECH e-Handbook — Assessing Product Reliability"
[NIST-RELIABILITY-CHECKS]: https://www.itl.nist.gov/div898/handbook/apr/section2/apr23.htm "NIST/SEMATECH e-Handbook — Testing Reliability Model Assumptions"
[JCGM-GUM]: https://www.bipm.org/en/doi/10.59161/jcgm100-2008e "JCGM 100:2008 — Guide to the Expression of Uncertainty in Measurement"
[JCGM-PUBLICATIONS]: https://www.bipm.org/en/committees/jc/jcgm/publications "JCGM publications, including GUM guides and amendments"
[SCIPY-STATS]: https://docs.scipy.org/doc/scipy/reference/stats.html "SciPy statistical functions documentation"
[STATSMODELS]: https://www.statsmodels.org/stable/user-guide.html "statsmodels user guide"
[STATSMODELS-ANOVA]: https://www.statsmodels.org/stable/anova.html "statsmodels ANOVA documentation"
[SALIB]: https://salib.readthedocs.io/en/stable/ "SALib sensitivity analysis documentation"
[PANDAS]: https://pandas.pydata.org/docs/ "pandas documentation"
[JUPYTER]: https://jupyter.org/documentation "Project Jupyter documentation"

[Back to Phase 3 README](README.md) · [Back to program README](../README.md)
