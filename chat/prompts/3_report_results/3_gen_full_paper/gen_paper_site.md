# gen_paper_site — report_results

> Phase: `gen_paper_repo` · `gen_full_paper`
> Run: `run_q27XJGeAT3TE` — When Two Classifiers Disagree, Does the Direction Tell You Which One Is Right?
>
> Full, verbatim record of every prompt the AI Inventor pipeline gave this agent — system-user, human-user and skill-input — in the order they landed. Nothing truncated.

## Task: `gen_paper_site` (sdk_openhands_agent)

### [1] SYSTEM-USER prompt · 2026-09-10 08:49:55 UTC

````
<task>
Build the paper's public web page: ONE self-contained `index.html` that lets a reader grasp
this paper faster than opening the PDF would. It is published as this run's GitHub Pages site, so
it is the first thing anyone sees.
</task>

<tool_use>
Maximize parallel tool calls. Parallelize independent operations, only sequentialize dependencies.
- Multiple searches/fetches on different topics → parallel in one turn
- Search then fetch results → sequential (need URLs first)
</tool_use>

<what_is_already_here>
Your workspace is the finished paper folder. It already holds everything the page is made of, and
you must not change any of it — you are adding one file, not revising the paper.

- `paper.tex` — the paper as it was actually written. This is the source of truth for
  every claim, name and NUMBER that goes on the page.
- `paper.pdf` — the compiled paper. The page must NOT link to it by this local name:
  the PDF is published on the code branch and the page on a different one. Link to it at the
  full URL below instead.
- `references.bib` — the bibliography, when the paper has one.
- `figures/` — every figure the paper uses, flattened into one folder.
- `workspace/` — the scratch folder the LaTeX task worked in. Ignore it.
</what_is_already_here>

<paper_text>
title: When Two Classifiers Disagree, Does the Direction Tell You Which One Is Right?
abstract: >-
  When two classifiers produce different labels on the same example, practitioners typically fall back on confidence scores
  or majority voting to decide which model to trust. We ask whether the direction of disagreement carries a systematic signal:
  does knowing that a simple model predicts the majority class while a complex model predicts the minority class tell us which
  prediction is correct? This question follows from the bias-variance tradeoff, which predicts that simple models err toward
  the mode while complex models err toward noise. We test this hypothesis across 719 configurations on three sentiment datasets,
  varying sample size, class imbalance, and model pair. We find no evidence for directional asymmetry: both the original rule
  and its inversion achieve accuracy indistinguishable from the majority-class prior. The confidence-based baseline outperforms
  both directional rules by over five percentage points. We show that an earlier report of below-chance accuracy for the original
  rule was driven by a confound between model complexity and feature representation and disappears when both models share
  the same features. The negative result rules out a natural intuition about the bias-variance tradeoff as a diagnostic tool
  for inter-model disagreement on sentiment data.
