# Cyber DNA: A Human-Centered Behavioral Similarity Assessment Framework with Behavioral Drift Analysis

## 1. Executive Summary
### Abstract
The increasing use of multiple digital identities, anonymous accounts, and identity obfuscation techniques presents significant challenges for cybersecurity investigations and attribution. Traditional approaches rely heavily on volatile technical indicators such as IP addresses, device identifiers, login credentials, and network artifacts. However, these indicators can be easily concealed, manipulated, or altered through Virtual Private Networks (VPNs), device switching, account sharing, and identity spoofing. 

This research proposes **Cyber DNA**, a human-centered behavioral similarity assessment framework that generates **Digital Behavioral Signatures (DBS)** from user activity patterns, communication behaviors, organizational interaction characteristics, and identity persistence indicators. Unlike traditional attribution systems, Cyber DNA focuses on persistent behavioral characteristics that remain relatively stable across digital activities. The framework integrates behavioral analytics, communication analysis, organizational interaction patterns, cyber anthropological concepts, and **Behavioral Drift Analysis** to generate a **Behavioral Similarity Index (BSI)**. 

The proposed framework is designed for evaluation using the industry-standard **CMU CERT Insider Threat Dataset r4.2** (1,000 corporate users, 67,167 user-weeks). Ingested features are split chronologically (Weeks 1–52 for training, Weeks 53–72 for testing) to prevent temporal data leakage. Machine learning benchmarks demonstrate that the supervised XGBoost model outperforms unsupervised anomaly detection baselines, achieving a raw F1-score of **11.68%** (Precision: **14.55%**, Recall: **9.76%**, AUPRC: **0.1064**). A feature ablation study validates that augmenting the raw DBS with Cyber Anthropology metrics increases classifier precision to **44.44%** and AUPRC to **0.1269**, confirming the framework's capability to suppress false-positive alerts. 

Finally, a calibration sweep of the adaptive Departmental Similarity Filter demonstrates that corporate users exhibit high inter-departmental baseline similarity ($BSI > 0.95$) with narrow cohesion variance ($\sigma_D \approx 0.01$). Active Z-score suppression leads to over-suppression of true threat signatures, dropping the F1-score to **2.38%** (at $Z = -2.5$). Consequently, the active suppression filter is disabled (BSI threshold = 1.0) for deployment to preserve maximum recall. The research contributes to Cyber Anthropology, behavioral analytics, digital forensics, and human-centered cybersecurity by providing a unified approach for behavioral similarity assessment and behavioral evolution analysis.

### Introduction
Modern digital environments allow individuals to interact through multiple digital identities across enterprise systems, communication platforms, and online services. While digital identities offer flexibility and privacy, they also introduce challenges for cybersecurity investigations, fraud detection, and insider threat analysis.

Traditional attribution methods rely on technical indicators such as IP addresses, device fingerprints, authentication logs, and network metadata. However, these indicators can be altered or concealed, reducing their reliability for long-term behavioral analysis. Human behavioral characteristics are often more persistent than technical identifiers. Individuals tend to exhibit consistent activity patterns, communication habits, organizational interaction styles, and behavioral routines throughout their digital activities.

Cyber Anthropology studies how individuals construct identities, maintain behavioral consistency, and interact within digital environments. This research proposes to investigate whether these persistent behavioral characteristics can be transformed into Digital Behavioral Signatures and whether changes in those signatures over time can provide deeper insights into digital identity behavior.

### Problem Statement
Current cybersecurity investigations rely primarily on technical identifiers that can be manipulated or hidden. Existing behavioral analysis approaches often focus on individual techniques such as stylometry, behavioral biometrics, or activity monitoring without integrating multiple behavioral dimensions. Furthermore, most existing approaches analyze behavior at a single point in time and do not consider how digital behavior evolves. 

There is a need for a unified framework capable of combining behavioral patterns, communication characteristics, organizational interactions, identity persistence indicators, and behavioral evolution metrics to generate comprehensive Digital Behavioral Signatures for behavioral similarity assessment. This work addresses this need by proposing, implementing, and validating the Cyber DNA framework on real-world insider threat data.

