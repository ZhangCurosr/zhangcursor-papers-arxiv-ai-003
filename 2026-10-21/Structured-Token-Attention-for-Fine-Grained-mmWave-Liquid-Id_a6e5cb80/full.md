# Structured-Token Attention for Fine-Grained mmWave Liquid Identification

Junseo Min

Department of Defense Convergence Technology

Korea University

Seoul, Republic of Korea

junseo min@korea.ac.kr

Joongheon Kim

Department of Electrical & Computer Engineering

Korea University

Seoul, Republic of Korea

joongheon@korea.ac.kr

Abstract—Fine-grained liquid identification requires a classifier to distinguish similar substances from compact millimeterwave measurements. We investigate structured-token attention, which represents a radar feature tensor through complementary antenna, feature, branch, and global views. The proposed StructAttn model embeds these views into eleven tokens and combines them with a three-layer transformer. Experiments on the public FG-LiquID data cover 30 liquids and 3,000 samples. Over five seeds on the released split, StructAttn achieves 96.70% mean best-epoch accuracy, matching the original-recipe MMNet baseline and exceeding a scalar-token attention model by 1.50 percentage points. A five-seed probability ensemble reaches 97%, corresponding to 18 errors among 600 test samples. Final-epoch and five-fold results complement the checkpoint-selected comparison, with StructAttn obtaining 95.30% out-of-fold accuracy. Token and feature analyses show that structured views are useful for prediction, while residual confusions concentrate in water, soft-drink, and edible-oil classes. These results support structured tokenization as a practical design choice for attention-based liquid recognition.

Index Terms—Millimeter-wave sensing, liquid identification, structured tokens, self-attention, sensor classification.

## I. INTRODUCTION

Contactless liquid identification is relevant to automated inspection and everyday sensing. Similar-looking liquids can belong to different categories, and different containers can hold the same substance. Millimeter-wave (mmWave) measurements provide an alternative source of information through the interaction between electromagnetic signals and the observed liquid. FG-LiquID demonstrates fine-grained recognition using a learned representation of radar-derived features [1].

A compact sensing tensor contains several kinds of structure. Measurements from one receiving antenna describe a common sensing channel, whereas values of the same feature across antennas describe a common observable. Locationrelated features and reflected signal strength also offer different views of a sample. Flattening this tensor into independent scalars leaves these relationships implicit and requires the classifier to recover them from limited training data.

Self-attention provides a mechanism for combining measurements according to the current sample [2]. Its usefulness depends on token construction. Unlike a scalar token, a complete antenna or feature slice encodes local relationships before interacting with other tokens. This motivates structured input views.

This paper develops StructAttn, a structured-token attention model for fine-grained mmWave liquid identification. The model constructs overlapping antenna, feature, location, reflection, and global views without adding measurements. A small token sequence is processed by a transformer, and the output combines a learned classification token with the mean of the measurement tokens. The design retains the semantics of the input dimensions while allowing interactions across views.

The evaluation examines structured tokenization against attention-based alternatives, compares MMNet under different checkpoint and aggregation settings, and identifies informative measurements and confusable liquids. It uses repeated seeds, token variants, feature masking, and out-of-fold predictions.

The main contribution is a measurement-aware token construction and its empirical characterization on FG-LiquID. A single StructAttn-S3 model reaches the same mean bestepoch accuracy as original-recipe MMNet, while a five-seed ensemble attains the highest ensemble accuracy among the compared configurations. Best-epoch, final-epoch, and crossvalidation results are interpreted separately.

## II. RELATED WORK

## A. Wireless Liquid Identification

mmWave studies examine 60 GHz connectivity [3] and antenna-array link budgets [4]. Related work addresses receive beamforming [5], two-stage beam training [6], and lowpower link setup [7]. Frequency-sharing analysis [8] and joint clustering, beamforming, and power allocation [9] characterize interference in communication systems. These studies provide physical and system context for mmWave measurements, while liquid recognition requires a task-specific classifier.

FG-LiquID uses mmWave sensing for fine-grained liquid recognition and introduces MMNet to process complementary measurement features [1]. Its feature representation is used in our evaluation. We retain the distinction between locationrelated measurements and reflection strength, but expose additional antenna and feature views to a shared attention module.

