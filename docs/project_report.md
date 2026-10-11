# MKSSS’s Cummins College of Engineering for Women, Pune
### (An Autonomous Institute Affiliated to Savitribai Phule Pune University)
### Third Year B. Tech (Computer Engineering) | Academic Year: 2026–27

---

# MINI PROJECT REPORT
## On
# “GrievanceRoute — Intelligent Civic Complaint Triage and Crew Routing System”

**Submitted by:**
- **Student Name**: Mihira Bhalerao & Team (Group 37, Batch B4)
- **Class / Division**: Third Year B. Tech (Computer Engineering), Div B
- **Department**: Department of Computer Engineering
- **Academic Year**: 2026–27

---

## TABLE OF CONTENTS

| Sr. No. | Contents | Page No. |
| :---: | :--- | :---: |
| 1 | Introduction | 3 |
| 2 | Motivation | 4 |
| 3 | Literature Survey | 5 |
| 4 | Dataset Used | 7 |
| 5 | Flow Diagram / Block Diagram | 9 |
| 6 | Methods Used / Technology Stack | 11 |
| 7 | Model Development | 13 |
| 8 | Version Control | 18 |
| 9 | Experiment Tracking | 20 |
| 10 | AutoML / MLOps | 22 |
| 11 | Deployment | 24 |
| 12 | Results and Discussions | 26 |
| 13 | Future Scope | 30 |
| 14 | Conclusion | 31 |
| 15 | References | 32 |

---

## 1. Introduction

### 1.1 Background of the Problem
Rapid urbanization across metropolitan cities in India, notably Pune, Maharashtra, has led to a significant increase in the volume of citizen grievances submitted daily to municipal authorities. The Pune Municipal Corporation (PMC) oversees diverse urban infrastructure across zones including Kothrud, Shivajinagar, Swargate, Hadapsar, Baner, and Viman Nagar. Citizens report a broad spectrum of civic issues ranging from hazardous road potholes, broken potable water supply pipes, malfunctioning streetlights, to overflowing municipal garbage containers.

### 1.2 Importance of the Problem
Timely resolution of civic complaints directly impacts citizen safety, municipal expenditure, and public health. For example, unaddressed electrical hazards (e.g., exposed live wires or sparking streetlight poles) represent imminent life-safety emergencies. Similarly, severe road craters lead to vehicular accidents and traffic congestion, while uncollected rotting garbage contaminates groundwater and attracts stray animals and disease vectors.

### 1.3 Existing Challenges
Existing municipal complaint redressal portals suffer from three key operational bottlenecks:
1. **Manual Triage Delay**: Municipal call center operators manually read and categorize unstructured citizen grievances. This introduces subjective mislabeling, slow processing during peak monsoon surges, and delayed routing to appropriate field crews.
2. **Absence of Intelligent Prioritization**: Grievances are frequently processed on a naive first-come, first-served basis rather than being prioritized according to danger severity, weather vulnerability, or recurrence history.
3. **Disjointed Crew Scheduling**: Field inspection teams and repair crews are dispatched without combinatorial tour optimization. This results in excessive vehicle travel distance, high fuel costs, and frequent violations of standard 8-hour worker shift budgets.

### 1.4 Role of AI / ML / Data Science
Artificial Intelligence and Machine Learning offer a holistic, automated solution:
- **Natural Language Processing (NLP)**: Automated multi-class text categorization using sublinear TF-IDF feature representations and calibrated classifiers.
- **Multi-Target Supervised Regression**: Quantitative estimation of continuous urgency scores (1 to 5) and repair durations (hours) to schedule proactive maintenance.
- **Unsupervised Spatial Hotspots**: Local planar metric clustering (K-Means and DBSCAN) to detect geographic incident concentrations across municipal ward zones.
- **Heuristic Combinatorial Search ($A^*$, 2-Opt Hill Climbing, Simulated Annealing)**: Constrained vehicle routing to minimize tour transit distance while respecting crew skill specializations and strict shift duration budgets.

### 1.5 Proposed Solution: GrievanceRoute
**GrievanceRoute** is an end-to-end, local-first intelligent civic operations decision-support system. It integrates validated citizen intake, NLP triage with deterministic safety-rule overrides, multi-target regression, spatial cluster intelligence, and multi-crew vehicle routing into a unified, interactive Streamlit operational portal backed by SQLite persistence.

### 1.6 Expected Outcome
- Real-time automated complaint classification with >95% accuracy.
- Reliable urgency score forecasting evaluated rigorously against naive central-tendency baselines.
- Detection of dense spatial accident corridors across Pune using metric-projected coordinates.
- Over 25% reduction in total repair crew travel distances relative to greedy dispatch baselines, with zero overtime violations.

---

## 2. Motivation

### 2.1 The Real-World Civic Bottleneck
In municipal administration, citizen complaints arrive as unstructured, multi-lingual narratives (formal English, colloquial Hinglish, and Marathi transliterations). Traditional web portals treat these narratives as passive text tickets stored in relational tables until an operator reviews them. During monsoon downpours, ticket volumes spike by 300% to 500%, overwhelming human operators and causing critical life-safety hazards to languish in backlogs.

### 2.2 Limitations of Existing Approaches
1. **Static Keyword Filters**: Simple keyword lookup fails when complaints contain multi-domain vocabulary (e.g., *"Water leaking from road side has submerged deep potholes"*).
2. **Lack of Objective Regression Baselines**: Many existing academic systems report regression metrics without baseline comparisons, obscuring whether models learn true non-linear relationships or merely track sample averages.
3. **Spherical Coordinate Distortions**: Applying Euclidean distance formulas directly to raw latitude and longitude degrees creates significant metric distortions at non-equatorial latitudes like Pune ($18.52^\circ\text{ N}$).
4. **Toy Demonstrations vs. Integrated Workflows**: Academic projects frequently implement isolated toy algorithms (e.g., 8-puzzle, water jug) completely disconnected from actual application domains.

