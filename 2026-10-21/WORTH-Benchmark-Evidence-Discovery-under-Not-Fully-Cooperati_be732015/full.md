# WORTH Benchmark: Evidence Discovery under Not-Fully-Cooperative Information

A Two-Episode Pilot

Bo Zou Chao Xu

Bread Studio bo@BreadMedia.com https://huggingface.co/BreadStudio

## Abstract

Existing reasoning evaluations typically provide task-relevant information to models as available premises, rarely examining concurrently how models discover evidence autonomously and how information presentation within narratives guides or obscures judgment. This paper proposes the WORTH Benchmark: models read original mystery narratives without clue annotations, autonomously select key clue sentences, identify case participants, and explain their reasoning process. The narrative materials are designed by professional authors such that evidence facilitating reasoning coexists with narrative arrangements that delay the revelation of truth. We report a pilot experiment under full-story conditions across two episodes, conducting a total of 70 formal runs on models, of which 67 runs are content-scorable. Scoring separately records hits on author-designated key clue sentences and participant selections; natural language explanations are used for case diagnosis and are not scored independently. The results show that clue hits and participant judgments are not synchronized; across 37 content-scorable runs in Episode 02, 31 runs simultaneously selected the same set of incorrect participants, while adjacent suspicion-oriented and exoneration-oriented sentences were selected 25 times and 0 times, respectively. These phenomena illustrate the diagnostic value of component-wise analysis and suggest that not-fully-cooperative informational relationships may influence evidence selection and judgment. This study only implements full-story conditions for two episodes, and does not establish stable model rankings or infer general mechanisms on this basis; human player records have not yet been cleaned, and this version does not report human-model comparisons.

## 1. Introduction

There are many varieties of existing large language model reasoning evaluations, among which premise-provided tasks typically share a common property: prompt information is helpful. Regardless of how dificult the problem is, how long the text is, or how complex the reasoning chain is, the input materials are designed as information to help the model solve the problem. What the model needs to resolve is how to understand and invoke this information, without questioning the truthfulness of the information itself.

Real-world information is rarely presented so helpfully or transparently. A statement can be entirely factual at the level of truth, yet mislead the receiver’s judgment through selective expression, omission, and emphasis. This paper uses “cooperative” and “adversarial” to roughly distinguish between two types of informational relationships. The adversariality referred to here does not mean hostile tone, aggressiveness, or false information; rather, it refers to the directional efect of the text on the reader’s judgment in terms of informational function. This distinction relates to the Cooperative Principle in pragmatics (Grice, 1975), the theory of epistemic vigilance (Sperber et al., 2010), and the survey on the application of Gricean maxims in natural language processing (Krause and Vossen, 2024); its precise positioning within large language model evaluation will be discussed in the related work section.

This distinction points to two related but distinct issues in current reasoning evaluations. First, most tasks measure reasoning ability after evidence has already been provided; “what is worth becoming evidence” falls outside the scope of evaluation. Second, lengthening the text or adding distracting information is not equivalent to taking not-fully-cooperative informational relationships as an evaluation condition—test designers may have increased dificulty, but they do not necessarily examine how information guides judgment through its presentation. Under the former condition, reasoning can only start from pre-compiled premises; under the latter condition, evaluation focuses more on the dificulty of information retrieval rather than how information presentation afects evidence judgment.

The evaluation proposed in this paper—WORTH—alters both conditions simultaneously. First, models must autonomously determine which sentences possess inferential value from unmarked natural narratives; “finding the starting point of reasoning” itself constitutes the evaluation target. Second, what the model confronts is a not-fully-cooperative information environment—stories have character trajectories, event sequences, and reasoning cores designed by professional authors, with these cores subsequently concealed through narrative techniques. The model must not only autonomously filter inferential information, but also make judgments in an environment where cooperative and adversarial information coexist.

Hence, this paper poses an antecedent question: When evidence is not pointed out and the informational environment is not entirely on the model’s side, can the model find the starting point of reasoning?

Testing this does not require inventing artificial distractions out of thin air. Mature mystery narratives are inherently texts where cooperative and adversarial information coexist: fiction authors must provide suficient information to deduce the truth, while delaying its revelation through narrative focus, salience control, and alternative explanations. The coexistence of cooperative and adversarial information is not post-hoc noise, but the intrinsic structure of mystery narratives. Therefore, WORTH adopts professionally written mystery narratives as the evaluation vehicle. It should be clarified that WORTH does not claim that stories are equivalent to the real world; rather, it treats them as a controlled natural narrative experimental environment—closer to real-world informational relationships than artificially arranged premises and distractors, while retaining definite event ground truth and reproducible scoring conditions.

A complete reasoning process encompasses clue localization, clue interpretation, evidence combination, and final conclusion, but the current evaluation directly quantifies two of these outputs: after reading the complete story, the model selects a limited quota of key clue sentences and determines case participants from candidate characters. Key clue sentences are the reasoning cores preset during the story planning phase, which are wrapped in narrative techniques in the final text with intentionally reduced salience. The evaluation also requires models to provide natural language explanations of their reasoning, but currently does not involve independent scoring of explanation quality.

This paper reports a two-episode pilot experiment. Episode 01 contains 120 sentences (12 key clue sentences), run 5 times each on 6 models; Episode 02 contains 134 sentences (20 key clue sentences), run 5 times each on 8 models; across both episodes, there are 70 formal runs in total. Both episodes have also been deployed as interactive narrative mystery games, and each has accumulated thousands of human-player score records; however, human data have not yet completed export and cleaning, and this version does not report human scores or human-model comparisons (see §7.3).

The two-episode pilot preliminarily exhibits three classes of phenomena that are not easily observable in premise-provided evaluations. First, the performance of the same model across diferent stages is inconsistent: a model can identify more key clue sentences yet still maintain an incorrect theory in participant judgment; conversely, it can be conservative in participant selection and make fewer errors, yet miss key evidence. Second, a shared error tendency emerges across diferent models—a substantial number of runs across multiple models converge on the exact same combination of characters, a combination that superficially enjoys ample evidentiary support but diverges from the ground truth. Third, models are more likely to select high-salience suspicion information and more likely to overlook low-salience counter-evidence and exonerating information. This paper reports these phenomena as observable behavioral structures, without inferring internal cognitive mechanisms of the models.

The contributions of this paper span three levels: conceptually, introducing evidence discovery and not-fully-cooperative informational relationships into large language model reasoning evaluation; methodologically, providing an executable evaluation framework based on professionally crafted natural narratives; empirically, demonstrating the three aforementioned classes of diagnostic phenomena through a two-episode pilot experiment.

The current work implements only the full-story condition and should be understood as a formalized pilot experiment rather than a mature leaderboard. The goal of this paper is not to prove a universal model cognitive mechanism using two stories, but to propose and preliminarily demonstrate a new diagnostic perspective: models need not only reason upon evidence, but also judge where their reasoning should begin when evidence is not pointed out and informational relationships are not purely cooperative.

## 2. Related Work

WORTH’s two concurrent conditions—evidence discovery and not-fully-cooperative informational relationships—are not entirely groundbreaking research, but align with several academic threads. This section first clarifies two premises commonly adopted by premise-provided evaluations, then explains attempts from diferent academic traditions to partially alter these premises, and finally situates WORTH’s specific position relative to mystery fiction-related evaluations.

## 2.1 Common Premises of Existing Reasoning Evaluations

From GSM8K (Cobbe et al., 2021) and MATH (Hendrycks et al., 2021) to GPQA (Rein et al., 2023), FrontierMath (Glazer et al., 2024), BIG-Bench Hard (Suzgun et al., 2022), and BIG-Bench Extra Hard (Kazemi et al., 2025), mainstream reasoning benchmarks diferentiate model capabilities by increasing the inferential complexity of the problem itself—multi-step computation, domain knowledge thresholds, and combinatorial explosions. These works have constructed systematic measurement instruments along the dimension of “whether conclusions can be correctly deduced given the premises,” but they typically share two design premises. First, the task objective, response space, and primary premises required for solution are pre-organized and provided by the evaluator, without taking open evidence identification as the core scoring target. Second, the prompt overall is designed for the purpose of supporting problem-solving; even when containing irrelevant information or distracting options, it typically does not take the narrative presentation of factual yet selective text to guide erroneous judgment as a core experimental variable. The two conditional shifts proposed in the Introduction—evidence discovery and not-fully-cooperative informational relationships—specifically target these two default premises.

## 2.2 Attempts to Partially Alter These Premises

Long-Context and Narrative Understanding. NarrativeQA (Kočiský et al., 2018) and LiteraryQA (Bonomo et al., 2025) employ books, movie scripts, and literary works; LongBench v2 (Bai et al., 2025) covers diverse real-world long documents and long-context tasks. RULER (Hsieh et al., 2024) and the Needle-in-a-Haystack series (including Sequential-NIAH (Yu et al., 2025); U-NIAH (Gao et al., 2025)) measure long-context processing capabilities from the perspectives of information localization, multi-hop tracking, or aggregation. While these works increase the dificulty of information retrieval, the retrieval targets or question-answer pairs are pre-defined by the evaluators; models do not need to independently judge “what is worth becoming evidence.” The relationship between the text and the model remains cooperative—interference stems from text length and detail density, rather than from the functional design of the text’s information.

Multi-Hop QA and Evidence Detection. HotpotQA (Yang et al., 2018) and MuSiQue (Trivedi et al., 2022) require models to combine evidence across paragraphs, systematically measuring the ability to piece together reasoning chains from dispersed information. HotpotQA also requires models to output sentence-level supporting facts and separately evaluates their accuracy, already incorporating evidence selection into quantifiable evaluation dimensions. DetectBench (Gu et al., 2024) (its early 2023 preprint titled Piecing Together Clues) goes a step further by independently reporting performance on evidence discovery and final question answering, presenting cases where “relevant evidence was found but the answer was still wrong.” These works demonstrate that separately measuring evidence selection and final reasoning is not an entirely novel attempt. Among them, HotpotQA and MuSiQue primarily use encyclopedic materials, whereas DetectBench includes detective narratives and implicit evidence. WORTH likewise poses explicit questions; its focus lies in incorporating both evidence layout and narrative obfuscation into material design within original professional narratives, and recording models’ clue selection and participant judgment.

Abductive Reasoning. αNLI (Bhagavatula et al., 2020) formalizes abductive reasoning as the task of selecting the more plausible explanation between two candidate hypotheses. True Detective (Del and Fishel, 2023) uses 191 long detective mysteries (averaging \~1,200 words) to test models’ ability to infer implicit causal relations; its dificulty is substantially higher than αNLI, and models indeed need to process information across longer narratives. However, αNLI’s hypothesis space is a predefined binary choice; True Detective answers specific questions given a puzzle, and the evaluation output is the final answer, without requiring the model to explicitly select the evidentiary sentences underlying its reasoning. The most defensible distinction between these benchmarks and WORTH lies in their output and scoring designs, rather than in text length.

Evidence Selection and Explanation Faithfulness. ERASER (DeYoung et al., 2020) established a framework for evaluating models’ ability to “provide reasoning evidence,” requiring models not only to produce answers but also to extract text rationales supporting those answers (sourced from encyclopedias, medical literature, news, etc.). Some pipelines in ERASER designed an evaluation mode where evidence is extracted first and predictions are made solely based on the extracted content; evidence selection in these designs is not purely post-hoc explanation. Explanation faithfulness research (Lyu et al., 2024) further focuses on whether models’ generated explanations truly reflect their decision-making process. ERASER focuses on cross-task rationale extraction and explanation evaluation; WORTH focuses on original professional narratives, observing evidence discovery under conditions of author-designed evidence layout and information obfuscation.

