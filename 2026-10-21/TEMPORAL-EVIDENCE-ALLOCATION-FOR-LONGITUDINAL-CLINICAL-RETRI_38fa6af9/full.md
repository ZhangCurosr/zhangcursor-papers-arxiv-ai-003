# TEMPORAL EVIDENCE ALLOCATION FOR LONGITUDINAL CLINICAL RETRIEVAL: A POSITION AND TECHNICAL REPORT

A PREPRINT

Soumya Ranjan Sahoo, Divya Bharti, Sanand Sasidharan GE HealthCare Technology and Innovation Center, India

## ABSTRACT

Electronic health records are written to support care, not retrieval. Across years of oncology notes, the primary diagnosis is restated in report after report, while the events that shape a patient’s course, such as a recurrence or a change in therapy, may be recorded only once. A retriever that ranks passages by similarity to the query keeps returning the repeated material and can miss these transitions, that is, it exhibits temporal redundancy across historical narratives. We argue that longitudinal clinical retrieval should be treated as allocating a limited evidence budget across time, not just ranking by relevance. We separate the task into three objectives: temporal evidence allocation, candidate reconstruction, and clinical validation. In Study A (13 clinical queries over 20 patient records, with two-stage reconstruction), the Temporal-15 configuration reaches a milestone slot recall of 0.538, compared with 0.388 for the Global-50 baseline. However, it also retrieves far more evidence (496 versus 50 indexed units per query), so the gain cannot be credited to allocation alone. When evidence is held fixed, removing prompted precedence rules raises schema-order reversals from 0.010 to 0.080. A five-patient, single-query pilot with fixed budgets finds that wider temporal coverage does not reliably yield more dated milestones. Together, these results suggest that how much a record says about a period is a poor guide to how useful that period is as evidence. Because no expert reference timelines are available, our measurements describe retrieval behavior rather than clinical accuracy. This position and technical report presents the retrieval analysis behind the Onco-CONSTRUE framework and sets out a research agenda for budget-constrained longitudinal clinical retrieval.

Keywords: longitudinal clinical retrieval, temporal evidence allocation, oncology timelines, retrieval-augmented generation, no-gold development diagnostics

## 1 Introduction: the missing transition problem

Consider an author-constructed oncology record. Six follow-up notes copy forward a cancer diagnosis. A single earlier pathology report records confirmation, and a later scan suggests progression. With a small evidence allowance, a global similarity search might spend most of its selections on the repeated notes. A time-aware allocation could give the isolated reports a chance to enter the context. If the model then places treatment before confirmation, a prompted precedence check could flag or discourage that order under the declared milestone schema. This example is illustrative, not an observed failure or measured benefit. It shows three separate decisions: where to search, which evidence adds information, and how to order candidate events.

Electronic health records contain the materials for a timeline, but rarely contain the timeline itself. Pathology, radiology, treatment records, laboratory results, and narrative notes describe different parts of a patient’s course. Some notes restate old events. Others describe a plan that was never carried out. A useful reconstruction must connect these observations without treating repetition as new evidence.

The missing transition is an IR problem before it is a generation problem. Diagnosis, treatment changes, and recurrence may appear only once among years of routine documentation. Semantic relevance alone does not tell a system how to spread its attention across that history. Longer context does not settle the issue either: models can underuse information in long inputs [1], and longitudinal clinical tasks still require temporal reasoning [2].

Our position is that longitudinal retrieval is evidence allocation. Time, source diversity, repetition, and the question being asked should help determine which evidence enters a finite context. Density describes the observation process, but not necessarily clinical importance. The next question is not whether to retrieve from dense periods, but when evidence from another period adds new clinical information.

This report develops the methodological foundation emerging from Onco-CONSTRUE. It extends the retrieval analysis underlying our accepted IEEE BHI 2026 abstract. That abstract describes a broader architecture, including Clinical Skill Units (CSUs), temporal governance, an independent validation stage, retry logic, endpoint computation, and privacy controls. Here we examine retrieval allocation and prompt-level candidate reconstruction, rather than the complete framework. The contribution is a task formulation, a measurement framework, and lessons from two studies, not a new oncology extraction model.

Study A is the main mechanism exploration: 20 patients, 13 clinical queries, two-stage reconstruction, four conditions, and three runs per condition. It examines retrieval exposure and a paired constraint ablation. Study B is a secondary budget-controlled pilot: five patients, one whole-course query, direct reconstruction, five policies, and three indexed-unit limits. It asks whether spreading the same number of indexed units across more periods also fills more milestone slots. Study B is not a matched reanalysis of Study A. It changes the task and does not test the effectiveness of the 13-query pipeline.

## What this paper claims and does not claim

Claims. Temporal evidence allocation should be an explicit IR objective. Retrieval and chronological reconstruction are distinct stages. Prompted precedence rules reduce schemaorder reversals in a paired comparison. No-gold diagnostics expose different failure modes. Broader temporal coverage does not guarantee more dated milestones.

Does not claim. Clinically accurate patient timelines, validated progression or treatment-line endpoints, superiority of a specific retriever at a matched budget, generalization beyond this cohort, or production and regulatory readiness.

## 2 Position: longitudinal retrieval is evidence allocation

The framework separates five questions:

• Temporal evidence allocation: where retrieval capacity is spent across the patient history.

• Temporal breadth: how much of the documented history appears in the selected evidence.