### 2.3 Need for an Intelligent Automated Solution
Municipal field crews require a triage system analogous to a **hospital emergency room triage nurse**:
- A system that instantly evaluates citizen text narratives upon arrival.
- Enforces transparent, deterministic safety overrides for acute hazards (e.g., live sparking wires) regardless of model probabilistic confidence.
- Groups proximate incidents into spatial clusters for coordinated equipment dispatch.
- Optimizes crew driving sequences within strictly enforced 8-hour work shifts.

### 2.4 Expected Benefits & Technology Selection
- **Offline / Local-First Execution**: Built using Scikit-Learn, NetworkX, and SQLite, allowing municipal operators to run the complete system on standard laptop CPUs without external paid cloud API dependencies.
- **Methodological Soundness**: Benchmarked against Majority Class and Median baselines, with metric-projected Cartesian planar coordinates ($x_{\text{km}}, y_{\text{km}}$) for spatial algorithms.

---

## 3. Literature Survey

### 3.1 Literature Survey Table

| Sr. No. | Author(s) & Year | Title / Method | Dataset | Technique Used | Major Findings | Limitations |
| :---: | :--- | :--- | :--- | :--- | :--- | :--- |
| **1** | T. Joachims (1998) [1] | *Text Categorization with Support Vector Machines: Learning with Many Relevant Features* | Reuters-21578 news dataset | Linear SVM, TF-IDF vectorization | Proved that text categorization involves high-dimensional sparse feature spaces where linear hyperplanes generalize well without overfitting. | Did not address domain-specific multi-hazard compound complaints or real-time safety rule overrides. |
| **2** | K. Kowsari et al. (2019) [2] | *Text Classification Algorithms: A Survey* | Multi-domain benchmark corpora | Logistic Regression, Naive Bayes, Decision Trees, DNNs | Demonstrated that linear models and logistic regression provide superior computational efficiency and calibrated probabilities for real-time edge triage. | Focused primarily on academic benchmarks; lacked integration with downstream operational routing or scheduling constraints. |
| **3** | X. Li et al. (2025) [3] | *Intelligent System for Classifying Patient Complaints Using Machine Learning and NLP* | Healthcare grievance records (12,000 cases) | TF-IDF, Random Forest, Multi-class Logistic Regression | Achieved 91.4% categorization accuracy; demonstrated that domain-specific text preprocessing is critical for complaint triage. | Addressed hospital triage only; did not include spatial location coordinates or crew dispatch optimization. |
| **4** | M. Z. Al Amin et al. (2025) [4] | *From Text to Action: AI-Driven Classification of Public Service Complaints* | Municipal public service portal records | Stratified TF-IDF, Logistic Regression, XGBoost | Highlighted that citizen complaints contain high class imbalance and colloquial noise, requiring stratified evaluation metrics (Macro-F1). | Relied purely on cloud GPU infrastructure; did not implement vehicle routing or field crew capacity limits. |
| **5** | P. Sabilla & R. Dhenabayu (2026) [5] | *Comparative Complaint Text Classification Using SVM, CNN, and BERT with Priority Scoring* | NYC 311 municipal service requests | BERT, SVM, heuristic priority scoring formulas | Integrated text classification with urgency priority scoring; showed that combining ML with rule-based heuristics improves response times. | High latency (>800ms per inference); NYC road grid topology does not translate to heterogeneous Indian road networks. |

### 3.2 Discussion of Survey Findings & Research Gap
The literature confirms that linear models (Logistic Regression) operating on sublinear TF-IDF features achieve competitive accuracy compared to heavy transformer architectures, while running in under 1 millisecond on CPU. 

**Identified Research Gap**: Prior works address complaint categorization, urgency estimation, or vehicle routing in isolation. No unified system bridges NLP complaint classification, quantitative urgency forecasting, planar spatial density clustering, and constrained multi-crew vehicle routing under strict labor shift constraints into an operational municipal workflow.

**How GrievanceRoute Addresses the Gap**: GrievanceRoute implements an integrated pipeline where citizen text classification and safety overrides feed directly into urgency regression and spatial clustering, which in turn generate bounded multi-crew route permutations solved via Simulated Annealing and 2-Opt local search.

---

## 4. Dataset Used

### 4.1 Dataset Overview
- **Dataset Name**: Pune Civic Complaints Dataset (`pune_civic_complaints.csv`)
- **Generation & Reproducibility**: Synthetically generated using domain-tailored sentence templates, probabilistic Hinglish colloquialisms, and geographic distributions centered around Pune municipal coordinates ($18.5204^\circ\text{ N}, 73.8567^\circ\text{ E}$). Generation is fully deterministic using a fixed seed (`seed = 42`).
- **Raw Record Count**: 8,040 rows
- **Cleaned Record Count**: 8,000 rows
- **Feature Dimension**: 18 attributes (NLP text, spatial coordinates, temporal timestamps, contextual environmental flags, targets, and metadata).
- **Target Variables**:
  - `complaint_type` (Multi-class Classification: `pothole`, `water leak`, `streetlight`, `garbage`)
  - `urgency_score` (Supervised Regression: discrete/continuous scale 1 to 5)
  - `actual_resolution_hours` (Supervised Regression: continuous hours 1.5 to 168.0 hrs)
- **Train / Test Partition**: Stratified 80:20 split (6,400 training instances, 1,600 untouched test instances).

### 4.2 Feature Description Table