Wireless liquid sensing also includes approaches based on WiFi. LiquImager jointly addresses liquid identification and container imaging using commercial WiFi devices [10].

![](images/3522db2dba923d8b05a49434106f71fbe67fb4906abcb93a4e08b133d08c6035.jpg)  
Fig. 1: Structured views and attention processing in StructAttn-S3.

This line of work emphasizes the sensing configuration and container-related information. Our focus is instead the classifier applied to an existing mmWave feature tensor. Crossplatform recognition rates are therefore not comparable.

## B. Attention for Structured Measurements

Wireless inference also depends on the task assigned to received measurements. Choi and Kim analyze blind signal classification errors for interference-cancellation decisions in nonorthogonal multiple access [11]. Lim et al. use deep residual learning for pilot design and channel estimation under hardware impairments [12]. Our task instead classifies liquids from an already extracted radar feature tensor, with structured tokens organizing the available observables.

The transformer models interactions using query, key, and value projections [2]. Set Transformer extends attention-based processing to sets of instances [13]. These methods motivate relational aggregation, although our tokens are not interchangeable set elements. Antenna identity, feature identity, and token type are preserved through learned embeddings.

FT-Transformer adapts transformer processing to tabular features and highlights the importance of strong neural baselines under consistent evaluation protocols [14]. Its featuretoken perspective is relevant to compact sensor inputs. StructAttn extends this perspective to overlapping multi-value views of a three-dimensional measurement tensor. AttnNet is a scalar-token baseline, not a reproduction of FT-Transformer. Multiscale LSTM forecasting similarly combines representations at different temporal scales [15], whereas our views follow antenna and feature dimensions.

Adaptive perception studies balance accuracy and processing cost through SAR filter selection [16], optical-flow-assisted detection [17], and joint frame-rate and recognition-model selection [18]. These system-level approaches complement our focus on representation design for fixed radar features.

## C. Training and Prediction Aggregation

Optimizer and regularization choices can influence the apparent benefit of an architecture. AdamW separates weight decay from adaptive gradient updates [19]. We therefore include MMNet-R, which keeps the MMNet architecture and applies the same modern training recipe used by the attention models. This comparison helps distinguish architecture changes from training-recipe effects.

Combining independently trained networks is another way to aggregate predictions [20]. We evaluate probability averaging over five seeds for MMNet, MMNet-R, and StructAttn-S3. Ensemble results are reported separately from single-model means because they describe different predictors and require multiple forward passes. The study evaluates classification performance without making an uncertainty-calibration claim.

## III. METHOD

## A. Task and Input Representation

Let $X \in \mathbb { R } ^ { P \times F \times R }$ denote one liquid measurement, where $P = 3$ data points, $F = 4$ feature types, and $R = 4$ receiving antennas. The feature types are distance, elevation angle of arrival, azimuth angle of arrival, and received signal strength (RSS). The classifier estimates a label $y \in \{ 1 , \ldots , C \}$ with $C = 3 0$ . Each sample therefore contains 48 scalar values.

For the modern training recipe, each input coordinate is standardized using training-set statistics. With coordinate index j, training mean $\mu _ { j }$ , and training standard deviation $\sigma _ { j } .$ the normalized value is

$$
\widetilde { x } _ { j } = \frac { x _ { j } - \mu _ { j } } { \operatorname* { m a x } ( \sigma _ { j } , \epsilon ) } ,\tag{1}
$$

where $\epsilon > 0$ prevents division by zero. Test measurements use the same training statistics. This preserves coordinate identities while aligning numerical scales.

## B. Structured Token Construction

Figure 1 summarizes the model. Each token is obtained by extracting and vectorizing a predefined slice of $\widetilde { X } .$ . Antenna tokens collect all data points and feature types for a fixed receiver. Feature tokens collect one observable across data points and receivers. These two views make the channel-wise and observable-wise organization available before attention is applied.

TABLE I: Token construction for StructAttn-S3.
<table><tr><td>View</td><td>Count</td><td>Values</td><td>Grouping</td></tr><tr><td>Antenna</td><td>4</td><td>12</td><td>One receiver</td></tr><tr><td>Feature</td><td>4</td><td>12</td><td>One observable</td></tr><tr><td>Location</td><td>1</td><td>36</td><td>Distance, angles</td></tr><tr><td>Reflection</td><td>1</td><td>12</td><td>RSS branch</td></tr><tr><td>Global</td><td>1</td><td>48</td><td>Complete tensor</td></tr><tr><td>Total</td><td>11</td><td>一</td><td>Without [CLS]</td></tr></table>

