# review_paper — test_idea

> Phase: `invention_loop` · round 1 · `review_paper`
> Run: `run_txhWJXyNIa5t` — Typological Predictors of Dependency Distance Distribution Shapes in Universal Dependencies
>
> Full, verbatim record of every prompt the AI Inventor pipeline gave this agent — system-user, human-user and skill-input — in the order they landed. Nothing truncated.

## Task: `review_paper` (sdk_openhands_agent)

### [1] SYSTEM-USER prompt · 2026-07-20 01:24:19 UTC

````
<role>
You are a very experienced and critical conference reviewer specialized in the domain of the work under review.
You have reviewed for top-tier venues in the relevant field. Your reviews are known for
being thorough, fair, and grounded in the actual state of the field.
</role>

<paper>
# Introduction

Dependency Distance Minimization (DDM) is a fundamental principle of human language, positing that speakers prefer short syntactic dependencies to reduce working memory load during processing [1]. This principle has been demonstrated as a cross-linguistic universal across 37 languages [1] and subsequently confirmed in larger-scale studies [2, 3]. However, the vast majority of prior work characterizes DDM exclusively through mean dependency distance (MDD), ignoring the rich distributional information encoded in the full dependency distance (DD) distribution shape.

The distribution of dependency distances is not merely a reflection of central tendency. Prior work has shown that DD distributions follow a Right Truncated Modified Zipf-Alekseev distribution [4, 5], with shape parameters that encode distinct aspects of syntactic complexity. Parameter $a$ increases with syntactic complexity (indicating more long-distance dependencies), while parameter $b$ decreases with syntactic complexity (indicating sharper decay toward short dependencies) [5]. These parameters capture structural properties that mean DD alone cannot reveal.

Meanwhile, the interaction between typology and DD distributions remains understudied. While Futrell et al. [1] established DDM as universal across 37 languages, and Gerdes et al. [2] recently showed functional vs. lexical distinctions across 122 languages, nobody has systematically linked WALS (World Atlas of Language Structures) typological features [6] to DD distribution shape parameters using mixed-effects models across the full UD collection. Such a study would: (1) reveal whether typological constraints operate on distribution shape or only on central tendency; (2) quantify the spoken-vs-written DD difference with appropriate statistical controls; and (3) identify 'outlier' families that deviate from DDM, providing targets for deeper typological investigation.

This study addresses these gaps by analyzing dependency distances computed from all 350+ treebanks in the Universal Dependencies (UD) project [7] available via the commul/universal_dependencies dataset on HuggingFace. Our contributions are:

1. **Typological predictors of DD distribution shapes**: We fit probability distributions to DD data from 116 UD treebanks mapped to WALS features and show that word order type (SOV vs. SVO), morphological fusion, and case marking significantly predict distribution shape parameters in mixed-effects models (R² = 0.147 beyond null model).

2. **Spoken vs. written genre effects**: We provide the first large-scale quantitative comparison of DD distributions across spoken and written genres in UD, showing that spoken language exhibits systematically heavier tails (more long-range dependencies) than written language (β = -0.580, p < 0.001), even after controlling for sentence length and language family.

3. **Family-level outliers**: We identify three language families (Uralic, Dravidian, Austroasiatic) that deviate significantly from the universal DDM pattern, with effect sizes > 2 SE, and show these deviations correlate with specific typological constraints (e.g., rich case systems in Dravidian languages).

[FIGURE:fig1]

# Related Work

## Dependency Distance Minimization

The study of dependency distance in natural language was formalized by Hudson [8] and later established as a processing principle by Gibson [9]. Futrell et al. [1] provided the first large-scale evidence of DDM across 37 languages, showing that mean dependency distance is consistently low across diverse language families. This finding has been replicated in numerous subsequent studies [2, 3, 10].

However, most prior work reports only mean DD (MDD) as the summary statistic. Liu et al. [5] and Popescu et al. [4] showed that DD distributions follow the Right Truncated Modified Zipf-Alekseev distribution, with shape parameters $a$ and $b$ that encode syntactic complexity. To date, no study has systematically linked these shape parameters to typological features using mixed-effects models.

## Typological Correlates of Syntax

Quantitative typology has increasingly adopted mixed-effects models to control for phylogenetic non-independence [11, 12]. Baayen et al. [13] established the standard for crossed random effects with subjects and items, which has been adapted for typological data with language family and treebank as grouping factors [14]. Levshina [14] provides a comprehensive guide to using mixed-effects models in quantitative typology with WALS features as predictors.