Misdirection, Deception, and Adversarial Examples. Adversarial NLI (Nie et al., 2020) increases the dificulty of natural language inference through human-and-model-in-the-loop adversarial annotation; GSM-IC (Shi et al., 2023) inserts irrelevant sentences into math problems to measure the degree of model distraction; RECALL (Liu et al., 2023) tests model robustness against external information that contradicts pre-trained knowledge; LoFa (Shen et al., 2026) tests models’ ability to resist fallacious persuasion; Contrast Sets (Gardner et al., 2020) test models’ decision boundaries through meaningful local perturbations (typically flipping labels). The commonality among these works is the artificial construction or rewriting of inputs to probe model boundaries, of which only some explicitly label such constructions as adversarial. Such externally applied test conditions difer from the narrative-intrinsic informational relationships examined by WORTH: the adversariality in the latter arises from the narrative design of professional authors and is an inherent structure of mystery narratives rather than a post-hoc perturbation.

The Cooperative Principle and Epistemic Vigilance in Pragmatics. The distinction between cooperative and adversarial relationships mentioned in the Introduction is theoretically aligned with Grice’s (1975) Cooperative Principle and the epistemic vigilance theory of Sperber et al. (2010). In recent years, researchers have begun introducing these pragmatic concepts into large language model research: Krause and Vossen (2024) surveyed the applications of Gricean maxims in natural language processing; related studies have examined single-agent trust and epistemic vigilance regarding external skills (Unlu, 2026), model compliance with versus challenging of users harmful beliefs (Cheng et al., 2026), and pragmatic performance as speakers and listeners in collaboration under asymmetric information (VanderHoeven et al., 2026). These studies touch upon model behavior both as information producers and receivers, but have been conducted primarily in conversational or short-text scenarios, without measuring model performance when confronting information obfuscation in long-form natural narratives.

## 2.3 Evaluations Related to Mystery Fiction and Detective Narratives

While the above lines of work touch upon individual aspects of WORTH, the most directly adjacent work involves existing evaluations centered on mystery fiction and detective narratives. In recent years, several studies have introduced mystery novels and detective stories into large language model evaluation.

DetectiveQA (Xu et al., 2024) utilizes detective novels averaging over 100K tokens to construct 1,200 Chinese and English human-crafted questions and reference reasoning steps, evaluating longcontext reasoning with step-by-step metrics. That study observed dificulties in evidence retrieval, but the tasks remain triggered by pre-written questions and do not require models to output a quota-restricted set of key evidentiary sentences from the full text.

WHODUNIT (Gupta, 2025) uses full texts of public-domain mystery novels, requiring models to identify the culprit after reading. This is one of the works most directly adjacent to WORTH in the task format of “reading a relatively complete mystery narrative and identifying the perpetrator.” However, two key diferences exist: first, WHODUNIT does not require models to explicitly select key clue sentences—the “evidence discovery” process is absent from the observable evaluation output, preventing the benchmark from discerning which evidence path the model took to reach the answer; second, using public-domain classic mystery novels introduces the risk of data contamination, as models may have encountered the plots and endings of these works during training.

WhodunitBench (Xie et al., 2024) tests model reasoning capabilities in multi-player interactive murder mystery game settings, where information is disclosed incrementally through multi-round dialogue and models must actively ask questions and reason. Its evaluation conditions difer fundamentally from WORTH’s single full-text reading with structured output. TurnaboutLLM (Yuan et al., 2025) extracts long-narrative contradiction identification tasks from Ace Attorney and Danganronpa; candidate testimonies and pieces of evidence are already explicitly segmented and labeled, requiring models to identify contradictory pairs across a large combinatorial space rather than delineating evidentiary sentences from unmarked narratives on their own. The computational approach proposed by Wagner et al. (2025) formalizes surprise, coherence, and “fair play” in narratives using an information-theoretic framework; its focus is on evaluating whether a work plays fair with readers, not on measuring whether readers or models can reason successfully under fair yet cognitively obscured conditions.

In summary, existing evaluations related to mystery fiction have introduced this genre into large language model testing, but their evaluation outputs consist primarily of final reasoning conclusions (identifying the culprit, answering questions), without requiring models to explicitly select the evidentiary sentences underlying their reasoning and incorporating them into itemized scoring. Furthermore, materials used in these works are mostly existing works, lacking experimental control where authors actively design information obfuscation conditions from the creative inception stage.

## 2.4 Positioning of WORTH

Synthesizing the above research trajectories, separately measuring evidence selection and reasoning conclusions is not an entirely novel attempt (as discussed in §2.2 regarding HotpotQA, DetectBench, ERASER, etc.), and multiple explorations have employed mystery fiction as an evaluation vehicle. WORTH’s positioning lies in concurrently realizing the following three conditions:

1. Autonomous Evidence Discovery—Models independently select clue sentences from unmarked, complete narratives; the selections themselves are incorporated into scoring and recorded separately from final participant judgments;

2. Not-Fully-Cooperative Informational Environment—Materials are designed from scratch by professional authors; the coexistence of cooperative and adversarial information constitutes the narrative’s intrinsic structure rather than an externally appended disturbance or noise;

3. Itemized Diagnostic Output—Clue hits and participant attributions are scored separately, allowing desynchronization between “what was found” and “what was concluded based on what was found” to be directly observed.

To the authors’ knowledge, no existing benchmark satisfies all three conditions simultaneously. Each condition appears individually or partially in existing literature: DetectBench separately reports implicit evidence discovery and task answering, while WORTH further emphasizes the joint design of evidence layout and obfuscation in original professional narratives; WHODUNIT uses full-length mystery novels but does not require explicit clue sentence selection; True Detective uses long-form detective puzzles, but its evaluation output is the final answer. WORTH’s contribution lies in combining these three conditions into an executable evaluation framework, rather than claiming to pioneer any single concept in isolation.

It should be noted that WORTH does not claim to have exhaustively covered the literature in any of the aforementioned research domains.

## 3. The WORTH Evaluation Framework

The Introduction raised two conditional shifts: autonomous evidence discovery and not-fullycooperative informational relationships. This section elaborates on how these two conditions are translated into an actionable and analyzable evaluation design, and explains why professionally authored mystery narratives serve as an appropriate experimental vehicle.

## 3.1 Autonomous Evidence Discovery and the Target Capability Chain

WORTH requires models to complete three separable stages. The first stage is clue localization: after reading a complete natural narrative, the model independently assesses which sentences among all sentences possess inferential value for identifying case participants, and selects a limited quota of sentences as its evidentiary basis. The second stage is analysis and reasoning: the model conducts analysis based on the selected clue sentences—analysis here is understood broadly, potentially involving logical deduction, physical commonsense, sociological knowledge, or combinations of multiple reasoning modalities. The third stage is participant attribution: based on the analytical results, the model identifies which candidate characters appearing in the story are case participants.

Current scoring directly quantifies the first and third stages. The score for clue sentence selection is based on the overlap between sentences selected by the model and author-designated key clue sentences (overlap with the author-designated key-sentence set K). Clue sentence selection employs a quota mechanism: selecting non-key sentences incurs no direct point deduction, but consumes the limited quota—the penalty is embedded in opportunity cost rather than explicit deduction. The participant attribution stage employs an explicit reward-and-penalty scheme: correctly identifying case participants yields rewards, while erroneously selecting non-participants incurs penalty deductions. The two episodes difer in the specific weight designs for clues and participants (frozen weights for each episode are detailed in §4.5), but share an overarching framework principle: clue sentences represent intermediate steps whose value is ultimately manifested in participant attribution; participant attribution is the terminal judgment, where an erroneous conclusion represents a definitive failure of judgment.

The second stage—analysis and reasoning—is currently not incorporated into quantitative scoring. The evaluation requires models to provide reasoning analysis in natural language, but does not independently score the analysis itself. This decision stems not only from operational considerations (reliable scoring of natural language analysis requires either expensive manual coding or introduces the circular dependency of another model judge), but also from an assessment of the function of the analysis stage: analysis is a processual output whose quality is ultimately reflected in clue selection and participant attribution outcomes; forcing independent quantification onto it risks distorting an open reasoning process into optimization for scoring heuristics. At the present stage, the primary value of the analytical output lies in providing interpretable process information for diagnostic evaluation—such as determining whether the model understood the function of a particular clue sentence, or tracing the reasoning trajectory behind an erroneous attribution—rather than serving as an independent scoring dimension. Whether this design choice warrants revision in future work is left to subsequent empirical accumulation.

## 3.2 Not-Fully-Cooperative Informational Relationships

The Introduction used “cooperative” and “adversarial” to roughly distinguish between two types of informational relationships. This section further elaborates on this distinction.

Adversariality refers to situations where, although information in the text is entirely truthful at the factual level, its presentation—including narrative placement, salience, and causal framing— functionally impairs the reader’s ability to form correct judgments. Adversariality is not false information, not hostile tone, and not random noise; rather, it represents informational control achieved through narrative design by professional authors.

Take an illustrative design from Episode 02. One case participant in the story appears with a limp in his left leg after a fight and subsequently walks with a crutch (S081). The story text factually states: “Geng Baishun limped in his left leg, and the injury was quite severe; for many days afterward, I saw him propping a crutch under his left arm, grimacing with pain at every move.” One detail is that, despite the injury being in his left leg, he supports the crutch with his left hand, whereas under normal circumstances one would use the contralateral hand. This anomaly is deliberately designed by the author—the injury is feigned, and the crutch serves another purpose—yet the story text does not inform the reader of this. What the reader sees is a plausible causal chain: fight → injury → crutch. Reader attention is captured by the fight event itself, rendering the crutch a natural consequence of the injury rather than a clue requiring independent scrutiny. The critical detail (left leg injured yet crutched on the left hand) is already presented in the story text, but why it is anomalous and how it relates to the case must be autonomously discovered and interpreted by the reader.

Cooperative information (evidence suficient to deduce the truth) and adversarial information (narrative arrangements reducing the salience of critical evidence) coexist within the same text. This is not post-hoc artificial noise, but the intrinsic structure of mystery narratives—mature mystery narratives inherently require authors to achieve two tasks simultaneously: provide evidence in principle suficient to deduce the truth, and delay the revelation of truth through narrative techniques.

## 3.3 Why Professionally Crafted Mystery Narratives Are Appropriate Experimental Vehicles

WORTH uses original, professionally authored mystery narratives designed from scratch as evaluation materials, rather than existing mystery novels or artificially assembled distracting texts. This choice is grounded in three reasons.

First, designing from scratch provides design-level support for the benchmark’s construct validity. WORTH measures whether models can discover the reasoning cores preset by the author—key clue sentences are designated as reasoning cores prior to story composition, and the narrative unfolds around them. If commercially published novels were selected, pinpointing reasoning clues accurately would be dificult, because within a finished mystery novel, determining which information was intentionally planted as critical clues and which emerged as incidental usable details during narration cannot be ascertained from the text alone. Designing from scratch means that the inferential function, salience positioning, and role within the evidence chain of every key clue sentence are established during the creative phase.

Second, original materials mitigate the exposure risk associated with directly utilizing existing mystery fiction. Classic works in the public domain may have entered model training datasets, where models’ memory of plots and endings would contaminate measurement; crafting from scratch makes material provenance and answer design more traceable, although it cannot guarantee that models have never encountered the stories prior to evaluation. The timeline relationship between the public release of materials and model testing across both episodes is detailed in §4.6.

Third, mystery narratives naturally provide a textual environment where cooperative and adversarial information coexist. If evaluation materials simply insert distractor sentences randomly into normal text, the distraction itself is artificial—this measures noise detection capability. Informational relationships in mystery narratives are not noise, but functional components of narration.