The location token concatenates distance and the two angle features, while the reflection token contains RSS. A global token includes the entire tensor. The reflection token and the RSS feature token contain the same input coordinates, but occupy distinct semantic roles in the token sequence. Their identities allow the network to use this information in both the feature and branch representations.

The overlapping groups in Table I summarize the same measurement without adding observations. They provide structured views for learning interactions. A separate data-point view is examined in the token-variant experiments.

## C. Embedding and Attention Encoder

For token t, let $g _ { t } ( \widetilde { X } ) \ \in \ \mathbb { R } ^ { m _ { t } }$ denote its extracted subvector. A token embedder projects it to width $\textit { d } = \ 1 9 2$ Each embedder follows a linear, batch-normalization, GELU, dropout, and linear sequence with hidden width 256. The embedded token is written as

$$
z _ { t } = \phi _ { t } \bigl ( g _ { t } ( \tilde { X } ) \bigr ) + e _ { t } + e _ { \tau ( t ) } ,\tag{2}
$$

where $e _ { t }$ encodes token identity and $e _ { \tau ( t ) }$ encodes token type. The notation $\phi _ { t }$ denotes the type-specific embedder assigned to token t.

A learned classification vector ${ z _ { \mathrm { c l s } } }$ is prepended to the eleven measurement tokens. The initial sequence $H ^ { ( 0 ) } \in$ R<sup>12×192</sup> passes through three pre-layer-normalized transformer layers. Each layer uses six attention heads, a feedforward hidden width of 384, and dropout of 0.1.

For one attention head, the normalized sequence U is mapped to query, key, and value matrices. The operation is

$$
Q = U W _ { Q } , \quad K = U W _ { K } , \quad V = U W _ { V } ,\tag{3}
$$

$$
\mathrm { A t t n } ( U ) = \mathrm { s o f t m a x } \left( { \frac { Q K ^ { \top } } { \sqrt { d _ { h } } } } \right) V ,\tag{4}
$$

where $d _ { h } = 3 2 .$ . Outputs of the six heads are concatenated and projected. A pre-normalized layer then applies residual updates

$$
\widehat { H } ^ { ( \ell ) } = H ^ { ( \ell - 1 ) } + \mathrm { M H A } \big ( \mathrm { L N } ( H ^ { ( \ell - 1 ) } ) \big ) ,
$$

$$
H ^ { ( \ell ) } = \widehat { H } ^ { ( \ell ) } + \mathrm { F F N } \big ( \mathrm { L N } ( \widehat { H } ^ { ( \ell ) } ) \big ) .\tag{5}
$$

(6)

Dropout is applied within these blocks. The attention weights vary with the input and therefore allow different samples to combine the structured views differently.

## D. Readout and Learning Objective

The classifier combines the final classification token with the average of the eleven measurement-token outputs. With $L = 3$ and $T = 1 1$ , the representation is

$$
r = \mathrm { L N } \left( h _ { \mathrm { c l s } } ^ { ( L ) } \oplus { \frac { 1 } { T } } \sum _ { t = 1 } ^ { T } h _ { t } ^ { ( L ) } \right) ,\tag{7}
$$

where $\oplus$ denotes concatenation. A linear classifier followed by softmax produces $p _ { \theta } ( c \mid X )$ . The readout combines learned and distributed summaries.

Training uses cross-entropy with label smoothing. For smoothing coefficient $\alpha = 0 . 1$ , the target distribution and loss are

$$
\begin{array} { l } { \displaystyle q _ { c } = ( 1 - \alpha ) \mathcal { H } [ c = y ] + \frac { \alpha } { C } , } \\ { \displaystyle \mathcal { L } = - \sum _ { c = 1 } ^ { C } q _ { c } \log p _ { \theta } ( c \mid X ) . } \end{array}\tag{8}
$$

Gaussian input noise with standard deviation 0.05 is used in the modern recipe. The classifier predicts the class with maximum output probability.

## E. Ensemble and Model Size