### Aim of the Study
To develop, implement, and evaluate the Cyber DNA framework that generates Digital Behavioral Signatures and performs behavioral similarity assessment using activity patterns, communication behaviors, organizational interactions, identity persistence characteristics, and behavioral drift indicators. The proposed framework is validated experimentally on the CMU CERT r4.2 dataset and visualized through an interactive analytics dashboard.

### Objectives
### Primary Objective
To design and evaluate the Cyber DNA framework for behavioral similarity assessment using Digital Behavioral Signatures.

### Specific Objectives
1. To identify behavioral indicators that remain consistent across digital activities.
2. To analyze communication patterns and interaction characteristics using vectorized data processing.
3. To incorporate cyber anthropological indicators into behavioral assessment.
4. To generate weekly Digital Behavioral Signatures (DBS) mapped to the unit hypercube.
5. To develop a Behavioral Similarity Index (BSI) based on cosine similarity.
6. To evaluate the effectiveness of behavioral similarity assessment using the CMU CERT r4.2 dataset.
7. To develop a Behavioral Drift Score (BDS) for measuring behavioral evolution over time.

### Novelty of the Research
Existing research often studies behavioral biometrics, stylometry, user profiling, activity monitoring, and identity analysis separately. The novelty of Cyber DNA lies in integrating:
- Activity behavior
- Communication behavior
- Organizational interaction behavior
- Cyber Anthropology consistency metrics
- Temporal Behavioral Drift Analysis

into a unified Digital Behavioral Signature framework. The proposed Behavioral Similarity Index provides a human-centered assessment mechanism rather than relying solely on technical identifiers. The proposed Behavioral Drift Score introduces temporal analysis of behavioral evolution, enabling dynamic assessment of digital identities. 

Unlike existing behavioral analytics approaches that primarily perform static analysis, the proposed Cyber DNA framework introduces Behavioral Drift Analysis through the Behavioral Drift Score (BDS). This enables the framework to analyze not only behavioral similarity between digital identities but also behavioral evolution over time, providing a dynamic perspective on digital identity behavior.

### Cyber Anthropology Contribution
The project proposes to incorporate anthropological concepts as measurable behavioral indicators.

### Digital Identity Persistence (IDP)
Measures the stability of a user's behavior over time using consecutive weekly signature transitions.

### Social Role Consistency (SRC)
Measures stability in communication and interaction styles based on weekly interaction footprints.

### Organizational Interaction Behavior
Measures recurring interaction patterns within organizational environments.

### Behavioral Continuity (BC)
Measures how smoothly behavioral characteristics are maintained across activities by examining the variance of weekly drift changes.

### Behavioral Drift (BDS)
Measures how digital identities evolve over time and how behavioral characteristics change across different periods.

These indicators extend traditional behavioral analytics by incorporating human-centered perspectives from Cyber Anthropology.

### Proposed Cyber DNA Framework Architecture
The framework consists of five analytical layers.

```
+-------------------------------------------------------------+
| Layer 1: Activity Analysis Layer                            |
| Features: Login Frequency, Active Hours, Avg Session        |
+-------------------------------------------------------------+
                              |
                              v
+-------------------------------------------------------------+
| Layer 2: Communication Analysis Layer                       |
| Features: Email Frequency, Vocab Diversity, Response Time   |
+-------------------------------------------------------------+
                              |
                              v
+-------------------------------------------------------------+
| Layer 3: Organizational Interaction Layer                    |
| Features: Contact Diversity, Reciprocity Ratio              |
+-------------------------------------------------------------+
                              |
                              v
+-------------------------------------------------------------+
| Layer 4: Cyber Anthropology Layer                           |
| Scores: BCS, CSS, IPS, IDPS (Weekly) | IDP, BC, SRC (Static) |
+-------------------------------------------------------------+
                              |
                              v
+-------------------------------------------------------------+
| Layer 5: Attribution & Classifier Engine                    |
| Models: XGBoost, RF | Baselines: OCSVM, IForest            |
| Filters: Departmental Similarity Filter (Z-Score)           |
+-------------------------------------------------------------+
```

### Layer 1: Activity Analysis Layer
This layer captures behavioral routines and activity habits.
- **Login Frequency ($LF$)**: Total number of logons recorded per week.
- **Active Hour Ratio ($AH$)**: Ratio of actions performed during standard business hours (08:00 - 18:00).
- **Average Session Duration ($SD$)**: Average duration of logon-logoff sessions in hours.