Precisely because the informational structure of such materials is the product of narrative design rather than post-hoc annotation, its production process difers from problem writing or crowdsourced annotation in conventional benchmarks. The latter can typically be completed by a team from a single professional background; in contrast, evaluations that employ natural narratives as vehicles and concurrently undertake evidence discovery and the measurement of not-fully-cooperative informational relationships require the coordinated integration of three professional competencies typically residing in diferent domains throughout material production.

The first is narrative design capability. At their best, evaluation materials are natural, plausible, and literarily competent mystery narratives, allowing cooperative and adversarial information to coexist organically within the same text.

The second is evaluation methodology capability. The narrative structure must serve quantifiable cognitive discrimination. The quantity, weight distribution, and salience gradients of key clue sentences are not literary judgments, but measurement design decisions; distractor characters require suficient superficial evidentiary pointing while remaining excludable by specific low-salience counter-evidence—appearing strongly suspect yet definitively exonerable. If a creative team lacks this capability, the story may be compelling in itself, yet fail to generate measurement signals with discriminatory power across models.

The third is diagnostic analytical capability. Evaluation is not a one-of procedure: model perfor mance in pilot experiments—such as common explanatory attractors across models, or asymmetric processing between high-salience suspicion information and low-salience counter-evidence—needs to be mapped back to material design. This feedback loop is essential to determine whether observed phenomena stem from the salience design of the story text itself or reflect systematic model characteristics, and to calibrate the evidentiary structure of subsequent episodes accordingly. Lacking this capability, the benchmark can neither iterate and improve from pilot results nor disentangle item efects from model efects.

In this project, these three capabilities were borne by the same small team—the narrative author participated in the top-level design of the evaluation architecture, while the evaluation designer participated in the narrative’s evidence layout and exclusion criteria setup. Such integration currently lacks standardized workflows to follow. Further formalization of narrative design methodology— including how to systematically design salience gradients and how to feed back model results into evidence structure calibration—constitutes a future direction for this project and is not expanded upon in this paper’s pilot experiment.

## 3.4 Current Implementation Scope and Subsequent Verification Conditions

WORTH’s design diferentiates between three conditions: full-story, evidence-cueing, and evidencemodification, intended to observe response variations under diferent conditions.

The first verification layer is the full-story condition, which is also the only condition implemented in this paper: models read unmarked, complete narratives and autonomously complete clue selection, reasoning analysis, and participant attribution.

The second verification layer is the evidence-cueing condition: retaining the complete story while explicitly marking the key clue sentences designated by the author, comparing participant attribution before and after prompting. This tests whether prompting key evidence alters judgment, though such a comparison alone cannot attribute diferences entirely to evidence discovery.

The third verification layer is the evidence-modification condition: modifying key evidence while maintaining narrative coherence and altering the answer accordingly, observing whether model judgments change alongside evidentiary shifts. This condition tests model responsiveness to textual evidence variations.

The latter two verification layers have not yet been implemented and do not constitute empirical evidence in this paper.

## 4. Design of the Two-Episode Pilot Experiment

This section describes the experimental design, response protocol, operational conditions, scoring rules, and data processing criteria of the two-episode pilot experiment. The two episodes difer in story content, evidence structure, and scoring parameters; raw scores cannot be aggregated or directly compared across episodes.

## 4.1 Task Materials

Each experimental episode uses an original Chinese mystery narrative as task material. Stories are presented to subjects as numbered natural sentences, with each sentence preceded by a localization identifier ranging from [S001] to [Snnn]; prompt instructions explicitly clarify that identifiers serve solely for localization and do not imply whether a sentence constitutes a clue.

Episode 01 comprises 120 natural sentences, revolving around a homicide occurring at a township grain depot and involving 6 candidate characters. Episode 02 comprises 134 natural sentences, continuing another homicide within the same narrative universe and involving 9 candidate characters. The two episodes difer in narrative complexity, evidence volume, character scale, and scoring weights: Episode 02 features more candidate characters (9 vs. 6) and key clue sentences increase from 12 to 20. The weight designs of both episodes emphasize diferent aspects: EP01 assigns uniform weights to clues (3 points each), diferentiates rewards for correct characters (7/5/5), and applies a uniform deduction for incorrect characters (-5); EP02 diferentiates clue weights (1–4 points), applies uniform rewards for correct characters (2 points each), and diferentiates deductions for incorrect characters (-2 to -8, penalizing the most misleading distractor characters more heavily). These diferences reflect evaluation iteration rather than an intentional construction of a dificulty gradient.

Both stories have been deployed on Bilibili’s Toy platform as interactive reasoning games. Players read the story incrementally through the game interface and submit a limited quota of clue sentences and case participant selections. As of the data freeze, each episode had accumulated thousands of human player score records. Platform cumulative records have not yet completed export and cleaning, and this version does not treat them as human-model comparison samples (see §4.8).

The public game pages are Episode 01 and Episode 02. These pages illustrate the player response environment; the current online game content is not a substitute for the frozen prompts and scoring versions used in the model experiments.

## 4.2 Design Status of Key Clue Sentences

Key clue sentences are inferential hubs preset by the author during the design of the story world, character trajectories, and event sequences, rather than post-hoc annotations made after text completion. Each key clue sentence is documented in the creative archive with its corresponding original sentence, a brief description of its inferential function, and its position within the evidence chain.

It should be noted that the author’s set of key clue sentences (K) represents the reasoning cores designated by the author, and does not represent the sole exhaustive set of all valid evidence in the story. An unmarked natural narrative may contain sentences unannotated by the author that nonetheless carry auxiliary inferential value, and multiple paths may lead to the correct conclusion. Current scoring is based on the overlap between sentences selected by the model and K (overlap with the author-designated key-sentence set K); hence, it measures the extent to which the model hits the author’s preset reasoning cores, rather than whether it exhausts all possible reasoning

pathways.

## 4.3 Response Protocol

Subjects receive the complete numbered story text alongside a structured response prompt. The prompt instructs subjects to complete three tasks: select key clue sentences from all sentences, determine case participants from candidate characters, and provide reasoning analysis in natural language.

The output format is a structured object containing seven mandatory fields: episode identifier, array of clue sentence identifiers, array of character identifiers, array of sentence-by-sentence clue explanations, combined evidence analysis, final conclusion, and confidence score. The instructions include an output self-check checklist, requiring clue identifiers to be non-duplicate and drawn from the story body, character identifiers to be non-duplicate and drawn from the candidate list, and sentence-by-sentence explanations to map one-to-one with clue identifiers.

Clue selection is subject to an upper bound: Episode 01 permits selecting at most 12 sentences, and Episode 02 permits at most 20 sentences; subjects may select fewer, but cannot exceed the quota. Character selection adopts a multi-select mode: subjects may select none, select one, or select multiple characters, with the prompt not disclosing the correct number of participants. The instructions for Episode 02 additionally provide an operational definition of “homicide participant”— “including those who planned, executed, or provided critical assistance to the homicide, not limited to those who directly carried out fatal acts”—and advise subjects that they need not exhaust the clue quota if confidence is insuficient.

The nine rules in the instructions also stipulate: utilize only the information provided in the current prompt; do not access the internet, search, or use external tools; the narrative perspective is reliable and narrator deceit need not be considered; do not pose questions to the test administrator or provide multiple alternative answers; and output only a single valid structured object without any additional text.

## 4.4 Scoring Information Disclosure

A deliberate design discrepancy exists between the scoring information available to subjects during testing and the complete frozen rules disclosed in the paper.

Information known to subjects includes: the total number of key clue sentences and the selection ceiling; that selecting correct clues adds points while selecting incorrect ones incurs no deduction; that selecting correct characters adds points while selecting incorrect ones incurs deductions; and that the prompt does not disclose the correct number of participants. Information unknown to subjects includes: the diferentiated weights of individual key clue sentences (Episode 02), the diferentiated penalty magnitudes for diferent incorrect characters, and the complete payof matrix.

This arrangement represents an explicit measurement design decision. If subjects knew the complete payof matrix in advance—for instance, knowing that misselecting a certain character incurs a severe penalty while another character incurs a mild penalty, or that certain clue sentences carry much higher scores than others—response behavior might shift from narrative reasoning to risk control under a known payof matrix. Subjects could avoid costly errors by selecting fewer characters, or optimize expected scores by prioritizing guesses on high-value clue sentences, thereby introducing strategic variance unrelated to narrative reasoning. Concealing diferentiated weights and penalty matrices aims to preserve natural narrative judgment conditions as much as possible and reduce construct-irrelevant variance. This paper does not frame this arrangement as having measured “pure reasoning ability,” but rather as having controlled for reasoning-irrelevant strategic factors within a reasonable scope.

Concealing this information from subjects while disclosing it to paper readers is not contradictory: the former protects measurement conditions, while the latter ensures transparency and reproducibility.

## 4.5 Scoring Rules

The scoring structures of both episodes adhere to the same logic—clue hits receive positive points, while participant attribution receives rewards for correct choices and penalties for incorrect ones—but difer in specific parameters.

Episode 01 adopts uniform weights. 12 key clue sentences are worth 3 points each; selecting a key sentence earns points, omitting it incurs no deduction, and selecting a non-key sentence likewise incurs no deduction but consumes the limited quota. Rewards for the 3 correct characters are 7 points, 5 points, and 5 points, respectively; incorrect characters incur a uniform deduction of 5 points. The maximum score is 53 points, and the theoretical minimum is −15 points.

Episode 02 adopts diferentiated weights. The 20 key clue sentences range from 1 to 4 points each, reflecting difering inferential dificulty and importance within the evidence chain; the clue component totals 41 points. The 3 correct characters receive 2 points each. Penalties for incorrect characters vary by character: the most plausible distractor characters incur the heaviest deductions (up to −8 points), while characters easier to eliminate incur milder deductions (−2 points). The maximum score is 47 points.

The asymmetry in penalty mechanisms between clue selection and participant attribution—where selecting non-key sentences carries no direct point deduction while selecting incorrect characters incurs explicit penalties—reflects their distinct roles within the reasoning process. Clue sentences represent intermediate steps whose value is ultimately realized in participant attribution; participant attribution is the terminal judgment, where an erroneous conclusion represents a definitive failure of judgment. The current total score represents a gameplay-equivalent score, and the clue score represents overlap with the author-designated key-sentence set K; neither is equivalent to a comprehensive measurement of complete reasoning capability.

## 4.6 Models and Run Configurations

Episode 01 tested 6 models, and Episode 02 tested 8 models. Model selection covered major commercial large language models publicly accessible at the time of data freezing; each group was run according to product portals and tier configurations recorded at the time, which were not uniformly set to the “highest” tier.

Each model was run 5 times, yielding 70 formal runs across both episodes. The operational conditions recorded in the experiments were: conducted in fresh dialogue sessions without inheriting prior conversation history; web search, external tools, product memory, and personalization settings disabled; complete prompts (numbered story text and response instructions) sent in a single turn without multi-turn interaction. Configuration screenshots and response screenshots exist for some models, with screenshots providing varying scopes of substantiation across toggles.

The model lineups across the two episodes partially overlap: Episode 01 includes GPT-5.6 Sol, Claude Opus 4.6, GLM-5.2, DeepSeek-V4-Flash, Kimi K3, and Gemini 3.1 Pro; Episode 02 includes GPT-5.6 Sol, Claude Opus 4.6, Gemini 3.1 Pro, GLM-5.3, Kimi K3, DeepSeek-V4-Pro, Hy4 preview, and MiniMax-M3. Certain model versions and access portals shifted between episodes: for example,