• Evidence exposure: how many indexed units and tokens reach each model stage.

• Reconstruction validity: whether candidate output follows the declared schema and order.

• No-gold development diagnostics: whether output behavior and evidence dependence are coherent enough to justify expert review.

Allocation chooses where to look, while ranking chooses items within those opportunities. Breadth describes the spread of attention, not event recovery. Exposure should be defined according to the appropriate model stage, as hundreds of retrieved units do not necessarily correspond to hundreds of units included in the final reconstruction prompt. Reconstruction validity concerns the structural integrity of the reconstruction process, whereas confirming whether an event actually occurred remains a clinical matter. No-gold diagnostics help identify failures before expensive annotation, rather than certify an output.

## 2.1 Budgeted allocation

For period w, let $N _ { w }$ be its indexed-unit count and $k _ { w }$ the number of units selected. A fixed indexed-unit allowance K imposes

$$
0 \le k _ { w } \le N _ { w } , \qquad \sum _ { w } k _ { w } \le K .\tag{1}
$$

Rank indexed units within each period by query similarity. Assign each period a weight, convert the weights to quotas, cap quotas at available units, and redistribute unused quota. Section 5 specifies the tested rules. A clinically meaningful weight does not necessarily increase in proportion to the number of indexed units. Repeated information may contribute little additional value, whereas a relatively sparse period may capture a critical transition or key change.

## 2.2 Three related research conversations

Longitudinal patient-record retrieval. Clinical IR links patient-specific questions to evidence [3], and RAG supplies that evidence to a generator [4]. Within record retrieval must also handle private, heterogeneous, and redundant histories. MedAlign grounds clinician-written instructions in longitudinal EHRs [5]. Query-dependent truncation and event and time aware EHR retrieval show why selection rules deserve study [6, 7].

Temporal events and timeline reconstruction. Temporal IR distinguishes when a document was written from when its events occurred [8]. Clinical temporal NLP separates event extraction, date normalization, and relation prediction [9]. ChemoTimelines makes oncology reconstruction a concrete evaluation task [10, 11]. Cross-modal work uses structured rows to calibrate narrative events [12]. We hold that upstream representation fixed and examine which evidence reaches reconstruction.

Evaluation without full clinical labels. Attribution, abstention, and completeness measure different aspects of generated clinical text [13–15]. They motivate separate diagnostics rather than a single plausibility score.

Downstream-aware evaluation such as eRAG offers a useful IR precedent [16], but requires downstream ground truth. No-gold development diagnostics measure inspectable behavior while leaving clinical correctness for later validation.

## 3 Oncology reconstruction task

## 3.1 Data and consolidated evidence layer

The internally held, de-identified source cohort contains 140 pseudonymized oncology patients, 1,235,872 OMOP records, and 14,961 clinical note or report records. Study A uses a prespecified, cost-controlled subset of 20 patients: ten with lung cancer and ten with prostate cancer, selected across follow-up, recurrence status, and documentation density. Its frozen derived index contains 209,052 dated rows, with a median of 9,435 per patient (range 924–32,376). The recorded follow-up field spans 17 - 88 months. This rage does not limit or truncate longer date spans present in the index.

Notes and report findings contribute atomic facts organized into OMOP-style event categories. Structured OMOP rows contribute complementary observations. The consolidated patient index stores event dates, source types, indexed-unit identifiers, text representations, and embeddings. This follows the broader goal of representing narrative NLP outputs alongside structured observations [17]. “OMOPstyle” describes the organization of extracted facts, not demonstrated complete CDM conformance. Raw clinical text and patient identifiers are not released.

The retrieval unit: An indexed evidence unit is one retrievable row in the consolidated index. It represents an OMOP-derived structured observation or an atomic fact derived from narrative material. It is not necessarily a complete note or an independent clinical event. A source record is the underlying note, report, or structured observation from which indexed content originates. More than one unit can originate from a narrative source.

An indexed-unit identifier uniquely identifies a retrievable row. The implementation calls this field id and renders it as source\_id in prompts. Retrieval deduplicates these IDs, not underlying notes or reports. A distinct indexed ID therefore does not establish a distinct source record. We use “distinct units” for the cross-query union counts below and are not report deduplicated at the level of the parent clinical source.

## 3.2 Why 13 focused clinical queries?

The main pipeline searches separately for chemotherapy, surgery, immunotherapy, prostate-specific antigen, radiology, biomarkers, clinical findings, pathology, staging, comorbidities, radiation, toxicity, and performance status. These 13 prespecified views serve different evidence needs. Pathology may establish confirmation, treatment records may establish exposure, and scans may describe disease status. Toxicity and performance-status notes can help interpret a treatment change. One whole-course request asks a single ranking to serve all those needs at once.

Focused queries make the search more directed. They give less frequently documented evidence types their own opportunity to enter the context, rather than requiring them to compete with every repeated description of the dominant diagnosis. Each query produces a source linked evidence timeline. Reconstruction combines the 13 views so that conflicts and missing information can be inspected across sources. This is our clinical design rationale. We did not run a controlled comparison proving that 13 queries outperform one.

## 3.3 Candidate milestones and generation

The 13 timelines feed 11 slots - first evidence, confirmation, three treatment-line starts, three treatment-line ends, and three disease-status transitions. The transition slots retain the legacy recurrence/progression field names. They are not adjudicated endpoints, and the study does not distinguish radiographic, biochemical, and clinical progression. The shared fields do not make recurrence and progression interchangeable.