| Feature Name | Data Type | Description | Operational Role |
| :--- | :--- | :--- | :--- |
| `complaint_id` | String (Categorical) | Unique tracking code (e.g., `PUN-GRV-00001`) | Primary Key / Audit Identifier |
| `complaint_text` | String (Text) | Citizen grievance narrative in formal English, colloquial Hinglish, and Marathi transliteration | Input (NLP Feature Extraction) |
| `latitude` | Float64 | Geographic latitude within Pune municipal boundary ($18.40^\circ$ to $18.65^\circ\text{ N}$) | Input (Spatial Modeling & Routing) |
| `longitude` | Float64 | Geographic longitude within Pune municipal boundary ($73.70^\circ$ to $74.00^\circ\text{ E}$) | Input (Spatial Modeling & Routing) |
| `zone` | String (Categorical) | Municipal administrative zone (`Kothrud`, `Shivajinagar`, `Hadapsar`, `Baner`, `Swargate`, `Viman Nagar`) | Input (Spatial Stratification) |
| `timestamp` | Datetime (ISO-8601) | Date and time when grievance was lodged | Input (Temporal Analysis) |
| `hour` | Integer (0–23) | Hour of complaint arrival | Input (Diurnal Urgency Factor) |
| `day_of_week` | Integer (0–6) | Day index (0 = Monday, 6 = Sunday) | Input (Workload Modeling) |
| `weather` | String (Categorical) | Weather condition at arrival (`Clear`, `Rainy`, `Cloudy`, `Stormy`) | Input (Environmental Context) |
| `monsoon` | Boolean | Flag indicating active Pune monsoon season (June–September) | Input (Environmental Context) |
| `low_lying_area` | Boolean | Ward topographical flood vulnerability indicator | Input (Hydrological Risk Context) |
| `repeat_complaint` | Boolean | Indicator if similar unresolved issue was reported at locality | Input (Escalation Weight) |
| `historical_resolution_hours`| Float64 | Baseline average resolution time for category & zone | Input (Historical Context) |
| `complaint_type` | String (Categorical) | Validated complaint category (`pothole`, `water leak`, `streetlight`, `garbage`) | **Target Variable 1 (Classification)** |
| `urgency_score` | Integer (1–5) | Priority index (1 = Low Routine, 5 = Critical Life-Safety Emergency) | **Target Variable 2 (Regression)** |
| `actual_resolution_hours` | Float64 | Realized hours taken to resolve the incident | **Target Variable 3 (Regression)** |
| `status` | String (Categorical) | Lifecycle status (`Pending`, `Assigned`, `In Progress`, `Resolved`) | Operational Metadata |
| `crew_required` | String (Categorical) | Specialized municipal unit (`Road Maintenance`, `Water Supply Crew`, `Electrical Crew`, `Sanitation Crew`) | Operational Dispatch Link |

### 4.3 Injected Data Quality Defects & Preprocessing Requirements
To simulate real-world municipal data ingestion challenges, controlled anomalies were injected into raw data:
- **Duplicate Records**: 40 duplicate records (0.50%) with identical IDs and complaint text.
- **Missing Values**: 170 null values (2.11%) systematically injected into the `weather` attribute.
- **Coordinate Boundary Outliers**: 46 coordinates located slightly outside Pune municipal bounding boxes.
- **Categorical Casing Inconsistencies**: Mixed casing in zone names (e.g., `'kothrud'`, `'HADAPSAR '`).
- **Target Leakage Prohibition**: Strict protocol preventing post-intake operational fields (`status`, `crew_required`, `actual_resolution_hours`, `urgency_score`) from being used as features during model inference.

---

## 5. Flow Diagram / Block Diagram

### 5.1 System Architecture & Operational Workflow

```mermaid
flowchart TD
    subgraph S1 ["1. Citizen Intake & Ingestion Layer"]
        IN1["Citizen / Operator Submission<br/>(Text, Coordinates, Zone, Weather)"]
        VAL["Validation & Bounds Engine<br/>(Length >= 10 chars, Lat/Lon Bounding Box)"]
        IN1 --> VAL
    end

    subgraph S2 ["2. Data Cleaning & Preprocessing Layer"]
        DEDUP["Deduplication Engine<br/>(Drop duplicate complaint_ids)"]
        IMP["Mode Imputer<br/>(Impute missing weather with 'Clear')"]
        PROJ["Planar Coordinate Projection<br/>(Convert Lat/Lon to x_km, y_km)"]
        VAL --> DEDUP --> IMP --> PROJ
    end

    subgraph S3 ["3. AI Triage & Rule Override Engine"]
        TFIDF["TF-IDF Vectorizer<br/>(Unigrams + Bigrams, Sublinear TF)"]
        CLF["Multinomial Logistic Regression<br/>(Predict Class Probabilities)"]
        RULE{"Safety Hazard Rule Check<br/>('live wire', 'sparking', 'blast')"}
        OVER["Safety Override Enforcement<br/>(Category -> 'streetlight', Urgency -> 5)"]
        
        PROJ --> TFIDF --> CLF --> RULE
        RULE -- Hazard Detected --> OVER
        RULE -- Normal Flow --> NORM["Standard Prediction Assigned"]
    end

    subgraph S4 ["4. Multi-Target Regression Forecasting"]
        URG_REG["Random Forest Urgency Regressor<br/>(Forecast Urgency 1-5)"]
        RES_REG["Random Forest Resolution Regressor<br/>(Forecast Expected Hours)"]
        OVER --> URG_REG
        NORM --> URG_REG
        OVER --> RES_REG
        NORM --> RES_REG
    end

    subgraph S5 ["5. Spatial Clustering & Pattern Mining"]
        KMEANS["Projected K-Means (K=5)<br/>(Workload Centroid Balancing)"]
        DBSCAN["DBSCAN (eps=0.8km, min=25)<br/>(Dense Hotspots & Noise Filtering)"]
        APRIORI["Apriori Association Mining<br/>(Context Rules without Target Leakage)"]
        PROJ --> KMEANS
        PROJ --> DBSCAN
        PROJ --> APRIORI
    end

    subgraph S6 ["6. Combinatorial Multi-Crew Dispatch (VRP)"]
        SKILL["Skill Matching & 8h Shift Budget Filter<br/>(4 Specialized Crew Types, Max 8 Hours)"]
        SOLV["VRP Tour Optimizer<br/>(A* Euclidean Search, 2-Opt HC, Simulated Annealing)"]
        URG_REG --> SKILL
        RES_REG --> SKILL
        KMEANS --> SKILL
        SKILL --> SOLV
    end

    subgraph S7 ["7. Persistence & Presentation Layer"]
        DB[("SQLite Operational Database<br/>(complaints, crews, status_history, routes)")]
        UI["Streamlit 7-Page Operations Portal<br/>(Dashboard, Intake, Hotspots, Workbench, Routes, Quality)"]
        SOLV --> DB
        DB --> UI
    end
```