The five-seed ensemble averages probabilities from independently trained checkpoints. Its prediction is

$$
{ \widehat { y } } _ { \mathrm { e n s } } = \arg \operatorname* { m a x } _ { c } { \frac { 1 } { 5 } } \sum _ { s = 1 } ^ { 5 } p _ { \theta _ { s } } ( c \mid X ) .\tag{9}
$$

Aggregation requires no additional classifier and retains the input representation and label space.

StructAttn-S3 contains 1,187,742 trainable parameters. Attention uses twelve positions including [CLS], giving 144 pairs per head. Embedding and projection layers also contribute to cost. The model is larger than the 238K-parameter MMNet baseline, and the present comparison does not assume lower inference latency or energy consumption.

## IV. EXPERIMENTS

## A. Dataset and Evaluation Protocol

The public FG-LiquID data contain 3,000 measurements from 30 liquids, with 100 samples per class. The released split contains 2,400 training and 600 test samples. Table III summarizes the categories. The liquor classes span 22%, 33%, 38%, 43%, 52%, 53%, 55%, 56%, 60%, 62%, 68%, and 75% alcohol by volume. These classes represent liquor labels rather than a synthetic ethanol–water mixture experiment.

Five training seeds are used for the main single-model comparison. Best-epoch accuracy is the maximum test accuracy across the training trajectory, and the reported mean and sample standard deviation summarize the five runs. Because the release has no dedicated validation split, these checkpoints were selected using the test set. The S3 configuration was also chosen using seed-0 test accuracy. Best-epoch and ensemble scores are therefore checkpoint-selected comparisons rather than estimates from an untouched model-selection holdout.

TABLE II: Released-split performance over five seeds. Accuracy and macro-F1 are percentages.
<table><tr><td>Model</td><td>Parameters</td><td>Best epoch</td><td>Final epoch</td><td>Macro-F1</td><td>Five-seed ensemble</td></tr><tr><td>Nearest centroid</td><td>0</td><td>70.17</td><td> $7 0 . 1 7$ </td><td>69.31</td><td></td></tr><tr><td>MLP</td><td>50K</td><td> $9 4 . 4 7 \pm 0 . 2 2$ </td><td> $9 3 . 7 3 \pm 0 . 4 5$ </td><td>94.23</td><td></td></tr><tr><td>MMNet</td><td>238K</td><td> $9 6 . 7 0 \pm 0 . 7 0$ </td><td> ${ \bf 9 6 . 3 0 \pm 0 . 7 6 }$ </td><td>96.66</td><td>96.33 (22 errors)</td></tr><tr><td>MMNet-R</td><td>238K</td><td> ${ \bf 9 6 . 9 3 \pm 0 . 0 9 }$ </td><td> $9 6 . 2 3 \pm 0 . 1 9$ </td><td>96.85</td><td>96.67 (20 errors)</td></tr><tr><td>NoAttn</td><td>283K</td><td> $9 2 . 3 7 \pm 0 . 1 4$ </td><td> $9 1 . 4 3 \pm 0 . 2 5$ </td><td>92.10</td><td></td></tr><tr><td>AttnNet</td><td>548K</td><td> $\dot { 9 5 . 2 0 } \pm \dot { 0 . 7 6 }$ </td><td> $9 4 . 5 3 \pm 0 . 9 2$ </td><td>94.84</td><td></td></tr><tr><td>StructAttn-S3</td><td>1.19M</td><td> $9 6 . 7 0 \pm 0 . 3 2$ </td><td> $9 5 . 9 3 \pm 0 . 4 9$ </td><td>96.56</td><td>97.00 (18 errors)</td></tr><tr><td>StructAttn-S2</td><td>2.56M</td><td> $9 6 . 7 0 \pm 0 . 1 8$ </td><td> $9 5 . 7 7 \pm 0 . 4 0$ </td><td>96.57</td><td></td></tr><tr><td>StructAttn-S5</td><td>1.19M</td><td> $9 6 . 4 3 \pm 0 . 3 7$ </td><td> $9 5 . 9 0 \pm 0 . 4 3$ </td><td>96.28</td><td></td></tr><tr><td>StructAttn-S6</td><td>1.19M</td><td> $9 4 . 1 7 \pm 0 . 2 9$ </td><td> $9 2 . 9 7 \pm 0 . 3 8$ </td><td>93.83</td><td></td></tr></table>