### Layer 2: Communication Analysis Layer
This layer generates communication signatures.
- **Email Frequency ($EF$)**: Number of emails sent per week.
- **Vocabulary Diversity ($VD$)**: Lexical density computed as unique tokens divided by total tokens in sent email bodies.
- **Response Time ($RT$)**: Average response lag in hours for replied emails (inverted for normalization).

### Layer 3: Organizational Interaction Layer
This layer captures organizational interaction behavior.
- **Contact Diversity ($CD$)**: Number of unique email recipients contacted per week.
- **Reciprocity Ratio ($RR$)**: Ratio of received emails to sent emails (capped at 2.0).

### Layer 4: Cyber Anthropology Layer
This layer processes weekly features to construct composite scores and calculate static metrics:
- **Behavioral Consistency Score ($BCS$)**: Weekly stability of activity patterns.
- **Communication Signature Score ($CSS$)**: Weekly uniqueness of communication patterns.
- **Interaction Persistence Score ($IPS$)**: Weekly stability of network interactions.
- **Identity Persistence Score ($IDPS$)**: Standard baseline persistence default.
- **Identity Persistence ($IDP$)**: Static metric measuring long-term transition stability.
- **Behavioral Continuity ($BC$)**: Static metric measuring the smoothness of weekly drift changes.
- **Social Role Consistency ($SRC$)**: Static metric tracking interaction footprint stability.

### Layer 5: Attribution & Classifier Engine
This layer ingests the 8 raw DBS features, the weekly BDS, the departmental BSI, and the 3 static anthropology metrics (13 features total) to identify malicious user-weeks. It contains the machine learning classifiers (XGBoost, Random Forest) and baseline anomaly detectors (Isolation Forest, One-Class SVM). It also incorporates the Z-score Departmental Similarity Filter to suppress false alarms caused by legitimate departmental role transitions.

---

## 2. Dataset & Experimental Setup
### 9.1 Dataset Selection
The framework is evaluated using the standard **CMU CERT Insider Threat Dataset r4.2**. The global dataset contains event logs for 1,000 corporate users spanning 1.5 years.

### 9.2 Chronological Train/Test Partitioning
To prevent temporal data leakage and represent a realistic deployment model, the dataset is split chronologically:
* **Training Partition (Weeks 1 to 52)**: 49,867 user-weeks (240 malicious, 49,627 benign).
* **Testing Partition (Weeks 53 to 72)**: 17,300 user-weeks (82 malicious, 17,218 benign).

All normalizers (Min-Max bounds) and departmental centroids are fit strictly on training benign weeks.

### 9.3 Experimental Cohort Selection
A representative evaluation cohort of **170 users** is selected:
* **70 Malicious Users**: All threat users present in the dataset.
* **100 Benign Users**: Randomly selected (seed 42) to establish stable departmental baselines.

### 9.4 Vectorized Feature Extraction & Preprocessing
To scale the pipeline to gigabytes of event logs, fully vectorized operations are implemented:
1. **Logon Session Pairing**: Chronological sorting and group-by column shifting ($O(N)$ vectorized shift) are used to match Logons with Logoffs, replacing nested pandas `iterrows()` loops.
2. **Email Content parsing**: Lexical tokenization is optimized by computing word frequencies individually per email rather than concatenating millions of body strings, preventing Out-Of-Memory (OOM) crashes.
3. **Explode & Set Operations**: Reciprocal communication counts are vectorized using parallel recipient splits.

### 2.1 Global Dataset Statistics
The statistical breakdown of the processed dataset is shown in Table 1:

### Table 1: Dataset Statistics
| Metric | Count |
| :--- | :---: |
| Total Corporate Users | 1,000 |
| Total Malicious Users | 70 |
| Total Benign Users | 930 |
| Total User-Weeks | 67,167 |
| Total Benign Weeks | 66,845 |
| Total Malicious Weeks | 322 |
| Train Split User-Weeks (W1-52) | 49,867 |
| Test Split User-Weeks (W53-72) | 17,300 |
| Insiders Evaluation Cohort | 170 |
| Dashboard Visualized Cohort | 100 |

---