GLM-5.2 changed to GLM-5.3, and DeepSeek-V4-Flash changed to DeepSeek-V4-Pro; Opus shifted from Antigravity’s Thinking to Claude.ai’s High + Extended, and Kimi shifted from oficial website “Advanced” to WorkBuddy “High”. EP02 DeepSeek’s tier was not recorded separately, and MiniMax’s tier was recorded as $\mathrm { n } / \mathrm { a } ;$ for EP01 GLM, configuration and execution screenshots showed “Highest” and “High” respectively, and this paper follows the execution record using “High”.

EP01 was first released publicly as a game on 2026-08-14 at 17:18 (UTC+8), and its model testing was also conducted on 2026-08-14. EP02 went online on 2026-08-21, and model testing was conducted from 2026-08-30 to 2026-08-31. Existing records cannot guarantee that test materials were unreleased prior to testing, nor can they determine whether model pretraining ingested the publicly released materials.

## 4.7 Handling of Format Validity

The response prompt requires subjects to output a valid structured object. In practical processing, whether a response is parseable as JSON and whether the selections within satisfy identifier and quantity constraints are recorded separately. That a response is directly parseable, or that complete JSON can be extracted from surrounding explanatory text, does not automatically imply that selections are valid; when overall JSON is unparseable, if valid selection arrays can be directly read from the raw text, content scoring can still be computed without repairing the raw response.

Among the 30 runs in Episode 01, 22 were parseable overall, 7 contained embedded parseable JSON, and 1 had invalid overall JSON but selections could be directly read; all 30 were contentscorable. Among the 40 runs in Episode 02, 26 were parseable overall, 9 contained embedded parseable JSON, and 5 had invalid overall JSON, among which selections in 4 runs could still be directly read and scored. Out of 40 runs, 3 were excluded: Gemini response05 and Hy4 response05 had parseable JSON but contained non-existent identifiers S207 and S146, respectively; Kimi response02 contained illegal expressions in selection fields and could not be read as valid identifier arrays. Consequently, EP02 yielded 37 content-scorable runs; excluded runs are not scored as zero.

Across both episodes, responses fully compliant with the output protocol numbered 22 and 25, respectively. Format compliance and content scores are reported separately.

## 4.8 Criteria for Human Player Data

Both narrative reasoning games have accumulated thousands of human player score records, but cumulative platform records cannot automatically be equated with independent, valid human samples. The human data criteria planned for this paper use cleaned valid first-attempts: for multiple attempts by the same player identifier within the same episode, only the initial submission is retained; trial plays and obvious anomaly records are excluded.

Operational conditions difer between humans and models. Human players read and submit incrementally through the game interface, whereas models receive the complete prompt in a single turn; human response times are uncontrolled, whereas model inference times are determined by respective platforms; human player counts vastly exceed the 5 runs per model. Therefore, subsequent human analyses will primarily provide baseline references for score distributions and error patterns on the same tasks, examining whether specific phenomena also appear in human responses, rather than treating large-sample human records and 5 runs per model as a symmetric statistical comparison. The aforementioned cleaning has not yet been completed, and this version does not report human data analysis results (see §7.3).

## 4.9 Semantic Boundaries of “Case Participant”

The core questions of the two episodes are “Who brought about the homicide?” (Episode 01) and “Which individuals are homicide participants?” (Episode 02). The natural semantic scope of the term “participant” may induce divergent interpretations across models and humans. The prompt for Episode 02 provided an operational definition—including planners, executors, or key facilitators—yet this definition still leaves borderline ambiguities. Furthermore, EP02 reviews the death of Uncle Six while also narrating the subsequent deaths of Qin Guanggui and Wang Yonghong; the correct set of characters for this episode corresponds to the latter two deaths, but the prompt only asks “Which individuals are homicide participants?” without explicitly delimiting the scope of the case. Raw responses in some runs analyzed both Uncle Six’s case and subsequent events. This paper treats this as a construct boundary of the pilot experiment, rather than attributing all attribution errors related to the definition of “participant” to failures of model reasoning. Relevant explanations should be evaluated in conjunction with the scope of the case and the meaning of participant actually addressed in the model’s response.

## 4.10 Cross-Episode Reporting Principles

Because the two episodes use diferent stories, diferent evidentiary structures, diferent candidate character sets, and diferent scoring parameters, raw scores cannot be directly summed, nor can they be used to determine which episode is “more dificult.” In the Results section, the two episodes are first reported separately, with cross-episode comparisons conducted solely on structural phenomena observable in both episodes (such as process dissociation, common attractors, and evidence asymmetry). Cross-episode comparisons are based on observable behavioral patterns and do not rely on numerical comparisons of raw scores.

## 5. Results: Behavioral Diferences Exhibited in the Pilot Experiment

This section reports the results of the two-episode pilot experiment. Sections 5.1 and 5.2 report intra-episode behavioral structures, and Section 5.3 extracts structural patterns shared across both episodes. All numbers are traceable to frozen scoring data. It must be reiterated: the scale of 70 formal runs across two episodes sufices only to support preliminary diagnostics, not to establish stable model rankings or infer generalized cognitive mechanisms.

## 5.1 Episode 01

EP01 collected a total of 30 model runs (6 models × 5 independent runs). The full text contains 120 sentences, with 12 author-designated key clue sentences (3 points each, maximum 36 points) and 6 candidate characters (selecting “I” awards 7 points, selecting Father or Director Huang awards 5 points each, with a 5-point deduction for each misselected character). The participant component has a maximum of 17 points, and the gameplay-equivalent total score has a maximum of 53 points.

The table below reports each model’s mean gameplay-equivalent total score and subscale means.

<table><tr><td>Model</td><td></td><td>Total Score Mean Clue Score Mean Participant Score Mean</td><td></td></tr><tr><td>GPT-5.6 Sol</td><td>11.20</td><td>10.20</td><td>1.00</td></tr></table>

<table><tr><td>Model Total Score Mean</td><td>Clue Score Mean</td><td>Participant Score Mean</td></tr><tr><td>Claude Opus 4.6</td><td>11.60</td><td>9.60 2.00</td></tr><tr><td>GLM-5.2</td><td>15.00</td><td>9.00 6.00</td></tr><tr><td>DeepSeek-V4-Flash</td><td>14.60</td><td>6.60 8.00</td></tr><tr><td>Kimi K3</td><td>9.40</td><td>8.40 1.00</td></tr><tr><td>Gemini 3.1 Pro</td><td>11.20</td><td>7.20 4.00</td></tr></table>

Note: Means for each model are calculated across 5 content-scorable runs. Total score = clue score + participant score; participant score includes rewards for correct selections and deductions for incorrect selections. Maximum scores for total score, clue score, and participant score are 53, 36, and 17 points, respectively.

## 5.1.1 Finding Clues Does Not Imply Identifying Participants

In EP01, performance in hitting key clue sentences was not synchronized with participant selection: the model that identified the most clues yielded the lowest mean for correct participants. This paper uses process dissociation to describe this desynchronization of output metrics, without asserting that internal model processes have been isolated. The table below presents the means of both metrics.
<table><tr><td>Model</td><td>Key Clue Hits Mean (/12)</td><td>Mean No. of Correct Participants Selected (/3)</td><td>Mean No. of Incorrect Participants Selected</td><td>Five-Run</td><td>Standard Devia- tion</td></tr><tr><td>GPT-5.6 Sol</td><td>3.4</td><td>0.8</td><td>0.6</td><td>14, 17, 4, −4,</td><td>11.3</td></tr><tr><td>Claude Opus 4.6</td><td>3.2</td><td>1.0</td><td>0.6</td><td>25 22, 7, 4, 6, 19</td><td>8.3</td></tr><tr><td>GLM-5.2</td><td>3.0</td><td>1.4</td><td>0.2</td><td>22, 16, 20, 14,</td><td>7.4</td></tr><tr><td>Kimi K3</td><td>2.8</td><td>1.0</td><td>0.8</td><td>3 19, 1, 12, 8, 7</td><td>6.7</td></tr><tr><td>Gemini 3.1 Pro</td><td>2.4</td><td>1.4</td><td>0.6</td><td>6, 19, 19, 6, 6</td><td>7.1</td></tr><tr><td>DeepSeek- V4-Flash</td><td>2.2</td><td>1.6</td><td>0.0</td><td>11, 13, 22, 8, 19</td><td>5.8</td></tr></table>

In the table, “Standard Deviation” measures the dispersion of scores across the five runs of the same model (sample standard deviation, rounded to one decimal place). GPT-5.6 Sol had the largest standard deviation (11.3), with five total scores ranging from −4 to 25, a span of 29 points; DeepSeek-V4-Flash had the smallest standard deviation (5.8), being the most stable among the six models. Because total scores can be negative (GPT exhibited negative scores in EP01), coeficient of variation (CV = standard deviation ÷ mean) is not used here, and raw standard deviations alongside the five individual scores are reported for direct comparison.

GPT-5.6 Sol identified the most key clue sentences (mean 3.4/12), but had the lowest mean for correct participants (0.8/3), with a mean of 0.6 incorrect participants per run. DeepSeek-V4-Flash hit the fewest clues (mean 2.2/12), but had the highest mean for correct participants (1.6/3), with zero incorrect selections across all five runs. These itemized outputs exhibit divergent behavioral profiles.

## 5.1.2 Case Observations of Erroneous Judgments

The following cases illustrate diferent error manifestations; mutual exclusivity classification or frequency counting was not performed across all responses.

• Participant Attribution Drift. GPT-5.6 Sol’s response04 noted that Uncle Six did not commit suicide and that Qin Guanggui and Wang Yonghong were involved in the grain depot deficit, yet deduced that “Qin Guanggui and Wang Yonghong. . . acted together,” ultimately selecting only these two non-correct characters.

• Extratextual Causal Completion. GLM-5.2’s response05 conjectured that the cupping apparatus “might have been tampered with” and further speculated that someone used it to administer drugs; the story text provided no evidence of apparatus tampering or drug administration, and this run also erroneously selected Qin Guanggui.

• Omission of Correct Participant. The first-person narrator “I” (R04) belongs to the author’s participant set, but was selected in 0 out of 30 runs. Some responses mentioned “my” cupping act, yet did not include R04 among participants; this boundary issue is discussed in §6.5.

## 5.1.3 Gemini 3.1 Pro: Scores at Only Two Discrete Levels

Gemini 3.1 Pro ran five times, with total scores taking only two values: three runs at 6 points and two runs at 19 points. Concurrently, in all five runs, the value entered in its confidence field was 100 in all five runs. Shifting scores alongside constant self-assessed confidence is a behavioral characteristic worth recording in this batch of runs; this is insuficient to determine how the mode interprets its own confidence.

## 5.1.4 Model Diagnostic Profiles

Synthesizing the above dimensions, the six models in EP01 exhibited distinguishable diagnostic profiles:

• GPT-5.6 Sol: Relatively high key sentence hits, poorer participant judgment, large score volatility.

• DeepSeek-V4-Flash: Lower mean key sentence hits, highest mean correct participants, zero incorrect selections across all five runs.

• Gemini 3.1 Pro: Total scores across five runs took only two values (6 and 19), with self-assessed confidence uniformly at 100.

• GLM-5.2: Mean key sentence hits of 3.0, mean correct participants of 1.4 (tied with Gemini), mean incorrect selections of 0.2.

• Claude Opus 4.6 and Kimi K3: Intermediate clue hits and participant selections, moderate volatility.

It must be emphasized that these profiles describe behavioral characteristics of the models in this specific pilot experiment, and do not constitute comprehensive evaluations of model reasoning ability. The same model may exhibit diferent behavioral patterns under diferent narrative structures and domain settings.