TABLE III: Composition of the released FG-LiquID split.
<table><tr><td>Category</td><td>Classes</td><td>Train</td><td>Test</td></tr><tr><td>Liquor</td><td>12</td><td>958</td><td>242</td></tr><tr><td>Edible oil</td><td>5</td><td>393</td><td>107</td></tr><tr><td>Soft drink</td><td>5</td><td>409</td><td>91</td></tr><tr><td>Water</td><td>2</td><td>161</td><td>39</td></tr><tr><td>Milk</td><td>2</td><td>157</td><td>43</td></tr><tr><td>Beer and wine</td><td>2</td><td>162</td><td>38</td></tr><tr><td>Coffee</td><td>1</td><td>78</td><td>22</td></tr><tr><td>Vinegar</td><td>1</td><td>82</td><td>18</td></tr><tr><td>Total</td><td>30</td><td>2,400</td><td>600</td></tr></table>

Final-epoch accuracy is reported alongside the best-epoch results to remove epoch selection from that comparison. A further evaluation uses stratified five-fold cross-validation over all 3,000 samples with seed 0 and final-epoch predictions. Each sample contributes one out-of-fold label, evaluating sample-level resampling rather than independent acquisition sessions.

Accuracy measures the fraction of correct predictions. Macro-F1 averages the class-wise F1 values over all 30 labels, providing a complementary measure when the released test counts vary by class. A single error changes overall test accuracy by approximately 0.167 percentage points. Classlevel test counts range from 12 to 29, so individual class percentages are interpreted together with their sample counts.

## B. Baselines and Training Settings

The comparison includes a nearest-centroid reference, a multilayer perceptron (MLP), original-recipe MMNet, and MMNet-R. Nearest centroid provides a feature-space reference without gradient training. NoAttn uses a token model without attention, whereas AttnNet uses per-scalar tokens. The baselines span direct feature classification and token interaction.

The modern recipe uses AdamW with learning rate 10<sup>−3</sup>, weight decay 0.05, batch size 128, and 300 epochs. The schedule uses ten warm-up epochs followed by cosine decay. Training-statistic normalization, label smoothing of 0.1, and Gaussian input noise of 0.05 are applied to MMNet-R and the attention models. Thus, MMNet-R is a training-recipe control for the proposed architecture.

Original-recipe MMNet uses Adam with learning rate 0.005, momentum coefficients 0.9 and 0.99, batch size 480, and 300 epochs. Its step schedule multiplies the learning rate by 0.8 every ten epochs. Weight decay of $1 0 ^ { - 5 }$ is combined with explicit $L _ { 2 }$ regularization of $9 \times 1 0 ^ { - 5 }$ . The MLP uses 200 epochs, batch size 128, learning rate 0.001, weight decay $1 0 ^ { - 4 }$ , dropout 0.3, and a factor-0.5 learning-rate step every 40 epochs.

## C. Main Recognition Results

Table II reports the main results. StructAttn-S3 achieves 96.70% mean best-epoch accuracy, matching MMNet and improving on AttnNet by 1.50 percentage points. The NoAttn-to-AttnNet difference is 2.83 points. These comparisons support token interaction and structured views within the tested model family, although parameter counts differ and the comparisons do not isolate attention under equal capacity.

MMNet-R obtains the highest single-model best-epoch mean of 96.93%. The original-recipe MMNet gives the highest final-epoch mean of 96.30%, compared with 95.93% for S3. The best-to-final gap is 0.77 points for S3 and 0.70 points for MMNet-R. Figure 2 shows these protocol-dependent differences.

The S3 ensemble reaches 97.00%, with 18 errors among 600 samples. The MMNet and MMNet-R ensembles make 22 and 20 errors, respectively. Thus, S3 improves the ensemble result by four and two correct predictions. This small margin is the best observed ensemble score, without a statistical-significance claim.

The MMNet and MMNet-R ensemble members were retrained separately from the main seed-sweep runs. Their mean selected-checkpoint accuracies are 96.57% and 96.87%, respectively, while the S3 member mean is 96.70%. Ensemble accuracy is therefore compared directly between ensemble predictors, rather than inferred from the single-model means in Table II.