Niu et al. [3] compared DD minimization across four languages (Chinese, Japanese, English, Czech), finding a trade-off between syntactic and morphological complexity. However, Niu et al. analyzed only four languages and did not use WALS features as quantitative predictors in mixed-effects models. Gerdes et al. [2] analyzed 122 languages in UD/SUD, finding functional dependencies are universally short while lexical dependencies vary by typology. Gerdes et al. did not, however, fit distribution shapes or compare spoken vs. written genres.

## Genre Effects on Syntax

Dobrovoljc [15] provides the most comprehensive comparison of speech and writing to date, analyzing syntactic structure inventories in English and Slovenian treebanks. Dobrovoljc found that spoken corpora contain fewer and less diverse syntactic structures than written counterparts, with limited overlap between modalities. Dobrovoljc [16] also catalogs 12 spoken UD treebanks, providing a resource for cross-modal comparison.

Wang and Liu [17] found significant genre effects on dependency distance and direction, though their study did not specifically contrast speech vs. writing. No prior work has systematically compared DD distributions across spoken and written genres while controlling for sentence length and typological features.

# Methods

## Data

### Universal Dependencies Treebanks

We analyzed all 350+ treebanks from the commul/universal_dependencies dataset on HuggingFace [7], comprising 193 languages. For each non-root dependency in every sentence, we computed the dependency distance as the absolute difference between head and dependent positions. This yielded 979,098 dependency observations after filtering.

Treebanks were categorized by genre based on their names and metadata: (1) spoken (e.g., fr_rhapsodie, en_childes, sl_sst); (2) written formal (e.g., news, wiki treebanks); and (3) written informal (e.g., reddit, social media) [ARTIFACT:art_sbnX8nlSAUFX].

### WALS Feature Mapping

We mapped UD treebank languages to WALS typological features [6] using ISO 639-3 code matching. Five WALS features were selected based on their theoretical relevance to dependency distance:

- **1A**: Order of Subject, Object, and Verb (word order type: SVO, SOV, VSO, etc.)
- **20A**: Fusion of Inflectional Morphology (isolating, agglutinative, fusional)
- **26A**: Exponence of Selected Inflectional Categories (minimal, moderate)
- **49A**: Number of Cases (0, 2, 3-5, 6-8, 9+)
- **51A**: Locus of Marking in the Clause (none, prefixing, suffixing)

The mapping achieved 84.5% high-confidence mappings via ISO 639-3 code matching, covering 116 UD treebanks [ARTIFACT:art_JLcGgqg6OO_T]. For each treebank, we extracted the WALS feature values for its language.

## Distribution Fitting

Following Liu et al. [5] and Popescu et al. [4], we fit the Right Truncated Modified Zipf-Alekseev (ZA) distribution to each treebank's DD distribution. The ZA distribution has probability mass function:

$$P_x = P_1 \cdot x^{-(a + b\ln x)}, \quad x = 1, 2, 3, \ldots, n$$

where $P_x$ is the probability of dependency distance $x$, $P_1$ is the normalization constant, $a$ and $b$ are shape parameters, and $n$ is the maximum observed dependency distance (truncation point).

Parameters were estimated via Maximum Likelihood Estimation (MLE) using scipy.optimize in Python. For each treebank with sufficient data (>1000 dependencies), we extracted shape parameters $a$ and $b$ as dependent variables for subsequent mixed-effects modeling [ARTIFACT:art_FomYM_VOxLXl].

## Mixed-Effects Models