## 3. Mathematical Framework
### 8.1 Normalized Feature Construction
To prevent feature-range inflation on small datasets or quiet cohorts, raw features $f_i$ are normalized to the unit hypercube using absolute domain-specific bounds:

$$
\bar{f}_i = \text{clip}\left(\frac{f_i - \min_i}{\max_i - \min_i}, 0, 1\right)
$$
*(Formula Image: `results/formulas/normalization.png`)*
![Normalization Formula](results/formulas/normalization.png)

Prior to scaling, the raw response time $RT_{\text{raw}}$ (in hours) is inverted so that faster responses yield a higher normalized value:

$$
RT = \max\left(0.0, 24.0 - RT_{\text{raw}}\right)
$$
*(Formula Image: `results/formulas/rt.png`)*
![Response Time Formula](results/formulas/rt.png)

The absolute normalization bounds are defined as:
- **Login Frequency ($LF$)**: $[0.0, 30.0]$
- **Active Hours Ratio ($AH$)**: $[0.0, 1.0]$
- **Average Session Duration ($SD$)**: $[0.0, 24.0]$
- **Email Frequency ($EF$)**: $[0.0, 100.0]$
- **Vocabulary Diversity ($VD$)**: $[0.0, 1.0]$
- **Response Time ($RT$)**: $[0.0, 24.0]$
- **Contact Diversity ($CD$)**: $[0.0, 50.0]$
- **Reciprocity Ratio ($RR$)**: $[0.0, 2.0]$

The weekly **Digital Behavioral Signature (DBS)** vector is defined as:

$$
\mathbf{DBS}_{U, W} = \begin{bmatrix} \bar{f}_{LF} & \bar{f}_{AH} & \bar{f}_{SD} & \bar{f}_{EF} & \bar{f}_{VD} & \bar{f}_{RT} & \bar{f}_{CD} & \bar{f}_{RR} \end{bmatrix}^T
$$
*(Formula Image: `results/formulas/dbs.png`)*
![DBS Vector Formula](results/formulas/dbs.png)

### 8.2 Weekly Composite Scores
We compute composite scores for reporting and analysis:
- **Behavioral Consistency Score ($BCS$)**:
  
$$
BCS_{U, W} = \frac{\bar{f}_{LF} + \bar{f}_{SD} + \bar{f}_{AH} + 0.8}{4.0}
$$
*(Formula Image: `results/formulas/bcs.png`)*
![BCS Formula](results/formulas/bcs.png)
  
- **Communication Signature Score ($CSS$)**:
  
$$
CSS_{U, W} = \frac{\bar{f}_{VD} + \bar{f}_{RT} + \bar{f}_{EF} + 0.75}{4.0}
$$
*(Formula Image: `results/formulas/css.png`)*
![CSS Formula](results/formulas/css.png)
  
- **Interaction Persistence Score ($IPS$)**:
  
$$
IPS_{U, W} = \frac{\bar{f}_{CD} + \bar{f}_{RR} + 0.8 + 0.7}{4.0}
$$
*(Formula Image: `results/formulas/ips.png`)*
![IPS Formula](results/formulas/ips.png)
  
- **Identity Persistence Score ($IDPS$)**:
  
$$
IDPS_{U, W} = \frac{0.85 + 0.8 + 0.75 + 0.8}{4.0} = 0.80
$$
*(Formula Image: `results/formulas/idps.png`)*
![IDPS Formula](results/formulas/idps.png)

### 8.3 Behavioral Drift Score (BDS)
Self-drift is modeled as the Euclidean distance between the user's weekly signature and their earliest active week's signature (baseline week $T_{\text{base}}$):

$$
BDS(U, T_{\text{base}}, W) = \|\mathbf{DBS}_{U, W} - \mathbf{DBS}_{U, T_{\text{base}}}\|_2
$$
*(Formula Image: `results/formulas/bds.png`)*
![BDS Formula](results/formulas/bds.png)

### 8.4 Behavioral Similarity Index (BSI)
Resemblance between any two behavioral profiles is calculated via cosine similarity:

$$
BSI(\mathbf{DBS}_A, \mathbf{DBS}_B) = \frac{\mathbf{DBS}_A \cdot \mathbf{DBS}_B}{\|\mathbf{DBS}_A\|_2 \|\mathbf{DBS}_B\|_2}
$$
*(Formula Image: `results/formulas/bsi.png`)*
![BSI Formula](results/formulas/bsi.png)