## 5.2 Episode 02

EP02 expanded the evaluation scale: 8 models × 5 runs = 40 formal runs, of which 37 were content-scorable (3 runs were excluded due to invalid selection content, see §4.7 for details). The full text contains 134 sentences, with 20 author-designated key clue sentences (ranging from 1 to 4 points each, maximum 41 points), 9 candidate characters, and a theoretical maximum gameplay-equivalent score of 47 points. The case structure of EP02 is more complex than EP01: the correct participant chain involves multi-layered divisions of labor—planning, execution, assistance, and cover-up—with necessary evidence dispersed across low-salience, cross-paragraph, multi-functional information.

The table below reports each model’s mean gameplay-equivalent total score and subscale means.
<table><tr><td>Model</td><td>Total Score Mean Clue Score Mean</td><td>Participant Score Mean</td></tr><tr><td>GPT-5.6 Sol</td><td>6.80 14.80</td><td>-8.00</td></tr><tr><td>Claude Opus 4.6</td><td>-1.00</td><td>12.20 -13.20</td></tr><tr><td>Gemini 3.1 Pro</td><td>5.00</td><td>12.00 -7.00</td></tr><tr><td>GLM-5.3</td><td>-6.40</td><td>10.00 -16.40</td></tr><tr><td>Kimi K3</td><td>-8.00</td><td>11.50 -19.50</td></tr><tr><td>DeepSeek-V4-Pro</td><td>-8.60</td><td>9.00 -17.60</td></tr><tr><td>Hy4 preview</td><td>-1.25</td><td>14.75 -16.00</td></tr><tr><td>MiniMax-M3</td><td>-9.00</td><td>7.00 -16.00</td></tr></table>

Note: Gemini 3.1 Pro, Kimi K3, and Hy4 preview have means calculated across 4 content-scorable runs each, while remaining models have means calculated across 5 runs; unparseable/non-scorable runs are not included in means, nor are they scored as zero. Total score = clue score + participant score; participant score includes rewards for correct selections and deductions for incorrect selections, and may be negative. Maximum scores for total score, clue score, and participant score are 47, 41, and 6 points, respectively. Raw scores between the two episodes are not directly compared.

EP02 likewise exhibited marked process dissociation. The most representative cases include: Hy4 preview’s response03 hit 9 key clue sentences (clue score 18), yet selected zero correct case participants; Kimi K3’s response03 hit a cohort-high 10 key clue sentences (clue score 17), but selected zero correct participants while misselecting 5 characters, yielding a participant score of −20 and a total score of −3. In contrast, GPT-5.6 Sol’s response01 hit only 5 key clue sentences (clue score 12), yet was the sole run to select correct participants without containing any incorrect characters (selecting Brother Lei and Geng Baishun while missing Geng Baili), achieving the episode-high score of 16/47 points. Identifying many clues does not equate to selecting correct participants.

## 5.2.1 Common Attractor: Convergent Errors Across Models

The most striking phenomenon in EP02 is the emergence of a common attractor. Across 37 content-scorable runs:

• 31/37 runs (83.8%) included the trio of “Father – Jia Changgeng – Director Huang” in participant selections;

• 16/37 runs (43.2%) selected strictly this trio, neither more nor fewer;

• 18/37 runs (48.6%) had this trio at the core, adding or omitting at most one character.

This convergence spanned all eight models and was not idiosyncratic behavior of any single model. It should be clarified that none of these three individuals were correct participants in EP02 (EP02’s correct participants were Brother Lei, Geng Baishun, and Geng Baili). Among them, Jia Changgeng assumed a high-salience suspect role in the story (substantial descriptions pointed to his suspicious behavior, −8 deduction), Director Huang held superficial connections to the case but functioned in fact as a distractor (−6 deduction), and Father was a correct participant in EP01 but not a participant in EP02 (−2 deduction).

The existence of a common attractor indicates that high-salience signals in the story (such as multiple depictions of Jia Changgeng’s suspicious actions) can pull participant selections toward the same erroneous direction across models and across runs. The significance of this phenomenon lies in providing an empirical metric to test the efectiveness of narrative design: if distractor structures preset by professional authors can generate consistent misdirection efects across disparate models, this in itself constitutes evidence of successful not-fully-cooperative informational design.

## 5.2.2 Evidence Asymmetry: S112 vs. S113

EP02 provides a representative case of asymmetric processing between positive and negative evidence. S112 and S113 are two adjacent sentences in the story with diametrically opposed functions:

• S113 (suspicion-oriented evidence): selected in 25/37 runs (67.6%)

• S112 (exoneration-oriented evidence / alibi evidence): selected in 0/37 runs (0%)

The two sentences are immediately adjacent in the text. The 25:0 selection frequency disparity demonstrates that a marked asymmetry exists in model evidence selection between suspicion-oriented information and exoneration-oriented information. It should be noted that physical adjacency does not imply equal processing weights; S113 itself encompasses multiple pieces of information, such as the private discussion act and the disappearance timeline, and specific rationales for selecting it may vary across runs. What is reported here is the disparity in selection frequencies, not a unified functional attribution for every selection.

## 5.2.3 S081 and Local Evidence-Selection Covariation

S081 describes Geng Baishun’s crutch anomaly. Across 37 content-scorable runs, it was selected 6 times: GPT-5.6 Sol’s response01, 03, 04, 05, Claude Opus 4.6’s response05, and Gemini 3.1 Pro’s response02. All 6 runs simultaneously selected Brother Lei and Geng Baishun; Gemini’s run also selected Geng Baili, but additionally misselected Jia Changgeng. Thus, what is observed here is a local co-occurrence between S081 and Geng Baishun’s selection, rather than six completely correct responses. Because a single response submits sentence and participant selections simultaneously, the temporal order in which the two selections arose, or any causal relation between them cannot be determined from this alone.

## 5.2.4 The S124 Phenomenon: Boundaries Between Puzzle Premise and Scored Clues

S124 describes Qin Guanggui being strangled from behind and hung from a tree, along with the crime scene having only footprints of the deceased leading toward the tree, with other footprints made later by those who discovered the body. This sentence constitutes the core puzzle premise of the case and provides constraints for inferring the modus operandi. The author positioned it as a foundational fact requiring explanation, and did not include it in the set of key clue sentences rewarding specific inferential hubs.

All 37/37 content-scorable runs selected S124, earning no points for this sentence under frozen rules. This unanimous selection shows that a stable divergence exists between the evidentiary set submitted by models and the author’s scoring set: models universally selected the core puzzle premise, whereas scoring emphasized other key sentences that unravel the puzzle. While S124 exhibited no selection rate variance in this batch of runs, its unanimous selection retains diagnostic value—it reminds us to distinguish between “failing to hit K” and “selecting information lacking inferential utility.”

## 5.2.5 Five 0/37 Key Clue Sentences

Among the 20 key clue sentences in EP02, five were never selected by any model across all 37 runs: S025, S074, S077, S106, and S112. However, the nature of these omissions difers:

• S112 was discussed in 5.2.2; its omission relates to the systematic neglect of exoneration-oriented evidence.

• Neighboring sentences to S025, S074, and S077 were selected in some runs; missing a specified sentence does not necessarily mean missing the entire segment of information. For example, MiniMax-M3’s response02 did not select S025, but selected the adjacent S026, using the past event of Jia Changgeng deceiving the Geng family on behalf of the Huang family to infer Jia’s relationship with the Huangs; that explanation did not explicitly utilize the old grievance between the Huang and Geng families stated in S025, so S026 cannot be treated as a fully equivalent substitute.

• Although no model selected S106, one cannot judge solely from sentence selection that the role of fear was entirely absent from explanations. GPT-5.6 Sol’s response01 selected S093 and S129, discussing terrifying paper figures and continuous intimidation; whether other runs utilized proximate information still requires inspecting explanations run by run.

Therefore, the raw 0/37 figure must be interpreted in conjunction with neighboring sentence selections, and cannot be simply equated with “complete omission.”

## 5.2.6 Predominance of Negative Scores and Score Distribution

Overall scores in EP02 were skewed low: 28/37 runs (75.7%) yielded negative gameplay-equivalent scores. The highest individual score was GPT-5.6 Sol’s response01, obtaining 16/47 points. The reason negative scores predominated is that the correct participant chain in EP02 involved multilayered division of labor, requiring integration of evidence dispersed across low-salience positions; meanwhile, most runs were drawn by the common attractor toward incorrect characters (such as Jia Changgeng), whose penalty deductions exceeded the points gained from hitting key clue sentences.

## 5.2.7 Selecting Correct Characters and Eliminating Incorrect Characters Are Distinct

At the participant selection level, EP02 further demonstrated the dissociation between “selecting correct characters” and “eliminating incorrect characters”:

• 15/37 runs (40.5%) identified at least 1 correct case participant;

• Yet among these 15 runs, 13 (86.7%) still concurrently included the distractor character Jia Changgeng.

This indicates that selecting correct characters and eliminating incorrect characters are two stages that can manifest separately. Models can make headway in the correct direction—indeed identifying some correct participants—while remaining unable to resist the pull of high-salience distractor signals, bundling Jia Changgeng into their selections as well. This aligns with findings in EP01: reasoning tasks under the WORTH framework comprise multiple sub-steps, and performing well on one step does not guarantee performing well on another.

## 5.2.8 EP02 Model Profiles

The diagnostic profiles of models in EP02 partially continued trends from EP01, while displaying new bifurcations:

• GPT-5.6 Sol: Produced the highest-scoring run across the episode (16/47), but also produced a negative run (−3), continuing its high-volatility characteristic from EP01.

• DeepSeek-V4-Pro: Total scores across five runs ranged from −12 to −6, all negative; averaged 4.2 incorrect selections, only slightly lower than Kimi’s 5.0, with participant selection not continuing the conservative and precise profile of DeepSeek-V4-Flash in EP01.

• Newly added Hy4 preview and MiniMax-M3 provided additional observation points in EP02, but cross-episode comparisons are unwarranted given the pilot scale.

## 5.3 Structural Patterns Shared Across Both Episodes

Raw scores between EP01 and EP02 cannot be directly compared—the two episodes difer in text length (120 vs. 134 sentences), number and point structure of key clue sentences (12 × 3 points vs. 20 × 1–4 points), case complexity and candidate character count (6 vs. 9 characters), and participating models do not completely overlap (6 vs. 8 models). Consequently, the following cross-episode comparison focuses on whether structural patterns appear in both episodes, rather than direct numerical comparisons.

## 5.3.1 Cross-Episode Consistency of Process Dissociation

Both episodes feature cases where clue hits and participant selections are desynchronized: in EP01, GPT-5.6 Sol’s mean key sentence hits exceeded DeepSeek-V4-Flash, yet its mean correct characters were lower; in EP02, Kimi K3’s response03 hit 10 key sentences, yet selected zero correct characters. “Process dissociation” here is a description of output discrepancies; cases across two episodes are insuficient to rule out the influence of story or prompt configurations.

## 5.3.2 Cross-Episode Consistency of Positive-Negative Evidence Asymmetry

Both episodes exhibited asymmetric model processing of “suspicion-oriented evidence” versus “exoneration-oriented evidence”:

• In EP01, S064 and S072, used by the author to eliminate Qin Guanggui and Wang Yonghong as direct perpetrators, were both 0/30; S094, involving Director Huang arranging cupping, was selected in 22/30 runs.

• In EP02, the 0:25 contrast between S112 and S113 provided more precise quantitative evidence. The joint emergence of this asymmetry across both episodes suggests that it may represent a structural tendency of current large language models when processing mystery narratives. However, it must be noted: this observation is grounded in a specific domain (mystery narratives) and specific designs (informational manipulation in professional narratives), and generalizing it to other domains requires further empirical verification.

