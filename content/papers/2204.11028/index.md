---
title: Reinforced Causal Explainer for Graph Neural Networks
arxiv_id: '2204.11028'
source_url: ''
authors:
- name: Xiang Wang
  orcid: null
  s2_author_id: '98285513'
  s2_url: null
- name: Y. Wu
  orcid: null
  s2_author_id: '40507402'
  s2_url: null
- name: An Zhang
  orcid: null
  s2_author_id: '2153659066'
  s2_url: null
- name: Fuli Feng
  orcid: null
  s2_author_id: '2163400298'
  s2_url: null
- name: Xiangnan He
  orcid: null
  s2_author_id: '7792071'
  s2_url: null
- name: Tat-seng Chua
  orcid: null
  s2_author_id: '143779329'
  s2_url: null
published_date: Apr 23, 2022
published_date_iso: '2022-04-23'
published_venue: ''
published_conference: ''
published_conference_short: ''
published_conference_slug: ''
abstract: 'Explainability is crucial for probing graph neural networks (GNNs), answering
  questions like ``Why the GNN model makes a certain prediction?''''. Feature attribution
  is a prevalent technique of highlighting the explanatory subgraph in the input graph,
  which plausibly leads the GNN model to make its prediction. Various attribution
  methods have been proposed to exploit gradient-like or attention scores as the attributions
  of edges, then select the salient edges with top attribution scores as the explanation.
  However, most of these works make an untenable assumption --- the selected edges
  are linearly independent --- thus leaving the dependencies among edges largely unexplored,
  especially their coalition effect. We demonstrate unambiguous drawbacks of this
  assumption --- making the explanatory subgraph unfaithful and verbose. To address
  this challenge, we propose a reinforcement learning agent, Reinforced Causal Explainer
  (RC-Explainer). It frames the explanation task as a sequential decision process
  --- an explanatory subgraph is successively constructed by adding a salient edge
  to connect the previously selected subgraph. Technically, its policy network predicts
  the action of edge addition, and gets a reward that quantifies the action''s causal
  effect on the prediction. Such reward accounts for the dependency of the newly-added
  edge and the previously-added edges, thus reflecting whether they collaborate together
  and form a coalition to pursue better explanations. It is trained via policy gradient
  to optimize the reward stream of edge sequences. As such, RC-Explainer is able to
  generate faithful and concise explanations, and has a better generalization power
  to unseen graphs. When explaining different GNNs on three graph classification datasets,
  RC-Explainer achieves better or comparable performance to state-of-the-art approaches
  w.r.t. two quantitative metrics: predictive accuracy, contrastivity, and safely
  passes sanity checks and visual inspections.'
codebase_url: https://github.com/xiangwang1223/reinforced_causal_explainer
extraction_model: cyankiwi/gemma-4-26B-A4B-it-AWQ-4bit
has_results: true
paper_type: method
proposed_models:
- GNNExplainer
- PGExplainer
- PGM-Explainer
- RC-Explainer
mrr: 0.0222
adjusted_mrr: 0.0074
mrr_dataset_count: 1
benchmark_categories:
- TU Dortmund
benchmark_coverage:
- benchmark: TU Dortmund
  benchmark_slug: tu-dortmund
  evaluated: 1
  total: 11
task_categories:
- graph_classification
experiment_scopes:
- graph-level
results:
- &id001
  dataset: REDDIT-MULTI-5K
  rows:
  - model: SpeGCL
    model_key: spegcl
    model_plain: SpeGCL
    value: 0.5944
    std: 0.0018
    metric: Accuracy
    higher_is_better: true
    is_baseline: false
    is_overridden: false
    override_reason: ''
    params_millions: null
    architecture_type: hybrid
    architecture_label: Hyb
    architecture_title: Hybrid MPNN + transformer
    arxiv_id: '2410.10365'
    title: 'SpeGCL: Self-supervised Graph Spectrum Contrastive Learning without Positive
      Samples'
    date: Oct 14, 2024
    date_display: Oct 2024
    date_iso: '2024-10-14'
    venue: IEEE Transactions on Neural Networks and Learning Systems
    codebase_url: ''
    uses_external_data: false
    input_feature_source: null
    feature_source_evidence: ''
    is_global_top: true
    global_rank: 1
    sort_value: 0.5944
    sort_std: 0.0018
    comparison_type: global_top
    comparison_source_title: ''
    comparison_source_arxiv: ''
    is_best: true
    is_std_outlier: false
  - model: GIN
    model_key: gin
    model_plain: GIN
    value: 0.576
    std: 0.015
    metric: Accuracy
    higher_is_better: true
    is_baseline: true
    is_overridden: false
    override_reason: ''
    params_millions: null
    architecture_type: gnn
    architecture_label: GNN
    architecture_title: Message-passing GNN
    arxiv_id: '2401.16011'
    title: 'GPS: graph contrastive learning via multi-scale augmented views from adversarial
      pooling'
    date: Jan 29, 2024
    date_display: Jan 2024
    date_iso: '2024-01-29'
    venue: Science China Information Sciences
    codebase_url: ''
    uses_external_data: false
    input_feature_source: null
    feature_source_evidence: ''
    is_global_top: true
    global_rank: 2
    sort_value: 0.576
    sort_std: 0.015
    comparison_type: global_top
    comparison_source_title: ''
    comparison_source_arxiv: ''
    is_best: false
    is_std_outlier: false
  - model: Sum--MLP (GIN-0)
    model_key: sum--mlp (gin-0)
    model_plain: Sum--MLP (GIN-0)
    value: 0.575
    std: 0.015
    metric: Accuracy
    higher_is_better: true
    is_baseline: true
    is_overridden: false
    override_reason: ''
    params_millions: null
    architecture_type: gnn
    architecture_label: GNN
    architecture_title: Message-passing GNN
    arxiv_id: '1810.00826'
    title: How Powerful are Graph Neural Networks?
    date: Oct 1, 2018
    date_display: Oct 2018
    date_iso: '2018-10-01'
    venue: International Conference on Learning Representations
    codebase_url: https://github.com/weihua916/powerful-gnns
    uses_external_data: false
    input_feature_source: null
    feature_source_evidence: ''
    is_global_top: true
    global_rank: 3
    sort_value: 0.575
    sort_std: 0.015
    comparison_type: global_top
    comparison_source_title: ''
    comparison_source_arxiv: ''
    is_best: false
    is_std_outlier: false
  - model: RC-Explainer
    model_key: rc-explainer
    model_plain: RC-Explainer
    value: 0.472
    std: null
    paper_value: 0.472
    paper_std: null
    metric: Accuracy
    higher_is_better: true
    is_baseline: false
    is_overridden: false
    override_reason: ''
    params_millions: null
    architecture_type: hybrid
    architecture_label: Hyb
    architecture_title: Hybrid MPNN + transformer
    uses_external_data: 0
    input_feature_source: null
    feature_source_evidence: ''
    table_ref: Table 1
    source_ref: this paper
    variant_inference_reason: 'dataset: exact match'
    evaluation_task: graph_classification
    protocol_decision: standard
    protocol_note: ACC@10% on REDDIT-MULTI-5K
    date: Apr 23, 2022
    date_display: Apr 2022
    date_iso: '2022-04-23'
    published_venue: ''
    published_conference: ''
    at_pub_value: null
    at_pub_std: null
    at_pub_source_arxiv: ''
    at_pub_source_title: ''
    at_pub_source_date_iso: ''
    at_pub_source_date_label: ''
    value_gap_source_date_iso: '2022-04-23'
    value_gap_source_date_label: '2022'
    gap_vs_at_pub: null
    worse_than_at_pub: false
    surpassed_since_pub: false
    better_than_at_pub: false
    insignificant_improvement_at_pub: false
    improvement_surpassed_since_pub: false
    insignificant_value_gap: false
    today_delta_significant: false
    true_value: 0.472
    true_std: null
    value_gap_source_arxiv: '2204.11028'
    value_gap_source_title: Reinforced Causal Explainer for Graph Neural Networks
    value_gap_source_is_current_paper: true
    value_gap: null
    has_value_note: false
    value_note: ''
    sort_value: 0.472
    sort_std: null
    global_rank: 29
    paper_rank: 29
    rank_delta: 0
    rank_delta_abs: 0
    rank_delta_direction: same
    has_value_gap: false
    comparison_type: null
    comparison_source_title: ''
    comparison_source_arxiv: ''
    is_best: false
    is_std_outlier: false
  - model: GraphSAGE
    model_key: graphsage
    model_plain: GraphSAGE
    value: 0.438
    std: 0.032
    metric: Accuracy
    higher_is_better: true
    is_baseline: true
    is_overridden: false
    override_reason: ''
    params_millions: null
    architecture_type: gnn
    architecture_label: GNN
    architecture_title: Message-passing GNN
    arxiv_id: '2401.16011'
    title: 'GPS: graph contrastive learning via multi-scale augmented views from adversarial
      pooling'
    date: Jan 29, 2024
    date_display: Jan 2024
    date_iso: '2024-01-29'
    venue: Science China Information Sciences
    codebase_url: ''
    uses_external_data: false
    input_feature_source: null
    feature_source_evidence: ''
    is_global_top: true
    global_rank: 31
    sort_value: 0.438
    sort_std: 0.032
    comparison_type: global_top
    comparison_source_title: ''
    comparison_source_arxiv: ''
    is_best: false
    is_std_outlier: false
  - model: PGM-Explainer
    model_key: pgm-explainer
    model_plain: PGM-Explainer
    value: 0.3
    std: null
    paper_value: 0.3
    paper_std: null
    metric: Accuracy
    higher_is_better: true
    is_baseline: false
    is_overridden: false
    override_reason: ''
    params_millions: null
    architecture_type: other_traditional
    architecture_label: Trad
    architecture_title: Traditional / classical method
    uses_external_data: 0
    input_feature_source: null
    feature_source_evidence: ''
    table_ref: Table 1
    source_ref: this paper
    variant_inference_reason: 'dataset: exact match'
    evaluation_task: graph_classification
    protocol_decision: standard
    protocol_note: ACC@10% on REDDIT-MULTI-5K
    date: Apr 23, 2022
    date_display: Apr 2022
    date_iso: '2022-04-23'
    published_venue: ''
    published_conference: ''
    at_pub_value: null
    at_pub_std: null
    at_pub_source_arxiv: ''
    at_pub_source_title: ''
    at_pub_source_date_iso: ''
    at_pub_source_date_label: ''
    value_gap_source_date_iso: '2022-04-23'
    value_gap_source_date_label: '2022'
    gap_vs_at_pub: null
    worse_than_at_pub: false
    surpassed_since_pub: false
    better_than_at_pub: false
    insignificant_improvement_at_pub: false
    improvement_surpassed_since_pub: false
    insignificant_value_gap: false
    today_delta_significant: false
    true_value: 0.3
    true_std: null
    value_gap_source_arxiv: '2204.11028'
    value_gap_source_title: Reinforced Causal Explainer for Graph Neural Networks
    value_gap_source_is_current_paper: true
    value_gap: null
    has_value_note: false
    value_note: ''
    sort_value: 0.3
    sort_std: null
    global_rank: 38
    paper_rank: 38
    rank_delta: 0
    rank_delta_abs: 0
    rank_delta_direction: same
    has_value_gap: false
    comparison_type: null
    comparison_source_title: ''
    comparison_source_arxiv: ''
    is_best: false
    is_std_outlier: false
  - model: CXPlain
    model_key: cxplain
    model_plain: CXPlain
    value: 0.279
    std: null
    paper_value: 0.279
    paper_std: null
    metric: Accuracy
    higher_is_better: true
    is_baseline: true
    is_overridden: false
    override_reason: ''
    params_millions: null
    architecture_type: other_traditional
    architecture_label: Trad
    architecture_title: Traditional / classical method
    uses_external_data: 0
    input_feature_source: null
    feature_source_evidence: ''
    table_ref: Table 1
    source_ref: this paper
    variant_inference_reason: 'dataset: exact match'
    evaluation_task: graph_classification
    protocol_decision: standard
    protocol_note: ACC@10% on REDDIT-MULTI-5K
    date: Apr 23, 2022
    date_display: Apr 2022
    date_iso: '2022-04-23'
    published_venue: ''
    published_conference: ''
    at_pub_value: null
    at_pub_std: null
    at_pub_source_arxiv: ''
    at_pub_source_title: ''
    at_pub_source_date_iso: ''
    at_pub_source_date_label: ''
    value_gap_source_date_iso: '2022-04-23'
    value_gap_source_date_label: '2022'
    gap_vs_at_pub: null
    worse_than_at_pub: false
    surpassed_since_pub: false
    better_than_at_pub: false
    insignificant_improvement_at_pub: false
    improvement_surpassed_since_pub: false
    insignificant_value_gap: false
    today_delta_significant: false
    true_value: 0.279
    true_std: null
    value_gap_source_arxiv: '2204.11028'
    value_gap_source_title: Reinforced Causal Explainer for Graph Neural Networks
    value_gap_source_is_current_paper: true
    value_gap: null
    has_value_note: false
    value_note: ''
    sort_value: 0.279
    sort_std: null
    global_rank: 39
    paper_rank: 39
    rank_delta: 0
    rank_delta_abs: 0
    rank_delta_direction: same
    has_value_gap: false
    comparison_type: null
    comparison_source_title: ''
    comparison_source_arxiv: ''
    is_best: false
    is_std_outlier: false
  - model: PGExplainer
    model_key: pgexplainer
    model_plain: PGExplainer
    value: 0.175
    std: null
    paper_value: 0.175
    paper_std: null
    metric: Accuracy
    higher_is_better: true
    is_baseline: false
    is_overridden: false
    override_reason: ''
    params_millions: null
    architecture_type: gnn
    architecture_label: GNN
    architecture_title: Message-passing GNN
    uses_external_data: 0
    input_feature_source: null
    feature_source_evidence: ''
    table_ref: Table 1
    source_ref: this paper
    variant_inference_reason: 'dataset: exact match'
    evaluation_task: graph_classification
    protocol_decision: standard
    protocol_note: ACC@10% on REDDIT-MULTI-5K
    date: Apr 23, 2022
    date_display: Apr 2022
    date_iso: '2022-04-23'
    published_venue: ''
    published_conference: ''
    at_pub_value: null
    at_pub_std: null
    at_pub_source_arxiv: ''
    at_pub_source_title: ''
    at_pub_source_date_iso: ''
    at_pub_source_date_label: ''
    value_gap_source_date_iso: '2022-04-23'
    value_gap_source_date_label: '2022'
    gap_vs_at_pub: null
    worse_than_at_pub: false
    surpassed_since_pub: false
    better_than_at_pub: false
    insignificant_improvement_at_pub: false
    improvement_surpassed_since_pub: false
    insignificant_value_gap: false
    today_delta_significant: false
    true_value: 0.175
    true_std: null
    value_gap_source_arxiv: '2204.11028'
    value_gap_source_title: Reinforced Causal Explainer for Graph Neural Networks
    value_gap_source_is_current_paper: true
    value_gap: null
    has_value_note: false
    value_note: ''
    sort_value: 0.175
    sort_std: null
    global_rank: 42
    paper_rank: 42
    rank_delta: 0
    rank_delta_abs: 0
    rank_delta_direction: same
    has_value_gap: false
    comparison_type: null
    comparison_source_title: ''
    comparison_source_arxiv: ''
    is_best: false
    is_std_outlier: false
  - model: SA
    model_key: sa
    model_plain: SA
    value: 0.158
    std: null
    paper_value: 0.158
    paper_std: null
    metric: Accuracy
    higher_is_better: true
    is_baseline: true
    is_overridden: false
    override_reason: ''
    params_millions: null
    architecture_type: gnn
    architecture_label: GNN
    architecture_title: Message-passing GNN
    uses_external_data: 0
    input_feature_source: null
    feature_source_evidence: ''
    table_ref: Table 1
    source_ref: this paper
    variant_inference_reason: 'dataset: exact match'
    evaluation_task: graph_classification
    protocol_decision: standard
    protocol_note: ACC@10% on REDDIT-MULTI-5K
    date: Apr 23, 2022
    date_display: Apr 2022
    date_iso: '2022-04-23'
    published_venue: ''
    published_conference: ''
    at_pub_value: null
    at_pub_std: null
    at_pub_source_arxiv: ''
    at_pub_source_title: ''
    at_pub_source_date_iso: ''
    at_pub_source_date_label: ''
    value_gap_source_date_iso: '2022-04-23'
    value_gap_source_date_label: '2022'
    gap_vs_at_pub: null
    worse_than_at_pub: false
    surpassed_since_pub: false
    better_than_at_pub: false
    insignificant_improvement_at_pub: false
    improvement_surpassed_since_pub: false
    insignificant_value_gap: false
    today_delta_significant: false
    true_value: 0.158
    true_std: null
    value_gap_source_arxiv: '2204.11028'
    value_gap_source_title: Reinforced Causal Explainer for Graph Neural Networks
    value_gap_source_is_current_paper: true
    value_gap: null
    has_value_note: false
    value_note: ''
    sort_value: 0.158
    sort_std: null
    global_rank: 43
    paper_rank: 43
    rank_delta: 0
    rank_delta_abs: 0
    rank_delta_direction: same
    has_value_gap: false
    comparison_type: null
    comparison_source_title: ''
    comparison_source_arxiv: ''
    is_best: false
    is_std_outlier: false
  - model: Grad-CAM
    model_key: grad-cam
    model_plain: Grad-CAM
    value: 0.158
    std: null
    paper_value: 0.158
    paper_std: null
    metric: Accuracy
    higher_is_better: true
    is_baseline: true
    is_overridden: false
    override_reason: ''
    params_millions: null
    architecture_type: gnn
    architecture_label: GNN
    architecture_title: Message-passing GNN
    uses_external_data: 0
    input_feature_source: null
    feature_source_evidence: ''
    table_ref: Table 1
    source_ref: this paper
    variant_inference_reason: 'dataset: exact match'
    evaluation_task: graph_classification
    protocol_decision: standard
    protocol_note: ACC@10% on REDDIT-MULTI-5K
    date: Apr 23, 2022
    date_display: Apr 2022
    date_iso: '2022-04-23'
    published_venue: ''
    published_conference: ''
    at_pub_value: null
    at_pub_std: null
    at_pub_source_arxiv: ''
    at_pub_source_title: ''
    at_pub_source_date_iso: ''
    at_pub_source_date_label: ''
    value_gap_source_date_iso: '2022-04-23'
    value_gap_source_date_label: '2022'
    gap_vs_at_pub: null
    worse_than_at_pub: false
    surpassed_since_pub: false
    better_than_at_pub: false
    insignificant_improvement_at_pub: false
    improvement_surpassed_since_pub: false
    insignificant_value_gap: false
    today_delta_significant: false
    true_value: 0.158
    true_std: null
    value_gap_source_arxiv: '2204.11028'
    value_gap_source_title: Reinforced Causal Explainer for Graph Neural Networks
    value_gap_source_is_current_paper: true
    value_gap: null
    has_value_note: false
    value_note: ''
    sort_value: 0.158
    sort_std: null
    global_rank: 44
    paper_rank: 44
    rank_delta: 0
    rank_delta_abs: 0
    rank_delta_direction: same
    has_value_gap: false
    comparison_type: null
    comparison_source_title: ''
    comparison_source_arxiv: ''
    is_best: false
    is_std_outlier: false
  - model: GNNExplainer
    model_key: gnnexplainer
    model_plain: GNNExplainer
    value: 0.125
    std: null
    paper_value: 0.125
    paper_std: null
    metric: Accuracy
    higher_is_better: true
    is_baseline: false
    is_overridden: false
    override_reason: ''
    params_millions: null
    architecture_type: gnn
    architecture_label: GNN
    architecture_title: Message-passing GNN
    uses_external_data: 0
    input_feature_source: null
    feature_source_evidence: ''
    table_ref: Table 1
    source_ref: this paper
    variant_inference_reason: 'dataset: exact match'
    evaluation_task: graph_classification
    protocol_decision: standard
    protocol_note: ACC@10% on REDDIT-MULTI-5K
    date: Apr 23, 2022
    date_display: Apr 2022
    date_iso: '2022-04-23'
    published_venue: ''
    published_conference: ''
    at_pub_value: null
    at_pub_std: null
    at_pub_source_arxiv: ''
    at_pub_source_title: ''
    at_pub_source_date_iso: ''
    at_pub_source_date_label: ''
    value_gap_source_date_iso: '2022-04-23'
    value_gap_source_date_label: '2022'
    gap_vs_at_pub: null
    worse_than_at_pub: false
    surpassed_since_pub: false
    better_than_at_pub: false
    insignificant_improvement_at_pub: false
    improvement_surpassed_since_pub: false
    insignificant_value_gap: false
    today_delta_significant: false
    true_value: 0.125
    true_std: null
    value_gap_source_arxiv: '2204.11028'
    value_gap_source_title: Reinforced Causal Explainer for Graph Neural Networks
    value_gap_source_is_current_paper: true
    value_gap: null
    has_value_note: false
    value_note: ''
    sort_value: 0.125
    sort_std: null
    global_rank: 45
    paper_rank: 45
    rank_delta: 0
    rank_delta_abs: 0
    rank_delta_direction: same
    has_value_gap: false
    comparison_type: null
    comparison_source_title: ''
    comparison_source_arxiv: ''
    is_best: false
    is_std_outlier: false
  rank_metric: Accuracy
  higher_is_better: true
  experiment_scope: graph-level
  dataset_primary_metric: Accuracy
  paper_metrics:
  - Accuracy
  metric: Accuracy
  uses_non_primary_metric: false
  paper_has_primary_metric: true
results_grouped:
- benchmark: TU Dortmund
  datasets:
  - *id001
datasets_by_scope:
- scope: graph-level
  label: Graph-level
  benchmarks:
  - benchmark: TU Dortmund
    benchmark_slug: tu-dortmund
    datasets:
    - dataset: REDDIT-MULTI-5K
      dataset_slug: reddit-multi-5k
main_figure: /figures/2204.11028/main_figure.jpegoptim.jpg
---