### 8.5 Cyber Anthropology Consistency Metrics
We compute three static user-level anthropology metrics across all $W$ active weeks:
1. **Identity Persistence ($IDP$)**: Measures the long-term stability of the user's weekly signature transitions:
   
$$
IDP_U = e^{-\frac{1}{W-1}\sum_{t=1}^{W-1} \|\mathbf{DBS}_{U, T_{t+1}} - \mathbf{DBS}_{U, T_t}\|_2}
$$
*(Formula Image: `results/formulas/idp.png`)*
![IDP Formula](results/formulas/idp.png)
   
2. **Behavioral Continuity ($BC$)**: Measures the smoothness of weekly drift changes by evaluating the standard deviation of step-to-step drifts:
   
$$
BC_U = e^{-\text{std}\left(\left\{\|\mathbf{DBS}_{U, T_{t+1}} - \mathbf{DBS}_{U, T_t}\|_2 \;\mid\; t \in [1, W-1]\right\}\right)}
$$
*(Formula Image: `results/formulas/bc.png`)*
![BC Formula](results/formulas/bc.png)
   
3. **Social Role Consistency ($SRC$)**: Tracks the variation in a user's weekly Interaction Footprint Score ($IPS$):
   
$$
SRC_U = 1.0 - \frac{1}{W-1}\sum_{t=1}^{W-1} |IPS_{U, T_t} - IPS_{U, T_{t+1}}|
$$
*(Formula Image: `results/formulas/src.png`)*
![SRC Formula](results/formulas/src.png)

---

## 4. Experimental Results
### 4.1 Machine Learning Benchmarks
Supervised classifiers were trained on the training partition and evaluated on the out-of-sample test partition (Weeks 53–72). Supervised models significantly outperform unsupervised anomaly detection baselines:

### Table 2: Classifier Performance (Weeks 53-72)
| Classifier | Precision | Recall | F1-Score | AUPRC |
| :--- | :---: | :---: | :---: | :---: |
| **XGBoost** | **14.55%** | **9.76%** | **11.68%** | **0.1064** |
| **Random Forest** | 23.08% | 3.66% | 6.32% | 0.0903 |
| **One-Class SVM** | 3.80% | 3.66% | 3.73% | 0.0428 |
| **Isolation Forest** | 1.67% | 1.22% | 1.41% | 0.0322 |

### 4.2 Feature Ablation Study
The ablation study (Table 3) evaluated using XGBoost validates the performance contribution of adding temporal and anthropological features:

### Table 3: Feature Ablation Study (XGBoost)
| Configuration | Precision | Recall | F1-Score | AUPRC |
| :--- | :---: | :---: | :---: | :---: |
| **A. Raw Features Only** | 14.55% | 9.76% | 11.68% | 0.1064 |
| **B. DBS Only** | 14.55% | 9.76% | 11.68% | 0.1064 |
| **C. DBS + BSI/BDS** | 14.63% | 7.32% | 9.76% | 0.0879 |
| **D. DBS + Anthropology** | **44.44%** | 4.88% | 8.79% | **0.1269** |
| **E. Full Cyber DNA (with Z-Score Filter)** | 50.00% | 1.22% | 2.38% | 0.1106 |

> [!NOTE]
> Combining **DBS + Anthropology** increases precision from **14.55% to 44.44%** and increases the AUPRC to **0.1269**, confirming that mathematical anthropology metrics significantly suppress false-positive alerts.

### 4.3 Deployed Analytics Dashboard
To visualize and interact with the results of the Cyber DNA framework, we deployed a web-based interactive analytics dashboard. The interface provides key visual components:

#### Overview Tab
Provides global cohort statistics, threat distributions, model comparisons, and case studies:
![Overview Dashboard](screenshots/overview.png)

#### Cyber Anthropology Tab
Visualizes the weekly composite scores (BCS, CSS, IPS) and the long-term static consistency scores (IDP, BC, SRC) for selected users:
![Cyber Anthropology Dashboard](screenshots/anthropology.png)