## 5.3.3 Systematic Omission of “I” and Unanimous Selection of S124

Correct character R04 in EP01 was selected by no model across 30 runs; S124, which was outside the author’s key clue sentence set in EP02, was selected by all 37 content-scorable runs. The two extreme selections point respectively to construct boundary issues regarding participant definitions and the scope of scored clues. Raw explanations and potential causes are discussed in §6.5 and §6.3, respectively.

## 6. Discussion

Section 5 reported the observable behavioral structures in the two-episode pilot experiment. This section discusses the implications of these results: why they provide diagnostic information not easily revealed by traditional reasoning evaluations, what empirical feedback they ofer for WORTH’s design assumptions, and which explanations still require subsequent experiments to disentangle.

## 6.1 Process Dissociation: Phenomena Manifested Under Autonomous Evidence Discovery

Itemized outputs across both episodes show that key sentence hits and participant judgments can be desynchronized. The EP01 model mean contrasts and EP02 run-level cases in Section 5 support reporting these two classes of results separately; they do not isolate internal reasoning steps within models.

Evaluations that report only final answer scores struggle to present performance in evidence discovery and participant judgment separately. When evidence is provided by the test designer, the front end of the reasoning chain (judging what is worth becoming evidence) is substituted by the test designer, allowing evaluation to see only the latter half from known premises to conclusions. WORTH’s autonomous evidence discovery condition renders this front-end stage an observable output as well. For instance, in EP01, GPT-5.6 Sol hit more key sentences yet correctly identified fewer characters, while DeepSeek-V4-Flash displayed the inverse combination. Looking solely at total scores would obscure this disparity; recording both outputs separately brings it to light. Measuring the two stages separately helps diferentiate model performance variations across distinct sub-processes, rather than observing only a conflated signal.

Of course, process dissociation has currently been observed only in two mystery narratives, and a scale of 70 runs is insuficient to establish stable quantitative estimates. Whether it exists similarly across other types of narratives and reasoning tasks requires more data to answer. Yet even if treated only as a recurring behavioral pattern, it demonstrates that in measuring reasoning ability, “what is found” and “what judgment is made using what was found” deserve separate investigation.

## 6.2 Common Attractor: Empirical Metric of Narrative Design Efectiveness

In EP02, 31/37 runs included the “Father – Jia Changgeng – Director Huang” trio in participant selections, spanning all eight models and displaying a concentrated erroneous selection pattern. Jia Changgeng was designed by the author as a high-salience suspect—substantial descriptions pointed to his suspicious conduct, and multiple clues superficially supported the judgment that he participated in the crime. Director Huang held superficial connections to the case but functioned in fact as a distractor. That 83.8% of runs contained the same set of incorrect characters aligns with the author’s intended suspicion-steering direction, providing a concrete entry point for analyzing how narrative interference afects participant judgment.

This phenomenon provides direct empirical support for WORTH’s second conditional shift—notfully-cooperative informational relationships. Section 3 argued why professionally authored mystery narratives serve as appropriate experimental vehicles: authors achieve two tasks concurrently— providing evidence in principle suficient to deduce the truth, and delaying the revelation of truth through narrative techniques. The common attractor links the author’s suspicion-steering design with actual model selections, representing an empirical phenomenon worth analyzing in not-fullycooperative information environments. Some responses also analyzed both Uncle Six’s case and subsequent death events concurrently (see §4.9), necessitating interpreting participant selections in light of their actual explanations. Subsequent control conditions can further test the impact of narrative obfuscation on this convergence.

However, alternative explanations must be preserved. The emergence of a common attractor can be attributed to at least three mechanisms, which current data cannot disentangle:

The first possibility is insuficient epistemic vigilance in models. Confronted with a superficially coherent explanatory framework, models do not inquire “whether this explanation missed something” or “whether counter-evidence was ignored”; once a framework explaining most phenomena is assembled, they halt there.

The second possibility is that salience control in the story design was overly potent. Depictions of Jia Changgeng’s suspicion overwhelmed counter-evidentiary information in volume and intensity, making it dificult even for subjects with critical capacity to resist. In other words, the problem may lie not in the models, but in the test’s distractor design being “too efective.”

The third possibility is a joint efect—insuficient epistemic vigilance in models compounded by potent salience control jointly produced highly convergent outcomes.

The evidence-cueing condition proposed in §3.4 can observe whether participant attribution shifts after key sentences are marked; the evidence-modification condition can observe how answers shift alongside alterations to key facts. Neither has been implemented yet, nor can any single control attribute the common attractor solely to story-text salience or model judgment styles. To specifically test the salience of suspicion descriptions, rewritten conditions that hold case facts constant would also need to be established.

## 6.3 Selection Boundaries Between Puzzle Premise and Evidence

The unanimous selection of S124 illustrates a boundary between author scoring design and model evidence selection. The author positioned it as the core puzzle premise, placing scoring emphasis on reasoning hubs that help crack the puzzle; models, in contrast, universally incorporated this sentence describing the death method and footprint constraints into evidence. These two orientations do not entirely coincide, yet the puzzle premise itself can constrain explanations; one cannot conclude that models conflated informational functions solely because S124 was not in K.

Raw explanations provide concrete examples: GPT-5.6 Sol’s response01 used S124 to rule out suicide and treated concealing footprints of companions as the core of solving the puzzle. The prompt also instructed selecting sentences highly relevant to motives, methods, or participant identities, providing clear textual justification for selecting S124. The 37/37 consistency indicates that this selection is robust, yet is insuficient by itself to determine whether models distinguished between the phenomenon to be explained and the critical clues that crack the puzzle.

This phenomenon does not warrant modifying the current frozen scoring. K is used to measure hits on preset reasoning hubs, while model selections and explanations provide richer diagnostic information. Only by combining both can one observe what models selected, how they used it, and where divergences lie relative to scoring objectives.

## 6.4 Evidence Asymmetry and Epistemic Vigilance

S112 and S113 are immediately adjacent in the story. S113 points toward suspicion and was selected in 25/37 runs; S112 provides exoneration-oriented evidence (alibi evidence) and was selected in 0/37 runs. The two sentences are physically contiguous in the text. The 25:0 frequency disparity reveals that suspicion-oriented information enters model evidence selection far more readily than exoneration-oriented information. Concurrently, it should be noted that S112’s phrasing includes the qualifier “most of the time,” rendering its exclusionary force weaker than an absolute alibi, which may partially account for its low selection rate; nonetheless, the 0/37 selection count remains a striking asymmetry.

This asymmetry is manifested across both episodes. In EP01, high-salience information related to conspiracy motives was broadly selected, while low-salience clues pointing to exoneration were rarely noted. In EP02, S112/S113 provided a concrete case of adjacent positions with starkly divergent selection frequencies. Cross-episode consistency suggests that asymmetric processing of positive and negative evidence may reflect a structural tendency of current models when handling mystery narratives, rather than an incidental artifact of one episode’s story structure.

The epistemic vigilance framework proposed by Sperber et al. provides an interpretive lens for this observation. Story texts in WORTH simultaneously contain information facilitating reasoning and information delaying reasoning; when models incorporate suspicion information while omitting clues used by authors to exonerate suspects, one possibility is that they accept superficially coherent explanations without adequately scrutinizing counter-evidence. This makes epistemic vigilance a direction worthy of further investigation.

However, boundaries of this observation must be made explicit. Current data originate from the mystery-narrative domain, where the pair of directions “suspicion” and “exoneration” carries domain specificity. Generalization to other domains—such as counterexample identification in scientific literature, exculpatory evidence assessment in legal argumentation, or risk signals in business decision-making—requires independent verification in those domains. Currently, one can only state that this asymmetry exists in mystery narratives, without confirming whether it reflects a general model trait or a domain-specific behavioral pattern.

## 6.5 Boundaries of Narrative Perspective

In EP01, the character appearing in the first person as “I” (R04) was a correct participant designated by the author, yet across 30/30 runs—spanning all six models—was not selected as a participant a single time. In contrast, S124 was selected by all content-scorable runs in EP02, despite not being in K. These two extreme selections touch respectively upon participant definitions and the boundary between core puzzle premises and scored clues.

Narrative perspective may influence model participant judgment, but raw responses provide more concrete clues: some runs actually noticed “my” causal role in the case—for instance, Kimi response04 termed “I” an “innocent tool being exploited,” and DeepSeek response05 and Gemini response05 mentioned the narrator’s cupping act in explanations—yet still did not select R04 as a participant. The test prompt listed R04 independently as a candidate character and provided a selected\_role\_ids field; selecting characters did not require locating a specific sentence as a carrier, making it unlikely that omission stemmed from selection mechanism constraints. A more probable explanation is that models adopted a definition of “participant” bounded by awareness or subjective intent, whereas the author’s correct character set encompassed unwitting causal facilitation. Another possibility is that the presentation of the candidate character list in response instructions influenced attention allocation. Current data cannot fully disentangle these hypotheses; systematic variations in narrative perspective in subsequent experiments (such as rewriting the same story in third person) can provide further evidence.

## 6.6 Design Justification and Pilot Feedback

Synthesizing results from Section 5 allows revisiting the design justification of the key clue sentence set and clarifying considerations regarding scoring disclosure.

Validity of the Key Clue Sentence Set. K does not consist of “sentences that seem important” annotated post-hoc by researchers from the story; rather, they are reasoning hubs planted in advance during the design phase by creators. The studio’s creative workflow specifies character trajectories and event logic first, after which narrative techniques are used to embed and obscure them—K emerges during the event design phase, reflecting the creative intent of “which informational nodes must be traversed to infer from A to B.” Narrative wrapping alters how conspicuous these nodes appear in the text, without changing their logical function. This means the epistemological status of K is closer to grading rubrics in examination design: test creators need not prove that no alternative solution path exists in the world; what requires demonstration is that this scoring rubric is internally consistent and capable of diferentiating responses of varying quality. Pilot results provide concrete cases for examining these designs: five zero-hit key clue sentences in EP02 precisely covered inferential steps required to rule out false hypotheses and complete the correct participant chain, with runs missing them systematically converging toward erroneous character combinations—these sentences occupied critical positions in ruling out false hypotheses within the author’s designed reasoning chain. While unanimous zero hits mean their empirical discriminatory power cannot be validated within this sample batch, their design-level logical function aligns with observed error directions. S124 presents another class of information: it was selected by all runs; appending a fixed point value to this existing batch of selections would add points equally across all runs. This fact describes its discrimination within this sample batch, and does not independently dictate whether it should enter K; the author’s basis for excluding it remains the aforementioned scoring objective (see §6.3).

Boundaries of Scoring Information Disclosure. As noted in §4.4, the prompt informs subjects of reward and penalty directions for clue and participant selections, but conceals specific weights. This design aims to reduce gaming strategies around point values; no disclosure control experiment has yet tested its actual efect. Instructions for EP02 already provided an operational definition of “homicide participant” (see §4.3).

## 6.7 Human Data

This version does not report human scores or human-model comparisons. Once verifiable data are obtained following the criteria in §4.8, subsequent work can examine whether phenomena such as shared participant selections and S124 selection rates also appear in player responses, aiding in distinguishing item efects from model-specific behaviors; such judgments cannot be made at present.

## 7. Scope of Research and Subsequent Verification

## 7.1 Scope of Applicability of Results

This pilot experiment comprises two story episodes and 70 formal model runs, with each model run 5 times per episode. On this basis, this paper reports scores, selection patterns, and specific errors of models under current task and operational conditions; the main text cites only selected run-by-run cases. Model means serve to summarize performance in this execution, and are not used to establish general capability rankings. Subsequent additions of stories and run counts can test the replicability of observed patterns across more tasks.