## D. Token Design and Regularization

Table IV compares token variants using seed 0. S1 contains antenna, feature, data-point, branch, and global tokens. S3 removes the three data-point tokens while keeping width 192 and three layers. Its best-epoch accuracy is 97.00%, compared with 96.33% for S1. This screening supports retaining antenna and feature views without a separate token for each data point.

S4 retains only the location, reflection, and global tokens and uses two transformer layers. It reaches 95.00% final-epoch accuracy, compared with 96.50% for S3 in this screening. The comparison is consistent with a benefit from richer structured views, but token removal and reduced depth occur together. This comparison does not isolate each token group’s contribution.

![](images/422c0f484076b0efbe864c9ba0dedcd07c64be0876b913804c1de17e088d2ab9.jpg)  
Fig. 2: Best- and final-epoch accuracy over five seeds.

TABLE IV: Token variants on seed 0. Accuracy is in percent.
<table><tr><td>Variant</td><td>Tokens</td><td>Width/layers</td><td>Params</td><td>Best</td><td>Final</td></tr><tr><td>S1</td><td>14</td><td>192/3</td><td>1.24M</td><td>96.33</td><td>96.00</td></tr><tr><td>S2</td><td>14</td><td>256/4</td><td>2.56M</td><td>96.83</td><td>96.00</td></tr><tr><td>S3</td><td>11</td><td>192/3</td><td>1.19M</td><td>97.00</td><td>96.50</td></tr><tr><td>S4</td><td>3</td><td>192/2</td><td>782K</td><td>96.33</td><td>95.00</td></tr></table>

The larger S2 model does not improve the five-seed bestepoch mean over S3, despite using approximately twice as many parameters. S5 adds an exponential moving average with decay 0.998 and obtains 96.43%. S6 additionally uses dropout 0.2, mixup coefficient 0.2, and input noise of 0.1, reaching 94.17%. The tested data favor the S3 configuration over these larger or more strongly regularized alternatives.

## E. Measurement Contributions

Feature masking is evaluated by retraining MMNet-R with selected inputs removed or retained. The results use finalepoch accuracy averaged over two seeds. As shown in Fig. 3, removing RSS reduces accuracy from 96.25% to 84.17%. Keeping only RSS reaches 91.42%. Reflection strength is therefore highly informative, while the other features provide complementary information.

Removing distance, elevation, or azimuth individually yields 95.83%, 95.75%, and 96.08%, respectively. Removing a single receiving antenna gives accuracies between 96.08% and 96.25%. Using only the first data point reaches 95.50%. These observations indicate substantial redundancy in the recorded feature tensor, which helps explain why additional data-point tokens need not improve recognition.

The recorded final-layer [CLS] attention patterns also vary by liquid category. Soft drinks emphasize the RSS feature token, oils and water emphasize distance, and liquor classes emphasize the reflection branch. These patterns describe model behavior rather than causal importance. Masking provides separate evidence about input usefulness.

![](images/47d79216c1c1640a9ef75d11bfeb27960aab44ea36e9adf7f5ef67b21d4febae.jpg)  
Fig. 3: Feature masking with MMNet-R at the final epoch.

TABLE V: Final-epoch five-fold results on all 3,000 samples.
<table><tr><td>Metric or category</td><td>MMNet-R</td><td>StructAttn-S3</td></tr><tr><td>Fold mean ± std</td><td>95.77 ± 0.40</td><td>95.30 ± 0.64</td></tr><tr><td>Liquor</td><td>99.8</td><td>99.9</td></tr><tr><td>Edible oil</td><td>90.6</td><td>88.6</td></tr><tr><td>Soft drink</td><td>92.0</td><td>91.8</td></tr><tr><td>Water</td><td>84.5</td><td>82.5</td></tr><tr><td>Other categories</td><td>98.8</td><td>98.8</td></tr></table>

## F. Cross-Validation and Class-Level Behavior

Table V presents five-fold results. MMNet-R obtains 95.77% out-of-fold accuracy and S3 obtains 95.30%, with fold standard deviations of 0.40 and 0.64 points. This ranking differs from the ensemble comparison on the released split. The results indicate that structured attention is competitive on the available measurements, while its strongest observed aggregate score is specific to the tested ensemble setting.