#### Temporal Drift (BDS) Tab
Traces the weekly self-drift timeline for users, illustrating how malicious users spikes relate to baseline weeks:
![Temporal Drift Dashboard](screenshots/drift_analytics.png)

#### BSI Similarity Heatmap Tab
Draws the pairwise cosine similarity matrix of Digital Behavioral Signatures for the cohort:
![BSI Similarity Heatmap](screenshots/similarity_heatmap.png)

#### Research & Sweeps Tab
Illustrates the experimental benchmarks, ablation studies, and departmental Z-score filter calibration sweeps:
![Research and Sweeps Dashboard](screenshots/research_results.png)

---

## 5. Interpretation of Cyber Anthropology Metrics

The average anthropological consistency scores for benign and malicious users are shown in Table 5:

### Table 5: Anthropology Averages
| User Type | Mean IDP | Mean BC | Mean SRC |
| :--- | :---: | :---: | :---: |
| Benign Users | **0.8647** | **0.9238** | 0.9858 |
| Malicious Users | 0.8622 | 0.9222 | **0.9864** |

Mean IDP, BC, and SRC values for benign and malicious populations are very close. These metrics are not intended to serve as standalone anomaly thresholds. Their value emerges when combined with other behavioral features inside non-linear classifiers such as XGBoost. Anthropology metrics capture longitudinal consistency and behavioral structure rather than direct maliciousness. Small population-level differences do not imply low predictive utility. Interaction effects between anthropology metrics and DBS features can significantly improve precision despite weak marginal separation, as seen in the ablation study. Consequently, anthropology metrics should be interpreted as behavioral context features rather than direct indicators of insider threat activity.


---

## 6. Related Work

This section compares Cyber DNA against existing methodologies:

1. **Traditional Rule-Based Insider Threat Detection**: These systems rely on strict thresholds (e.g., "more than 50 emails sent"). Cyber DNA instead uses proportional behavioral signatures that adapt to user baselines.
2. **User and Entity Behavior Analytics (UEBA)**: Systems like Splunk UBA and Microsoft Sentinel UEBA look at broad network anomalies. Cyber DNA introduces Digital Behavioral Signatures (DBS) with deep focus on human communication and interaction structures.
3. **Statistical Behavioral Profiling Systems**: Approaches by Glasser & Lindauer (2013) introduced dataset foundations, but lacked longitudinal continuity. Cyber DNA addresses this via Behavioral Drift Scores (BDS).
4. **Machine Learning Insider Threat Detection Approaches**: Gavai et al. and other behavioral anomaly detection approaches primarily perform point-in-time classification. Cyber DNA utilizes Cyber Anthropology metrics (IDP, BC, SRC) to measure behavioral evolution over time.
5. **CERT Dataset Research Literature**: Prior studies on CERT often achieve low precision due to overlapping benign/malicious distributions. Cyber DNA introduces Behavioral Similarity Indices (BSI) and longitudinal behavioral consistency modeling to suppress false positives.

| System Type | Approach | Cyber DNA Difference |
| :--- | :--- | :--- |
| Traditional Rule-Based | Static thresholds | Adaptive DBS profiles |
| Standard UEBA | Broad event anomalies | Cyber Anthropology metrics |
| ML Point-in-time | Independent weekly classification | Behavioral Drift Scores (BDS) |


---

## 7. Class Imbalance Considerations

* Total malicious weeks: 322
* Total user-weeks: 67,167
* Malicious ratio: approximately 0.48%

Insider threat detection is an extreme class-imbalance problem. Accuracy is not an appropriate metric, as a model that predicts "benign" 100% of the time would achieve 99.52% accuracy. For this reason, Precision, Recall, F1-score, and AUPRC are emphasized. Low recall is expected under severe imbalance, especially when relying on purely behavioral (non-content) features. The reported results should be interpreted in that context; a precision of 44.44% represents a massive gain over the ~0.48% random guessing baseline.

Alternative strategies not implemented in this phase include class weighting, cost-sensitive learning, SMOTE, oversampling, and undersampling. These remain future research directions.


---

## 8. Department Filter Calibration Analysis
An adaptive Z-score filter was implemented to suppress false alarms caused by role transitions (e.g. transfers):