A slot can contain an ISO date or null. It also records status (documented, approximate, inferred, or unknown), confidence, indexed-unit identifiers, supporting evidence, and a reason. The prompt permits abstention instead of forcing a date.

Queries are embedded with a private deployment of text-embedding-3-large. A private enterprise GPT-5 deployment (version 2025-08-07) generates the evidence views and candidate milestones. The constrained prompt supplies ten adjacent, task-specific precedence relations used in this exploratory schema. They operationalize the tested reconstruction format. They are not proposed as universal oncology chronology. These are model instructions, not a deterministic temporal solver.

## 3.4 What reaches each model stage

Each selected unit enters a clinical-query prompt as its indexed ID, event date, and stored text representation. A bracketed header contains source\_id=UNIT\_ID and event\_date=YYYY-MM-DD, followed on the next line by the unit’s text. Structured observations and narrative facts share this wrapper; their text lengths can differ.

For windowed retrieval, selections are unioned and deduplicated by indexed-unit ID before the query prompt is built. The means of 496 and 965 units per query count that deduplicated selection. The runner includes every selected unit in its query prompt, without application-side unit thinning at this stage. Inclusion in a submitted prompt does not show that the model used every item.

The query model compresses those units into one generated evidence view per clinical query. Milestone reconstruction

C. Milestone Reconstruction Worked illustructon, 3 of 13 evidence views

![](images/d1775d04391e983d417bfaedd6546a6f309f805cc8444d9feea95384cff14072.jpg)  
Pale: no indexed rows in the bin Gray: after the last indexed row

![](images/2df4fc1fe645934f0c8b66ff87aa096349956e2da67e86284559360ba4f29951.jpg)  
Darker cells: more selected rows Primary study: unequal budgets

![](images/84c66cef621a45a174e935cbbe2acbcbb300e1d274fa017bf8f39ae2f8f6dd08.jpg)  
3. Candidate milestone sequence Milestone Date Source First evidence 02 Nov 2020 E1 Confirmation 10 Dec 2020 E2 1L start 15 Mar 2021 E3 1L end 20 Sep 2021 E4 Progression 05 Aug 2022 E5  
Figure 1: From irregular records to candidate milestones. (A) Indexed-unit counts in three-month periods for five de-identified patients, aligned to their first indexed event. Gray cells follow the last indexed unit; color shows log (1 + units). (B) Saved selections for one chemotherapy query in Study A, and counts differ across policies. (C) An author-constructed example links dated evidence views to prompted chronology checks and candidate milestones. E1–E5 are illustrative source links. 1L is the first systemic treatment line.

receives all 13 views, plus a metadata-only catalog of the union of selected units across queries. Catalog entries contain the indexed ID, event date, and event type, not the original text. Above 2,500 distinct units, the catalog is thinned to 2,500 evenly spaced entries over sorted IDs. The 13 views are not thinned by this rule. The cap applies to all selected units in the catalog, not only to units cited in the views.

Selections → ID-deduplicated units

→ query prompts → 13 evidence views

→ milestone prompt + metadata catalog.

Study A’s retrieval exposure describes the query stage, not the final milestone context length. Study B supplies selected units directly to reconstruction.

## 3.5 Three metric families

Output behavior comprises slot fill (the fraction of 11 slots assigned a date) and abstention (null or unknown slots). We retain “coverage” for the historical Study A measure, but mean output completeness, not clinical recall.

Temporal validity measures schema-order reversals among pairs with both dates present. The denominator is essential: missing dates can leave a seemingly wellordered output largely untested. Study A reports the mean output-level reversal rate, excluding outputs with no evaluable pair, rather than a pooled ratio over all pairs.

Evidence behavior measures indexed-unit linkage and sensitivity to evidence removal. In Study A, date-near support means that a dated slot cites at least one indexed unit within 30 days of its predicted date. Leave-one-citation-out stability checks whether another such unit remains when a citation is removed. It measures redundancy in local support, rather than rerunning the generator. Study B removes indexed units and reruns retrieval and reconstruction. Secondary diagnostics appear in Appendix A.

## 4 Study A: temporal allocation and constraint ablation

## 4.1 Design

The main study holds the 20-patient index, 13 query texts, scorer, model, and output schema fixed across four conditions. Each has three repeated runs per patient.

## Global-50.

Select the 50 highest-scoring indexed units across the patient’s history for each clinical query.

![](images/e69be3c939fed2ae2fa485e79705ffe8c939a8d804dc2348baa9fbedce2daa0d.jpg)  
Figure 2: The data-to-timeline framework. Narrative facts and structured OMOP observations form a dated, sourcelinked index. Study A retrieves evidence for 13 clinical queries, generates their evidence views, and reconstructs 11 candidate milestones. The dashed bypass shows Study B’s direct reconstruction from one whole-course retrieval request. The downstream box describes intended real-world-evidence research, not an evaluated endpoint pipeline.

## Global-50/no-constraints.

Reuse Global-50’s evidence and 13 generated views, then reconstruct without the ten precedence rules. This is the paired constraint ablation.

## Temporal-15.

Use overlapping three-month windows with a one-month stride. Select up to 15 relevant units per non-empty window, deduplicate indexed-unit identifiers, and order the retained evidence by date.

## Density-Adaptive.

Use the same windows but increase the quota with indexedunit count:

$$
k _ { w } = \operatorname* { m i n } \left( 4 0 , \operatorname* { m a x } \left( 1 0 , \lceil 0 . 3 5 N _ { w } \rceil \right) \right) .\tag{2}
$$

Select all available units if fewer than the quota exist. The floor gives sparse windows an allowance and the ceiling limits dense windows. The coefficient and bounds were fixed engineering choices, not fitted optima.

Each condition contains 20 × 3 = 60 milestone outputs and 20 × 13 × 3 = 780 query-level timeline artifacts. The no-constraint condition reuses Global-50’s timeline artifacts rather than generating new views. Primary results are descriptive means over 20 patients and three runs. Because runs are nested within patients, Table 1 does not treat the 60 outputs as independent observations. The runner checkpointed outputs and saved prompt hashes and retrieval traces. Appendix A reports a separate five-patient sensitivity analysis within Study A, and it is not Study B.

Table 1: Study A: descriptive means over 20 patients and three runs. Higher values indicate more fill, date-near cited support, and citation-removal stability, lower schemaorder reversal rates are preferable. Fill and abstention are complementary in these outputs, not two accuracy measures. Support means a cited unit lies within 30 days of the assigned date, not semantic entailment. Stability means another date-near cited unit remains after one citation is removed.

<table><tr><td>Policy</td><td>Fill</td><td>Reversals</td><td>Support Abstain</td><td></td><td>Stability</td></tr><tr><td>Global-50</td><td>.388</td><td>.010</td><td>.959</td><td>.612</td><td>.586</td></tr><tr><td>No-constraints</td><td>.405</td><td>.080</td><td>.981</td><td>.595</td><td>.600</td></tr><tr><td>Temporal-15</td><td>.538</td><td>.000</td><td>.951</td><td>.462</td><td>.801</td></tr><tr><td>Density-Adaptive .553</td><td></td><td>.011</td><td>.936</td><td>.447</td><td>.821</td></tr></table>

## 4.2 Main results

Temporal-15 fills more slots than Global-50: 0.538 versus 0.388 (Table 1). More date-near support also survives single-citation removal: 0.801 versus 0.586. This comes with much greater exposure. Mean indexed units per query rise from 50 to 496, and mean distinct units across the 13 queries rises from 244 to 1,522.

Density-Adaptive increases exposure to 965 indexed units per query and 2,739 distinct units across queries. Yet fill rises only from 0.538 to 0.553, and dropout stability from 0.801 to 0.821. Date-near support falls from 0.951 to 0.936. Repeated-run date agreement also falls (Appendix A). Almost doubling the evidence relative to Temporal-15 does not produce comparable diagnostic gains.

The paired ablation provides the cleanest controlled contrast in Study A. Removing precedence instructions while reusing Global-50’s evidence and views raises the mean schema-order reversal rate from 0.010 to 0.080. Across all outputs, 163, 164, 260, and 267 pairs are evaluable for Global-50, no-constraints, Temporal-15, and Density-Adaptive, respectively. These are denominator counts, not the denominator of a pooled Table 1 rate. Retrieval and reconstruction safeguards therefore address different problems. The effect concerns compliance with the declared milestone order.

Across all 20 patients, we first average the three runs within patient and then subtract paired fill values. Temporal-15 minus Global-50 has a median difference of 0.121 (IQR 0.000–0.197): 14 patients improve, five tie, and one declines. Density-Adaptive minus Temporal-15 has a median of 0.000 (IQR 0.000–0.030): seven improve, nine tie, and four decline. These distributions describe heterogeneity rather than a significance test; quartiles use linear interpolation at $( n - 1 ) q$ . The aggregate paired summary accompanies the source package.

## 5 Study B: evidence budgets

## 5.1 Purpose and single-query protocol

This secondary pilot asks: with the same number of indexed units, does evidencefrom more periods lead to more dated milestones? Five density-stratified patients were previously frozen for an independent-model audit. For each patient, five policies retrieve 50, 100, or 200 distinct indexed units. The model reconstructs the 11 milestones directly, using precedence instructions and allowing null dates.

The exact retrieval query in the frozen configuration is:

“Retrieve the evidence needed to reconstruct the longitudinal oncology trajectory, including first cancer evidence, pathological confirmation, starts and ends of successive systemic treatment lines, and subsequent progression or recurrence.”

One whole-course request makes the allowance easy to define: K indexed units for one patient request, rather than 13 allowances followed by overlapping evidence views. This simplifies a budget experiment. It does not preserve the main pipeline’s clinical decomposition. Study B changes the queries, uses non-overlapping windows, and bypasses the 13-view stage. Its fill values should not be compared directly with Study A’s or used to judge the benefit of focused queries.

## 5.2 Five policies in plain language

## Global top-K.

Take the indexed units most similar to the whole-course query, regardless of date.

## Global MMR.

Prefer relevant units while discouraging similar selections. We use maximal marginal relevance [18] with $\lambda = 0 . 5 ,$ the top 2K candidates, and min–max-normalized query scores.

## Temporal-equal allocation.

Spread the allowance roughly evenly over three-month periods containing indexed units. Reserve one unit per period when feasible, then distribute the remainder. If there are more periods than units allowed, sample periods across the history.

## Density-proportional allocation.

Give more of the allowance to periods containing more units. A period’s weight is its indexed-unit count $N _ { w } .$

## Relevance-weighted temporal allocation.