Table VI gives representative S3 out-of-fold confusion counts. Liquor classes are separated almost perfectly in both models, whereas water, oil, and soft-drink categories account for most residual errors. For S3, mineral water has 74 correct predictions out of 100, with 14 assigned to tap water and 12 to soda. Olive oil has 81 correct predictions, with the remaining 19 assigned to soybean oil. Soybean oil has 83 correct predictions, with 17 assigned to olive oil. These bidirectional confusions are consistent with measured signatures.

The released-split per-class results provide a complementary view of ensemble behavior. Compared with one original MMNet run, the S3 ensemble reduces soda errors from five to one and corrects the two errors in each of the 38% and 56% liquor classes. Some classes move in the opposite direction, including mineral water. This comparison is diagnostic because it contrasts one run with an ensemble and uses only 12–29 samples per class.

## G. Effect of the Number of Liquid Classes

The class-subset experiment restricts the released split to K randomly selected liquids. Three subsets are evaluated for each K < 30 using final-epoch predictions. Figure 4 shows the mean and observed range across subsets. Both models achieve 100% for the sampled two-class tasks, and S3 also achieves 100% for the sampled five-class tasks.

TABLE VI: Representative S3 out-of-fold confusions.
<table><tr><td>True liquid</td><td>Correct/100</td><td>Predicted instead</td><td>Count</td></tr><tr><td>Mineral water</td><td>74</td><td>Tap water</td><td>14</td></tr><tr><td>Olive oil</td><td></td><td>Soda</td><td>12</td></tr><tr><td>Soybean oil</td><td>81 83</td><td>Soybean oil Olive oil</td><td>19 17</td></tr><tr><td>Soda</td><td>84</td><td>Tap water</td><td>10</td></tr><tr><td></td><td></td><td>Mineral water</td><td>6</td></tr><tr><td>Corn oil</td><td>90</td><td>Peanut oil</td><td>9</td></tr><tr><td>Peanut oil</td><td>91</td><td>Corn oil</td><td>9</td></tr></table>

![](images/50cd8a592bd0cfe9ecc03974ebcf2b37577dd7f7d695f9394307c86995301889.jpg)  
Fig. 4: Accuracy across sampled liquid subsets. Bands show ranges.

At K = 10, S3 ranges from 95.4% to 100%, while at $K =$ 15 it ranges from 96.3% to 100%. Accuracy is therefore not determined by class count alone. Including a confusable pair can make a smaller task harder than a larger task composed of more separable liquids. Three sampled subsets characterize this dependence without covering all combinations.

Each liquid contributes 100 measurements, and subsets retain the released split. The ranges reflect label combinations rather than repeated training seeds.

The $K = 3 0$ endpoint is a single full-class run, with 96.2% for MMNet-R and 96.5% for S3 at the precision reported in the subset study. It is distinct from both the five-seed final-epoch means and the cross-validation results. Separate reporting clarifies the effect of class composition.

## V. CONCLUSION

This paper presented structured-token attention for finegrained mmWave liquid identification. Antenna, feature, branch, and global views expose complementary relationships in a compact radar tensor. On FG-LiquID, StructAttn-S3 matches the original-recipe MMNet best-epoch mean of 96.70% and improves on scalar-token attention by 1.50 percentage points. Its five-seed ensemble reaches 97.00%, while final-epoch and cross-validation results provide complementary views of performance.

The analysis identifies RSS as a central recognition cue and locates the remaining ambiguity mainly within similar liquid groups. Evaluation covers released measurements and samplelevel splits. An independent validation partition and additional acquisition conditions are natural extensions for assessing configuration selection and transfer. Structured tokenization provides a basis for further attention-based liquid sensing.

## REFERENCES

[1] Y. Liang et al., “Fg-liquid: A contact-less fine-grained liquid identifier by pushing the limits of millimeter-wave sensing,” Proc. ACM Interact. Mob. Wearable Ubiquitous Technol., vol. 5, no. 3, Sep. 2021.

[2] A. Vaswani et al., “Attention is All you Need,” in Proc. Advances in Neural Information Processing Systems (NIPS), Long Beach, CA, USA, December 2017, pp. 5998–6008.