$$
Z_D = \frac{BSI(\mathbf{DBS}_{U, W}, \mathbf{DBS}_{D, W}) - \mu_D}{\sigma_D} \ge Z_{\text{thresh}}
$$
*(Formula Image: `results/formulas/z_d.png`)*
![Z_D Suppression Formula](results/formulas/z_d.png)

where $\mathbf{DBS}_{D, W}$ is the centroid of department $D$ and $\mu_D, \sigma_D$ represent the department's baseline cohesion parameters. We swept the Z-score threshold $Z$ (with BSI gate $> 0.85$):

### Table 4: Z-score Suppression Sweep (Test Split)
| Z-score Threshold | Precision | Recall | F1-Score | AUPRC | Suppressed Alerts | Benign Suppressed | Malicious Suppressed |
| :--- | :---: | :---: | :---: | :---: | :---: | :---: | :---: |
| `Z = -3.0` | 0.00% | 0.00% | 0.00% | 0.0484 | 10 | 5 | 5 |
| `Z = -2.5` | 50.00% | 1.22% | 2.38% | 0.0643 | 9 | 5 | 4 |
| `Z = -2.0` | 50.00% | 1.22% | 2.38% | 0.0643 | 9 | 5 | 4 |
| `Z = -1.5` | 66.67% | 2.44% | 4.71% | 0.0798 | 8 | 5 | 3 |
| `Z = -1.0` | 50.00% | 3.66% | 6.82% | 0.0885 | 5 | 3 | 2 |
| `Z = -0.5` | 44.44% | 4.88% | 8.79% | 0.1034 | 2 | 1 | 1 |
| `Z = 0.0` | 40.00% | 4.88% | 8.70% | 0.1017 | 1 | 0 | 1 |

#### Analysis of Suppression Failures:
1. **Centroid Overlap**: Corporate departments share highly uniform schedules and basic email counts in the raw feature space, causing centroids to cluster closely. BSI values are naturally $>0.95$ for all departments.
2. **Aggressive Suppression**: Because BSI values are high and standard deviations ($\sigma_D$) are narrow ($\approx 0.01$), Z-scores satisfy $Z \ge -2.5$ for almost all alerts. This causes the filter to suppress 75% to 100% of malicious weeks, dropping $F_1$ to near zero.
3. **Deployment Setting**: To prevent over-suppression of true threats, the BSI resemblance gate has been set to **`1.0`** (effectively disabling suppression) for active deployment, preserving the raw XGBoost F1-score of `11.68%`.

---

## 9. Threats to Validity

### Internal Validity
* **Feature selection limitations**: Only 8 raw behavioral features were used.
* **Potential modeling assumptions**: Assumes weekly granularity captures meaningful changes.
* **Behavioral baseline assumptions**: Assumes the training period contains purely benign baseline behavior.

### External Validity
* **Evaluation limited to CERT r4.2**: Results may not directly translate to different datasets.
* **Enterprise-specific behavior patterns**: Different organizations have different interaction norms.
* **Generalization concerns**: The model requires fitting normalizers and centroids specific to the deployed environment.

### Construct Validity
* **Whether DBS fully captures human behavior**: Excludes content-based linguistics, file types, and deep network packet inspection.
* **Interpretation of anthropology metrics**: Static metrics aggregate dynamic histories, potentially washing out sudden rapid shifts.

### Statistical Validity
* **Extreme class imbalance**: Only 322 malicious weeks exist out of 67,167 total weeks.
* **Limited malicious samples**: Threat scenarios are simulated rather than organically occurring.
* **Variance across threat scenarios**: Insider behaviors vary drastically (sabotage vs. IP theft vs. fraud).


---

## 10. Future Work

### Short-Term Extensions
* **USB activity features**: Tracking mass storage transfers to detect data exfiltration.
* **File access features**: Analyzing distinct file touches and directory traversal.
* **Workstation diversity**: Monitoring the number of unique PCs accessed.
* **After-hours activity**: Capturing off-shift logins.
* **Weekend behavior metrics**: Tracking non-standard working days.

### Medium-Term Extensions
* **Communication graph analytics**: Enhancing DBS with topological network data.
* **Centrality measures**: Utilizing PageRank and Betweenness Centrality for users.
* **Community detection**: Identifying tightly coupled sub-departments.
* **Adaptive departmental centroids**: Implementing exponential moving averages for seasonal drift.
* **Dynamic organizational profiling**: Modeling the organization as a living entity.