paper_text: |-
  # When Two Classifiers Disagree, Does the Direction Tell You Which One Is Right?

  ## Abstract

  When two classifiers produce different labels on the same example, practitioners typically fall back on confidence scores or majority voting to decide which model to trust. We ask whether the *direction* of disagreement carries a systematic signal: does knowing that a simple model predicts the majority class while a complex model predicts the minority class tell us which prediction is correct? This question follows from the bias-variance tradeoff, which predicts that simple models err toward the mode while complex models err toward noise. We test this hypothesis across 719 configurations on three sentiment datasets, varying sample size, class imbalance, and model pair. We find no evidence for directional asymmetry: both the original rule and its inversion achieve accuracy indistinguishable from the majority-class prior. The confidence-based baseline outperforms both directional rules by over five percentage points. We show that an earlier report of below-chance accuracy for the original rule was driven by a confound between model complexity and feature representation and disappears when both models share the same features. The negative result rules out a natural intuition about the bias-variance tradeoff as a diagnostic tool for inter-model disagreement on sentiment data.

  ## Introduction

  Sentiment classification on small datasets is unstable. Models overfit, benchmarks contain label noise, and it is unclear which model to trust when they disagree. When a logistic regression and a random forest produce different labels on the same sentence, the standard response is to pick the prediction with higher confidence or to fall back to majority voting. Both approaches measure the *magnitude* of disagreement but ignore its *direction*.

  The direction of disagreement should matter, at least in principle. A simple model with strong inductive bias toward the majority class should be reliable when it predicts the majority and unreliable when it predicts the minority. A complex model that captures genuine minority-class signals but overfits to noise in the majority class should be reliable on minority predictions and unreliable on majority predictions. If this intuition is correct, the pattern of disagreement between two dissimilar classifiers should systematically predict which one is right.

  We formalized this intuition as the *disagreement asymmetry oracle* in a previous study and tested it on two sentiment datasets. We reported 42.4% accuracy for the directional rule, below the 50% chance level, and concluded that the bias-variance asymmetry does not manifest as a usable signal. Reviewers of that work identified a critical confound: our simple model used word-level TF-IDF features while our complex model used character n-grams. Their disagreements may have reflected representation differences rather than complexity differences, making it impossible to attribute results to the bias-variance tradeoff. Reviewers also noted that 42.4% accuracy implies the *inverted* rule achieves 57.6%, and asked whether the asymmetry operates in the opposite direction of the hypothesis.

  This paper addresses both concerns. We re-run the experiment with matched feature representations, where both models use the same TF-IDF word n-gram features, and test both the original and inverted rules. We expand the study to three datasets (SST-2, IMDB, and Twitter Financial News), two model pairs (logistic regression vs. random forest, and Naive Bayes vs. support vector machine), and add probability calibration to ensure fair confidence comparisons. We test 719 configurations across four sample sizes, three class imbalance ratios, and ten random seeds.

  We find that neither the original nor the inverted directional rule works. Both achieve 49.0% accuracy on disagreement samples, identical to the majority-class prior and indistinguishable from random guessing. The effect holds across both model pairs, all three datasets, all sample sizes, and all imbalance ratios. No configuration reaches statistical significance after multiple-comparisons correction. The original 42.4% result was an artifact of the feature confound: when both models share features, the directional signal vanishes entirely.

  Our contribution is threefold. First, we rule out the disagreement asymmetry hypothesis after controlling for the feature representation confound that invalidated the earlier study. Second, we show that the inverted rule — the most natural alternative to the original hypothesis — also fails, closing off the most promising direction for future work. Third, we release an experimental suite with matched features, calibrated probabilities, and rigorous statistical testing that can be reused to test this hypothesis on other domains.

  [FIGURE:fig1]

  **Summary of Contributions**

  - We test the disagreement asymmetry oracle with matched feature representations, eliminating the word-level vs. character-level confound from our previous study \footnote{Code: \url{https://github.com/ai-inventor-papers/ai-invention-2f324c-disagreement-asymmetry-oracle/tree/main/round-2/experiment-1}}.
  - We find that both the original and inverted directional rules achieve 49.0% accuracy on disagreement samples, indistinguishable from the majority-class prior across 719 configurations.
  - We show that the original 42.4% result was driven by the feature confound and disappears when both models share features.
  - We demonstrate that confidence-based selection (54.3%) remains the practical default for resolving inter-model disagreements on sentiment data.

  ## Related Work

  **Trust scores.** Jiang et al. [1] propose the trust score, which measures agreement between a classifier and a modified nearest-neighbor classifier. High trust scores identify correctly classified examples with high precision, outperforming the classifier's own confidence score. The trust score measures *agreement magnitude*, not disagreement direction. Our work tests whether the direction of disagreement between two *dissimilar* classifiers carries predictive signal.

  **Ensemble diversity.** The ensemble learning literature studies how diversity among members improves performance [2, 3]. Kuncheva and Whitaker [2] introduce the Q-statistic and correlation coefficient as measures of pairwise disagreement. Gong et al. [3] review diversity measures and their relationship to ensemble accuracy. None of this work examines whether the *direction* of individual disagreements predicts correctness.

  **Dynamic ensemble selection.** Dynamic classifier selection methods choose the best model for each test instance based on local accuracy estimates [4, 5]. These methods use a separate oracle set to estimate each model's competence region. Our approach asks whether the disagreement pattern itself, without any oracle set, encodes information about correctness.

  **Label noise detection.** Methods like FINE [6] use loss patterns and representation dynamics to detect noisy labels. Han et al. [7] survey label-noise representation learning methods. These approaches rely on a single model's training dynamics, not on inter-model disagreement. Our work asks whether disagreement between two models trained on the same data provides a cheaper signal for label quality.

  **Active learning disagreement.** Active learning uses disagreement between models to select informative samples for labeling [8]. Vote entropy, consensus entropy, and max disagreement measure how much models disagree, not which one is right. Our work tests the complementary question: when models disagree, can we predict the correct label from the pattern of disagreement?

  **Learning from disagreement.** Uma et al. [9] survey methods for learning from human annotator disagreement. The focus is on soft labels and crowdsourcing, not on inter-model disagreement as a diagnostic tool. They note that "the question of how to leverage inter-model disagreement remains underexplored" [9].

  **Classifier calibration.** Comparing confidence scores across models requires calibrated probabilities. Logistic regression outputs are naturally calibrated, while random forest and support vector machine outputs are typically not [10, 11]. We calibrate both models using Platt scaling before comparing confidence, addressing a limitation of our previous study.

  **Pervasive label errors.** Freestone et al. [12] show that label errors in benchmarks destabilize results across models. They do not propose using inter-model disagreement direction to detect which labels are wrong, but their work motivates the search for cheap diagnostics for label quality.

  To our knowledge, no prior work studies the direction of inter-model disagreement as a systematic predictor of correctness.

  ## Methods

  ### Models

  We train two classifiers with different inductive biases on the same training data, using **matched feature representations** to eliminate the confound identified in our previous study:

  1. **Simple model pair**: Logistic regression ($L_2$ regularization, $C=1.0$, max 1000 iterations) and Multinomial Naive Bayes ($\alpha=0.1$). Both models have strong inductive biases — linear decision boundaries and feature independence, respectively.

  2. **Complex model pair**: Random forest (100 trees, no depth limit) and linear support vector machine ($C=1.0$, max 1000 iterations). Both models can fit non-linear decision boundaries (random forest) or find optimal separating hyperplanes with margin maximization (SVM).

  Both models in each pair use the **same TF-IDF feature representation**: word-level unigrams and bigrams, maximum 5,000 features, minimum document frequency 2, sublinear TF scaling. This eliminates the feature confound identified by reviewers of our previous study.

  ### Datasets

  We use three binary sentiment datasets:

  - **SST-2** [13]: 67,349 movie review sentences with binary sentiment labels (44% negative, 56% positive).
  - **IMDB** [14]: 25,000 movie reviews with balanced sentiment labels (50/50).
  - **Twitter Financial News** \footnote{Code: \url{https://github.com/ai-inventor-papers/ai-invention-2f324c-disagreement-asymmetry-oracle/tree/main/round-1/dataset-1}}: 3,365 finance-related tweets with binary sentiment labels (43% bearish, 57% bullish).

  ### Experimental Protocol

  For each dataset, we create subsamples at four sizes (100, 200, 500, 1000) and three class imbalance ratios (1.0, 1.5, 2.0), where the ratio is majority-to-minority. Each configuration is repeated with 10 random seeds, giving 720 total configurations (4 sizes $\times$ 3 ratios $\times$ 10 seeds $\times$ 3 datasets $\times$ 2 model pairs). Of these, 719 completed successfully and 652 produced at least one disagreement on the test set.

  Each subsample is split 80/20 into train and test. Both models are trained on the training split. Probabilities are calibrated using Platt scaling on a held-out validation set before evaluation. On the test set, we identify all samples where the two models disagree and evaluate the following methods:

  **Inverted directional rule**: If the simple model predicts the minority class, trust the simple model. Otherwise, trust the complex model.

  **Original directional rule**: If the simple model predicts the majority class, trust the simple model. Otherwise, trust the complex model.

  **Confidence baseline**: Trust the model with higher calibrated predicted probability for its prediction.

  **Always-trust-accurate**: Always trust the model that is more accurate on the disagreement subset (oracle baseline).

  **Majority prior**: Always predict the majority class on the disagreement set.

  ### Statistical Testing

  For each configuration, we test whether the inverted rule's accuracy exceeds the majority-class prior on the disagreement set using a binomial test. We apply the Benjamini-Hochberg procedure across all 652 configurations with disagreements to control the false discovery rate at $\alpha = 0.05$. We report both raw and adjusted p-values.

  ## Results

  ### Overall Performance

  Across all 652 configurations with disagreements, both the inverted and original directional rules achieve a mean accuracy of 49.0%, identical to the majority-class prior (49.0%). The confidence baseline achieves 54.3%, and the oracle baseline (always trust the more accurate model) achieves 67.3%.

  [FIGURE:fig2]

  The directional rules perform at chance. This is not a marginal effect: the confidence baseline outperforms both directional rules by 5.3 percentage points on average. The gap between the directional rules and the oracle baseline (18.3 percentage points) shows that information about which model is correct *does* exist on the disagreement set, but the directional rule cannot access it.

  ### Per-Dataset Breakdown

  Table 1 shows the mean accuracy of each method broken down by dataset.

  [FIGURE:fig3]

  The pattern holds across all three datasets. On IMDB, the confidence baseline achieves the highest accuracy (56.7%), suggesting that confidence carries more signal on longer review texts. On SST-2 and Twitter Financial News, the confidence baseline is lower (52.5% and 53.4%), but still above both directional rules.

  ### Per-Model-Pair Breakdown

  The results are consistent across both model pairs. For logistic regression vs. random forest, the inverted rule achieves 50.7% and the original rule achieves 46.7%. For Naive Bayes vs. SVM, the inverted rule achieves 47.3% and the original rule achieves 51.3%. Neither pair shows a systematic directional signal.

  ### Effect of Sample Size and Imbalance

  The inverted rule's accuracy varies from 41.6% at sample size 100 to 51.0% at sample size 1000, but the variation is consistent with sampling noise rather than a systematic trend. The correlation between sample size and inverted accuracy is positive ($r = 0.215$, $p < 10^{-8}$), but this reflects the fact that larger samples produce more disagreements, making the accuracy estimate more stable rather than indicating a real effect.

  The accuracy varies across imbalance ratios: 47.3% at ratio 1.0, 52.2% at ratio 1.5, and 47.4% at ratio 2.0. The correlation between imbalance ratio and inverted accuracy is negative ($r = -0.133$, $p = 0.0003$), but the effect is small and inconsistent with any theoretical prediction.

  ### Statistical Significance

  Of 652 configurations with disagreements, 67 (10.3%) show raw significance at $p < 0.05$. After Benjamini-Hochberg correction, zero configurations remain significant. The mean raw p-value is 0.616, and the mean adjusted p-value is 1.0.

  ### Feature Confound Analysis

  Our previous study reported 42.4% accuracy for the original directional rule \footnote{Code: \url{https://github.com/ai-inventor-papers/ai-invention-2f324c-disagreement-asymmetry-oracle/tree/main/round-1/experiment-1}}. That study compared a model using word-level TF-IDF features (logistic regression) against a model using character n-gram features (random forest). The 42.4% result — 7.6 percentage points below chance — suggested the inverted rule might achieve 57.6%.

  The current study eliminates this confound by using matched TF-IDF features for both models. With matched features, the original rule achieves 49.0% and the inverted rule achieves 49.0%. The 42.4% result was driven by the feature representation difference, not by the bias-variance tradeoff.

  [FIGURE:fig4]

  This is a critical finding: the original study's negative result was an artifact of comparing two different feature spaces. The simple model's "bias" was not toward the majority class — it was toward word-level patterns. The complex model's "variance" was not noise sensitivity — it was character-level sensitivity. Their disagreements reflected representation mismatch, not complexity differences.

  ## Discussion

  ### Why the Hypothesis Failed

  The disagreement asymmetry oracle was motivated by the bias-variance tradeoff: simple models should be biased toward the majority class, and complex models should capture minority-class signals. The intuition is theoretically sound but does not translate to a usable signal in practice for three reasons.

  **First**, the bias-variance tradeoff operates at the population level, not the instance level. A simple model's tendency to predict the majority class is an aggregate property, not a per-instance guarantee. On any given disagreement, the simple model may be right for reasons unrelated to its bias.

  **Second**, even with matched features, the two models in each pair have different inductive biases that do not align with the majority-minority axis. Logistic regression and random forest disagree for reasons related to their decision boundaries (linear vs. tree-based), not to their treatment of class balance. Naive Bayes and SVM disagree because of their different assumptions about feature independence and margin maximization.

  **Third**, the sentiment classification task may not exhibit the kind of noise structure that the hypothesis requires. If label noise is roughly symmetric across classes, the simple model's majority-class bias does not give it an advantage on majority-class disagreements.

  ### What the Negative Result Means

  The negative result does not imply that disagreement is uninformative. The confidence baseline achieves 54.3% accuracy, above chance, showing that the *magnitude* of disagreement (as captured by calibrated confidence scores) does carry signal. The oracle baseline achieves 67.3%, showing that information about which model is correct exists but is not accessible through a simple directional rule.

  This suggests that the bias-variance asymmetry, if it exists at all, is not accessible through the binary directional rules we tested. A more sophisticated oracle that accounts for local data density, feature-space geometry, or model calibration might recover the signal.

  ### Limitations

  Our study has several limitations. We test two model pairs on three sentiment datasets. The hypothesis might hold for other model families (e.g., neural networks vs. linear models) or other domains where the bias-variance tradeoff manifests differently. The small sample sizes (100–1000) may not be sufficient to reveal the effect, though the effect should be strongest in small-sample regimes where the bias-variance tradeoff matters most. We do not test the effect of model calibration on the directional rule itself, only on the confidence baseline.

  ### Multi-Model Extension

  The directional rule might generalize to settings with more than two models. With three or more models, the pattern of disagreement becomes richer: a 2-vs-1 split encodes more information than a binary disagreement. The model that disagrees with the majority might be the one that is wrong, or it might be the one that is right. This question remains open.

  ## Conclusion

  We tested whether the direction of disagreement between a simple and a complex classifier predicts which model is correct on sentiment classification tasks. The hypothesis, motivated by the bias-variance tradeoff, predicts that simple models are more reliable on majority-class predictions and complex models on minority-class predictions. We find no evidence for this pattern across 719 configurations on SST-2, IMDB, and Twitter Financial News. Both the original and inverted directional rules achieve 49.0% accuracy, indistinguishable from the majority-class prior. The original 42.4% result from our previous study was driven by a confound between model complexity and feature representation and disappears when both models share features.

  The negative result rules out a natural intuition about the bias-variance tradeoff as a diagnostic tool for inter-model disagreement. Confidence-based selection remains the practical default, achieving 54.3% accuracy on disagreement samples.

  **Future work**:
  - Test the hypothesis on image classification and tabular datasets.
  - Investigate whether neural network model pairs exhibit directional asymmetry.
  - Study whether multi-model disagreement patterns (e.g., 2-vs-1 splits) carry more signal than binary disagreements.
  - Develop oracles that combine directional information with local data density or feature-space geometry.

  ## References

  [1] Jiang, H., Kim, B., & Gupta, M. (2018). To trust or not to trust a classifier. *Neural Information Processing Systems*, 5546–5557.

  [2] Kuncheva, L. I., & Whitaker, C. J. (2003). Measures of diversity in classifier ensembles and a correlation-based analysis. *Machine Learning*, 51(2), 181–207.

  [3] Gong, Z., Zhong, P., & Hu, W. (2018). Diversity in machine learning. *IEEE Access*, 7, 64323–64350.

  [4] Rodriguez, J. J., Kuncheva, L. I., & Alonso, C. J. (2017). Dynamic classifier selection: Recent advances and perspectives. *Information Fusion*, 36, 124–135.

  [5] Zhou, Z.-H., & Wu, J. (2018). K-nearest oracles borderline dynamic classifier ensemble selection. *International Joint Conference on Neural Networks*, 1–8.

  [6] Kim, T., Ko, J., Cho, S., Choi, J., & Yun, S.-Y. (2021). FINE samples for learning with noisy labels. *Neural Information Processing Systems*, 24137–24149.

  [7] Han, B., Yao, Q., Liu, T., Niu, G., Tsang, I. W., Kwok, J. T., & Sugiyama, M. (2020). A survey of label-noise representation learning: Past, present and future. *arXiv preprint arXiv:2011.04406*.

  [8] Danka, P. (2018). modAL: a modular active learning library for Python. *Journal of Machine Learning Research*, 19(129), 1–6.

  [9] Uma, A., Fornaciari, T., Hovy, D., Paun, S., Plank, B., & Poesio, M. (2021). Learning from disagreement: A survey. *Journal of Artificial Intelligence Research*, 72, 1385–1470.

  [10] Wang, C. (2023). Calibration in deep learning: A survey of the state-of-the-art. *arXiv preprint arXiv:2308.01222*.

  [11] Naeini, M. P., Cooper, G. F., & Hauskrecht, M. (2015). Obtaining well calibrated probabilities using bayesian model averaging. *Proceedings of the 32nd International Conference on Machine Learning*, 2901–2909.

  [12] Freestone, J., Durrant, J., & Ellul, J. (2019). Pervasive label errors in test sets for natural language inference tasks. *arXiv preprint arXiv:1909.13133*.

  [13] Socher, R., Perelygin, A., Wu, J., Chuang, J., Mangatar, C., Pang, B., & Ng, A. Y. (2013). Recursive deep models for semantic compositionality over a sentiment treebank. *Proceedings of the 2013 Conference on Empirical Methods in Natural Language Processing*, 1631–1642.

  [14] Maas, A. L., Daly, R. E., Pham, P. T., Huang, D., Ng, A. Y., & Potts, C. (2011). Learning word vectors for sentiment analysis. *Proceedings of the 49th Annual Meeting of the Association for Computational Linguistics*, 142–150.
summary: >-
  We test whether the direction of disagreement between a simple and a complex classifier predicts which model is correct
  on sentiment classification tasks. Across 719 configurations on three datasets with matched features and calibrated probabilities,
  both the original and inverted directional rules achieve 49.0% accuracy, indistinguishable from the majority-class prior.
  We show that an earlier below-chance result was driven by a feature representation confound and disappears when both models
  share features. Confidence-based selection remains the practical default at 54.3%.
</paper_text>

<available_figures>
Each line gives the path the PAGE must use, then the figure's title and caption. It is the same
path the file has on disk here: the publish step copies the page and its figures into one folder,
so what works in this workspace is what works on the live site.

- figures/fig1_v0.jpg — "Disagreement Asymmetry Hypothesis" (caption: "The disagreement asymmetry oracle hypothesis: when a simple model and a complex model disagree, the direction of disagreement should predict which model is correct. The original rule (top) trusts the simple model on majority-class predictions; the inverted rule (bottom) trusts the simple model on minority-class predictions. Both rules achieve 49.0% accuracy, indistinguishable from the majority-class prior.")
- figures/fig2_v0.png [render from fig2_v0.pdf first] — "Overall Accuracy Comparison" (caption: "Mean accuracy across 652 configurations with disagreements. Both directional rules achieve 49.0%, identical to the majority-class prior. The confidence baseline achieves 54.3%. The oracle baseline (always trust the more accurate model) achieves 67.3%, showing that information about correctness exists but is not accessible through directional rules.")
- figures/fig3_v0.png [render from fig3_v0.pdf first] — "Per-Dataset Accuracy Breakdown" (caption: "Mean accuracy broken down by dataset. The pattern holds across all three datasets: both directional rules perform at chance while the confidence baseline exceeds chance. IMDB shows the largest confidence gap (56.7% vs 49.0%).")
- figures/fig4_v0.png [render from fig4_v0.pdf first] — "Feature Confound Analysis" (caption: "Comparison of the original directional rule accuracy between the previous study (unmatched features: word-level TF-IDF vs. character n-grams) and the current study (matched features: both use TF-IDF word n-grams). The 42.4% result from the previous study was driven by the feature confound and disappears when both models share features.")
</available_figures>

<figure_requirements>
- Reference every figure as `figures/` plus its filename, exactly as listed above.
  The publish step copies the page and its figures into one folder together, so that relative
  path is what resolves on the live site; anything else breaks once published.
- A browser cannot draw a PDF in an image element. Data figures are delivered as vector PDF for
  LaTeX's benefit, so for each one check whether a PNG of the same name already sits in
  `figures/`; if it does not, render one there at about 200 DPI with pdftoppm or
  pymupdf before referencing it. Renderable formats: .avif, .gif, .jpeg, .jpg, .png, .svg, .webp.
- Write those PNG files into `figures/` and nowhere else — that folder is published, a
  new folder of your own is not.
- Use each figure's own caption. Do not invent new ones, and do not describe a figure you did not
  place on the page.
- Look at every figure before you place it. A figure whose axis labels are unreadable at the size
  you give it is worse than no figure.
</figure_requirements>

<page_structure>
In this order, top to bottom:

1. HERO — the paper's title, the author line as the paper gives it, and a one-paragraph TL;DR in
   plain language: what was asked, what was found, and the single number that carries the finding.
   Not the abstract, and not a rewrite of it. Below it, two links: the PDF and the code
   repository, both at the exact URLs given in the links section below.
2. CONTRIBUTIONS — the paper's actual contributions as three to five scannable cards, each a short
   heading plus one or two sentences. If the paper claims four things, show four cards, not five.
3. METHOD — a walkthrough a technically literate non-specialist can follow: what goes in, what
   happens to it, what comes out, and why the design is the way it is. Lead with the paper's own
   method figure when it has one.
4. RESULTS — the paper's real headline numbers, read out of `paper.tex` and the data
   files behind it, each next to what it was measured on and what it is being compared against.
   A number that is not in the paper does not go on the page, and neither does a comparison the
   paper did not make. If a slot has no number, drop the slot.
5. FIGURE GALLERY — every figure, each with its caption, click-to-enlarge into a lightbox that
   closes on Escape, on a click outside, and on a visible close control.
6. LIMITATIONS — what the paper says it does not show. Verbatim in substance; do not soften it.
7. FOOTER — links to the PDF and the repository again, and the citation if the paper carries one.

A sticky section navigation runs alongside all of it and marks where the reader currently is.
</page_structure>

<technical_requirements>
- ONE file. All CSS in a style element, all JavaScript in a script element, both inline in
  `index.html`. No build step, no bundler, no framework, no external script, stylesheet, web
  font or analytics — nothing fetched at load time. The page must render with the network off,
  and the only files it may point at are the figures listed above and the PDF beside it.
- System font stack only, since no font may be downloaded.
- Light theme. Responsive from a 360px phone to a wide desktop, with no horizontal page scroll;
  wide content scrolls inside its own container.
- Honour prefers-reduced-motion: under it, transitions and any scroll-driven effect stop.
- Keyboard-navigable: every control reachable by Tab in a sensible order, a visible focus ring,
  the lightbox trapping focus while open and returning it to the thumbnail on close, and a skip
  link to the main content.
- Semantic HTML: one top-level heading, headings that descend without skipping, landmark elements,
  and alt text on every image that says what the figure shows rather than repeating its number.
- No emoji anywhere. No purple-to-blue gradients. No decorative icon fonts.
- Keep the whole file comfortably under a megabyte.
</technical_requirements>

<writing_register>
Write in the register of the field's best papers (the paper this page presents, which was written to them), not in the register of a language
model. Four things are measured on the finished draft, and a draft outside them is sent back with
the numbers:
- Never use: delve, underscore, showcase, intricate, pivotal, realm, commendable, meticulous, tapestry, garner, multifaceted, it is worth noting, plays a crucial role, not only ... but also. These are 10 to 30 times more frequent in machine-written abstracts than in
  human ones, and reviewers read them as such.
- Em dashes: at most 3 per 1,000 words. Use a comma, a colon or a full stop.
- Sentence rhythm: mix short and long sentences. An interquartile range of sentence length under
  8 words reads as machine-written.
- Hedging: at most 15 hedges (may, likely, suggests, appears) per 1,000
  words. State what the evidence supports plainly; hedge where it is thin, not everywhere.
Style never changes substance: numbers, claims, citations and figure markers stay exactly as the
evidence gives them. The user's original request (delivered as a separate message) overrides all
of this wherever the two conflict.
</writing_register>

<links>
Use these two URLs VERBATIM wherever the page links to the paper or the code. Do not shorten them,
do not turn either into a relative path, and do not compose one of your own.

- The paper PDF: https://cdn.jsdelivr.net/gh/ai-inventor-papers/ai-invention-2f324c-disagreement-asymmetry-oracle@main/paper.pdf
- The code repository: https://github.com/ai-inventor-papers/ai-invention-2f324c-disagreement-asymmetry-oracle

Both carry the branch this run publishes to. A link without it opens a DIFFERENT run's work —
it resolves and looks correct, which is why it must be copied rather than derived. They begin
resolving only after this run finishes publishing, so do NOT try to open or verify them.
</links>

FIRST, add ALL of these to your todo list using your task/todo-tracking tool:

CRITICAL: Todo content must be copied exactly as is written here, with NO CHANGES. These todos are intentionally detailed so that another LLM could read each one without any external context and understand exactly what it has to do.

<todos>
TODO 1. Read and STRICTLY follow these skills: aii-web-tools.
TODO 2. Read `paper.tex` end to end and list `figures/`. Write down the
paper's title, its author line, its contributions, and every headline number together with the
sentence it appears in — those sentences are the only numbers allowed on the page. Note which
figures are PDFs and so need a PNG rendered.
TODO 3. Render a PNG at about 200 DPI, into `figures/`, for every figure not already
in a browser-renderable format, then LOOK at each image you plan to use so you know what it shows
and how large it has to be on the page to stay legible.
TODO 4. Write `index.html` following the page_structure and technical_requirements sections
above: one file, inline CSS and JavaScript, every image referenced through the published figure
prefix.
TODO 5. VERIFY THE NUMBERS: for each number on the page, grep `paper.tex` for it and
confirm it appears there with the same meaning. Delete any number you cannot find. Then confirm
every claim on the page is one the paper actually makes.
TODO 6. VERIFY THE PAGE: confirm `index.html` has no external script, stylesheet or font
reference; that every image path starts with the published figure prefix and names a file that
exists in `figures/`; and that the PDF and repository links are character-for-
character the two URLs given in the links section, not `paper.pdf` and not any URL you
composed. Then open the page in a browser, screenshot it at a phone width and a desktop width,
read both screenshots, and fix anything cramped, overlapping or cut off.
TODO 7. ACCESSIBILITY PASS: tab through the whole page and confirm every control is reachable with a
visible focus ring, the lightbox traps focus and closes on Escape, headings descend without
skipping, and every image has alt text. Fix what fails.
</todos>

---

Output the result as JSON to: `/ai-inventor/aii_data/runs/run_q27XJGeAT3TE/4_gen_paper_repo/_4_assemble_paper/paper/.sdk_openhands_agent_struct_out.json`

JSON Schema:
```json
{
  "$defs": {
    "PaperSiteExpectedFiles": {
      "description": "All expected output files from paper-site generation.",
      "properties": {
        "site_html_path": {
          "description": "Path to the single self-contained HTML page. Example: 'index.html'",
          "title": "Site Html Path",
          "type": "string"
        }
      },
      "required": [
        "site_html_path"
      ],
      "title": "PaperSiteExpectedFiles",
      "type": "object"
    }
  },
  "description": "Paper site \u2014 structured output from presentation-page generation.",
  "properties": {
    "summary": {
      "description": "Brief summary of the page you built: the sections it carries, which figures it shows, which numbers it quotes and where each came from in the paper.",
      "maxLength": 5000,
      "minLength": 300,
      "title": "Summary",
      "type": "string"
    },
    "out_expected_files": {
      "$ref": "#/$defs/PaperSiteExpectedFiles",
      "description": "All output files you created. Must include index.html."
    }
  },
  "required": [
    "summary",
    "out_expected_files"
  ],
  "title": "PaperSite",
  "type": "object"
}
```

IMPORTANT: this task is NOT complete until `/ai-inventor/aii_data/runs/run_q27XJGeAT3TE/4_gen_paper_repo/_4_assemble_paper/paper/.sdk_openhands_agent_struct_out.json` exists and contains JSON matching the schema above.
````

### [2] HUMAN-USER prompt · 2026-09-10 08:49:55 UTC

```
Compare two simple baselines for sentiment classification on a small public dataset.
```

### [3] SKILL-INPUT — aii-web-tools · 2026-09-10 08:50:09 UTC

The agent loaded the **aii-web-tools** skill; its `SKILL.md` (the instructions injected into the agent's context) follows verbatim.

````
---
name: aii-web-tools
description: "Runs web search, page fetch as markdown, and regex grep over full HTML or PDF text via this skill's own scripts (aii_fast_web_search.py, aii_fast_web_fetch.py) — a free-first keyless search stack with Serper fallback that works even where built-in WebSearch and WebFetch are absent. Use when a query, page, or paper must be searched, read, or mined for an exact quote, number, table value, or methodology sentence, and whenever a lossy summary would lose the detail. Triggers: web search, scholarly search, OpenAlex, Crossref, Serper, fetch a URL as markdown, read a PDF, arXiv, regex grep a page, exact quote, table value, citation check. NOT for: planning a broad multi-source literature review or mass verification campaign — use aii-web-research-tools; NOT for a PDF file already on disk — extraction, form filling, merging and PDF creation are anthropic-pdf; NOT for driving a browser or testing a UI."
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
   implementations — free-first web search (keyless general/scholarly engines,
   Serper fallback), html2text + PyMuPDF for fetch, and regex grep over the full
   document text. They work without any built-in web tools.

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

### 1. Search the web (free-first: general or scholarly)

```bash
# general web (default): keyless engines (ddgs, marginalia); Serper only if they miss
$PY "$SKILL_DIR/scripts/aii_fast_web_search.py" --query "neuro-symbolic FOL translation LLM" --max-results 10
# scholarly mode: OpenAlex + Crossref (DOIs, citation counts)
$PY "$SKILL_DIR/scripts/aii_fast_web_search.py" --query "neuro-symbolic FOL translation" --mode scholarly
```

Returns ranked title / URL / snippet lines. `--mode general` (default) uses
keyless general engines; `--mode scholarly` uses academic APIs. Both fall back
to Serper (paid) only when the free engines miss. Use search first to scan the
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

### [4] SYSTEM-USER prompt · 2026-09-10 09:00:26 UTC

```
SITE VERIFICATION FAILED: 1 problem(s) in index.html.

- image source '' does not start with 'figures/', so it will not resolve once the page is published beside its figures folder

You MUST:
1. Fix every problem listed above in index.html.
2. Keep the page ONE self-contained file — all CSS and JavaScript inline, no external scripts, stylesheets or web fonts, nothing fetched at load time.
3. Point every image at figures/<filename>, where <filename> is a browser-renderable image that really exists in your figures/ folder. A vector PDF figure needs a PNG rendered beside it first; reference the PNG.
4. Re-open the page and confirm it still renders before finishing.
```

### [5] SYSTEM-USER prompt · 2026-09-10 09:01:42 UTC

```
SITE VERIFICATION FAILED: 1 problem(s) in index.html.

- image source '' does not start with 'figures/', so it will not resolve once the page is published beside its figures folder

You MUST:
1. Fix every problem listed above in index.html.
2. Keep the page ONE self-contained file — all CSS and JavaScript inline, no external scripts, stylesheets or web fonts, nothing fetched at load time.
3. Point every image at figures/<filename>, where <filename> is a browser-renderable image that really exists in your figures/ folder. A vector PDF figure needs a PNG rendered beside it first; reference the PNG.
4. Re-open the page and confirm it still renders before finishing.
```