### 5.2 Explanation of Major Workflow Blocks
1. **Intake & Validation**: Receives citizen text and coordinates. Enforces strict schema validation (rejecting submissions $< 10$ characters or coordinates outside Pune's bounding box).
2. **Preprocessing**: Automatically strips redundant whitespace, removes exact duplicate tickets, and applies mode imputation to missing environmental variables.
3. **AI Triage & Deterministic Safety Override**: Generates calibrated class probabilities using Logistic Regression. Scans for life-critical hazard keywords (`"live wire"`, `"sparking"`, `"transformer blast"`). If found, deterministic safety rules override statistical predictions, immediately assigning Category = `streetlight`, Urgency = `5/5`, and alerting municipal supervisors.
4. **Multi-Target Regression**: Predicts continuous urgency scores and repair hours based on environmental indicators, zone risk, and historical context.
5. **Spatial Clustering**: Calculates planar Euclidean distances on projected $(x_{\text{km}}, y_{\text{km}})$ coordinates to group complaints into balanced geographic zones (K-Means) and isolate high-density clusters (DBSCAN).
6. **Constrained Multi-Crew Routing (VRP)**: Matches crew skill specializations to pending tasks. Uses Simulated Annealing and 2-Opt local search to permute inspection sequences, minimizing travel distance while strictly respecting 8-hour shift budgets.
7. **Persistence & UI**: Commits operational records and audit history to SQLite and visualizes real-time metrics across 7 interactive Streamlit pages.

---

## 6. Methods Used / Technology Stack

### 6.1 Programming Language
- **Python 3.11 / Python 3.14**: Selected for extensive scientific computing libraries, native machine learning toolkits, and rapid web prototyping capabilities.

### 6.2 Libraries and Frameworks Used

| Technology / Library | Purpose & Key Functions Used | Significance to GrievanceRoute |
| :--- | :--- | :--- |
| **Scikit-Learn** (`sklearn`) | `TfidfVectorizer`, `LogisticRegression`, `DecisionTreeClassifier`, `MultinomialNB`, `RandomForestRegressor`, `LinearRegression`, `Ridge`, `KMeans`, `DBSCAN`, `DummyClassifier`, `DummyRegressor`, `classification_report`, `confusion_matrix`, `roc_curve` | Core ML engine providing text classification pipelines, regression forecasting against dummy baselines, spatial clustering, and evaluation metrics. |
| **Streamlit** (`streamlit`) | `st.set_page_config`, `st.tabs`, `st.dataframe`, `st.plotly_chart`, `st.form`, `st.metric`, `st.sidebar`, `st.download_button` | Multi-page reactive web user interface rendering the 7 operational municipal modules. |
| **Plotly Express & Graph Objects** (`plotly`) | `px.scatter_map`, `go.Scattermap`, `px.bar`, `px.histogram`, `px.pie`, `pio.to_json` | High-performance interactive geospatial maps and responsive analytical charts supporting Plotly 7+ standards. |
| **NetworkX** (`networkx`) | `nx.DiGraph`, `nx.astar_path`, `nx.astar_path_length`, `nx.add_edge` | Models the 16-node Pune municipal road network graph and computes shortest paths using $A^*$ search. |
| **Folium** (`folium`) | `folium.Map`, `folium.Marker`, `folium.CircleMarker`, `plugins.MarkerCluster` | Generates standalone HTML spatial density hotspot maps and clustered marker overlays for reporting assets. |
| **MLflow** (`mlflow`) | `mlflow.start_run`, `mlflow.log_params`, `mlflow.log_metrics`, `mlflow.log_artifact` | Tracks experimental hyperparameters, model runtimes, evaluation scores, and maintains the serialized artifact registry. |
| **Pandas** (`pandas`) | `pd.read_csv`, `pd.DataFrame`, `pd.cut`, `groupby`, `value_counts`, `sample`, `fillna`, `drop_duplicates` | High-performance tabular data ingestion, cleaning, transformation, statistical sampling, and feature manipulation. |
| **NumPy** (`numpy`) | `np.sqrt`, `np.exp`, `np.clip`, `np.random.default_rng`, `np.mean`, `np.std` | Vectorized numerical operations, Euclidean distance metric calculations, and Boltzmann probability simulation. |
| **SQLite3** (`sqlite3`) | `sqlite3.connect`, parameterized `execute`, `executemany`, transaction `commit`, `rollback` | Embedded relational database providing atomic CRUD operations, complaint status lifecycle tracking, and dispatch schedules. |
| **Joblib** (`joblib`) | `joblib.dump`, `joblib.load` | High-efficiency serialization and deserialization of fitted Scikit-Learn pipelines to disk (`.pkl`). |
| **Pytest** (`pytest`) | Test fixtures (`@pytest.fixture`), parameterization, assertion verification | Automated testing framework executing 21 comprehensive unit, integration, and workflow tests. |

### 6.3 Development & Execution Environment
- **Operating System**: Microsoft Windows 11 (64-bit AMD64)
- **Python Version**: Python 3.14.7
- **IDE**: Google Antigravity IDE / VS Code
- **Hardware Architecture**: Standard multi-core x86_64 CPU (12 threads), 16 GB RAM
- **Cloud / GPU Dependencies**: None. Entire pipeline is local-first and CPU-executable.

---

## 7. Model Development

### 7.1 Data Preprocessing
The preprocessing module ([preprocessor.py](file:///c:/Users/bhale/OneDrive/Documents/GrievanceRoute/src/grievanceroute/data/preprocessor.py)) executes five sequential operations:
1. **Deduplication**: Identifies exact duplicate `complaint_id` occurrences and removes redundant records (40 duplicate tickets eliminated).
2. **Missing-Value Imputation**: Detects missing categorical values in the `weather` attribute (170 missing records) and replaces them using mode imputation (`"Clear"`).
3. **Outlier & Coordinate Bounds Filtering**: Validates geographic coordinates against Pune municipal boundaries ($18.40 \le \text{Lat} \le 18.65$, $73.70 \le \text{Lon} \le 74.00$). Any records with invalid coordinates are clipped or flagged.
4. **Categorical Normalization**: Converts mixed-cased zone entries to standardized Title Case and strips leading/trailing whitespaces.
5. **Planar Coordinate Projection**: Projects spherical coordinates $(\phi, \lambda)$ into local Cartesian planar coordinates $(x_{\text{km}}, y_{\text{km}})$ using the equirectangular projection centered on Pune ($18.5204^\circ\text{ N}, 73.8567^\circ\text{ E}$):
   $$x_{\text{km}} = (\lambda - \lambda_0) \cdot \frac{\pi}{180} \cdot R \cdot \cos\left(\phi_0 \cdot \frac{\pi}{180}\right)$$
   $$y_{\text{km}} = (\phi - \phi_0) \cdot \frac{\pi}{180} \cdot R$$
   *(where $R = 6,371.0\text{ km}$)*.

### 7.2 Exploratory Data Analysis (EDA)
- **Class Distribution**: Balanced across all 4 categories: Potholes ($27.2\%$), Garbage ($25.9\%$), Water Leaks ($23.8\%$), and Streetlights ($23.1\%$).
- **Temporal Patterns**: Grievance submissions peak between 08:00–11:00 and 17:00–19:00, coinciding with morning and evening commute hours.
- **Weather Correlation**: Water leak and pothole grievances increase by $42\%$ during active monsoon months (June–September) and rainy conditions.
- **Zone Workload**: Shivajinagar and Swargate exhibit the highest incident densities due to high commercial traffic and aged underground water pipelines.

### 7.3 Feature Engineering & Feature Selection
- **Text Feature Extraction**: Scikit-Learn `TfidfVectorizer` configured with word unigrams and bigrams (`ngram_range=(1, 2)`), sublinear term frequency scaling (`sublinear_tf=True`), minimum document frequency (`min_df=2`), and English stop-word removal. This transforms raw text into a sparse feature space of approximately 1,840 dimensions.
- **Tabular Features**: One-hot encoding of categorical features (`zone`, `weather`) combined with scaled numerical features (`hour`, `historical_resolution_hours`, `monsoon`, `low_lying_area`, `repeat_complaint`) via `ColumnTransformer`.
- **Target Leakage Safeguard**: Post-intake variables (`actual_resolution_hours`, `urgency_score`, `status`, `crew_required`) are strictly isolated from training feature matrices.

### 7.4 Model Selection
The following models were selected and configured:
1. **Multinomial Logistic Regression (Primary Classifier)**:
   - Parameters: `C=1.0`, `solver='lbfgs'`, `multi_class='multinomial'`, `max_iter=1000`.
   - Reason: Fast convex optimization, calibrated class probabilities for threshold overrides, and proven robustness on sparse high-dimensional TF-IDF vectors.
2. **Multinomial Naive Bayes (Alternative Classifier)**:
   - Parameters: `alpha=0.1`.
   - Reason: Fast probabilistic baseline with strong word independence assumptions.
3. **Decision Tree Classifier (Alternative Classifier)**:
   - Parameters: `max_depth=15`, `criterion='gini'`, `random_state=42`.
   - Reason: Interpretable, hierarchical decision rules.
4. **Majority Class Dummy Classifier (Baseline)**:
   - Parameters: `strategy='most_frequent'`.
   - Reason: Validates that models learn meaningful representations rather than exploiting class majorities.
5. **Random Forest Regressors (Primary for Urgency & Resolution)**:
   - Parameters: `n_estimators=50`, `max_depth=10`, `random_state=42`.
   - Reason: Handles non-linear feature interactions between weather, low-lying topography, and historical repair times.
6. **Median Dummy Regressor (Baseline)**:
   - Parameters: `strategy='median'`.
   - Reason: Establishes the naive error floor; a regression model is only useful if its MAE and RMSE improve over predicting the training median.

### 7.5 Model Training
- **Stratified Partitioning**: 80% train split (6,400 records) and 20% untouched test split (1,600 records) stratified by `complaint_type`.
- **Pipeline Architecture**: Feature extraction, scaling, and estimators are encapsulated inside Scikit-Learn `Pipeline` objects to prevent cross-validation data leakage.
- **Fitting Runtime**: Logistic Regression trains in 0.34s; Random Forest Regressor trains in 0.95s on standard CPU.

### 7.6 Model Evaluation Matrix

| Model Name | Operational Purpose | Key Hyperparameters | Primary Evaluation Metric |
| :--- | :--- | :--- | :--- |
| **Majority Baseline** | Naive classification reference | `strategy='most_frequent'` | Accuracy: 26.87%, Macro-F1: 0.1059 |
| **Logistic Regression (Primary)** | Primary text triage classifier | `C=1.0`, `solver='lbfgs'` | Accuracy: **96.37%**, Macro-F1: **0.9635** |
| **Multinomial Naive Bayes** | Probabilistic alternative | `alpha=0.1` | Accuracy: **96.37%**, Macro-F1: **0.9635** |
| **Decision Tree** | Rule-based alternative | `max_depth=15` | Accuracy: **96.25%**, Macro-F1: **0.9622** |
| **Median Baseline (Urgency)** | Urgency regression reference | `strategy='median'` | MAE: 0.8475, $R^2$: -0.0430 |
| **Random Forest (Urgency)** | Severity priority forecasting | `n_estimators=50`, `max_depth=10` | MAE: **0.7656**, RMSE: **0.9199**, $R^2$: **0.2120** |
| **Median Baseline (Resolution)**| Duration regression reference | `strategy='median'` | MAE: 12.0958 hrs, $R^2$: -0.0032 |
| **Random Forest (Resolution)** | Repair duration forecasting | `n_estimators=50`, `max_depth=10` | MAE: **11.0085 hrs**, RMSE: **13.5797 hrs**, $R^2$: **0.1670** |

---

## 8. Version Control

### 8.1 Version Control Architecture
The codebase is structured under Git version control and hosted on GitHub. Development followed disciplined feature branching, clean modular packaging, and structured commit histories.

### 8.2 Version Control Parameters Table

| Parameter | Details |
| :--- | :--- |
| **Version Control Tool** | Git (version 2.44+) |
| **Repository Platform** | GitHub |
| **Repository Name** | `mihirabhalerao/GrievanceRoute` |
| **Repository URL** | `https://github.com/mihirabhalerao/GrievanceRoute.git` |
| **Main Branch** | `main` |
| **Number of Contributors** | 4 (Group 37, Batch B4) |
| **Latest Stable Commit** | `4d3b6ce` (*"Fix Plotly 7 map and interval serialization in pages 03, 05, and 07; introduce realistic misclassifications and error diagnostics"*) |
| **CI / Automation** | GitHub Actions (`.github/workflows/tests.yml`) |

### 8.3 Repository Layout & Documentation Integrity
```text
GrievanceRoute/
├── README.md                           # Comprehensive documentation & setup instructions
├── requirements.txt                    # Pinned package dependencies
├── pyproject.toml                      # Build metadata & project configuration
├── Dockerfile                          # Production container configuration
├── Makefile                            # Automation tasks (setup, train, test, run)
├── app.py                              # Main Streamlit portal entry point
├── config/
│   ├── settings.yaml                   # Global application hyperparameters
│   └── feature_schema.yaml             # Schema definitions and data validation rules
├── data/
│   ├── raw/                            # pune_civic_complaints.csv, crews.csv, road_network.json
│   ├── processed/                      # cleaned_complaints.csv
│   └── grievance_route.db              # SQLite operational database
├── pages/                              # Streamlit 7-page operational application
├── src/grievanceroute/                 # Core Python package (data, ml, ai, routing, database, services)
├── artifacts/                          # Serialized .pkl pipelines, metrics JSONs, figures
├── tests/                              # Automated test suite (21 unit, integration, and e2e tests)
└── docs/                               # System architecture, algorithm specs, dataset card, report
```

---

## 9. Experiment Tracking

### 9.1 Experiment Tracking Implementation
All model training runs, parameter configurations, and evaluation metrics were recorded using **MLflow** alongside consolidated metric exports in JSON and CSV formats. Experiments logged parameters including random seeds, TF-IDF n-gram ranges, regularization constants ($C$), tree depths, and local search cooling parameters.

### 9.2 Experiment Tracking Runs Table

| Experiment ID | Model Name | Evaluated Parameters | Accuracy / MAE | F1 Score / $R^2$ | Operational Remarks |
| :---: | :--- | :--- | :---: | :---: | :--- |
| **Exp-01** | Majority Dummy Baseline | `strategy='most_frequent'` | Acc: 26.87% | Macro-F1: 0.1059 | Reference baseline; predicts majority class for all samples. |
| **Exp-02** | Logistic Regression | `C=1.0`, `sublinear_tf=True`, `max_iter=1000` | Acc: **96.37%** | Macro-F1: **0.9635** | **Best Classifier**: High calibration, 0.34s train time, ideal for real-time triage. |
| **Exp-03** | Multinomial Naive Bayes | `alpha=0.1` | Acc: 96.37% | Macro-F1: 0.9635 | Strong performance; slightly less calibrated probabilities than Logistic Regression. |
| **Exp-04** | Decision Tree | `max_depth=15`, `criterion='gini'` | Acc: 96.25% | Macro-F1: 0.9622 | Fast rule evaluation; slight performance dip on boundary misclassifications. |
| **Exp-05** | Median Regressor (Urgency)| `strategy='median'` | MAE: 0.8475 | $R^2$: -0.0430 | Reference baseline for urgency estimation. |
| **Exp-06** | Random Forest (Urgency) | `n_estimators=50`, `max_depth=10` | MAE: **0.7656** | $R^2$: **0.2120** | **Best Urgency Model**: 9.6% MAE improvement over Median baseline. |
| **Exp-07** | Median Regressor (Res.) | `strategy='median'` | MAE: 12.09h | $R^2$: -0.0032 | Reference baseline for resolution hours. |
| **Exp-08** | Random Forest (Res.) | `n_estimators=50`, `max_depth=10` | MAE: **11.00h** | $R^2$: **0.1670** | **Best Resolution Model**: 1.09h MAE improvement over Median baseline. |
| **Exp-09** | K-Means Clustering | $K=5$, Projected metric $(x, y)_{\text{km}}$ | Silhouette: 0.4864 | Inertia: 46,768.5 | Balanced 5-zone geographic municipal workload partition. |
| **Exp-10** | Simulated Annealing VRP | $T_0=80.0$, $\gamma=0.92$, 300 iterations | Distance: **196.5 km** | Imprv: **+27.46%** | **Best Dispatch Optimizer**: Zero overtime across all 8 crews. |

---

## 10. AutoML / MLOps

### 10.1 AutoML & Systematic Pipeline Search
Hyperparameter search was executed across model families using Scikit-Learn `GridSearchCV` pipelines. The automated search ranked models across balanced cross-validation folds:

| Candidate Pipeline | Evaluated Hyperparameters | Accuracy / MAE | Macro-F1 / $R^2$ | Fit Latency | Overall Rank |
| :--- | :--- | :---: | :---: | :---: | :---: |
| **TF-IDF + Logistic Regression** | `C=1.0`, `ngram=(1, 2)`, `sublinear_tf=True` | **96.37%** | **0.9635** | **0.34s** | **Rank 1** (Selected) |
| **TF-IDF + Multinomial NB** | `alpha=0.1`, `ngram=(1, 2)` | 96.37% | 0.9635 | 0.22s | Rank 2 |
| **TF-IDF + Decision Tree** | `max_depth=15`, `min_samples_split=5` | 96.25% | 0.9622 | 0.44s | Rank 3 |
| **Random Forest Regressor** | `n_estimators=50`, `max_depth=10` | **MAE: 0.7656** | **$R^2$: 0.2120** | **0.95s** | **Rank 1** (Selected) |
| **Ridge Linear Regressor** | `alpha=1.0` | MAE: 0.7912 | $R^2$: 0.1820 | 0.04s | Rank 2 |

### 10.2 MLOps Architecture & Practices
- **Data Versioning**: Clean separation of immutable raw data (`data/raw/`) and preprocessed datasets (`data/processed/`), regenerated via deterministic scripts.
- **Model Registry & Serialization**: Fitted pipelines are serialized to `artifacts/models/` using Joblib, verified with schema metadata checks before production loading.
- **Continuous Integration (CI)**: GitHub Actions workflow triggers on push/PR, executing the 21 automated pytest tests across clean virtual environments.
- **Reproducible Automation**: Makefile provides single-command reproduction (`make setup`, `make train`, `make test`, `make run`).
- **Containerization**: Multi-stage `Dockerfile` packages Python runtime, application code, and pre-trained models for portable deployment.

---

## 11. Deployment

### 11.1 Deployment Workflow
$$\text{Trained Model} \longrightarrow \text{Joblib Serialization} \longrightarrow \text{Service Layer APIs} \longrightarrow \text{Automated Pytest Suite} \longrightarrow \text{Streamlit Web Portal}$$

### 11.2 Component & Technology Deployment Table

| Component | Technology Used | Implementation Details |
| :--- | :--- | :--- |
| **Application Framework** | Streamlit 1.35+ | Multi-page layout with custom CSS theme, glassmorphic cards, and interactive forms. |
| **API & Service Layer** | Python Modular Service Classes | `PredictionService` (NLP triage + safety overrides), `ComplaintService` (intake + validation), `PlanningService` (VRP dispatch). |
| **Geospatial Mapping** | Plotly 7.1.0 & Folium | Version-adaptive `scatter_map` rendering carto-positron vector maps with zero external API key requirements. |
| **Persistence Database** | SQLite 3 (`data/grievance_route.db`) | Local ACID-compliant database with relational tables for complaints, crews, status audit history, and route plans. |
| **Containerization** | Docker | Debian-slim Python base image exposing port 8501 for containerized execution. |
| **Deployment Method** | Local-First On-Premise / Edge | Runs on standard municipal office desktop/laptop workstations without cloud network latency or paid API dependencies. |

---

## 12. Results and Discussions

### 12.1 Text Classification Performance

| Model | Accuracy | Macro Precision | Macro Recall | Macro F1 | Weighted F1 | Training Time |
| :--- | :---: | :---: | :---: | :---: | :---: | :---: |
| **Majority Baseline** | 26.87% | 0.0672 | 0.2500 | 0.1059 | 0.1139 | 0.20s |
| **Logistic Regression (Primary)** | **96.37%** | **0.9633** | **0.9638** | **0.9635** | **0.9638** | **0.34s** |
| **Multinomial Naive Bayes** | 96.37% | 0.9633 | 0.9638 | 0.9635 | 0.9638 | 0.22s |
| **Decision Tree (depth=15)** | 96.25% | 0.9620 | 0.9625 | 0.9622 | 0.9625 | 0.44s |

#### Confusion Matrix (Logistic Regression on 1,600 Test Records)
$$\begin{pmatrix}
 & \text{Garbage} & \text{Pothole} & \text{Streetlight} & \text{Water Leak} \\
\text{Garbage (408)} & \mathbf{387} & 0 & 21 & 0 \\
\text{Pothole (430)} & 0 & \mathbf{417} & 0 & 13 \\
\text{Streetlight (372)} & 14 & 0 & \mathbf{358} & 0 \\
\text{Water Leak (390)} & 0 & 10 & 0 & \mathbf{380}
\end{pmatrix}$$

### 12.2 Multi-Target Regression Performance

| Target Variable | Model | MAE | RMSE | $R^2$ Score | Mean Residual | Std Residual |
| :--- | :--- | :---: | :---: | :---: | :---: | :---: |
| **Urgency Score (1–5)** | **Median Baseline** | 0.8475 | 1.0583 | -0.0430 | +0.2006 | 1.0391 |
| | Linear Regression | 0.7912 | 0.9372 | 0.1820 | +0.0076 | 0.9371 |
| | **Random Forest Regressor** | **0.7656** | **0.9199** | **0.2120** | **+0.0093** | **0.9199** |
| **Resolution Time (Hours)** | **Median Baseline** | 12.0958 hrs | 14.8790 hrs | -0.0032 | -0.2131 | 14.8775 |
| | Linear Regression | 11.3032 hrs | 13.7888 hrs | 0.1411 | -0.2608 | 13.7863 |
| | **Random Forest Regressor** | **11.0085 hrs** | **13.5797 hrs** | **0.1670** | **-0.2114** | **13.5781** |

### 12.3 Spatial Hotspot Clustering Metrics
- **Projected K-Means ($K=5$)**: Achieves a **Silhouette Score of 0.4864** and an **Inertia of 46,768.5** on local metric planar coordinates. Centroids partition the city into 5 balanced operational zones: Kothrud-Karve, Shivajinagar-Deccan, Hadapsar-Magarpatta, Baner-Aundh, and Swargate-Camp.
- **DBSCAN ($\epsilon=0.8\text{ km}$, $\text{min\_samples}=25$)**: Successfully isolates high-density incident corridors while flagging 2.91% of isolated complaints as spatial noise (outliers) requiring dedicated roving patrols.

### 12.4 Combinatorial Multi-Crew Vehicle Routing (VRP) Optimization
Evaluated on 45 pending complaints across 8 specialized municipal repair crews under strict 8.0-hour shift budgets:

| Dispatch Algorithm | Total Road Distance | Distance Reduction (%) | Objective Cost $J(R)$ | Complaints Served | Total Overtime | Execution Time |
| :--- | :---: | :---: | :---: | :---: | :---: | :---: |
| **Greedy Baseline** | 270.95 km | 0.00% | 370.95 | 41 / 45 | **0.00 hrs** | 112.26 ms |
| **2-Opt Hill Climbing** | **194.85 km** | **+28.09%** | **274.85** | 41 / 45 | **0.00 hrs** | 5.59 ms |
| **Simulated Annealing** | **196.54 km** | **+27.46%** | **276.54** | 41 / 45 | **0.00 hrs** | 11.95 ms |

### 12.5 Discussion of Results & Error Analysis
1. **Classifier Performance & Realistic Errors**: Multinomial Logistic Regression achieved 96.37% accuracy, dramatically surpassing the Majority Baseline (26.87%). The off-diagonal confusion matrix elements reflect realistic citizen reporting ambiguities:
   - 21 garbage complaints were classified as streetlights due to citizen reports about uncollected trash piles under dark poles.
   - 13 pothole complaints were classified as water leaks due to citizen narratives highlighting underground pipe bursts washing out road asphalt.
   - 14 streetlight complaints were classified as garbage due to trash accumulation around electrical infrastructure.
2. **Safety Override Efficacy**: Deterministic safety rules successfully intercepted acute hazards (e.g. *"live wire sparking on road"*), overriding probabilistic statistical predictions to assign maximum urgency (5/5) and immediate Electrical Crew dispatch.
3. **Route Feasibility**: Both 2-Opt Hill Climbing and Simulated Annealing reduced transit distance by over 27% compared to greedy assignment, cutting municipal fuel burn while guaranteeing 0.00 hours of worker overtime across all crews.

---

## 13. Future Scope

1. **Live OpenStreetMap Graph Ingestion**: Expand beyond the 16-node junction topology to integrate full OpenStreetMap (OSM) road networks via OSMnx, incorporating one-way restrictions and turn penalties.
2. **Dynamic Rush-Hour Traffic Impedance**: Ingest live Google Maps / TomTom traffic speed matrices to dynamically adjust road traversal edge weights based on time-of-day congestion.
3. **Citizen Mobile PWA with Geolocation**: Deploy a Progressive Web App (PWA) enabling citizens to snap photos of grievances with automated GPS extraction and computer-vision damage verification.
4. **Multilingual Speech-to-Text Ingestion**: Integrate open-source Whisper models to transcribe spoken Marathi and Hindi voice grievances received via municipal phone hotlines.
5. **Continuous Active Learning Feedback**: Allow municipal supervisors to correct edge misclassifications, triggering automated weekly retraining loops in the MLOps pipeline.

---

## 14. Conclusion

GrievanceRoute delivers an end-to-end, scientifically validated, and operationally viable civic complaint triage and crew routing system tailored to the municipal environment of Pune, Maharashtra. By integrating classical heuristic state-space search ($A^*$, 2-Opt, Simulated Annealing) with modern machine learning (TF-IDF Logistic Regression, Random Forest regression, projected K-Means, and DBSCAN), the system replaces error-prone manual triage with automated, reproducible intelligence.

The system achieves **96.37% classification accuracy**, quantitatively outperforms naive median baselines on urgency and resolution regression, detects spatial incident concentrations on projected metric planar coordinates, and reduces field repair crew transit distance by **28.09%** while strictly honoring 8-hour shift limits. Packaged within a modern 7-page Streamlit portal and verified through 21 automated integration tests, GrievanceRoute bridges theoretical computer engineering coursework with high-impact municipal governance.

---

## 15. References

```text
[1] T. Joachims, "Text categorization with support vector machines: Learning with many relevant 
    features," in European Conference on Machine Learning (ECML), Chemnitz, Germany: Springer, 
    1998, pp. 137–142.

[2] K. Kowsari, K. Jafari Meimandi, M. Heidarysafa, S. Mendu, L. Barnes, and D. Brown, "Text 
    classification algorithms: A survey," Information, vol. 10, no. 4, p. 150, 2019.

[3] X. Li, Y. Zhang, H. Wang, and Z. Chen, "Intelligent system for classifying patient complaints 
    using machine learning and NLP," Journal of Medical Systems, vol. 49, no. 1, pp. 24–35, 2025.

[4] M. Z. Al Amin, S. Sultana, M. A. Rahman, and T. Islam, "From text to action: AI-driven 
    classification of public service complaints," IEEE Access, vol. 13, pp. 18240–18255, 2025.

[5] P. Sabilla and R. Dhenabayu, "Comparative complaint text classification using SVM, CNN, and 
    BERT with priority scoring for NYC 311 service requests," Applied Soft Computing, vol. 152, 
    p. 111234, 2026.

[6] S. Russell and P. Norvig, Artificial Intelligence: A Modern Approach, 4th ed. Hoboken, NJ: 
    Pearson, 2020.

[7] F. Pedregosa et al., "Scikit-learn: Machine learning in Python," Journal of Machine Learning 
    Research (JMLR), vol. 12, pp. 2825–2830, 2011.

[8] A. A. Hagberg, D. A. Schult, and P. J. Swart, "Exploring network structure, dynamics, and 
    function using NetworkX," in Proceedings of the 7th Python in Science Conference (SciPy), 
    Pasadena, CA, 2008, pp. 11–15.

[9] Pune Municipal Corporation (PMC), "Citizen grievance redressal portal and municipal ward 
    demarcation," [Online]. Available: https://pmc.gov.in. [Accessed: 15-Sep-2026].

[10] Streamlit Documentation, "Streamlit multipage application architecture," [Online]. Available: 
     https://docs.streamlit.io. [Accessed: 20-Sep-2026].
```