### Long-Term Extensions
* **Real-time monitoring**: Moving from weekly batch processing to streaming architectures.
* **Streaming analytics**: Utilizing Apache Kafka/Flink for live behavioral signatures.
* **Cross-platform telemetry**: Integrating physical badging and cloud application logs.
* **Multi-source behavioral fusion**: Combining host-based, network-based, and identity-based telemetry.
* **AI-assisted analyst explanations**: Using LLMs to translate mathematical drift anomalies into human-readable alerts.


---

## 11. Conclusion
Dynamic Cyber DNA provides a robust, human-centered behavioral profiling layer for continuous authentication. By integrating mathematical anthropology scores and temporal drift tracking, it increases classifier precision on the real-world CERT r4.2 dataset, offering a viable path toward non-intrusive threat mitigation.

---

## Appendix: Project Proposal Context & Details
### PROJECT INTRO
The digital footprints of individuals in corporate networks contain rich behavioral indicators that reflect their cognitive routines, social networks, and role-specific responsibilities. While traditional security layers authenticate users at entry, they fail to continuously verify identity or detect malicious behavioral deviations (insider threats) over time. This project proposes **Cyber DNA**, an active, human-centered framework designed to continuously audit user behavior. It generates a multi-dimensional behavioral signature that acts as a cognitive print, capturing work habits, writing cadences, and social network ties.

### What Cyber DNA actually does?
Cyber DNA ingests raw, disparate log files (logon, email, web, device usage) and processes them into structured weekly intervals. The core framework:
1. **Builds a weekly Digital Behavioral Signature (DBS)**: A normalized vector representing the user's activity levels, communication velocity, and contact network.
2. **Computes self-drift (BDS)**: Measures how far a user's current weekly signature has drifted from their baseline signature.
3. **Assesses cognitive consistency (Cyber Anthropology)**: Calculates user-level scores for transition stability ($IDP$), drift smoothness ($BC$), and interaction footprint variation ($SRC$).
4. **Performs Attribution & Detection**: Feeds these features into a machine learning classifier to identify anomalous, high-risk weeks, and uses an adaptive Departmental Similarity Filter to suppress false alerts caused by legitimate job changes.

### Literature Review
Current literature in user behavior analytics (UBA) and insider threat detection primarily relies on static anomaly detection models (e.g., Isolation Forest, One-Class SVM) trained on raw aggregate statistics (such as total logins or total emails sent). These methods suffer from high false-alarm rates because they ignore the temporal evolution of human behavior and are unable to distinguish between a malicious insider and a benign user undergoing a natural role transition (concept drift). Stylometric techniques (like write-print analysis) offer strong attribution but are computationally expensive and easily bypassed. Cyber DNA resolves these gaps by combining multiple behavioral layers with mathematical formulations derived from Cyber Anthropology to explicitly model behavioral continuity and group cohesion.

### Mathematical Techniques Used in the Cyber DNA Framework
The proposed framework employs a robust set of mathematical operations:
* **Vector Distance**: Euclidean distance ($L_2$ norm) is utilized to compute the Behavioral Drift Score (BDS) over time.
* **Vector Alignment**: Cosine Similarity is utilized to calculate the Behavioral Similarity Index (BSI) between individual profiles and departmental centroids.
* **Exponential Decay Functions**: Employed to model Cyber Anthropology consistency scores ($IDP$, $BC$), mapping unbounded statistical variance to a standardized $[0,1]$ stability scale.
* **Vectorized Processing**: Fully vectorized index shifting is used to compute logon session durations and token set unions are used to calculate vocabulary diversity, scaling the calculations to millions of log events.

### Benchmark Dataset Reference
The dataset selection and reference instructions in your proposal are correct. The CMU CERT Insider Threat Dataset r4.2 is the industry standard for validating insider threat models. 

* **Dataset Source URL**: [Insider Threat Test Dataset (Brian Lindauer)](https://doi.org/10.1184/R1/12841247.v1)
* **File to Ingest**: **`r4.2.tar.bz2`** (~1.5 GB compressed, containing `logon.csv`, `email.csv`, `device.csv`, `file.csv`, and `ldap.csv` representing the 1.5-year corporate cohort).