## 7.2 Content Covered by Current Scoring

Gameplay-equivalent total scores consist of clue scores and participant scores, quantifying outcomes of responding under frozen rules. Clue scores take K as reference; the phenomenon of neighboring sentence selection reported in Section 5.2.5 indicates that missing designated sentences does not necessarily equal missing corresponding information. Natural language explanations have been preserved and used for case analysis, but have not been scored independently, nor have inter-rater reliability tests across independent coders been conducted. Future work could conduct functional coding on neighboring selections and explanation content to disentangle sentence selection variance, information omission, and reasoning errors.

## 7.3 Subsequent Verification

Section 3.4 proposed two classes of controls not yet implemented: first, retaining the complete story while highlighting author-designated key clue sentences, comparing shifts in participant attribution; second, modifying key evidence while maintaining story coherence and altering answers accordingly, observing whether model judgments shift alongside evidence changes. These test the efect of evidence cueing and model responsiveness to evidence shifts, respectively.

Player records exist on game platforms for both episodes, but export and cleaning remain incomplete; this version does not report human scores or human-model comparisons. After verifiable data are obtained in the future, same-task reference analyses will be conducted. For model testing conducted after materials become public, material release dates and model versions should be recorded, and combined with new stories and evidence-modification conditions to examine result replicability.

## 8. Conclusion

This paper presents WORTH, introducing autonomous evidence discovery and not-fully-cooperative informational relationships into large language model reasoning evaluation. Through professionally crafted natural narratives, WORTH requires models to autonomously select key clues, identify case participants, and explain their reasoning process from complete stories, separately recording performance in evidence selection and participant attribution.

Across two episodes, 70 formal runs were conducted, of which 67 runs were content-scorable. Pilot results demonstrate the diagnostic value of this evaluation framework: hitting more key clues does not guarantee more accurate participant judgments; diferent models converge on selecting identical distractor characters; and information pointing toward suspicion versus exoneration exhibits marked selection asymmetry. Total scores and their subscales present scoring outcomes of these selections, while specific sentences, characters, and explanations exhibit traceable discrepancies in erroneous judgments.

These results indicate that observing evidence selection and final judgment separately can reveal reasoning behavioral diferences dificult to convey through a single total score. Subsequent work will further examine these patterns through additional stories, evidence-cueing, and evidence-modification conditions. What WORTH emphasizes is that reasoning evaluation must examine how models identify evidence from information, and how they transform evidence into judgment.

## Acknowledgments

We especially thank Shuwen Yang, Zhiyuan Zhu, and Weimin Zong for their help with data organization, statistical testing, providing model API access, and assisting with model testing.

## Appendix A. Compact Experimental Specification

## A.1 Task and Response Protocol

Each run received, in a single turn, the complete Chinese story with neutral sentence identifiers, the candidate-character list, and the response instructions. The model selected up to the episode-specific clue quota, selected zero or more candidate characters without being told the number of correct participants, and returned seven fields: episode\_id, clue\_sentence\_ids, selected\_role\_ids, clue\_interpretations, evidence\_combination, final\_conclusion, and confidence. Clue interpretations were required to correspond one-to-one with the selected sentence identifiers. Runs used fresh conversations, with search, external tools or connectors, memory, and personalization disabled. Natural-language explanations were retained for diagnosis but were not assigned an independent score.

## A.2 Episode-Level Scoring Summary

<table><tr><td>Episode</td><td>Story and selection space</td><td>Clue scoring</td><td>Participant scoring</td><td>Theoretical total range</td></tr><tr><td>EP01</td><td>120 sentences; at most 12 clue selections; 6 candidates, 3 correct</td><td>12 key sentences, 3 points each (36 total)</td><td>Correct participants: +7, +5, +5; each incorrect participant: -5</td><td>-15 to 53</td></tr><tr><td>EP02</td><td>participants 134 sentences; at most 20 clue selections; 9 candidates, 3 correct participants</td><td>20 key sentences, weighted 1-4 points (41 total)</td><td>Each correct participant: +2; incorrect participants: -2 to -8 by character</td><td>-22 to 47</td></tr></table>

In both episodes, omitting a key sentence and selecting a sentence outside the author-designated set K received zero clue points rather than a penalty. The two episodes use diferent stories and payof structures; their raw scores are therefore reported separately and are not summed or treated as a common dificulty scale.

## A.3 Model and Run Configurations

Each row below represents five formal runs. Product and tier labels reproduce the settings recorded at execution time; they should not be interpreted as standardized compute levels across vendors.
<table><tr><td>Episode</td><td>Model</td><td>Access interface</td><td>Recorded tier or mode</td><td>Test window</td></tr><tr><td>EP01</td><td>GPT-5.6 Sol</td><td>ChatGPT web</td><td>High</td><td>2026-08-14</td></tr><tr><td>EP01</td><td>Claude Opus 4.6</td><td>Antigravity</td><td>Thinking</td><td>2026-08-14</td></tr><tr><td>EP01</td><td>GLM-5.2</td><td>Zhipu web</td><td>High (Deep Thinking)</td><td>2026-08-14</td></tr><tr><td>EP01</td><td>DeepSeek-V4- Flash</td><td>TraeWork app</td><td>V4-Flash</td><td>2026-08-14</td></tr><tr><td>EP01</td><td>Kimi K3</td><td>Kimi website</td><td>Advanced</td><td>2026-08-14</td></tr><tr><td>EP01</td><td>Gemini 3.1 Pro</td><td>Antigravity IDE</td><td>High</td><td>2026-08-14</td></tr><tr><td>EP02</td><td>GPT-5.6 Sol</td><td>ChatGPT web</td><td>High</td><td>2026-08-30</td></tr><tr><td>EP02</td><td>Claude Opus 4.6</td><td>Claude.ai</td><td>High + Extended</td><td>2026-08-30 to</td></tr><tr><td>EP02</td><td>Gemini 3.1 Pro</td><td>Antigravity IDE</td><td>High</td><td>2026-08-31 2026-08-30</td></tr><tr><td>EP02</td><td>GLM-5.3</td><td>Zhipu website</td><td>Deep</td><td>2026-08-30</td></tr><tr><td>EP02</td><td>Kimi K3</td><td>WorkBuddy for</td><td>High</td><td>2026-08-30</td></tr><tr><td>EP02</td><td>DeepSeek-V4-Pro</td><td>macOS TraeWork app</td><td>Not separately</td><td>2026-08-30</td></tr><tr><td>EP02</td><td>Hy4 preview</td><td>WorkBuddy for</td><td>recorded High</td><td>2026-08-30</td></tr><tr><td>EP02</td><td>MiniMax-M3</td><td>macOS WorkBuddy for macOS</td><td>n/a</td><td>2026-08-30</td></tr></table>

For EP01 GLM-5.2, the configuration and execution screenshots showed “Highest” and “High,” respectively; the table follows the execution record and reports High, with Deep Thinking enabled. The EP02 DeepSeek tier was not separately recorded, and the MiniMax-M3 interface exposed no applicable tier label.

## A.4 Run Validity and Exclusions

<table><tr><td colspan="7">Directly Embedded</td></tr><tr><td>Episode</td><td>Formal runs</td><td>parseable JSON</td><td>parseable JSON</td><td>Invalid overall JSON</td><td>Content- scorable runs</td><td>protocol- compliant runs</td></tr><tr><td>EP01</td><td>30</td><td>22</td><td>7</td><td>1</td><td>30</td><td>22</td></tr><tr><td>EP02</td><td>40</td><td>26</td><td>9</td><td>5</td><td>37</td><td>25</td></tr><tr><td>Total</td><td>70</td><td>48</td><td>16</td><td>6</td><td>67</td><td>47</td></tr></table>

Parseability and content validity were evaluated separately. The single EP01 response with invalid overall JSON still contained directly readable selection arrays, so all 30 EP01 runs remained content-scorable. In EP02, four of the five responses with invalid overall JSON retained readable, valid selection arrays. Three EP02 runs were excluded from content scoring:

• Gemini 3.1 Pro response05 selected the nonexistent sentence identifier S207.

• Hy4 preview response05 selected the nonexistent sentence identifier S146.

• Kimi K3 response02 used illegal expressions in the selection fields, so valid identifier arrays could not be recovered.

Excluded runs were not assigned a score of zero. One additional EP01 Codex run was retained only as an exploratory auxiliary control; it was not part of the formal model set and is not included in the 70 formal runs reported in this paper.

## References

Yushi Bai, Shangqing Tu, Jiajie Zhang, Hao Peng, Xiaozhi Wang, Xin Lv, Shulin Cao, Jiazheng Xu, Lei Hou, Yuxiao Dong, Jie Tang, and Juanzi Li. LongBench v2: Towards deeper understanding and reasoning on realistic long-context multitasks. In Proceedings of the 63rd Annual Meeting of the Association for Computational Linguistics (Volume 1: Long Papers), pages 3639–3664. Association for Computational Linguistics, 2025. doi: 10.18653/v1/2025.acl-long.183. URL https://aclanthology.org/2025.acl-long.183/.

Chandra Bhagavatula, Ronan Le Bras, Chaitanya Malaviya, Keisuke Sakaguchi, Ari Holtzman, Hannah Rashkin, Doug Downey, Scott Wen-tau Yih, and Yejin Choi. Abductive commonsense reasoning. In International Conference on Learning Representations, 2020. URL https://arxiv.or g/abs/1908.05739.

Tommaso Bonomo, Luca Giofré, and Roberto Navigli. LiteraryQA: Towards efective evaluation of long-document narrative QA. In Proceedings of the 2025 Conference on Empirical Methods in Natural Language Processing, pages 34086–34107. Association for Computational Linguistics, 2025. doi: 10.18653/v1/2025.emnlp-main.1729. URL https://aclanthology.org/2025.emnlp-main.1729/.

Myra Cheng, Robert D. Hawkins, and Dan Jurafsky. Accommodation and epistemic vigilance: A pragmatic account of why LLMs fail to challenge harmful beliefs. arXiv preprint arXiv:2601.04435, 2026. URL https://arxiv.org/abs/2601.04435.

Karl Cobbe, Vineet Kosaraju, Mohammad Bavarian, Mark Chen, Heewoo Jun, Lukasz Kaiser, Matthias Plappert, Jerry Tworek, Jacob Hilton, Reiichiro Nakano, Christopher Hesse, and John Schulman. Training verifiers to solve math word problems. arXiv preprint arXiv:2110.14168, 2021. URL https://arxiv.org/abs/2110.14168.

Maksym Del and Mark Fishel. True detective: A deep abductive reasoning benchmark undoable for GPT-3 and challenging for GPT-4. In Proceedings of the 12th Joint Conference on Lexical and Computational Semantics (\*SEM 2023), pages 314–322. Association for Computational Linguistics, 2023. doi: 10.18653/v1/2023.starsem-1.28. URL https://aclanthology.org/2023.starsem-1.28/.

Jay DeYoung, Sarthak Jain, Nazneen Fatema Rajani, Eric Lehman, Caiming Xiong, Richard Socher, and Byron C. Wallace. ERASER: A benchmark to evaluate rationalized NLP models. In Proceedings of the 58th Annual Meeting of the Association for Computational Linguistics, pages 4443–4458. Association for Computational Linguistics, 2020. doi: 10.18653/v1/2020.acl-main.408. URL https://aclanthology.org/2020.acl-main.408/.