Give more selections to periods that contain more units and appear more relevant to the query. Soften density with a square root, then adjust it using the relevance of the period’s strongest units. This is a fixed rule, not a model that learns or conducts follow-up searches.

The last three policies use non-overlapping three-month periods starting at the first indexed event. They rank units by query similarity within each period. For relevanceweighted allocation the weight is

$$
a _ { w } = \sqrt { N _ { w } } \left( 1 + \frac { r _ { w } } { W } \right) ,\tag{3}
$$

where W counts periods containing indexed units and $r _ { w } \in \{ 1 , \ldots , W \}$ ranks the average similarity of each period’s best three available units. Higher relevance receives a higher rank. Capacity-constrained largest-remainder allocation converts weights to quotas: assign whole-number shares, cap them at available units, and redistribute the remainder. All observed conditions return exactly K units. The saved name is query\_adaptive; the unchanged Figure 3 labels it “Query adaptive.” Neither this policy nor density-proportional allocation is Study A’s overlappingwindow Density-Adaptive method.

## 5.3 Measurements and completion

Temporal breadth is

$$
B = \frac { \# \{ w : k _ { w } > 0 \} } { \# \{ w : N _ { w } > 0 \} } .\tag{4}
$$

The denominator excludes periods with no indexed units. If units exist in 20 periods and retrieval selects at least one from 15, temporal breadth is 75%. Slot fill counts requested milestones receiving dates. API-reported input tokens measure exposure. The baseline comprises ${ \bar { 5 } } \times 5 \times 3 = 7 5$ patient–policy–budget conditions. Retrieval is rerun under five fixed dropout seeds, each removing approximately 10% of indexed units: 375 perturbed retrieval sets. Generation is performed for the 75 baseline conditions and once per condition using seed 37, producing 150 generation artifacts in total. All 150 completed successfully.

## 5.4 Results: spreading evidence does not reliably fill more slots

Temporal-equal represents 95.2%, 100%, and 100% of documented periods at allowances of 50, 100, and 200 units. Global top-K represents 47.6%, 55.4%, and 63.6%. Density-proportional represents 60.0%, 67.0%, and 75.9%; relevance-weighted temporal allocation represents 74.9%, 88.6%, and 96.1%. Temporal-equal’s breadth partly follows from its design: it explicitly spreads units across periods.

These breadth differences do not yield a consistent ordering of slot fill. Across 15 policy–budget cells, fill ranges from 21.8% to 29.1%. Global top-K has the highest observed fill at 50 units, four methods tie at 100, and three tie at 200. Increasing the allowance does not consistently improve fill. Five patients cannot establish equivalence, but the observed results do not support a consistent winner.

Mean input length across policies rises from approximately 3.6k to 6.2k to 11.4k tokens at the three allowances. More input produces no consistent fill increase in this protocol. No schema-order reversal is observed, but only 6–10 precedence pairs can be evaluated per policy budget cell across all five patients. Missing dates leave most relations untested. Secondary perturbation results appear in Appendix A.

## 6 What the two studies jointly show

## 6.1 Documentation density is not evidence utility

Study A gives the central design lesson. A density-based quota nearly doubles exposure relative to a fixed window quota, with modest changes in fill and citation removal stability. Support and repeated run agreement do not improve. Study B reaches a complementary conclusion under a simpler protocol, showing that selecting units from a greater number of periods does not consistently increase slot coverage.

A busy period can contain repeated surveillance, copiedforward diagnoses, billing rows, or multiple representations of one event. A sparse period can hold the report that changes the interpretation of the course. Our data do not identify which mechanism caused each result. They do show why indexed-unit count should not be treated as marginal clinical value.

The next allocation rule should ask whether another unit adds relevant information, covers a missing period, resolves a conflict, or repeats what the model has already seen. Relevance, temporal novelty, redundancy, and task need are candidate signals. They are proposals for the next comparison, not validated components of the present system.

## 6.2 Search breadth and ordering solve different problems

Retrieval creates access to evidence. Reconstruction assigns events and dates. A source can enter the context without being used correctly, and a well-ordered output can omit the decisive transition. The paired constraint abla tion shows that reconstruction instructions change schema order even when evidence is fixed. Study B shows that breadth and fill can move separately. Neither property can substitute for the other.

The 13 views preserve clinically directed searches before a model combines the course. The single query pilot intentionally removes that stage for a simpler budget question. A future experiment should compare these query designs while holding the remaining pipeline and total allowance fixed.

## 6.3 A compact evaluation checklist

A no-gold diagnostic protocol should answer five questions:

1. What entered the context? Report indexed-unit and token exposure, temporal breadth, and query structure.

2. What did the model state or leave unknown? Report slot fill and abstention together.

3. What order was tested? State the schema, evaluablepair count, and reversals.

4. What supports the output? Distinguish citation membership, date-near support, and semantic support.

5. What happens when evidence or generation changes? Separate indexed-unit removal, evidence ordering, and repeated-run agreement.

The checklist makes results easier to inspect and compare. It also exposes scores that rest on missing dates or weak provenance checks.

## 7 Clinical boundary and limitations

The claims boundary in the introduction applies throughout. Candidate timelines may help reviewers locate evidence, but validated progression and treatment-line endpoints require definitions and adjudication. Real-world progression-free survival also requires treatment indexing, progression-or-death rules, death linkage, and censoring [19, 20]. Those endpoints and downstream decisions are outside this evaluation.

The cohort is small, internally held, and limited to lung and prostate cancer. Expert reference timelines are unavailable. A filled slot may contain an incorrect date, and a nearby citation may not be sufficient to verify that the

![](images/e41c012c55540ef69a25df719f22d68c38a3cbc28fd80c754989915e99b7d0f6.jpg)

![](images/2d4c3489c9494f0f5ab9c8f179ad7fbae26f2a647009204de25d573aea159e72.jpg)

![](images/ba28a3db49150662afe6efe23876f7701f067a27b1e38f9ce1dbd77ff13fef32.jpg)  
Five patients, one broad query, direct reconstruction.  
Bars: mean across policies , Whiskers: range of policy means

Figure 3: Study B: selecting evidence under fixed indexed-unit limits in five patients. Each method selects 50, 100, or 200 indexed units, and the graphic’s “Record budget $\mathbf { K } ^ { \ast }$ counts units, not full notes. (A) Percentage of three-month periods containing units from which at least one unit is selected. (B) The percentage of the 11 milestones assigned a date reflects output completeness rather than correctness. (C) Model input length in tokens. Bars represent the average of the five policy means, while whiskers indicate the minimum and maximum policy means rather than statistical uncertainty. “Query adaptive” denotes relevance-weighted temporal allocation. All methods use one whole-course query and reconstruct milestones directly. Selecting units from more periods does not consistently produce more dated milestones.

event occurred. Upstream extraction, OMOP alignment, and deduplication are held fixed and unvalidated here. The broader Onco-CONSTRUE architecture is outside the evaluated scope.

Study A’s retrieval conditions are not budget matched: their differences combine allocation and volume. Study B controls indexed units within its own protocol, not tokens, and changes queries, window overlap, and reconstruction. It cannot remove Study A’s volume confound. Its five patients and one baseline generation per condition limit comparison; it has no power analysis or basis for an equivalence claim.

Both studies use one private model deployment. An openmodel audit was incomplete at manuscript freeze and contributes no results. The 2,500 entry milestone metadata catalog cap described in Methods can omit an indexed ID retained in a generated view, complicating provenance in higher-volume conditions. Saved retrieval traces remain complete. Study A’s token estimates are calculated by dividing character counts by four, whereas Study B uses API-reported token usage. Exact primary study latency and cost were not consistently saved.

The chronology schema is task specific. Progression can occur before treatment ends, and treatment intervals can overlap. A reversal under the chosen adjacent order is schema noncompliance, not necessarily a clinically impossible sequence. Partial orders and endpoint specific relations need separate evaluation. The pilot’s small pair counts and weaker provenance checks are documented with its results and in Appendix A, not treated as strong validation signals.

## 8 Research agenda

## 8.1 Keep the main pipeline fixed when testing budgets

The next comparison should retain the 13 queries, window geometry, evidence order, and reconstruction prompt while controlling the total distinct units and tokens supplied. It should compare uniform, density-based, relevanceweighted, and redundancy-aware allocation. A separate experiment should compare one whole-course request with focused clinical views at the same total allowance. These tests would isolate questions the present protocols cannot answer.

## 8.2 Use controlled cases before full annotation

Several tests need no complete clinical timelines. Synthetic dated chains can test order and abstention. Removing the only supporting source can test whether the model withdraws a date. Conflicting dates can test whether it reports uncertainty. Duplicate insertion can test whether repetition creates false confidence. Uniform date shifts, with index relations preserved, can test whether reconstructed dates shift consistently. These are proposed tests; success on constructed cases would still need confirmation on clinical records.

MedAlign and ChemoTimelines offer complementary tasks for designing these evaluations [5, 10, 11]. They should inform benchmark design rather than be assumed to provide a matching reference for this multimodal 11- slot trajectory. Expert review remains valuable for later event-level validation. The methodological argument does not depend on completing that annotation first.

## 8.3 Make the measurement framework reusable

The source package includes aggregate figure data, the public pilot audit, and plotting code. Equations 1–4 specify the budget constraint, relevance weighting, and breadth measure, and the pilot query is quoted verbatim. These materials let readers reproduce the graphics and inspect the measurement choices without patient records.

Prompt and schema templates are useful next release items, subject to institutional policy and IP review. This package does not release the clinical index or private prompt corpus. Any release should document query texts, permitted unknowns, precedence relations, source-link rules, and perturbation denominators. The accepted BHI abstract provides the broader Onco-CONSTRUE provenance, whereas this report presents the more focused retrieval argument and the completed studies. They should be cited for their distinct scopes.

## 9 Conclusion

Longitudinal clinical retrieval must decide how to spend attention across a patient history. Study A shows more milestone fill at much greater temporal exposure and isolates the effect of prompted precedence rules. Its density-based expansion adds much more material for modest diagnostic gains. Study B shows that broader coverage alone does not consistently fill more milestones under a simplified indexed unit budget protocol.

Documentation density is not evidence utility. A useful next system must decide when an evidence unit adds new clinical information, not merely when another unit is available. Temporal evidence allocation, separate reconstruction checks, and no-gold development diagnostics provide a practical foundation for that work.

## A Secondary diagnostics and protocol details

## A.1 Study A: repeatability, anchors, and sensitivity

Run repeatability is the fraction of milestone dates present in paired runs that agree within 30 days. It is 0.880 for Global-50, 0.924 for no-constraints, 0.881 for Temporal-15, and 0.858 for Density-Adaptive. Mean pairwise retrieval-set Jaccard overlap is 1.000, 0.9999, and 0.99999 for the three retrieval policies. With index and embeddings frozen, retrieval is effectively deterministic; most residual date variation occurs during generation.

Weak-anchor agreement asks whether a cited unit’s event type belongs to a milestone-specific compatible set. It is 0.816, 0.817, 0.768, and 0.770 for Global-50, noconstraints, Temporal-15, and Density-Adaptive. Event type is only a weak anchor: compatibility does not establish the event’s meaning or date.

A prespecified five-patient sensitivity sample averages three runs per patient, then uses 20,000 paired patientbootstrap resamples. It is separate from Study B, although the samples are not required to be disjoint. Coverage is 0.376, 0.485, and 0.497 for Global-50, Temporal-15, and Density-Adaptive. Temporal-15 minus Global-50 is +0.109, with a 95% bootstrap interval [+0.012, +0.206]. Density-Adaptive minus Temporal-15 is +0.012 [0.000, +0.024]. Corresponding dropout differences are +0.150 [+0.035, +0.271] and +0.062 [−0.008, +0.170]. With five patient clusters these are sensitivity summaries, not population-level precision estimates.

Table 2: Study A’s five-patient sensitivity sample, not Study B. Tokens are character-based input proxies.
<table><tr><td>Policy</td><td>Units/query</td><td>Distinct</td><td>Tokens</td></tr><tr><td>Global-50</td><td>50</td><td>200</td><td>36k</td></tr><tr><td>Temporal-15</td><td>344</td><td>1,006</td><td>164k</td></tr><tr><td>Density-Adaptive</td><td>704</td><td>1,883</td><td>313k</td></tr></table>

Across Study A’s 1,665 non-empty overlapping windows, median $N _ { w }$ is 107 (IQR 35-424; range 1-8,907). The density quota operates at its minimum in 21.9% of windows, proportionally in 29.4%, and at its maximum in 48.7%. These describe the frozen operating point, not an optimal quota.

## A.2 Study B: perturbation and weaker provenance checks

Corpus-dropout seeds are 11, 23, 37, 53, and 71, with generation performed only for seed 37. Retrieval-set Jaccard overlap ranges from 0.786 to 0.818 across policy budget means. Baseline evidence follows retrieval order, whereas perturbed evidence follows indexed-unit ID order. Output changes combine removal, reretrieval, and ordering effects.

Exact date agreement after dropout is 81.8–96.4%, but includes 37–43 double-null agreements among 55 slots per cell. Agreement that both outputs omit a date does not show that a reconstructed event survived. The aggregate audit records both double-null and non-null denominators, and policies are not ranked according to raw agreement.

Citation membership checks whether at least one cited identifier belongs to selected units. Cell means are 90- 100%. The evaluator assigns 1 to an all null output, so means include vacuous cases. Membership is weaker than

Study A’s date-near check and does not test semantic support. Cell mean API call durations range from 37.3 to 46.8 seconds, and these measurements reflect service observations rather than an efficiency comparison.

## References

[1] Nelson F. Liu, Kevin Lin, John Hewitt, Ashwin Paranjape, Michele Bevilacqua, Fabio Petroni, and Percy Liang. Lost in the middle: How language models use long contexts. Transactions ofthe Associationfor Computational Linguistics, 12:157–173, 2024. doi: 10.1162/tacl\_a\_00638.

[2] Maya Kruse, Shiyue Hu, Nicholas Derby, Yifu Wu, Samantha Stonbraker, Bingsheng Yao, Dakuo Wang, Elizabeth M. Goldberg, and Yanjun Gao. Large language models with temporal reasoning for longitudinal clinical summarization and prediction. In Findings of the Association for Computational Linguistics: EMNLP 2025, pages 20715–20735, 2025. doi: 10.18653/v1/2025.findings-emnlp.1128.

[3] Kirk Roberts, Dina Demner-Fushman, Ellen M. Voorhees, and William R. Hersh. Overview of the TREC 2016 clinical decision support track. Technical report, National Institute of Standards and Technology, 2016. URL https://trec.nist.gov/pubs/trec25/papers/ Overview-CL.pdf.

[4] Patrick Lewis, Ethan Perez, Aleksandra Piktus, Fabio Petroni, Vladimir Karpukhin, Naman Goyal, Heinrich Kuttler, Mike Lewis, Wen-tau Yih, Tim Rocktäschel, Sebastian Riedel, and Douwe Kiela. Retrieval-augmented generation for knowledge-intensive nlp tasks. In Advances in Neural Information Processing Systems, volume 33, pages 9459– 9474, 2020.

[5] Scott L. Fleming, Alejandro Lozano, William J. Haberkorn, Jenelle A. Jindal, Eduardo Reis, Rahul Thapa, Louis Blankemeier, Julian Z. Genkins, Ethan Steinberg, Ashwin Nayak, et al. MedAlign: A clinician-generated dataset for instruction following with electronic medical records. In Proceedings of the AAAI Conference on Artificial Intelligence, volume 38, pages 22021–22030, 2024. doi: 10.1609/aaai.v38i20.30205.

[6] Ashish Chouhan and Michael Gertz. heiDS at ArchEHR-QA 2025: From fixed-k to query-dependent-k for retrievalaugmented generation. In Proceedings ofthe 24th Workshop on Biomedical Language Processing (Shared Tasks), pages 50–61, 2025. doi: 10.18653/v1/2025.bionlp-share.6.

[7] Lang Cao, Qingyu Chen, and Yue Guo. EHR-RAG: Bridging long-horizon structured electronic health records and large language models via enhanced retrieval-augmented generation. arXiv preprint arXiv:2601.21340, 2026. URL https://arxiv.org/abs/2601.21340.

[8] Ricardo Campos, Gaël Dias, Alípio Mário Jorge, and Adam Jatowt. Survey of temporal information retrieval and related applications. ACM Computing Surveys, 47(2):15:1–15:41, 2014. doi: 10.1145/2619088.

[9] Timothy Miller, Steven Bethard, Dmitriy Dligach, and Guergana Savova. End-to-end clinical temporal information extraction with multi-head attention. In Proceedings of the 22nd Workshop on Biomedical Natural Language Processing and BioNLP Shared Tasks, pages 313–319, 2023. doi: 10.18653/v1/2023.bionlp-1.28.

[10] Jiarui Yao, Harry Hochheiser, WonJin Yoon, Eli Goldner, and Guergana Savova. Overview of the 2024 shared task on chemotherapy treatment timeline extraction. In Proceedings ofthe 6th Clinical Natural Language Processing Workshop, pages 557–569, 2024. doi: 10.18653/v1/2024.clinicalnlp-1.53.

[11] Jiarui Yao, Harry Hochheiser, WonJin Yoon, Eli T. Goldner, and Guergana K. Savova. Overview of the 2025 shared task on chemotherapy treatment timeline extraction. In Proceedings ofthe 7th Clinical Natural Language Processing Workshop, pages 1–10, 2025. URL https: //aclanthology.org/2025.clinicalnlp-1.1/.

[12] Sayantan Kumar, Shahriar Noroozizadeh, Juyong Kim, and Jeremy C. Weiss. Text knows what, tables know when: Clinical timeline reconstruction via retrieval-augmented multimodal alignment. arXiv preprint arXiv:2605.15168, 2026. URL https://arxiv.org/abs/2605.15168.

[13] Jan Buchmann, Xiao Liu, and Iryna Gurevych. Attribute or abstain: Large language models as long document assistants. In Proceedings of the 2024 Conference on Empirical Methods in Natural Language Processing, pages 8113–8140, 2024. doi: 10.18653/v1/2024.emnlp-main.463.

[14] Yiqing Xie, Sheng Zhang, Hao Cheng, Pengfei Liu, Zelalem Gero, Cliff Wong, Tristan Naumann, Hoifung Poon, and Carolyn Rose. DocLens: Multi-aspect fine-grained evaluation for medical text generation. In Proceedings of the 62nd Annual Meeting ofthe Associationfor Computational Linguistics (Volume 1: Long Papers), pages 649–679, 2024. doi: 10.18653/v1/2024.acl-long.39.

[15] Aishik Nagar, Yutong Liu, Andy T. Liu, Viktor Schlegel, Vijay Prakash Dwivedi, Arun-Kumar Kaliya-Perumal, Guna Pratheep Kalanchiam, Yili Tang, and Robby T. Tan. uMedSum: A unified framework for clinical abstractive summarization. In Proceedings of the 63rd Annual Meeting of the Association for Computational Linguistics (Volume 1: Long Papers), pages 2653–2672, 2025. doi: 10.18653/v1/2025.acl-long.134. URL https: //aclanthology.org/2025.acl-long.134/.

[16] Alireza Salemi and Hamed Zamani. Evaluating retrieval quality in retrieval-augmented generation. In Proceedings of the 47th International ACM SIGIR Conference on Research and Development in Information Retrieval, pages 2395–2400, 2024. doi: 10.1145/3626772.3657957. URL https://arxiv.org/abs/2404.13781.

[17] Vipina K. Keloth, Juan M. Banda, Michael Gurley, Paul M. Heider, Georgina Kennedy, Hongfang Liu, Feifan Liu, Timothy Miller, Karthik Natarajan, et al. Representing and utilizing clinical textual data for real world studies: An OHDSI approach. Journal of Biomedical Informatics, 142: 104343, 2023. doi: 10.1016/j.jbi.2023.104343.

[18] Jade Goldstein and Jaime Carbonell. Summarization: (1) using MMR for diversity-based reranking and (2) evaluating summaries. In TIPSTER TEXT PROGRAM PHASE III: Proceedings of a Workshop, pages 181–195, 1998. doi: 10.3115/1119089.1119120. URL https: //aclanthology.org/X98-1025/.

[19] Sandra D. Griffith, Rebecca A. Miksad, Geoff Calkins, Paul You, Nicole G. Lipitz, Ariel B. Bourla, Erin Williams, Daniel J. George, Deborah Schrag, Sean Khozin, William B. Capra, Michael D. Taylor, and Amy P. Abernethy. Characterizing the feasibility and performance of real-world tumor

progression end points and their association with overall survival in a large advanced non–small-cell lung cancer data set. JCO Clinical Cancer Informatics, 3:1–13, 2019. doi: 10.1200/CCI.19.00013.

[20] U.S. Food and Drug Administration. Real-world data: Assessing electronic health records and medical claims data to support regulatory decision-making for drug and biological products: Guidance for industry, July 2024. URL https://www.fda.gov/media/152503/download. Final guidance; accessed September 23, 2026.