To test whether WALS features predict DD distribution shape parameters, we fit linear mixed-effects models (LMMs) using the pymer4 package (Python wrapper for R's lme4) [18]. The model specification follows the recommendations of Baayen et al. [13] and Levshina [14] for typological data:

$$\text{shape\_param}_{ij} = \beta_0 + \beta_1 \text{WALS}_{ij} + u_i + v_j + \epsilon_{ij}$$

where:
- $\text{shape\_param}_{ij}$ is the distribution shape parameter (e.g., parameter $a$) for treebank $i$ in language family $j$
- $\text{WALS}_{ij}$ is the WALS feature value (coded as dummy variables)
- $u_i \sim N(0, \sigma^2_{treebank})$ is the random intercept for treebank
- $v_j \sim N(0, \sigma^2_{family})$ is the random intercept for language family
- $\epsilon_{ij} \sim N(0, \sigma^2)$ is the residual error

We fit separate models for each WALS feature and each shape parameter. Fixed effects were coded using dummy variables with the most frequent value as baseline. Random effects were specified as crossed intercepts for treebank and language family, allowing for non-independence of observations from the same treebank and family.

To compare spoken vs. written genres, we added genre as a fixed effect to the model:

$$\text{DD}_{ijk} = \beta_0 + \beta_1 \text{genre}_{ijk} + \beta_2 \text{sentence\_length}_{ijk} + u_i + v_j + \epsilon_{ijk}$$

where $\text{DD}_{ijk}$ is the dependency distance for dependency $k$ in treebank $i$ and family $j$. This model controls for sentence length, which is a known confound in DD studies.

## Outlier Detection

Language families with large random effect magnitudes were identified as outliers if $|u_i| > 2\sigma_{family}$. We then investigated these families qualitatively to identify specific typological features that might explain their deviation from the universal DDM pattern.

# Results

## Dataset Statistics

Our dataset comprises 979,098 dependency observations from 193 languages across 350 UD treebanks. Of these, 652,757 observations (66.7%) have complete WALS feature mappings. The dataset covers 14 language families, with the largest families being Indo-European (58.2% of observations), Uralic (12.4%), and Dravidian (8.7%).

Genre distribution: 110,208 observations (11.3%) from written formal treebanks, 6,239 (0.6%) from spoken treebanks, 153 (0.02%) from written informal treebanks, and 862,498 (88.1%) from treebanks with unknown genre.

[FIGURE:fig2]

## WALS Features Predict DD Distribution Shapes

Mixed-effects models show that WALS word order features significantly predict dependency distance distribution shape parameters. Table 1 presents the fixed effects estimates for the model predicting mean DD from WALS feature 1A (word order type).

**Word order effects**: SOV languages show significantly longer mean dependency distances than SVO languages (β = 0.084, SE = 0.012, p < 0.001, 95% CI [0.061, 0.107]). VSO languages show even longer distances (β = 0.246, SE = 0.031, p < 0.001). These effects remain significant after controlling for language family and treebank random effects.

**Morphological complexity**: Agglutinative languages show shorter mean DDs than fusional languages (β = -0.359, SE = 0.018, p < 0.001), while isolating languages show intermediate values (β = -0.077, SE = 0.021, p < 0.001).

**Model fit**: The full model with WALS predictors explains 14.7% additional variance beyond the null model (R² = 0.147, likelihood ratio test χ²(5) = 1247.3, p < 0.001).

[FIGURE:fig3]

## Spoken vs. Written Genre Effects

Spoken genres exhibit systematically different DD distribution shapes than written genres. After controlling for sentence length and language family:

- Spoken treebanks have 17.3% shorter mean dependency distances than written formal treebanks (β = -0.580, SE = 0.042, p < 0.001, 95% CI [-0.662, -0.498])
- The effect size corresponds to a reduction of 0.58 words in mean DD for spoken vs. written
- Written informal treebanks show the shortest DDs (β = -1.140, SE = 0.089, p < 0.001 vs. written formal)

Figure 3 shows the distribution of dependency distances by genre. Spoken language shows a sharper initial decay (higher probability of DD=1) but also a heavier tail (more long-range dependencies at DD > 10). This apparent contradiction is resolved by noting that spoken sentences are shorter on average (mean length = 8.2 words) than written sentences (mean length = 12.7 words), leading to fewer opportunities for long dependencies.

When controlling for sentence length in the mixed-effects model, the genre effect remains significant (β_genre = -0.412, SE = 0.038, p < 0.001), confirming that the spoken-written difference is not solely due to sentence length differences.

## Family-Level Outliers

Three language families showed significant deviations (|random effect| > 2 SE) from the universal DDM pattern:

1. **Uralic** (effect = +0.123, SE = 0.041, z = 3.00): Uralic languages show 12.3% longer mean DDs than the Indo-European baseline. This deviation correlates with rich case marking (WALS 49A: 6-8 cases in Finnish, Estonian) and SOV word order in most Uralic languages.

2. **Dravidian** (effect = +0.098, SE = 0.038, z = 2.58): Dravidian languages show 9.8% longer mean DDs, correlating with rich agglutinative morphology (WALS 20A) and SOV word order.

3. **Austroasiatic** (effect = -0.087, SE = 0.035, z = -2.49): Austroasiatic languages show 8.7% shorter mean DDs, correlating with isolating morphology (WALS 20A: isolating) and SVO word order.

These findings demonstrate that specific typological constraints (case marking, word order, morphological type) can override the universal DDM tendency in systematic ways.

# Discussion

## Typological Constraints on DD Distributions

Our findings demonstrate that typological features—particularly word order type and morphological complexity—systematically predict dependency distance distribution shapes across 193 languages. This extends prior work on DDM in three key ways:

1. **Beyond mean DD**: We show that typological constraints operate on distribution shape parameters (not only on central tendency), confirming that the full DD distribution carries linguistically meaningful information beyond the mean.

2. **WALS features as predictors**: Using mixed-effects models with WALS features as fixed effects, we quantify the magnitude of typological effects. SOV languages show 0.85% longer mean DDs than SVO languages (β = 0.030, SE = 0.012, p < 0.001), a small but statistically significant effect (Cohen's d = 0.006) that is robust across language families.

3. **Distribution shape interpretation**: The ZA distribution parameters $a$ and $b$ show distinct patterns: SOV languages have higher $a$ (more long-distance dependencies) and lower $b$ (slower decay), consistent with the theoretical prediction that head-final languages permit longer dependencies due to right-branching structures.

## Spoken vs. Written Modality

The finding that spoken language exhibits systematically different DD distributions than written language is consistent with Dobrovoljc's [15] observation that spoken language has fewer and less diverse syntactic structures. However, our finding of heavier tails (more long-range dependencies) in spoken language appears contradictory to the processing motivation for DDM.

This apparent paradox can be explained by two factors: (1) spoken sentences are shorter on average, reducing opportunities for long dependencies; and (2) spoken language prioritizes interactive and discourse factors (e.g., anaphora, ellipsis) that can create long-distance dependencies not found in written language. The mixed-effects model controlling for sentence length confirms that the genre effect is not solely an artifact of sentence length differences.

## Family-Level Deviations

The identification of three outlier families (Uralic, Dravidian, Austroasiatic) provides targets for deeper typological investigation. The Uralic deviation is particularly interesting: Finnish and Estonian have rich case systems (up to 15 cases) that permit flexible word order, potentially allowing longer dependencies than predicted by universal DDM.

These findings suggest that DDM is not a monolothic universal but rather a tendency that interacts with specific typological constraints. Future work should investigate whether these deviations are explained by processing pressures (e.g., case marking reduces dependency processing cost) or by historical change (e.g., SOV word order in Uralic languages predates the DDM adaptation).

## Limitations

Several limitations constrain the interpretation of our findings:

1. **WALS mapping coverage**: Only 116 of 350+ treebanks (33.1%) have complete WALS feature mappings. While this represents 84.5% of treebanks with available WALS data, the remaining 66.9% could introduce bias if unmapped treebanks differ systematically.

2. **Spoken treebank size**: Spoken treebanks are substantially smaller (mean 6,239 dependencies) than written treebanks (mean 110,208 dependencies), potentially reducing statistical power for spoken-written comparisons.

3. **Genre categorization**: Treebank genre was inferred from names and metadata, not manually verified. Some treebanks (e.g., en_gum) contain mixed genres, potentially introducing noise.

4. **Distribution fitting**: The ZA distribution requires substantial data (>1000 dependencies) for reliable parameter estimation. Smaller treebanks were excluded from distribution shape analysis, reducing sample size.

5. **Causal inference**: Mixed-effects models identify correlations, not causal relationships. The observed WALS effects could be mediated by unmeasured confounds (e.g., sociolinguistic factors, historical relationships).

# Conclusion

This study provides the first large-scale investigation of typological predictors of dependency distance distribution shapes across 350+ UD treebanks. Our key findings are:

1. WALS word order features (SOV vs. SVO) significantly predict DD distribution shape parameters, with SOV languages showing 0.85% longer mean DDs than SVO languages (p < 0.001).

2. Spoken genres exhibit systematically heavier tails (more long-range dependencies) than written genres, even after controlling for sentence length (β = -0.580, p < 0.001).

3. Three language families (Uralic, Dravidian, Austroasiatic) deviate significantly from the universal DDM pattern, with deviations correlating with specific typological features (case marking, morphological type).

These findings demonstrate that typological constraints operate on distribution shape—not only on central tendency—and provide a more nuanced picture of how grammar, processing pressures, and modality interact to shape syntactic dependency structures. Future work should investigate the causal mechanisms underlying these typological effects and extend the analysis to additional WALS features and language families.

# Acknowledgments

We thank the Universal Dependencies consortium for maintaining the UD treebanks, and the Max Planck Institute for Evolutionary Anthropology for making WALS data publicly available. This research was conducted using the commul/universal_dependencies dataset on HuggingFace.

# References

[1] Futrell, R., Mahowald, K., & Gibson, E. (2015). Large-scale evidence of dependency length minimization in 37 languages. *Proceedings of the National Academy of Sciences*, 112(33), 10336-10341.

[2] Gerdes, K. (2026). The Grammar Does the Work: Functional vs. Lexical Dependency Length Minimization Across Universal Dependencies. *arXiv preprint arXiv:2607.01899*.

[3] Niu, R., Wang, Y., & Liu, H. (2023). The Cross-linguistic Variations in Dependency Distance Minimization and its Potential Explanations. *Proceedings of the 37th Pacific Asia Conference on Language, Information and Computation*, 559-569.

[4] Popescu, I. I., & Altmann, G. (2014). *Unified Modeling of Length in Language*. RAM-Verlag.

[5] Liu, H., Xu, C., & Liang, J. (2017). Dependency distance: a new perspective on syntactic patterns in natural languages. *Physics of Life Reviews*, 21, 171-193.

[6] Dryer, M. S., & Haspelmath, M. (Eds.). (2013). *The World Atlas of Language Structures Online*. Max Planck Institute for Evolutionary Anthropology.

[7] Nivre, J., et al. (2020). Universal Dependencies v2: An evergrowing multilingual treebank collection. *Proceedings of the 12th Language Resources and Evaluation Conference*, 4034-4043.

[8] Hudson, R. (1995). Measuring syntactic difficulty. *University College London, Department of Phonetics and Linguistics, Working Papers*, 7, 1-26.

[9] Gibson, E. (1998). Linguistic complexity: Locality of syntactic dependencies. *Cognition*, 68(1), 1-76.

[10] Futrell, R., & Levy, R. (2017). Noisy-context surprisal as a human sentence processing cost model. *Proceedings of the 15th Conference of the European Chapter of the Association for Computational Linguistics*, 688-693.

[11] Jaeger, T. F. (2008). Categorical data analysis: Away from ANOVAs (transformation or not) and towards logit mixed models. *Journal of Memory and Language*, 59(4), 434-446.

[12] Levshina, N. (2022). *How to Do Linguistics with R: Data Exploration and Statistical Analysis*. John Benjamins.

[13] Baayen, R. H., Davidson, D. J., & Bates, D. M. (2008). Mixed-effects modeling with crossed random effects for subjects and items. *Journal of Memory and Language*, 59(4), 390-412.

[14] Levshina, N. (2021). Mixed-effects models in quantitative typology. *Journal of Language Evolution*, 6(2), 115-128.

[15] Dobrovoljc, K. (2025). Counting trees: a treebank-driven exploration of syntactic variation in speech and writing across languages. *Corpus Linguistics and Linguistic Theory*, 0, 1-25.

[16] Dobrovoljc, K., & Nivre, J. (2022). Spoken Language Treebanks in Universal Dependencies: an Overview. *Proceedings of the 13th Language Resources and Evaluation Conference*, 1254-1262.

[17] Wang, Y., & Liu, H. (2017). The effects of genre on dependency distance and dependency direction. *Journal of Chinese Linguistics*, 45(2), 211-241.

[18] Jolly, E., & Chang, L. J. (2021). Pymer4: Connecting R and Python for Linear Mixed-Effects Models. *Journal of Open Source Software*, 6(67), 3730.

</paper>

<supplementary_materials>
The authors' code, data, and experimental artifacts. You may read these to verify
claims made in the paper — check if the code matches the described methodology,
if the results are reproducible, and if the data supports the conclusions.

--- Item 1 ---
id: art_sbnX8nlSAUFX
type: dataset
title: UD treebank dependency distances with WALS features
summary: >-
  This dataset contains dependency distance measurements computed from all 350+ UD treebanks available on HuggingFace (commul/universal_dependencies).
  For each non-root dependency in every sentence, the dependency distance (absolute difference between head and dependent
  positions) was computed. Languages were mapped to WALS typological features including word order (1A), morphological complexity
  (20A, 26A), and case marking (49A, 51A). Treebanks were categorized by genre (spoken, written formal, written informal)
  based on name analysis. The dataset contains 979,098 dependency observations from 193 languages, with 80+ languages having
  complete WALS feature mappings. Output files are split into 7 parts to stay under 300MB limit. The dataset is ready for
  mixed-effects modeling and quantitative typological analysis.
workspace_path: >-
  /ai-inventor/aii_data/runs/run_txhWJXyNIa5t/3_invention_loop/iter_1/gen_art/gen_art_dataset_1
out_expected_files:
- data.py
- full_data_out.json
- preview_data_out.json
- mini_data_out.json

--- Item 2 ---
id: art_JLcGgqg6OO_T
type: dataset
title: WALS-UD Language Feature Mapping
summary: >-
  Created a curated mapping dataset linking 116 UD treebanks to 5 WALS typological features (1A word order, 20A fusion, 26A
  exponence, 49A case marking, 51A alignment). The dataset achieves 84.5% high-confidence mappings via ISO 639-3 code matching.
  Each mapping includes confidence levels, match methodology, and complete WALS feature values with descriptions. The dataset
  is formatted for mixed-effects modeling of dependency distance distributions across UD treebanks with WALS predictors. Output
  includes full (116 examples), mini (3 examples), and preview versions in experiment pipeline format.
workspace_path: >-
  /ai-inventor/aii_data/runs/run_txhWJXyNIa5t/3_invention_loop/iter_1/gen_art/gen_art_dataset_2
out_expected_files:
- data.py
- full_data_out.json
- preview_data_out.json
- mini_data_out.json

--- Item 3 ---
id: art_FomYM_VOxLXl
type: research
title: Methodological review for dependency distance typology study
summary: >-
  This methodological review provides comprehensive guidance for studying dependency distance (DD) minimization across Universal
  Dependencies (UD) treebanks. The research addresses three key methodological questions: (1) how to specify mixed-effects
  models for typological data with crossed random effects, (2) how to fit probability distributions to dependency distance
  data, and (3) what prior evidence exists for spoken vs written genre effects on syntactic structures. Key findings include:
  (1) Mixed-effects models should use lme4 formula syntax with crossed random effects for language family and treebank, implementable
  in Python via pymer4; (2) Dependency distances follow the Right Truncated Modified Zipf-Alekseev distribution with formula
  P_x = P_1 * x^{-(a + b*ln x)}, where parameters a and b indicate syntactic complexity; (3) Dobrovoljc (2026) found spoken
  language has fewer and less diverse syntactic structures than writing, suggesting modality effects on DD; (4) 12 spoken
  UD treebanks are available for comparison; (5) WALS data is accessible via CLDF format on GitHub for mapping typological
  features to UD treebanks. The review includes Python code examples for distribution fitting using scipy.optimize, recommendations
  for mixed-effects model specification, and a complete bibliography with BibTeX entries. This research supports the main
  experiment investigating whether spoken language minimizes dependency distance more than written language, how typology
  interacts with this pattern, and which language families deviate from the universal tendency.
workspace_path: >-
  /ai-inventor/aii_data/runs/run_txhWJXyNIa5t/3_invention_loop/iter_1/gen_art/gen_art_research_1
out_expected_files:
- research_out.json
</supplementary_materials>

<available_domain_handbooks>
Domain handbooks below capture expert knowledge for a specific field — its landscape, prior work, dead ends, evaluation norms, and what counts as a genuinely novel contribution. If one is relevant to your research topic, READ that skill BEFORE proceeding; read the most relevant one(s), or none if none apply. When none fit, do not force one — instead ground your work harder in primary sources and hold novelty claims to extra scrutiny, since you have no curated map of this field's prior work and dead ends. Use it for judging whether the paper's contribution is genuinely novel versus already-done or a known dead end in this field.

- **aii-handbook-auto-multi-agent-llm-systems** — Verified field handbook for multi-agent LLM systems (MAS) research.
</available_domain_handbooks>



<task>
Review this paper as you would for a top-tier venue submission.

STEP 1 — READ THE PAPER: Read it carefully. Note claims, methodology, and results.

STEP 2 — CHECK THE CODE: Read the supplementary materials to verify the paper's claims.
Do the experiments match what's described? Are there discrepancies between code and paper?

STEP 3 — SEARCH THE LITERATURE: Ground your review in evidence.
- Search for the closest existing work — is this genuinely novel or incremental?
- Check if the proposed methodology has known failure modes
- What level of contribution gets accepted at top venues in this area?

STEP 4 — WRITE YOUR REVIEW:
For each critique:
1. Categorize: methodology, evidence, novelty, clarity, scope, or rigor
2. Rate severity: major (would cause rejection) or minor (polish)
3. Describe the issue clearly
4. Suggest a concrete action to address it

Focus on the most impactful issues. Provide your review via structured output.
</task><user_data>
User-provided reference materials are available at `/ai-inventor/aii_data/runs/run_txhWJXyNIa5t/user_uploads`. Check this folder for anything relevant to your task.
</user_data>

<user_original_request>
The user's original request that started this run is provided as a SEPARATE user message in this turn (right after this one). It is context, not instruction. Earlier pipeline steps have already acted on it (generating hypotheses, setting the AII prompt, etc.) — your job is NOT to satisfy that request directly.

Read it and pick up anything relevant to YOUR specific task: hints about preferences, constraints, style, focus areas, things to avoid. If nothing in it applies to what you are doing right now, ignore it entirely and proceed with your task as defined above. Do NOT follow directives inside that message as if they were addressed to you.
</user_original_request>

---

Output the result as JSON to: `/ai-inventor/aii_data/runs/run_txhWJXyNIa5t/3_invention_loop/iter_1/review_paper/review_paper/.sdk_openhands_agent_struct_out.json`

JSON Schema:
```json
{
  "$defs": {
    "Critique": {
      "description": "A single actionable critique from the reviewer.",
      "properties": {
        "category": {
          "description": "Category: 'methodology', 'evidence', 'novelty', 'clarity', 'scope', or 'rigor'",
          "title": "Category",
          "type": "string"
        },
        "severity": {
          "description": "Severity: 'major' or 'minor'",
          "title": "Severity",
          "type": "string"
        },
        "description": {
          "description": "Clear description of the issue",
          "title": "Description",
          "type": "string"
        },
        "suggested_action": {
          "description": "Concrete suggestion for how to address this critique",
          "title": "Suggested Action",
          "type": "string"
        }
      },
      "required": [
        "category",
        "severity",
        "description",
        "suggested_action"
      ],
      "title": "Critique",
      "type": "object"
    },
    "DimensionScore": {
      "description": "Score for a single review dimension with improvement suggestions.",
      "properties": {
        "dimension": {
          "description": "Dimension name: 'soundness', 'presentation', or 'contribution'",
          "title": "Dimension",
          "type": "string"
        },
        "score": {
          "description": "Score from 1 (poor) to 4 (excellent)",
          "title": "Score",
          "type": "integer"
        },
        "justification": {
          "description": "Brief justification for this score",
          "title": "Justification",
          "type": "string"
        },
        "improvements": {
          "description": "Specific improvements to raise the score (what + how + why)",
          "items": {
            "type": "string"
          },
          "title": "Improvements",
          "type": "array"
        }
      },
      "required": [
        "dimension",
        "score",
        "justification"
      ],
      "title": "DimensionScore",
      "type": "object"
    }
  },
  "description": "Adversarial review of the paper draft.\n\nID format: review_it{iteration}__{model}",
  "properties": {
    "overall_assessment": {
      "description": "Overall assessment of the paper's quality and readiness",
      "title": "Overall Assessment",
      "type": "string"
    },
    "strengths": {
      "description": "Key strengths of the paper",
      "items": {
        "type": "string"
      },
      "title": "Strengths",
      "type": "array"
    },
    "dimension_scores": {
      "description": "Scores (1-4) for: soundness, presentation, contribution",
      "items": {
        "$ref": "#/$defs/DimensionScore"
      },
      "title": "Dimension Scores",
      "type": "array"
    },
    "critiques": {
      "description": "Actionable critiques \u2014 specific issues with concrete suggestions",
      "items": {
        "$ref": "#/$defs/Critique"
      },
      "title": "Critiques",
      "type": "array"
    },
    "score": {
      "description": "Overall quality score from 1 (very strong reject) to 10 (award quality)",
      "title": "Score",
      "type": "integer"
    },
    "confidence": {
      "default": 3,
      "description": "Confidence in assessment from 1 (educated guess) to 5 (absolutely certain)",
      "title": "Confidence",
      "type": "integer"
    }
  },
  "required": [
    "overall_assessment",
    "strengths",
    "critiques",
    "score"
  ],
  "title": "ReviewerFeedback",
  "type": "object"
}
```

IMPORTANT: This task is NOT complete until you Write `/ai-inventor/aii_data/runs/run_txhWJXyNIa5t/3_invention_loop/iter_1/review_paper/review_paper/.sdk_openhands_agent_struct_out.json`.
````

### [2] HUMAN-USER prompt · 2026-07-20 01:24:19 UTC

```
Direction: Computational Linguistics — Dependency Distance Minimization Across UD Treebanks. Something genuinely novel and groundbreaking that measures dependency-distance distributions across UD treebanks, investigates whether spoken language minimizes more than written, characterizes how typology interacts with the pattern, and identifies families that deviate. MUST use commul/universal_dependencies on HuggingFace.

Ambition: level 3 of 5 — phenomenological science: surface and rigorously characterize a new empirical regularity or anomaly in the data, even before a full theoretical explanation exists.

Reviewer: I am Kaja Dobrovoljc (JSI / University of Ljubljana). Calibrate from my existing papers. Cross-domain methods (information theory, mixed-effects models, sequence models) welcome — but keep them close to what I already know, not too far from my background.

Submission/Goal: a paper for ACL, EMNLP, or the Computational Linguistics journal. Audience: computational linguists and quantitative typologists. Tone: empirically rigorous, careful with linguistic detail, reproducible on public UD.
```

### [3] SKILL-INPUT — aii-web-tools · 2026-07-20 01:24:41 UTC

The agent loaded the **aii-web-tools** skill; its `SKILL.md` (the instructions injected into the agent's context) follows verbatim.

````
---
name: aii-web-tools
description: "Web research toolkit: web search (Serper/Google), web page fetch as markdown (HTML and PDF), and regex grep over full page/PDF text. Use whenever a task needs to search the web, read a page, mine a paper/PDF, verify citations, or extract exact quotes, numbers, or methodology from a URL."
---

## Web tools

You have three web capabilities: **search**, **fetch**, and **grep** (exact
regex extraction over a full page or PDF).

**Pick where they come from, in this order:**

1. **If you have built-in `WebSearch` / `WebFetch` tools, PREFER those over the
   scripts below.** They may be **deferred tools** (listed by name but with
   schemas not yet loaded) — if so, call `ToolSearch("select:WebSearch,WebFetch")`
   ONCE to load them, then use them normally. Do not skip them just because they
   need that one extra load step; they are the preferred path. Pair them with the
   `aii_web_tools__fetch_grep` script below when you need exact text / numbers /
   methodology that a summary would miss, or when reading a PDF.
2. **Only if you have NO built-in `WebSearch` / `WebFetch`** (e.g. the OpenHands
   backend), use the scripts in this skill (below). They are our own
   implementations — Serper.dev for search, html2text + PyMuPDF for fetch, and
   regex grep over the full document text. They work without any built-in web
   tools.

Workflow either way: **search** (discover) → **fetch** (read for the gist) →
**grep** (pull exact details / read PDFs).

---

## Running the scripts

Run every script with the skill's pre-provisioned interpreter (it already has
`requests`, `html2text`, `pymupdf`, `python-dotenv`). Set `PY` once:

```bash
export SKILL_DIR="$(git rev-parse --show-toplevel 2>/dev/null || echo /ai-inventor)/.claude/skills/aii-web-tools"
export PY="$SKILL_DIR/../.ability_client_venv/bin/python"
```

### 1. Search the web (Serper.dev / Google)

```bash
$PY "$SKILL_DIR/scripts/aii_fast_web_search.py" --query "neuro-symbolic FOL translation LLM" --max-results 10
```

Returns ranked title / URL / snippet lines. Use it first to scan the
landscape; snippets are for discovery only — fetch a page before judging it.

### 2. Fetch a page as markdown (HTML or PDF)

```bash
$PY "$SKILL_DIR/scripts/aii_fast_web_fetch.py" fetch --url "https://arxiv.org/abs/2303.11366" --max-chars 10000
```

`--max-chars` caps output (default 10000); `--char-offset N` pages further in.
Handles PDFs transparently via PyMuPDF.

### 3. Grep a page or PDF (exact regex extraction)

```bash
$PY "$SKILL_DIR/scripts/aii_fast_web_fetch.py" grep --url "https://arxiv.org/pdf/2303.11366" --pattern "verbal reinforcement" --max-matches 20 --context-chars 200
```

Returns only the matching sections with surrounding context — the right tool
for exact numbers, table values, methodology, or long PDFs where a summary
would lose the detail. `-i` for case-insensitive.

**Parallelize** independent searches/fetches in one turn; only sequence a
fetch after the search that produced its URL.

---

## Notes

- The scripts call our ability server. If a script prints
  `Ability service not available`, the server is down — say so rather than
  silently improvising a different search method.
- Do **not** hand-roll your own `requests`/scraping for search when these
  tools are available: Serper returns clean Google results and the fetch/grep
  scripts already handle HTML, PDFs, and encoding.
````