Yunfan Gao, Yun Xiong, Wenlong Wu, Zijing Huang, Bohan Li, and Haofen Wang. U-NIAH: Unified RAG and LLM evaluation for long context needle-in-a-haystack. arXiv preprint arXiv:2503.00353, 2025. URL https://arxiv.org/abs/2503.00353.

Matt Gardner, Yoav Artzi, Victoria Basmov, Jonathan Berant, Ben Bogin, Sihao Chen, Pradeep Dasigi, Dheeru Dua, Yanai Elazar, Ananth Gottumukkala, Nitish Gupta, Hannaneh Hajishirzi, Gabriel Ilharco, Daniel Khashabi, Kevin Lin, Jiangming Liu, Nelson F. Liu, Phoebe Mulcaire, Qiang Ning, Sameer Singh, Noah A. Smith, Sanjay Subramanian, Reut Tsarfaty, Eric Wallace, Ally Zhang, and Ben Zhou. Evaluating models’ local decision boundaries via contrast sets. In Findings of the Association for Computational Linguistics: EMNLP 2020, pages 1307–1323. Association for Computational Linguistics, 2020. doi: 10.18653/v1/2020.findings-emnlp.117. URL https://aclanthology.org/2020.findings-emnlp.117/.

Elliot Glazer, Ege Erdil, Tamay Besiroglu, Diego Chicharro, Evan Chen, Alex Gunning, Caroline Falkman Olsson, Jean-Stanislas Denain, Anson Ho, Emily de Oliveira Santos, Olli Järviniemi, Matthew Barnett, Robert Sandler, Matej Vrzala, Jaime Sevilla, Qiuyu Ren, Elizabeth Pratt, Lionel Levine, Grant Barkley, Natalie Stewart, Bogdan Grechuk, Tetiana Grechuk, Shreepranav Varma Enugandla, and Mark Wildon. FrontierMath: A benchmark for evaluating advanced mathematical reasoning in AI. arXiv preprint arXiv:2411.04872, 2024. URL https://arxiv.org/abs/2411.04872.

H. Paul Grice. Logic and conversation. In Peter Cole and Jerry L. Morgan, editors, Syntax and Semantics, Volume 3: Speech Acts, pages 41–58. Academic Press, New York, 1975. URL https://brill.com/display/book/edcoll/9789004368811/BP000003.xml.

Zhouhong Gu, Lin Zhang, Xiaoxuan Zhu, Jiangjie Chen, Wenhao Huang, Yikai Zhang, Shusen Wang, Zheyu Ye, Yan Gao, Hongwei Feng, and Yanghua Xiao. DetectBench: Can large language model detect and piece together implicit evidence? In Findings of the Association for Computational Linguistics: EMNLP 2024, pages 199–222. Association for Computational Linguistics, 2024. doi: 10.18653/v1/2024.findings-emnlp.11. URL https://aclanthology.org/2024.findings-emnlp.11/.

Kshitij Gupta. WHODUNIT: Evaluation benchmark for culprit detection in mystery stories. arXiv preprint arXiv:2502.07747, 2025. URL https://arxiv.org/abs/2502.07747.

Dan Hendrycks, Collin Burns, Saurav Kadavath, Akul Arora, Steven Basart, Eric Tang, Dawn Song, and Jacob Steinhardt. Measuring mathematical problem solving with the MATH dataset. In Advances in Neural Information Processing Systems, volume 34, 2021. URL https://arxiv.org/ab s/2103.03874.

Cheng-Ping Hsieh, Simeng Sun, Samuel Kriman, Shantanu Acharya, Dima Rekesh, Fei Jia, Yang Zhang, and Boris Ginsburg. RULER: What’s the real context size of your long-context language

models? In Proceedings of the First Conference on Language Modeling, 2024. URL https: //arxiv.org/abs/2404.06654.

Mehran Kazemi, Bahare Fatemi, Hritik Bansal, John Palowitch, Chrysovalantis Anastasiou, Sanket Vaibhav Mehta, Lalit K. Jain, Virginia Aglietti, Disha Jindal, Peter Chen, Nishanth Dikkala, Gladys Tyen, Xin Liu, Uri Shalit, Silvia Chiappa, Kate Olszewska, Yi Tay, Vinh Q. Tran, Quoc V. Le, and Orhan Firat. BIG-bench extra hard. In Proceedings of the 63rd Annual Meeting of the Association for Computational Linguistics (Volume 1: Long Papers), pages 26473–26501. Association for Computational Linguistics, 2025. doi: 10.18653/v1/2025.acl-long.1285. URL https://aclanthology.org/2025.acl-long.1285/.

Tomáš Kočiský, Jonathan Schwarz, Phil Blunsom, Chris Dyer, Karl Moritz Hermann, Gábor Melis, and Edward Grefenstette. The NarrativeQA reading comprehension challenge. Transactions of the Association for Computational Linguistics, 6:317–328, 2018. doi: 10.1162/tacl\_a\_00023. URL https://aclanthology.org/Q18-1023/.

Lea Krause and Piek T.J.M. Vossen. The gricean maxims in NLP – a survey. In Proceedings of the 17th International Natural Language Generation Conference, pages 470–485. Association for Computational Linguistics, 2024. URL https://aclanthology.org/2024.inlg-main.39/.

Yi Liu, Lianzhe Huang, Shicheng Li, Sishuo Chen, Hao Zhou, Fandong Meng, Jie Zhou, and Xu Sun. RECALL: A benchmark for LLMs robustness against external counterfactual knowledge. arXiv preprint arXiv:2311.08147, 2023. URL https://arxiv.org/abs/2311.08147.

Qing Lyu, Marianna Apidianaki, and Chris Callison-Burch. Towards faithful model explanation in NLP: A survey. Computational Linguistics, 50(2):657–723, 2024. doi: 10.1162/coli\_a\_00511. URL https://aclanthology.org/2024.cl-2.6/.

Yixin Nie, Adina Williams, Emily Dinan, Mohit Bansal, Jason Weston, and Douwe Kiela. Adversarial NLI: A new benchmark for natural language understanding. In Proceedings of the 58th Annual Meeting of the Association for Computational Linguistics, pages 4885–4901. Association for Computational Linguistics, 2020. doi: 10.18653/v1/2020.acl-main.441. URL https://aclanthology .org/2020.acl-main.441/.

David Rein, Betty Li Hou, Asa Cooper Stickland, Jackson Petty, Richard Yuanzhe Pang, Julien Dirani, Julian Michael, and Samuel R. Bowman. GPQA: A graduate-level google-proof Q&A benchmark. arXiv preprint arXiv:2311.12022, 2023. URL https://arxiv.org/abs/2311.12022.

Xudong Shen, Li Yuan, Ye Chen, Xin Wu, Yi Cai, and Zhiyong Wu. Truth or sophistry? LoFa: A benchmark for LLM robustness against logical fallacies. In Proceedings of the 64th Annual Meeting of the Association for Computational Linguistics (Volume 1: Long Papers), pages 24236–24268. Association for Computational Linguistics, 2026. doi: 10.18653/v1/2026.acl-long.1112. URL https://aclanthology.org/2026.acl-long.1112/.

Freda Shi, Xinyun Chen, Kanishka Misra, Nathan Scales, David Dohan, Ed H. Chi, Nathanael Schärli, and Denny Zhou. Large language models can be easily distracted by irrelevant context. In Proceedings of the 40th International Conference on Machine Learning, volume 202 of Proceedings of Machine Learning Research, pages 31210–31227. PMLR, 2023. URL https://proceedings.mlr. press/v202/shi23a.html.

Dan Sperber, Fabrice Clément, Christophe Heintz, Olivier Mascaro, Hugo Mercier, Gloria Origgi, and Deirdre Wilson. Epistemic vigilance. Mind & Language, 25(4):359–393, 2010. doi: 10.1111/j. 1468-0017.2010.01394.x. URL https://doi.org/10.1111/j.1468-0017.2010.01394.x.

Mirac Suzgun, Nathan Scales, Nathanael Schärli, Sebastian Gehrmann, Yi Tay, Hyung Won Chung, Aakanksha Chowdhery, Quoc V. Le, Ed H. Chi, Denny Zhou, and Jason Wei. Challenging BIG-Bench tasks and whether chain-of-thought can solve them. arXiv preprint arXiv:2210.09261, 2022. URL https://arxiv.org/abs/2210.09261.

Harsh Trivedi, Niranjan Balasubramanian, Tushar Khot, and Ashish Sabharwal. MuSiQue: Multihop questions via single-hop question composition. Transactions of the Association for Computational Linguistics, 10:539–554, 2022. doi: 10.1162/tacl\_a\_00475. URL https://aclanthology.org/2022. tacl-1.31/.

Eren Unlu. Know when to trust the skill: Delayed appraisal and epistemic vigilance for single-agent LLMs. arXiv preprint arXiv:2604.16753, 2026. URL https://arxiv.org/abs/2604.16753.

Hannah VanderHoeven, Abhijnan Nath, and Nikhil Krishnaswamy. Flout at your own risk: LLMs struggle with pragmatic cooperativity under epistemic asymmetry. arXiv preprint arXiv:2607.11053, 2026. URL https://arxiv.org/abs/2607.11053.

Eitan Wagner, Renana Keydar, and Omri Abend. The challenge and reward of fair play in narrative: A computational approach. arXiv preprint arXiv:2507.13841, 2025. URL https: //arxiv.org/abs/2507.13841.

Junlin Xie, Ruifei Zhang, Zhihong Chen, Xiang Wan, and Guanbin Li. WhodunitBench: Evaluating large multimodal agents via murder mystery games. In Advances in Neural Information Processing Systems, volume 37, pages 86655–86687, 2024. URL https://papers.nips.cc/paper\_files/paper/2 024/hash/9dd4533e7e4e5ed809344280609c5b05-Abstract-Datasets\_and\_Benchmarks\_Track.h tml.

Zhe Xu, Jiasheng Ye, Xiaoran Liu, Xiangyang Liu, Tianxiang Sun, Zhigeng Liu, Qipeng Guo, Linlin Li, Qun Liu, Xuanjing Huang, and Xipeng Qiu. DetectiveQA: Evaluating long-context reasoning on detective novels. arXiv preprint arXiv:2409.02465, 2024. URL https://arxiv.org/abs/2409.02465.

Zhilin Yang, Peng Qi, Saizheng Zhang, Yoshua Bengio, William W. Cohen, Ruslan Salakhutdinov, and Christopher D. Manning. HotpotQA: A dataset for diverse, explainable multi-hop question answering. In Proceedings of the 2018 Conference on Empirical Methods in Natural Language Processing, pages 2369–2380. Association for Computational Linguistics, 2018. doi: 10.18653/v1/ D18-1259. URL https://aclanthology.org/D18-1259/.

Yifei Yu, Qian-Wen Zhang, Lingfeng Qiao, Di Yin, Fang Li, Jie Wang, Zengxi Chen, Suncong Zheng, Xiaolong Liang, and Xing Sun. Sequential-NIAH: A needle-in-a-haystack benchmark for extracting sequential needles from long contexts. In Proceedings of the 2025 Conference on Empirical Methods in Natural Language Processing, pages 29450–29468. Association for Computational Linguistics, 2025. URL https://aclanthology.org/2025.emnlp-main.1497/.

Yuan Yuan, Muyu He, Muhammad Adil Shahid, Ziyang Li, Jiani Huang, and Li Zhang. TurnaboutLLM: A deductive reasoning benchmark from detective games. In Proceedings of the 2025 Conference on Empirical Methods in Natural Language Processing, pages 1951–1965. Association for Computational Linguistics, 2025. doi: 10.18653/v1/2025.emnlp-main.101. URL https://aclanthology.org/2025.emnlp-main.101/.