[3] J. Kim and W. Lee, “Feasibility Study of 60 GHz Millimeter-Wave Technologies for Hyperconnected Fog Computing Applications,” IEEE Internet of Things Journal, vol. 4, no. 5, pp. 1165–1173, October 2017.

[4] J. Kim et al., “60 GHz Modular Antenna Array Link Budget Estimation with WiGig Baseband and Millimeter-Wave Specific Attenuation,” International Journal ofAntennas and Propagation, vol. 2017, pp. 1–9, June 2017.

[5] J. Kim and A. F. Molisch, “Fast millimeter-wave beam training with receive beamforming,” Journal of Communications and Networks, vol. 16, no. 5, pp. 512–522, October 2014.

[6] J. Kim and S.-N. Hong, “Dynamic two-stage beam training for energyefficient millimeter-wave 5G cellular systems,” Telecommunication Systems, vol. 59, no. 1, pp. 111–122, May 2014.

[7] J. Kim et al., “Fast and Low-Power Link Setup for IEEE 802.15.3c Multi-Gigabit/s Wireless Sensor Networks,” IEEE Communications Letters, vol. 18, no. 3, pp. 455–458, March 2014.

[8] S. Han et al., “Numerical approximation of millimeter-wave frequency sharing between cellular systems and fixed service systems,” Journal of Communications and Networks, vol. 22, no. 1, pp. 37–45, February 2020.

[9] B. Lim et al., “Joint User Clustering, Beamforming, and Power Allocation for mmWave-NOMA With Imperfect SIC,” IEEE Transactions on Wireless Communications, vol. 23, no. 3, pp. 2025–2038, March 2024.

[10] F. Shang et al., “LiquImager: Fine-grained Liquid Identification and Container Imaging System with COTS WiFi Devices,” Proc. ofthe ACM on Interactive, Mobile, Wearable and Ubiquitous Technologies, vol. 8, no. 1, pp. 1–29, March 2024.

[11] M. Choi and J. Kim, “Blind Signal Classification Analysis and Impact on User Pairing and Power Allocation in Nonorthogonal Multiple Access,” IEEE Access, vol. 8, pp. 100 916–100 929, June 2020.

[12] B. Lim et al., “Joint Pilot Design and Channel Estimation Using Deep Residual Learning for Multi-Cell Massive MIMO Under Hardware Impairments,” IEEE Transactions on Vehicular Technology, vol. 71, no. 7, pp. 7599–7612, July 2022.

[13] J. Lee et al., “Set Transformer: A Framework for Attention-based Permutation-Invariant Neural Networks,” in Proc. International Conference on Machine Learning (ICML), Long Beach, CA, USA, June 2019, pp. 3744–3753.

[14] Y. Gorishniy et al., “Revisiting Deep Learning Models for Tabular Data,” in Proc. Advances in Neural Information Processing Systems (NeurIPS), Virtual conference, December 2021, pp. 18 932–18 943.

[15] D. Kim et al., “Multiscale LSTM-Based Deep Learning for Very-Short-Term Photovoltaic Power Generation Forecasting in Smart City Energy Management,” IEEE Systems Journal, vol. 15, no. 1, pp. 346–354, March 2021.

[16] K. Kim et al., “Stabilized Detection Accuracy Maximization Using Adaptive SAR Image Processing in LEO Networks,” IEEE Transactions on Vehicular Technology, vol. 71, no. 5, pp. 5661–5665, May 2022.

[17] W. J. Yun et al., “Self-Configurable Stabilized Real-Time Detection Learning for Autonomous Driving Applications,” IEEE Transactions on Intelligent Transportation Systems, vol. 24, no. 1, pp. 885–890, January 2023.

[18] G. S. Kim et al., “Joint frame rate adaptation and object recognition model selection for stabilized unmanned aerial vehicle surveillance,” ETRI Journal, vol. 45, no. 5, pp. 811–821, October 2023.

[19] I. Loshchilov and F. Hutter, “Decoupled Weight Decay Regularization,” in Proc. International Conference on Learning Representations (ICLR), New Orleans, LA, USA, May 2019.

[20] B. Lakshminarayanan et al., “Simple and Scalable Predictive Uncertainty Estimation using Deep Ensembles,” in Proc. Advances in Neural Information Processing Systems (NIPS), Long Beach, CA, USA, December 2017, pp. 6402–6413.