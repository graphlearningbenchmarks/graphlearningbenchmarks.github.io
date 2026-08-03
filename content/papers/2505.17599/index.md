---
title: Dynamic Bundling with Large Language Models for Zero-Shot Inference on Text-Attributed
  Graphs
arxiv_id: '2505.17599'
source_url: ''
authors:
- name: Yusheng Zhao
  orcid: null
  s2_author_id: '2124210104'
  s2_url: null
- name: Qixin Zhang
  orcid: null
  s2_author_id: '2363414178'
  s2_url: null
- name: Xiao Luo
  orcid: null
  s2_author_id: '2256770719'
  s2_url: null
- name: Weizhi Zhang
  orcid: null
  s2_author_id: '2267498932'
  s2_url: null
- name: Zhiping Xiao
  orcid: null
  s2_author_id: '2277282523'
  s2_url: null
- name: Wei Ju
  orcid: null
  s2_author_id: '2154453854'
  s2_url: null
- name: Philip S. Yu
  orcid: null
  s2_author_id: '2298201493'
  s2_url: null
- name: Ming Zhang
  orcid: null
  s2_author_id: '1596795872'
  s2_url: null
published_date: May 23, 2025
published_date_iso: '2025-05-23'
published_venue: NeurIPS 2025
published_conference: NeurIPS 2025
published_conference_short: NeurIPS
published_conference_slug: neurips
abstract: 'Large language models (LLMs) have been used in many zero-shot learning
  problems, with their strong generalization ability. Recently, adopting LLMs in text-attributed
  graphs (TAGs) has drawn increasing attention. However, the adoption of LLMs faces
  two major challenges: limited information on graph structure and unreliable responses.
  LLMs struggle with text attributes isolated from the graph topology. Worse still,
  they yield unreliable predictions due to both information insufficiency and the
  inherent weakness of LLMs (e.g., hallucination). Towards this end, this paper proposes
  a novel method named ynamic T xt Bu dling up rvision (DENSE) that queries LLMs with
  bundles of texts to obtain bundle-level labels and uses these labels to supervise
  graph neural networks. Specifically, we sample a set of bundles, each containing
  a set of nodes with corresponding texts of close proximity. We then query LLMs with
  the bundled texts to obtain the label of each bundle. Subsequently, the bundle labels
  are used to supervise the optimization of graph neural networks, and the bundles
  are further refined to exclude noisy items. To justify our design, we also provide
  theoretical analysis of the proposed method. Extensive experiments across ten datasets
  validate the effectiveness of the proposed method.'
codebase_url: ''
extraction_model: cyankiwi/gemma-4-26B-A4B-it-AWQ-4bit
has_results: true
paper_type: method
proposed_models:
- DENSE
mrr: 0.0132
adjusted_mrr: 0.0132
mrr_dataset_count: 3
benchmark_categories:
- Classic
- Heterophilic Graphs
benchmark_coverage:
- benchmark: Classic
  benchmark_slug: classic
  evaluated: 1
  total: 12
- benchmark: Heterophilic Graphs
  benchmark_slug: heterophilic-graphs
  evaluated: 2
  total: 13
task_categories:
- node_classification
experiment_scopes:
- node-level
results:
- &id003
  dataset: Cornell
  rows:
  - model: Kron
    model_key: p^2gnn
    model_plain: Kron
    value: 0.9541
    std: 0.0272
    metric: Accuracy
    higher_is_better: true
    is_baseline: false
    is_overridden: false
    override_reason: ''
    params_millions: null
    architecture_type: hybrid
    architecture_label: Hyb
    architecture_title: Hybrid MPNN + transformer
    arxiv_id: '2603.09195'
    title: '$P^2$GNN: Two Prototype Sets to boost GNN Performance'
    date: Mar 10, 2026
    date_display: Mar 2026
    date_iso: '2026-03-10'
    venue: arXiv.org
    codebase_url: ''
    uses_external_data: false
    input_feature_source: null
    feature_source_evidence: ''
    is_global_top: true
    global_rank: 1
    sort_value: 0.9541
    sort_std: 0.0272
    comparison_type: global_top
    comparison_source_title: ''
    comparison_source_arxiv: ''
    is_best: true
    is_std_outlier: false
  - model: Kron
    model_key: acm-gcn
    model_plain: Kron
    value: 0.948
    std: 0.038
    metric: Accuracy
    higher_is_better: true
    is_baseline: true
    is_overridden: false
    override_reason: ''
    params_millions: null
    architecture_type: gnn
    architecture_label: GNN
    architecture_title: Message-passing GNN
    arxiv_id: '2504.19785'
    title: Heterophily-informed Message Passing
    date: Apr 28, 2025
    date_display: Apr 2025
    date_iso: '2025-04-28'
    venue: Trans. Mach. Learn. Res.
    codebase_url: https://github.com/AaltoML/heterophily-imp
    uses_external_data: false
    input_feature_source: null
    feature_source_evidence: ''
    is_global_top: true
    global_rank: 2
    sort_value: 0.948
    sort_std: 0.038
    comparison_type: global_top
    comparison_source_title: ''
    comparison_source_arxiv: ''
    is_best: true
    is_std_outlier: false
  - model: Kron
    model_key: rf-gcn
    model_plain: Kron
    value: 0.9429
    std: null
    metric: Accuracy
    higher_is_better: true
    is_baseline: false
    is_overridden: false
    override_reason: ''
    params_millions: null
    architecture_type: gnn
    architecture_label: GNN
    architecture_title: Message-passing GNN
    arxiv_id: '2504.13426'
    title: Simplifying Graph Convolutional Networks with Redundancy-Free Neighbors
    date: Apr 18, 2025
    date_display: Apr 2025
    date_iso: '2025-04-18'
    venue: null
    codebase_url: ''
    uses_external_data: false
    input_feature_source: null
    feature_source_evidence: ''
    is_global_top: true
    global_rank: 3
    sort_value: 0.9429
    sort_std: null
    comparison_type: global_top
    comparison_source_title: ''
    comparison_source_arxiv: ''
    is_best: true
    is_std_outlier: false
  - model: DENSE
    model_key: dense
    model_plain: DENSE
    value: 0.8482
    std: null
    paper_value: 0.8482
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
    uses_external_data: 1
    input_feature_source: null
    feature_source_evidence: ''
    table_ref: Table 1
    source_ref: this paper
    variant_inference_reason: 'dataset: exact match'
    evaluation_task: node_classification
    protocol_decision: standard
    protocol_note: Standard node classification on Cornell web page network.
    date: May 23, 2025
    date_display: May 2025
    date_iso: '2025-05-23'
    published_venue: NeurIPS 2025
    published_conference: NeurIPS 2025
    at_pub_value: null
    at_pub_std: null
    at_pub_source_arxiv: ''
    at_pub_source_title: ''
    at_pub_source_date_iso: ''
    at_pub_source_date_label: ''
    value_gap_source_date_iso: '2025-05-23'
    value_gap_source_date_label: NeurIPS 2025
    gap_vs_at_pub: null
    worse_than_at_pub: false
    surpassed_since_pub: false
    better_than_at_pub: false
    insignificant_improvement_at_pub: false
    improvement_surpassed_since_pub: false
    insignificant_value_gap: false
    today_delta_significant: false
    true_value: 0.8482
    true_std: null
    value_gap_source_arxiv: '2505.17599'
    value_gap_source_title: Dynamic Bundling with Large Language Models for Zero-Shot
      Inference on Text-Attributed Graphs
    value_gap_source_is_current_paper: true
    value_gap: null
    has_value_note: false
    value_note: ''
    sort_value: 0.8482
    sort_std: null
    global_rank: 109
    paper_rank: 109
    rank_delta: 0
    rank_delta_abs: 0
    rank_delta_direction: same
    has_value_gap: false
    comparison_type: null
    comparison_source_title: ''
    comparison_source_arxiv: ''
    is_best: false
    is_std_outlier: false
  - model: LLM-BP
    model_key: llm-bp
    model_plain: LLM-BP
    value: 0.8328
    std: null
    paper_value: 0.8328
    paper_std: null
    metric: Accuracy
    higher_is_better: true
    is_baseline: true
    is_overridden: false
    override_reason: ''
    params_millions: null
    architecture_type: hybrid
    architecture_label: Hyb
    architecture_title: Hybrid MPNN + transformer
    uses_external_data: 1
    input_feature_source: null
    feature_source_evidence: ''
    table_ref: Table 1
    source_ref: wang2025model
    variant_inference_reason: 'dataset: exact match'
    evaluation_task: node_classification
    protocol_decision: standard
    protocol_note: Standard node classification on Cornell web page network.
    date: May 23, 2025
    date_display: May 2025
    date_iso: '2025-05-23'
    published_venue: NeurIPS 2025
    published_conference: NeurIPS 2025
    at_pub_value: null
    at_pub_std: null
    at_pub_source_arxiv: ''
    at_pub_source_title: ''
    at_pub_source_date_iso: ''
    at_pub_source_date_label: ''
    value_gap_source_date_iso: '2025-05-23'
    value_gap_source_date_label: NeurIPS 2025
    gap_vs_at_pub: null
    worse_than_at_pub: false
    surpassed_since_pub: false
    better_than_at_pub: false
    insignificant_improvement_at_pub: false
    improvement_surpassed_since_pub: false
    insignificant_value_gap: false
    today_delta_significant: false
    true_value: 0.8328
    true_std: null
    value_gap_source_arxiv: '2505.17599'
    value_gap_source_title: Dynamic Bundling with Large Language Models for Zero-Shot
      Inference on Text-Attributed Graphs
    value_gap_source_is_current_paper: true
    value_gap: null
    has_value_note: false
    value_note: ''
    sort_value: 0.8328
    sort_std: null
    global_rank: 137
    paper_rank: 137
    rank_delta: 0
    rank_delta_abs: 0
    rank_delta_direction: same
    has_value_gap: false
    comparison_type: null
    comparison_source_title: ''
    comparison_source_arxiv: ''
    is_best: false
    is_std_outlier: false
  - model: TE-3-Large
    model_key: te-3-large
    model_plain: TE-3-Large
    value: 0.815
    std: null
    paper_value: 0.815
    paper_std: null
    metric: Accuracy
    higher_is_better: true
    is_baseline: true
    is_overridden: false
    override_reason: ''
    params_millions: null
    architecture_type: null
    architecture_label: null
    architecture_title: ''
    uses_external_data: 1
    input_feature_source: null
    feature_source_evidence: ''
    table_ref: Table 1
    source_ref: openai2024textembedding
    variant_inference_reason: 'dataset: exact match'
    evaluation_task: node_classification
    protocol_decision: standard
    protocol_note: Standard node classification on Cornell web page network.
    date: May 23, 2025
    date_display: May 2025
    date_iso: '2025-05-23'
    published_venue: NeurIPS 2025
    published_conference: NeurIPS 2025
    at_pub_value: null
    at_pub_std: null
    at_pub_source_arxiv: ''
    at_pub_source_title: ''
    at_pub_source_date_iso: ''
    at_pub_source_date_label: ''
    value_gap_source_date_iso: '2025-05-23'
    value_gap_source_date_label: NeurIPS 2025
    gap_vs_at_pub: null
    worse_than_at_pub: false
    surpassed_since_pub: false
    better_than_at_pub: false
    insignificant_improvement_at_pub: false
    improvement_surpassed_since_pub: false
    insignificant_value_gap: false
    today_delta_significant: false
    true_value: 0.815
    true_std: null
    value_gap_source_arxiv: '2505.17599'
    value_gap_source_title: Dynamic Bundling with Large Language Models for Zero-Shot
      Inference on Text-Attributed Graphs
    value_gap_source_is_current_paper: true
    value_gap: null
    has_value_note: false
    value_note: ''
    sort_value: 0.815
    sort_std: null
    global_rank: 168
    paper_rank: 168
    rank_delta: 0
    rank_delta_abs: 0
    rank_delta_direction: same
    has_value_gap: false
    comparison_type: null
    comparison_source_title: ''
    comparison_source_arxiv: ''
    is_best: false
    is_std_outlier: false
  - model: LLM2Vec
    model_key: llm2vec
    model_plain: LLM2Vec
    value: 0.8126
    std: null
    paper_value: 0.8126
    paper_std: null
    metric: Accuracy
    higher_is_better: true
    is_baseline: true
    is_overridden: false
    override_reason: ''
    params_millions: null
    architecture_type: null
    architecture_label: null
    architecture_title: ''
    uses_external_data: 1
    input_feature_source: null
    feature_source_evidence: ''
    table_ref: Table 1
    source_ref: behnamghader2024llm2vec
    variant_inference_reason: 'dataset: exact match'
    evaluation_task: node_classification
    protocol_decision: standard
    protocol_note: Standard node classification on Cornell web page network.
    date: May 23, 2025
    date_display: May 2025
    date_iso: '2025-05-23'
    published_venue: NeurIPS 2025
    published_conference: NeurIPS 2025
    at_pub_value: 0.8126
    at_pub_std: null
    at_pub_source_arxiv: '2502.11836'
    at_pub_source_title: 'Model Generalization on Text Attribute Graphs: Principles
      with Large Language Models'
    at_pub_source_date_iso: '2025-02-17'
    at_pub_source_date_label: '2025'
    value_gap_source_date_iso: '2025-05-23'
    value_gap_source_date_label: NeurIPS 2025
    gap_vs_at_pub: null
    worse_than_at_pub: false
    surpassed_since_pub: false
    better_than_at_pub: false
    insignificant_improvement_at_pub: false
    improvement_surpassed_since_pub: false
    insignificant_value_gap: false
    today_delta_significant: false
    true_value: 0.8126
    true_std: null
    value_gap_source_arxiv: '2505.17599'
    value_gap_source_title: Dynamic Bundling with Large Language Models for Zero-Shot
      Inference on Text-Attributed Graphs
    value_gap_source_is_current_paper: true
    value_gap: null
    has_value_note: false
    value_note: ''
    sort_value: 0.8126
    sort_std: null
    global_rank: 173
    paper_rank: 173
    rank_delta: 0
    rank_delta_abs: 0
    rank_delta_direction: same
    has_value_gap: false
    comparison_type: null
    comparison_source_title: ''
    comparison_source_arxiv: ''
    is_best: false
    is_std_outlier: false
  - model: GraphMAE
    model_key: graphmae
    model_plain: GraphMAE
    value: 0.2304
    std: null
    paper_value: 0.2304
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
    source_ref: hou2022graphmae
    variant_inference_reason: 'dataset: exact match'
    evaluation_task: node_classification
    protocol_decision: standard
    protocol_note: Standard node classification on Cornell web page network.
    date: May 23, 2025
    date_display: May 2025
    date_iso: '2025-05-23'
    published_venue: NeurIPS 2025
    published_conference: NeurIPS 2025
    at_pub_value: 0.7514
    at_pub_std: 0.0965
    at_pub_source_arxiv: '2408.13471'
    at_pub_source_title: Disentangled Generative Graph Representation Learning
    at_pub_source_date_iso: '2024-08-24'
    at_pub_source_date_label: '2024'
    value_gap_source_date_iso: '2024-08-24'
    value_gap_source_date_label: '2024'
    gap_vs_at_pub: 0.5209999999999999
    worse_than_at_pub: true
    surpassed_since_pub: false
    better_than_at_pub: false
    insignificant_improvement_at_pub: false
    improvement_surpassed_since_pub: false
    insignificant_value_gap: false
    today_delta_significant: true
    true_value: 0.7514
    true_std: 0.0965
    value_gap_source_arxiv: '2408.13471'
    value_gap_source_title: Disentangled Generative Graph Representation Learning
    value_gap_source_is_current_paper: false
    value_gap: 0.5209999999999999
    has_value_note: false
    value_note: ''
    sort_value: 0.7514
    sort_std: 0.0965
    global_rank: 249
    paper_rank: 565
    rank_delta: 316
    rank_delta_abs: 316
    rank_delta_direction: worse
    has_value_gap: true
    comparison_type: behind
    comparison_source_title: Disentangled Generative Graph Representation Learning
    comparison_source_arxiv: '2408.13471'
    is_best: false
    is_std_outlier: false
  - model: DGI
    model_key: dgi
    model_plain: DGI
    value: 0.1466
    std: null
    paper_value: 0.1466
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
    source_ref: velivckovic2018deep
    variant_inference_reason: 'dataset: exact match'
    evaluation_task: node_classification
    protocol_decision: standard
    protocol_note: Standard node classification on Cornell web page network.
    date: May 23, 2025
    date_display: May 2025
    date_iso: '2025-05-23'
    published_venue: NeurIPS 2025
    published_conference: NeurIPS 2025
    at_pub_value: 0.6335
    at_pub_std: 0.0461
    at_pub_source_arxiv: '2211.14065'
    at_pub_source_title: 'Beyond Smoothing: Unsupervised Graph Representation Learning
      with Edge Heterophily Discriminating'
    at_pub_source_date_iso: '2022-11-25'
    at_pub_source_date_label: AAAI 2022
    value_gap_source_date_iso: '2026-04-02'
    value_gap_source_date_label: '2026'
    gap_vs_at_pub: 0.48689999999999994
    worse_than_at_pub: true
    surpassed_since_pub: false
    better_than_at_pub: false
    insignificant_improvement_at_pub: false
    improvement_surpassed_since_pub: false
    insignificant_value_gap: false
    today_delta_significant: true
    true_value: 0.7082
    true_std: 0.0271
    value_gap_source_arxiv: '2604.01878'
    value_gap_source_title: 'ASPECT: Node-Level Adaptive Spectral Fusion for Graph
      Contrastive Learning'
    value_gap_source_is_current_paper: false
    value_gap: 0.5616000000000001
    has_value_note: false
    value_note: ''
    sort_value: 0.7082
    sort_std: 0.0271
    global_rank: 284
    paper_rank: 574
    rank_delta: 290
    rank_delta_abs: 290
    rank_delta_direction: worse
    has_value_gap: true
    comparison_type: behind
    comparison_source_title: 'Beyond Smoothing: Unsupervised Graph Representation
      Learning with Edge Heterophily Discriminating'
    comparison_source_arxiv: '2211.14065'
    is_best: false
    is_std_outlier: false
  - model: SBERT
    model_key: sbert
    model_plain: SBERT
    value: 0.6366
    std: null
    paper_value: 0.6366
    paper_std: null
    metric: Accuracy
    higher_is_better: true
    is_baseline: true
    is_overridden: false
    override_reason: ''
    params_millions: null
    architecture_type: llm
    architecture_label: LLM
    architecture_title: LLM applied to graphs
    uses_external_data: 1
    input_feature_source: null
    feature_source_evidence: ''
    table_ref: Table 1
    source_ref: reimers2019sentence
    variant_inference_reason: 'dataset: exact match'
    evaluation_task: node_classification
    protocol_decision: standard
    protocol_note: Standard node classification on Cornell web page network.
    date: May 23, 2025
    date_display: May 2025
    date_iso: '2025-05-23'
    published_venue: NeurIPS 2025
    published_conference: NeurIPS 2025
    at_pub_value: 0.6366
    at_pub_std: null
    at_pub_source_arxiv: '2502.11836'
    at_pub_source_title: 'Model Generalization on Text Attribute Graphs: Principles
      with Large Language Models'
    at_pub_source_date_iso: '2025-02-17'
    at_pub_source_date_label: '2025'
    value_gap_source_date_iso: '2025-05-23'
    value_gap_source_date_label: NeurIPS 2025
    gap_vs_at_pub: null
    worse_than_at_pub: false
    surpassed_since_pub: false
    better_than_at_pub: false
    insignificant_improvement_at_pub: false
    improvement_surpassed_since_pub: false
    insignificant_value_gap: false
    today_delta_significant: false
    true_value: 0.6366
    true_std: null
    value_gap_source_arxiv: '2505.17599'
    value_gap_source_title: Dynamic Bundling with Large Language Models for Zero-Shot
      Inference on Text-Attributed Graphs
    value_gap_source_is_current_paper: true
    value_gap: null
    has_value_note: false
    value_note: ''
    sort_value: 0.6366
    sort_std: null
    global_rank: 347
    paper_rank: 347
    rank_delta: 0
    rank_delta_abs: 0
    rank_delta_direction: same
    has_value_gap: false
    comparison_type: null
    comparison_source_title: ''
    comparison_source_arxiv: ''
    is_best: false
    is_std_outlier: false
  - model: RoBERTa
    model_key: roberta
    model_plain: RoBERTa
    value: 0.6168
    std: null
    paper_value: 0.6168
    paper_std: null
    metric: Accuracy
    higher_is_better: true
    is_baseline: true
    is_overridden: false
    override_reason: ''
    params_millions: null
    architecture_type: llm
    architecture_label: LLM
    architecture_title: LLM applied to graphs
    uses_external_data: 1
    input_feature_source: null
    feature_source_evidence: ''
    table_ref: Table 1
    source_ref: liu2019roberta
    variant_inference_reason: 'dataset: exact match'
    evaluation_task: node_classification
    protocol_decision: standard
    protocol_note: Standard node classification on Cornell web page network.
    date: May 23, 2025
    date_display: May 2025
    date_iso: '2025-05-23'
    published_venue: NeurIPS 2025
    published_conference: NeurIPS 2025
    at_pub_value: 0.6168
    at_pub_std: null
    at_pub_source_arxiv: '2502.11836'
    at_pub_source_title: 'Model Generalization on Text Attribute Graphs: Principles
      with Large Language Models'
    at_pub_source_date_iso: '2025-02-17'
    at_pub_source_date_label: '2025'
    value_gap_source_date_iso: '2025-05-23'
    value_gap_source_date_label: NeurIPS 2025
    gap_vs_at_pub: null
    worse_than_at_pub: false
    surpassed_since_pub: false
    better_than_at_pub: false
    insignificant_improvement_at_pub: false
    improvement_surpassed_since_pub: false
    insignificant_value_gap: false
    today_delta_significant: false
    true_value: 0.6168
    true_std: null
    value_gap_source_arxiv: '2505.17599'
    value_gap_source_title: Dynamic Bundling with Large Language Models for Zero-Shot
      Inference on Text-Attributed Graphs
    value_gap_source_is_current_paper: true
    value_gap: null
    has_value_note: false
    value_note: ''
    sort_value: 0.6168
    sort_std: null
    global_rank: 354
    paper_rank: 354
    rank_delta: 0
    rank_delta_abs: 0
    rank_delta_direction: same
    has_value_gap: false
    comparison_type: null
    comparison_source_title: ''
    comparison_source_arxiv: ''
    is_best: false
    is_std_outlier: false
  - model: GPT-3.5-turbo
    model_key: gpt-3.5-turbo
    model_plain: GPT-3.5-turbo
    value: 0.4554
    std: null
    paper_value: 0.4554
    paper_std: null
    metric: Accuracy
    higher_is_better: true
    is_baseline: true
    is_overridden: false
    override_reason: ''
    params_millions: null
    architecture_type: llm
    architecture_label: LLM
    architecture_title: LLM applied to graphs
    uses_external_data: 1
    input_feature_source: null
    feature_source_evidence: ''
    table_ref: Table 1
    source_ref: achiam2023gpt
    variant_inference_reason: 'dataset: exact match'
    evaluation_task: node_classification
    protocol_decision: standard
    protocol_note: Standard node classification on Cornell web page network.
    date: May 23, 2025
    date_display: May 2025
    date_iso: '2025-05-23'
    published_venue: NeurIPS 2025
    published_conference: NeurIPS 2025
    at_pub_value: 0.4554
    at_pub_std: null
    at_pub_source_arxiv: '2502.11836'
    at_pub_source_title: 'Model Generalization on Text Attribute Graphs: Principles
      with Large Language Models'
    at_pub_source_date_iso: '2025-02-17'
    at_pub_source_date_label: '2025'
    value_gap_source_date_iso: '2025-05-23'
    value_gap_source_date_label: NeurIPS 2025
    gap_vs_at_pub: null
    worse_than_at_pub: false
    surpassed_since_pub: false
    better_than_at_pub: false
    insignificant_improvement_at_pub: false
    improvement_surpassed_since_pub: false
    insignificant_value_gap: false
    today_delta_significant: false
    true_value: 0.4554
    true_std: null
    value_gap_source_arxiv: '2505.17599'
    value_gap_source_title: Dynamic Bundling with Large Language Models for Zero-Shot
      Inference on Text-Attributed Graphs
    value_gap_source_is_current_paper: true
    value_gap: null
    has_value_note: false
    value_note: ''
    sort_value: 0.4554
    sort_std: null
    global_rank: 499
    paper_rank: 499
    rank_delta: 0
    rank_delta_abs: 0
    rank_delta_direction: same
    has_value_gap: false
    comparison_type: null
    comparison_source_title: ''
    comparison_source_arxiv: ''
    is_best: false
    is_std_outlier: false
  - model: GPT-4o
    model_key: gpt-4o
    model_plain: GPT-4o
    value: 0.4554
    std: null
    paper_value: 0.4554
    paper_std: null
    metric: Accuracy
    higher_is_better: true
    is_baseline: true
    is_overridden: false
    override_reason: ''
    params_millions: null
    architecture_type: llm
    architecture_label: LLM
    architecture_title: LLM applied to graphs
    uses_external_data: 1
    input_feature_source: null
    feature_source_evidence: ''
    table_ref: Table 1
    source_ref: hurst2024gpt
    variant_inference_reason: 'dataset: exact match'
    evaluation_task: node_classification
    protocol_decision: standard
    protocol_note: Standard node classification on Cornell web page network.
    date: May 23, 2025
    date_display: May 2025
    date_iso: '2025-05-23'
    published_venue: NeurIPS 2025
    published_conference: NeurIPS 2025
    at_pub_value: 0.4554
    at_pub_std: null
    at_pub_source_arxiv: '2502.11836'
    at_pub_source_title: 'Model Generalization on Text Attribute Graphs: Principles
      with Large Language Models'
    at_pub_source_date_iso: '2025-02-17'
    at_pub_source_date_label: '2025'
    value_gap_source_date_iso: '2025-05-23'
    value_gap_source_date_label: NeurIPS 2025
    gap_vs_at_pub: null
    worse_than_at_pub: false
    surpassed_since_pub: false
    better_than_at_pub: false
    insignificant_improvement_at_pub: false
    improvement_surpassed_since_pub: false
    insignificant_value_gap: false
    today_delta_significant: false
    true_value: 0.4554
    true_std: null
    value_gap_source_arxiv: '2505.17599'
    value_gap_source_title: Dynamic Bundling with Large Language Models for Zero-Shot
      Inference on Text-Attributed Graphs
    value_gap_source_is_current_paper: true
    value_gap: null
    has_value_note: false
    value_note: ''
    sort_value: 0.4554
    sort_std: null
    global_rank: 500
    paper_rank: 500
    rank_delta: 0
    rank_delta_abs: 0
    rank_delta_direction: same
    has_value_gap: false
    comparison_type: null
    comparison_source_title: ''
    comparison_source_arxiv: ''
    is_best: false
    is_std_outlier: false
  - model: GOFA
    model_key: gofa
    model_plain: GOFA
    value: 0.395
    std: null
    paper_value: 0.395
    paper_std: null
    metric: Accuracy
    higher_is_better: true
    is_baseline: true
    is_overridden: false
    override_reason: ''
    params_millions: null
    architecture_type: llm
    architecture_label: LLM
    architecture_title: LLM applied to graphs
    uses_external_data: 1
    input_feature_source: null
    feature_source_evidence: ''
    table_ref: Table 1
    source_ref: kong2024gofa
    variant_inference_reason: 'dataset: exact match'
    evaluation_task: node_classification
    protocol_decision: standard
    protocol_note: Standard node classification on Cornell web page network.
    date: May 23, 2025
    date_display: May 2025
    date_iso: '2025-05-23'
    published_venue: NeurIPS 2025
    published_conference: NeurIPS 2025
    at_pub_value: 0.395
    at_pub_std: null
    at_pub_source_arxiv: '2502.11836'
    at_pub_source_title: 'Model Generalization on Text Attribute Graphs: Principles
      with Large Language Models'
    at_pub_source_date_iso: '2025-02-17'
    at_pub_source_date_label: '2025'
    value_gap_source_date_iso: '2025-05-23'
    value_gap_source_date_label: NeurIPS 2025
    gap_vs_at_pub: null
    worse_than_at_pub: false
    surpassed_since_pub: false
    better_than_at_pub: false
    insignificant_improvement_at_pub: false
    improvement_surpassed_since_pub: false
    insignificant_value_gap: false
    today_delta_significant: false
    true_value: 0.395
    true_std: null
    value_gap_source_arxiv: '2505.17599'
    value_gap_source_title: Dynamic Bundling with Large Language Models for Zero-Shot
      Inference on Text-Attributed Graphs
    value_gap_source_is_current_paper: true
    value_gap: null
    has_value_note: false
    value_note: ''
    sort_value: 0.395
    sort_std: null
    global_rank: 531
    paper_rank: 531
    rank_delta: 0
    rank_delta_abs: 0
    rank_delta_direction: same
    has_value_gap: false
    comparison_type: null
    comparison_source_title: ''
    comparison_source_arxiv: ''
    is_best: false
    is_std_outlier: false
  - model: OFA
    model_key: ofa
    model_plain: OFA
    value: 0.2984
    std: null
    paper_value: 0.2984
    paper_std: null
    metric: Accuracy
    higher_is_better: true
    is_baseline: true
    is_overridden: false
    override_reason: ''
    params_millions: null
    architecture_type: llm
    architecture_label: LLM
    architecture_title: LLM applied to graphs
    uses_external_data: 1
    input_feature_source: null
    feature_source_evidence: ''
    table_ref: Table 1
    source_ref: liu2023one
    variant_inference_reason: 'dataset: exact match'
    evaluation_task: node_classification
    protocol_decision: standard
    protocol_note: Standard node classification on Cornell web page network.
    date: May 23, 2025
    date_display: May 2025
    date_iso: '2025-05-23'
    published_venue: NeurIPS 2025
    published_conference: NeurIPS 2025
    at_pub_value: 0.2984
    at_pub_std: null
    at_pub_source_arxiv: '2502.11836'
    at_pub_source_title: 'Model Generalization on Text Attribute Graphs: Principles
      with Large Language Models'
    at_pub_source_date_iso: '2025-02-17'
    at_pub_source_date_label: '2025'
    value_gap_source_date_iso: '2025-05-23'
    value_gap_source_date_label: NeurIPS 2025
    gap_vs_at_pub: null
    worse_than_at_pub: false
    surpassed_since_pub: false
    better_than_at_pub: false
    insignificant_improvement_at_pub: false
    improvement_surpassed_since_pub: false
    insignificant_value_gap: false
    today_delta_significant: false
    true_value: 0.2984
    true_std: null
    value_gap_source_arxiv: '2505.17599'
    value_gap_source_title: Dynamic Bundling with Large Language Models for Zero-Shot
      Inference on Text-Attributed Graphs
    value_gap_source_is_current_paper: true
    value_gap: null
    has_value_note: false
    value_note: ''
    sort_value: 0.2984
    sort_std: null
    global_rank: 549
    paper_rank: 549
    rank_delta: 0
    rank_delta_abs: 0
    rank_delta_direction: same
    has_value_gap: false
    comparison_type: null
    comparison_source_title: ''
    comparison_source_arxiv: ''
    is_best: false
    is_std_outlier: false
  - model: UniGLM
    model_key: uniglm
    model_plain: UniGLM
    value: 0.2303
    std: null
    paper_value: 0.2303
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
    uses_external_data: 1
    input_feature_source: null
    feature_source_evidence: ''
    table_ref: Table 1
    source_ref: fang2024uniglm
    variant_inference_reason: 'dataset: exact match'
    evaluation_task: node_classification
    protocol_decision: standard
    protocol_note: Standard node classification on Cornell web page network.
    date: May 23, 2025
    date_display: May 2025
    date_iso: '2025-05-23'
    published_venue: NeurIPS 2025
    published_conference: NeurIPS 2025
    at_pub_value: 0.2303
    at_pub_std: null
    at_pub_source_arxiv: '2502.11836'
    at_pub_source_title: 'Model Generalization on Text Attribute Graphs: Principles
      with Large Language Models'
    at_pub_source_date_iso: '2025-02-17'
    at_pub_source_date_label: '2025'
    value_gap_source_date_iso: '2025-05-23'
    value_gap_source_date_label: NeurIPS 2025
    gap_vs_at_pub: null
    worse_than_at_pub: false
    surpassed_since_pub: false
    better_than_at_pub: false
    insignificant_improvement_at_pub: false
    improvement_surpassed_since_pub: false
    insignificant_value_gap: false
    today_delta_significant: false
    true_value: 0.2303
    true_std: null
    value_gap_source_arxiv: '2505.17599'
    value_gap_source_title: Dynamic Bundling with Large Language Models for Zero-Shot
      Inference on Text-Attributed Graphs
    value_gap_source_is_current_paper: true
    value_gap: null
    has_value_note: false
    value_note: ''
    sort_value: 0.2303
    sort_std: null
    global_rank: 566
    paper_rank: 566
    rank_delta: 0
    rank_delta_abs: 0
    rank_delta_direction: same
    has_value_gap: false
    comparison_type: null
    comparison_source_title: ''
    comparison_source_arxiv: ''
    is_best: false
    is_std_outlier: false
  - model: LLaGA
    model_key: llaga
    model_plain: LLaGA
    value: 0.1257
    std: null
    paper_value: 0.1257
    paper_std: null
    metric: Accuracy
    higher_is_better: true
    is_baseline: true
    is_overridden: false
    override_reason: ''
    params_millions: null
    architecture_type: llm
    architecture_label: LLM
    architecture_title: LLM applied to graphs
    uses_external_data: 1
    input_feature_source: null
    feature_source_evidence: ''
    table_ref: Table 1
    source_ref: chen2024llaga
    variant_inference_reason: 'dataset: exact match'
    evaluation_task: node_classification
    protocol_decision: standard
    protocol_note: Standard node classification on Cornell web page network.
    date: May 23, 2025
    date_display: May 2025
    date_iso: '2025-05-23'
    published_venue: NeurIPS 2025
    published_conference: NeurIPS 2025
    at_pub_value: 0.1257
    at_pub_std: null
    at_pub_source_arxiv: '2502.11836'
    at_pub_source_title: 'Model Generalization on Text Attribute Graphs: Principles
      with Large Language Models'
    at_pub_source_date_iso: '2025-02-17'
    at_pub_source_date_label: '2025'
    value_gap_source_date_iso: '2025-05-23'
    value_gap_source_date_label: NeurIPS 2025
    gap_vs_at_pub: null
    worse_than_at_pub: false
    surpassed_since_pub: false
    better_than_at_pub: false
    insignificant_improvement_at_pub: false
    improvement_surpassed_since_pub: false
    insignificant_value_gap: false
    today_delta_significant: false
    true_value: 0.1257
    true_std: null
    value_gap_source_arxiv: '2505.17599'
    value_gap_source_title: Dynamic Bundling with Large Language Models for Zero-Shot
      Inference on Text-Attributed Graphs
    value_gap_source_is_current_paper: true
    value_gap: null
    has_value_note: false
    value_note: ''
    sort_value: 0.1257
    sort_std: null
    global_rank: 575
    paper_rank: 575
    rank_delta: 0
    rank_delta_abs: 0
    rank_delta_direction: same
    has_value_gap: false
    comparison_type: null
    comparison_source_title: ''
    comparison_source_arxiv: ''
    is_best: false
    is_std_outlier: false
  - model: ZeroG
    model_key: zerog
    model_plain: ZeroG
    value: 0.1047
    std: null
    paper_value: 0.1047
    paper_std: null
    metric: Accuracy
    higher_is_better: true
    is_baseline: true
    is_overridden: false
    override_reason: ''
    params_millions: null
    architecture_type: llm
    architecture_label: LLM
    architecture_title: LLM applied to graphs
    uses_external_data: 1
    input_feature_source: null
    feature_source_evidence: ''
    table_ref: Table 1
    source_ref: li2024zerog
    variant_inference_reason: 'dataset: exact match'
    evaluation_task: node_classification
    protocol_decision: standard
    protocol_note: Standard node classification on Cornell web page network.
    date: May 23, 2025
    date_display: May 2025
    date_iso: '2025-05-23'
    published_venue: NeurIPS 2025
    published_conference: NeurIPS 2025
    at_pub_value: 0.1047
    at_pub_std: null
    at_pub_source_arxiv: '2502.11836'
    at_pub_source_title: 'Model Generalization on Text Attribute Graphs: Principles
      with Large Language Models'
    at_pub_source_date_iso: '2025-02-17'
    at_pub_source_date_label: '2025'
    value_gap_source_date_iso: '2025-05-23'
    value_gap_source_date_label: NeurIPS 2025
    gap_vs_at_pub: null
    worse_than_at_pub: false
    surpassed_since_pub: false
    better_than_at_pub: false
    insignificant_improvement_at_pub: false
    improvement_surpassed_since_pub: false
    insignificant_value_gap: false
    today_delta_significant: false
    true_value: 0.1047
    true_std: null
    value_gap_source_arxiv: '2505.17599'
    value_gap_source_title: Dynamic Bundling with Large Language Models for Zero-Shot
      Inference on Text-Attributed Graphs
    value_gap_source_is_current_paper: true
    value_gap: null
    has_value_note: false
    value_note: ''
    sort_value: 0.1047
    sort_std: null
    global_rank: 576
    paper_rank: 576
    rank_delta: 0
    rank_delta_abs: 0
    rank_delta_direction: same
    has_value_gap: false
    comparison_type: null
    comparison_source_title: ''
    comparison_source_arxiv: ''
    is_best: false
    is_std_outlier: false
  - model: GraphGPT
    model_key: graphgpt
    model_plain: GraphGPT
    value: 0.1018
    std: null
    paper_value: 0.1018
    paper_std: null
    metric: Accuracy
    higher_is_better: true
    is_baseline: true
    is_overridden: false
    override_reason: ''
    params_millions: null
    architecture_type: hybrid
    architecture_label: Hyb
    architecture_title: Hybrid MPNN + transformer
    uses_external_data: 1
    input_feature_source: null
    feature_source_evidence: ''
    table_ref: Table 1
    source_ref: tang2024graphgpt
    variant_inference_reason: 'dataset: exact match'
    evaluation_task: node_classification
    protocol_decision: standard
    protocol_note: Standard node classification on Cornell web page network.
    date: May 23, 2025
    date_display: May 2025
    date_iso: '2025-05-23'
    published_venue: NeurIPS 2025
    published_conference: NeurIPS 2025
    at_pub_value: 0.1018
    at_pub_std: null
    at_pub_source_arxiv: '2502.11836'
    at_pub_source_title: 'Model Generalization on Text Attribute Graphs: Principles
      with Large Language Models'
    at_pub_source_date_iso: '2025-02-17'
    at_pub_source_date_label: '2025'
    value_gap_source_date_iso: '2025-05-23'
    value_gap_source_date_label: NeurIPS 2025
    gap_vs_at_pub: null
    worse_than_at_pub: false
    surpassed_since_pub: false
    better_than_at_pub: false
    insignificant_improvement_at_pub: false
    improvement_surpassed_since_pub: false
    insignificant_value_gap: false
    today_delta_significant: false
    true_value: 0.1018
    true_std: null
    value_gap_source_arxiv: '2505.17599'
    value_gap_source_title: Dynamic Bundling with Large Language Models for Zero-Shot
      Inference on Text-Attributed Graphs
    value_gap_source_is_current_paper: true
    value_gap: null
    has_value_note: false
    value_note: ''
    sort_value: 0.1018
    sort_std: null
    global_rank: 577
    paper_rank: 577
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
  experiment_scope: node-level
  dataset_primary_metric: Accuracy
  paper_metrics:
  - Accuracy
  metric: Accuracy
  uses_non_primary_metric: false
  paper_has_primary_metric: true
- &id002
  dataset: Texas
  rows:
  - model: DoG
    model_key: p^2gnn
    model_plain: DoG
    value: 0.9672
    std: 0.0147
    metric: Accuracy
    higher_is_better: true
    is_baseline: false
    is_overridden: false
    override_reason: ''
    params_millions: null
    architecture_type: hybrid
    architecture_label: Hyb
    architecture_title: Hybrid MPNN + transformer
    arxiv_id: '2603.09195'
    title: '$P^2$GNN: Two Prototype Sets to boost GNN Performance'
    date: Mar 10, 2026
    date_display: Mar 2026
    date_iso: '2026-03-10'
    venue: arXiv.org
    codebase_url: ''
    uses_external_data: false
    input_feature_source: null
    feature_source_evidence: ''
    is_global_top: true
    global_rank: 1
    sort_value: 0.9672
    sort_std: 0.0147
    comparison_type: global_top
    comparison_source_title: ''
    comparison_source_arxiv: ''
    is_best: true
    is_std_outlier: false
  - model: DoG
    model_key: dog
    model_plain: DoG
    value: 0.966
    std: 0.021
    metric: Accuracy
    higher_is_better: true
    is_baseline: false
    is_overridden: false
    override_reason: ''
    params_millions: null
    architecture_type: null
    architecture_label: null
    architecture_title: ''
    arxiv_id: '2503.12563'
    title: 'Diffusion on Graph: Augmentation of Graph Structure for Node Classification'
    date: Mar 16, 2025
    date_display: Mar 2025
    date_iso: '2025-03-16'
    venue: Trans. Mach. Learn. Res.
    codebase_url: https://github.com/Statistical-Deep-Learning/DoG
    uses_external_data: true
    input_feature_source: raw_features
    feature_source_evidence: DoG generates synthetic graph structures to boost the
      performance of GNNs.
    is_global_top: true
    global_rank: 2
    sort_value: 0.966
    sort_std: 0.021
    comparison_type: global_top
    comparison_source_title: ''
    comparison_source_arxiv: ''
    is_best: true
    is_std_outlier: false
  - model: DoG
    model_key: gpf-plus
    model_plain: DoG
    value: 0.9583
    std: 0.0419
    metric: Accuracy
    higher_is_better: true
    is_baseline: true
    is_overridden: false
    override_reason: ''
    params_millions: null
    architecture_type: gnn
    architecture_label: GNN
    architecture_title: Message-passing GNN
    arxiv_id: '2406.05346'
    title: 'ProG: A Graph Prompt Learning Benchmark'
    date: Jun 8, 2024
    date_display: Jun 2024
    date_iso: '2024-06-08'
    venue: Neural Information Processing Systems
    codebase_url: https://github.com/sheldonresearch/ProG
    uses_external_data: true
    input_feature_source: null
    feature_source_evidence: ''
    is_global_top: true
    global_rank: 3
    sort_value: 0.9583
    sort_std: 0.0419
    comparison_type: global_top
    comparison_source_title: ''
    comparison_source_arxiv: ''
    is_best: true
    is_std_outlier: false
  - model: Gemini-2.5-flash
    model_key: gemini-2.5-flash
    model_plain: Gemini-2.5-flash
    value: 0.9305
    std: null
    paper_value: 0.9305
    paper_std: null
    metric: Accuracy
    higher_is_better: true
    is_baseline: true
    is_overridden: false
    override_reason: ''
    params_millions: null
    architecture_type: null
    architecture_label: null
    architecture_title: ''
    uses_external_data: 1
    input_feature_source: null
    feature_source_evidence: ''
    table_ref: Table 2
    source_ref: this paper
    variant_inference_reason: 'dataset: exact match'
    evaluation_task: node_classification
    protocol_decision: standard
    protocol_note: Accuracy under different LLM backbones for DENSE.
    date: May 23, 2025
    date_display: May 2025
    date_iso: '2025-05-23'
    published_venue: NeurIPS 2025
    published_conference: NeurIPS 2025
    at_pub_value: null
    at_pub_std: null
    at_pub_source_arxiv: ''
    at_pub_source_title: ''
    at_pub_source_date_iso: ''
    at_pub_source_date_label: ''
    value_gap_source_date_iso: '2025-05-23'
    value_gap_source_date_label: NeurIPS 2025
    gap_vs_at_pub: null
    worse_than_at_pub: false
    surpassed_since_pub: false
    better_than_at_pub: false
    insignificant_improvement_at_pub: false
    improvement_surpassed_since_pub: false
    insignificant_value_gap: false
    today_delta_significant: false
    true_value: 0.9305
    true_std: null
    value_gap_source_arxiv: '2505.17599'
    value_gap_source_title: Dynamic Bundling with Large Language Models for Zero-Shot
      Inference on Text-Attributed Graphs
    value_gap_source_is_current_paper: true
    value_gap: null
    has_value_note: false
    value_note: ''
    sort_value: 0.9305
    sort_std: null
    global_rank: 33
    paper_rank: 33
    rank_delta: 0
    rank_delta_abs: 0
    rank_delta_direction: same
    has_value_gap: false
    comparison_type: null
    comparison_source_title: ''
    comparison_source_arxiv: ''
    is_best: false
    is_std_outlier: false
  - model: DENSE
    model_key: dense
    model_plain: DENSE
    value: 0.9251
    std: null
    paper_value: 0.9251
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
    evaluation_task: node_classification
    protocol_decision: standard
    protocol_note: Standard node classification on Texas web page network.
    date: May 23, 2025
    date_display: May 2025
    date_iso: '2025-05-23'
    published_venue: NeurIPS 2025
    published_conference: NeurIPS 2025
    at_pub_value: 0.622
    at_pub_std: null
    at_pub_source_arxiv: '2211.15335'
    at_pub_source_title: 'You Can Have Better Graph Neural Networks by Not Training
      Weights at All: Finding Untrained GNNs Tickets'
    at_pub_source_date_iso: '2022-11-28'
    at_pub_source_date_label: LoG 2022
    value_gap_source_date_iso: '2025-05-23'
    value_gap_source_date_label: NeurIPS 2025
    gap_vs_at_pub: 0.30310000000000004
    worse_than_at_pub: false
    surpassed_since_pub: false
    better_than_at_pub: true
    insignificant_improvement_at_pub: false
    improvement_surpassed_since_pub: false
    insignificant_value_gap: false
    today_delta_significant: false
    true_value: 0.9251
    true_std: null
    value_gap_source_arxiv: '2505.17599'
    value_gap_source_title: Dynamic Bundling with Large Language Models for Zero-Shot
      Inference on Text-Attributed Graphs
    value_gap_source_is_current_paper: true
    value_gap: null
    has_value_note: false
    value_note: ''
    sort_value: 0.9251
    sort_std: null
    global_rank: 40
    paper_rank: 40
    rank_delta: 0
    rank_delta_abs: 0
    rank_delta_direction: same
    has_value_gap: true
    comparison_type: improved
    comparison_source_title: 'You Can Have Better Graph Neural Networks by Not Training
      Weights at All: Finding Untrained GNNs Tickets'
    comparison_source_arxiv: '2211.15335'
    is_best: false
    is_std_outlier: false
  - model: GPT-4o
    model_key: gpt-4o
    model_plain: GPT-4o
    value: 0.9251
    std: null
    paper_value: 0.9251
    paper_std: null
    metric: Accuracy
    higher_is_better: true
    is_baseline: true
    is_overridden: false
    override_reason: ''
    params_millions: null
    architecture_type: llm
    architecture_label: LLM
    architecture_title: LLM applied to graphs
    uses_external_data: 1
    input_feature_source: null
    feature_source_evidence: ''
    table_ref: Table 2
    source_ref: this paper
    variant_inference_reason: 'dataset: exact match'
    evaluation_task: node_classification
    protocol_decision: standard
    protocol_note: Accuracy under different LLM backbones for DENSE.
    date: May 23, 2025
    date_display: May 2025
    date_iso: '2025-05-23'
    published_venue: NeurIPS 2025
    published_conference: NeurIPS 2025
    at_pub_value: 0.631
    at_pub_std: null
    at_pub_source_arxiv: '2502.11836'
    at_pub_source_title: 'Model Generalization on Text Attribute Graphs: Principles
      with Large Language Models'
    at_pub_source_date_iso: '2025-02-17'
    at_pub_source_date_label: '2025'
    value_gap_source_date_iso: '2025-05-23'
    value_gap_source_date_label: NeurIPS 2025
    gap_vs_at_pub: 0.29410000000000003
    worse_than_at_pub: false
    surpassed_since_pub: false
    better_than_at_pub: true
    insignificant_improvement_at_pub: false
    improvement_surpassed_since_pub: false
    insignificant_value_gap: false
    today_delta_significant: false
    true_value: 0.9251
    true_std: null
    value_gap_source_arxiv: '2505.17599'
    value_gap_source_title: Dynamic Bundling with Large Language Models for Zero-Shot
      Inference on Text-Attributed Graphs
    value_gap_source_is_current_paper: true
    value_gap: null
    has_value_note: false
    value_note: ''
    sort_value: 0.9251
    sort_std: null
    global_rank: 39
    paper_rank: 39
    rank_delta: 0
    rank_delta_abs: 0
    rank_delta_direction: same
    has_value_gap: true
    comparison_type: improved
    comparison_source_title: 'Model Generalization on Text Attribute Graphs: Principles
      with Large Language Models'
    comparison_source_arxiv: '2502.11836'
    is_best: false
    is_std_outlier: false
  - model: GPT-4.1-nano
    model_key: gpt-4.1-nano
    model_plain: GPT-4.1-nano
    value: 0.9037
    std: null
    paper_value: 0.9037
    paper_std: null
    metric: Accuracy
    higher_is_better: true
    is_baseline: true
    is_overridden: false
    override_reason: ''
    params_millions: null
    architecture_type: null
    architecture_label: null
    architecture_title: ''
    uses_external_data: 1
    input_feature_source: null
    feature_source_evidence: ''
    table_ref: Table 2
    source_ref: this paper
    variant_inference_reason: 'dataset: exact match'
    evaluation_task: node_classification
    protocol_decision: standard
    protocol_note: Accuracy under different LLM backbones for DENSE.
    date: May 23, 2025
    date_display: May 2025
    date_iso: '2025-05-23'
    published_venue: NeurIPS 2025
    published_conference: NeurIPS 2025
    at_pub_value: null
    at_pub_std: null
    at_pub_source_arxiv: ''
    at_pub_source_title: ''
    at_pub_source_date_iso: ''
    at_pub_source_date_label: ''
    value_gap_source_date_iso: '2025-05-23'
    value_gap_source_date_label: NeurIPS 2025
    gap_vs_at_pub: null
    worse_than_at_pub: false
    surpassed_since_pub: false
    better_than_at_pub: false
    insignificant_improvement_at_pub: false
    improvement_surpassed_since_pub: false
    insignificant_value_gap: false
    today_delta_significant: false
    true_value: 0.9037
    true_std: null
    value_gap_source_arxiv: '2505.17599'
    value_gap_source_title: Dynamic Bundling with Large Language Models for Zero-Shot
      Inference on Text-Attributed Graphs
    value_gap_source_is_current_paper: true
    value_gap: null
    has_value_note: false
    value_note: ''
    sort_value: 0.9037
    sort_std: null
    global_rank: 62
    paper_rank: 62
    rank_delta: 0
    rank_delta_abs: 0
    rank_delta_direction: same
    has_value_gap: false
    comparison_type: null
    comparison_source_title: ''
    comparison_source_arxiv: ''
    is_best: false
    is_std_outlier: false
  - model: GPT-3.5-turbo
    model_key: gpt-3.5-turbo
    model_plain: GPT-3.5-turbo
    value: 0.893
    std: null
    paper_value: 0.893
    paper_std: null
    metric: Accuracy
    higher_is_better: true
    is_baseline: true
    is_overridden: false
    override_reason: ''
    params_millions: null
    architecture_type: llm
    architecture_label: LLM
    architecture_title: LLM applied to graphs
    uses_external_data: 1
    input_feature_source: null
    feature_source_evidence: ''
    table_ref: Table 2
    source_ref: this paper
    variant_inference_reason: 'dataset: exact match'
    evaluation_task: node_classification
    protocol_decision: standard
    protocol_note: Accuracy under different LLM backbones for DENSE.
    date: May 23, 2025
    date_display: May 2025
    date_iso: '2025-05-23'
    published_venue: NeurIPS 2025
    published_conference: NeurIPS 2025
    at_pub_value: 0.5614
    at_pub_std: null
    at_pub_source_arxiv: '2502.11836'
    at_pub_source_title: 'Model Generalization on Text Attribute Graphs: Principles
      with Large Language Models'
    at_pub_source_date_iso: '2025-02-17'
    at_pub_source_date_label: '2025'
    value_gap_source_date_iso: '2025-05-23'
    value_gap_source_date_label: NeurIPS 2025
    gap_vs_at_pub: 0.3316
    worse_than_at_pub: false
    surpassed_since_pub: false
    better_than_at_pub: true
    insignificant_improvement_at_pub: false
    improvement_surpassed_since_pub: false
    insignificant_value_gap: false
    today_delta_significant: false
    true_value: 0.893
    true_std: null
    value_gap_source_arxiv: '2505.17599'
    value_gap_source_title: Dynamic Bundling with Large Language Models for Zero-Shot
      Inference on Text-Attributed Graphs
    value_gap_source_is_current_paper: true
    value_gap: null
    has_value_note: false
    value_note: ''
    sort_value: 0.893
    sort_std: null
    global_rank: 74
    paper_rank: 74
    rank_delta: 0
    rank_delta_abs: 0
    rank_delta_direction: same
    has_value_gap: true
    comparison_type: improved
    comparison_source_title: 'Model Generalization on Text Attribute Graphs: Principles
      with Large Language Models'
    comparison_source_arxiv: '2502.11836'
    is_best: false
    is_std_outlier: false
  - model: Deepseek-V3
    model_key: deepseek-v3
    model_plain: Deepseek-V3
    value: 0.8556
    std: null
    paper_value: 0.8556
    paper_std: null
    metric: Accuracy
    higher_is_better: true
    is_baseline: true
    is_overridden: false
    override_reason: ''
    params_millions: null
    architecture_type: null
    architecture_label: null
    architecture_title: ''
    uses_external_data: 1
    input_feature_source: null
    feature_source_evidence: ''
    table_ref: Table 2
    source_ref: this paper
    variant_inference_reason: 'dataset: exact match'
    evaluation_task: node_classification
    protocol_decision: standard
    protocol_note: Accuracy under different LLM backbones for DENSE.
    date: May 23, 2025
    date_display: May 2025
    date_iso: '2025-05-23'
    published_venue: NeurIPS 2025
    published_conference: NeurIPS 2025
    at_pub_value: null
    at_pub_std: null
    at_pub_source_arxiv: ''
    at_pub_source_title: ''
    at_pub_source_date_iso: ''
    at_pub_source_date_label: ''
    value_gap_source_date_iso: '2025-05-23'
    value_gap_source_date_label: NeurIPS 2025
    gap_vs_at_pub: null
    worse_than_at_pub: false
    surpassed_since_pub: false
    better_than_at_pub: false
    insignificant_improvement_at_pub: false
    improvement_surpassed_since_pub: false
    insignificant_value_gap: false
    today_delta_significant: false
    true_value: 0.8556
    true_std: null
    value_gap_source_arxiv: '2505.17599'
    value_gap_source_title: Dynamic Bundling with Large Language Models for Zero-Shot
      Inference on Text-Attributed Graphs
    value_gap_source_is_current_paper: true
    value_gap: null
    has_value_note: false
    value_note: ''
    sort_value: 0.8556
    sort_std: null
    global_rank: 145
    paper_rank: 145
    rank_delta: 0
    rank_delta_abs: 0
    rank_delta_direction: same
    has_value_gap: false
    comparison_type: null
    comparison_source_title: ''
    comparison_source_arxiv: ''
    is_best: false
    is_std_outlier: false
  - model: LLM-BP
    model_key: llm-bp
    model_plain: LLM-BP
    value: 0.8166
    std: null
    paper_value: 0.8166
    paper_std: null
    metric: Accuracy
    higher_is_better: true
    is_baseline: true
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
    evaluation_task: node_classification
    protocol_decision: standard
    protocol_note: Standard node classification on Texas web page network.
    date: May 23, 2025
    date_display: May 2025
    date_iso: '2025-05-23'
    published_venue: NeurIPS 2025
    published_conference: NeurIPS 2025
    at_pub_value: 0.8166
    at_pub_std: null
    at_pub_source_arxiv: '2502.11836'
    at_pub_source_title: 'Model Generalization on Text Attribute Graphs: Principles
      with Large Language Models'
    at_pub_source_date_iso: '2025-02-17'
    at_pub_source_date_label: '2025'
    value_gap_source_date_iso: '2025-05-23'
    value_gap_source_date_label: NeurIPS 2025
    gap_vs_at_pub: null
    worse_than_at_pub: false
    surpassed_since_pub: false
    better_than_at_pub: false
    insignificant_improvement_at_pub: false
    improvement_surpassed_since_pub: false
    insignificant_value_gap: false
    today_delta_significant: false
    true_value: 0.8166
    true_std: null
    value_gap_source_arxiv: '2505.17599'
    value_gap_source_title: Dynamic Bundling with Large Language Models for Zero-Shot
      Inference on Text-Attributed Graphs
    value_gap_source_is_current_paper: true
    value_gap: null
    has_value_note: false
    value_note: ''
    sort_value: 0.8166
    sort_std: null
    global_rank: 234
    paper_rank: 234
    rank_delta: 0
    rank_delta_abs: 0
    rank_delta_direction: same
    has_value_gap: false
    comparison_type: null
    comparison_source_title: ''
    comparison_source_arxiv: ''
    is_best: false
    is_std_outlier: false
  - model: DGI
    model_key: dgi
    model_plain: DGI
    value: 0.1123
    std: null
    paper_value: 0.1123
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
    evaluation_task: node_classification
    protocol_decision: standard
    protocol_note: Standard node classification on Texas web page network.
    date: May 23, 2025
    date_display: May 2025
    date_iso: '2025-05-23'
    published_venue: NeurIPS 2025
    published_conference: NeurIPS 2025
    at_pub_value: 0.6059
    at_pub_std: 0.0756
    at_pub_source_arxiv: '2211.14065'
    at_pub_source_title: 'Beyond Smoothing: Unsupervised Graph Representation Learning
      with Edge Heterophily Discriminating'
    at_pub_source_date_iso: '2022-11-25'
    at_pub_source_date_label: AAAI 2022
    value_gap_source_date_iso: '2026-04-02'
    value_gap_source_date_label: '2026'
    gap_vs_at_pub: 0.4936
    worse_than_at_pub: true
    surpassed_since_pub: false
    better_than_at_pub: false
    insignificant_improvement_at_pub: false
    improvement_surpassed_since_pub: false
    insignificant_value_gap: false
    today_delta_significant: true
    true_value: 0.8148
    true_std: 0.0279
    value_gap_source_arxiv: '2604.01878'
    value_gap_source_title: 'ASPECT: Node-Level Adaptive Spectral Fusion for Graph
      Contrastive Learning'
    value_gap_source_is_current_paper: false
    value_gap: 0.7025
    has_value_note: false
    value_note: ''
    sort_value: 0.8148
    sort_std: 0.0279
    global_rank: 242
    paper_rank: 661
    rank_delta: 419
    rank_delta_abs: 419
    rank_delta_direction: worse
    has_value_gap: true
    comparison_type: behind
    comparison_source_title: 'Beyond Smoothing: Unsupervised Graph Representation
      Learning with Edge Heterophily Discriminating'
    comparison_source_arxiv: '2211.14065'
    is_best: false
    is_std_outlier: false
  - model: LLM2Vec
    model_key: llm2vec
    model_plain: LLM2Vec
    value: 0.7668
    std: null
    paper_value: 0.7668
    paper_std: null
    metric: Accuracy
    higher_is_better: true
    is_baseline: true
    is_overridden: false
    override_reason: ''
    params_millions: null
    architecture_type: null
    architecture_label: null
    architecture_title: ''
    uses_external_data: 0
    input_feature_source: null
    feature_source_evidence: ''
    table_ref: Table 1
    source_ref: this paper
    variant_inference_reason: 'dataset: exact match'
    evaluation_task: node_classification
    protocol_decision: standard
    protocol_note: Standard node classification on Texas web page network.
    date: May 23, 2025
    date_display: May 2025
    date_iso: '2025-05-23'
    published_venue: NeurIPS 2025
    published_conference: NeurIPS 2025
    at_pub_value: 0.7668
    at_pub_std: null
    at_pub_source_arxiv: '2502.11836'
    at_pub_source_title: 'Model Generalization on Text Attribute Graphs: Principles
      with Large Language Models'
    at_pub_source_date_iso: '2025-02-17'
    at_pub_source_date_label: '2025'
    value_gap_source_date_iso: '2025-05-23'
    value_gap_source_date_label: NeurIPS 2025
    gap_vs_at_pub: null
    worse_than_at_pub: false
    surpassed_since_pub: false
    better_than_at_pub: false
    insignificant_improvement_at_pub: false
    improvement_surpassed_since_pub: false
    insignificant_value_gap: false
    today_delta_significant: false
    true_value: 0.7668
    true_std: null
    value_gap_source_arxiv: '2505.17599'
    value_gap_source_title: Dynamic Bundling with Large Language Models for Zero-Shot
      Inference on Text-Attributed Graphs
    value_gap_source_is_current_paper: true
    value_gap: null
    has_value_note: false
    value_note: ''
    sort_value: 0.7668
    sort_std: null
    global_rank: 319
    paper_rank: 319
    rank_delta: 0
    rank_delta_abs: 0
    rank_delta_direction: same
    has_value_gap: false
    comparison_type: null
    comparison_source_title: ''
    comparison_source_arxiv: ''
    is_best: false
    is_std_outlier: false
  - model: TE-3-Large
    model_key: te-3-large
    model_plain: TE-3-Large
    value: 0.7542
    std: null
    paper_value: 0.7542
    paper_std: null
    metric: Accuracy
    higher_is_better: true
    is_baseline: true
    is_overridden: false
    override_reason: ''
    params_millions: null
    architecture_type: null
    architecture_label: null
    architecture_title: ''
    uses_external_data: 0
    input_feature_source: null
    feature_source_evidence: ''
    table_ref: Table 1
    source_ref: this paper
    variant_inference_reason: 'dataset: exact match'
    evaluation_task: node_classification
    protocol_decision: standard
    protocol_note: Standard node classification on Texas web page network.
    date: May 23, 2025
    date_display: May 2025
    date_iso: '2025-05-23'
    published_venue: NeurIPS 2025
    published_conference: NeurIPS 2025
    at_pub_value: null
    at_pub_std: null
    at_pub_source_arxiv: ''
    at_pub_source_title: ''
    at_pub_source_date_iso: ''
    at_pub_source_date_label: ''
    value_gap_source_date_iso: '2025-05-23'
    value_gap_source_date_label: NeurIPS 2025
    gap_vs_at_pub: null
    worse_than_at_pub: false
    surpassed_since_pub: false
    better_than_at_pub: false
    insignificant_improvement_at_pub: false
    improvement_surpassed_since_pub: false
    insignificant_value_gap: false
    today_delta_significant: false
    true_value: 0.7542
    true_std: null
    value_gap_source_arxiv: '2505.17599'
    value_gap_source_title: Dynamic Bundling with Large Language Models for Zero-Shot
      Inference on Text-Attributed Graphs
    value_gap_source_is_current_paper: true
    value_gap: null
    has_value_note: false
    value_note: ''
    sort_value: 0.7542
    sort_std: null
    global_rank: 337
    paper_rank: 337
    rank_delta: 0
    rank_delta_abs: 0
    rank_delta_direction: same
    has_value_gap: false
    comparison_type: null
    comparison_source_title: ''
    comparison_source_arxiv: ''
    is_best: false
    is_std_outlier: false
  - model: GraphMAE
    model_key: graphmae
    model_plain: GraphMAE
    value: 0.1765
    std: null
    paper_value: 0.1765
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
    evaluation_task: node_classification
    protocol_decision: standard
    protocol_note: Standard node classification on Texas web page network.
    date: May 23, 2025
    date_display: May 2025
    date_iso: '2025-05-23'
    published_venue: NeurIPS 2025
    published_conference: NeurIPS 2025
    at_pub_value: 0.7432
    at_pub_std: 0.0456
    at_pub_source_arxiv: '2408.13471'
    at_pub_source_title: Disentangled Generative Graph Representation Learning
    at_pub_source_date_iso: '2024-08-24'
    at_pub_source_date_label: '2024'
    value_gap_source_date_iso: '2024-08-24'
    value_gap_source_date_label: '2024'
    gap_vs_at_pub: 0.5667
    worse_than_at_pub: true
    surpassed_since_pub: false
    better_than_at_pub: false
    insignificant_improvement_at_pub: false
    improvement_surpassed_since_pub: false
    insignificant_value_gap: false
    today_delta_significant: true
    true_value: 0.7432
    true_std: 0.0456
    value_gap_source_arxiv: '2408.13471'
    value_gap_source_title: Disentangled Generative Graph Representation Learning
    value_gap_source_is_current_paper: false
    value_gap: 0.5667
    has_value_note: false
    value_note: ''
    sort_value: 0.7432
    sort_std: 0.0456
    global_rank: 351
    paper_rank: 658
    rank_delta: 307
    rank_delta_abs: 307
    rank_delta_direction: worse
    has_value_gap: true
    comparison_type: behind
    comparison_source_title: Disentangled Generative Graph Representation Learning
    comparison_source_arxiv: '2408.13471'
    is_best: false
    is_std_outlier: false
  - model: SBERT
    model_key: sbert
    model_plain: SBERT
    value: 0.6458
    std: null
    paper_value: 0.6458
    paper_std: null
    metric: Accuracy
    higher_is_better: true
    is_baseline: true
    is_overridden: false
    override_reason: ''
    params_millions: null
    architecture_type: llm
    architecture_label: LLM
    architecture_title: LLM applied to graphs
    uses_external_data: 0
    input_feature_source: null
    feature_source_evidence: ''
    table_ref: Table 1
    source_ref: this paper
    variant_inference_reason: 'dataset: exact match'
    evaluation_task: node_classification
    protocol_decision: standard
    protocol_note: Standard node classification on Texas web page network.
    date: May 23, 2025
    date_display: May 2025
    date_iso: '2025-05-23'
    published_venue: NeurIPS 2025
    published_conference: NeurIPS 2025
    at_pub_value: 0.6458
    at_pub_std: null
    at_pub_source_arxiv: '2502.11836'
    at_pub_source_title: 'Model Generalization on Text Attribute Graphs: Principles
      with Large Language Models'
    at_pub_source_date_iso: '2025-02-17'
    at_pub_source_date_label: '2025'
    value_gap_source_date_iso: '2025-05-23'
    value_gap_source_date_label: NeurIPS 2025
    gap_vs_at_pub: null
    worse_than_at_pub: false
    surpassed_since_pub: false
    better_than_at_pub: false
    insignificant_improvement_at_pub: false
    improvement_surpassed_since_pub: false
    insignificant_value_gap: false
    today_delta_significant: false
    true_value: 0.6458
    true_std: null
    value_gap_source_arxiv: '2505.17599'
    value_gap_source_title: Dynamic Bundling with Large Language Models for Zero-Shot
      Inference on Text-Attributed Graphs
    value_gap_source_is_current_paper: true
    value_gap: null
    has_value_note: false
    value_note: ''
    sort_value: 0.6458
    sort_std: null
    global_rank: 458
    paper_rank: 458
    rank_delta: 0
    rank_delta_abs: 0
    rank_delta_direction: same
    has_value_gap: false
    comparison_type: null
    comparison_source_title: ''
    comparison_source_arxiv: ''
    is_best: false
    is_std_outlier: false
  - model: RoBERTa
    model_key: roberta
    model_plain: RoBERTa
    value: 0.6225
    std: null
    paper_value: 0.6225
    paper_std: null
    metric: Accuracy
    higher_is_better: true
    is_baseline: true
    is_overridden: false
    override_reason: ''
    params_millions: null
    architecture_type: llm
    architecture_label: LLM
    architecture_title: LLM applied to graphs
    uses_external_data: 0
    input_feature_source: null
    feature_source_evidence: ''
    table_ref: Table 1
    source_ref: this paper
    variant_inference_reason: 'dataset: exact match'
    evaluation_task: node_classification
    protocol_decision: standard
    protocol_note: Standard node classification on Texas web page network.
    date: May 23, 2025
    date_display: May 2025
    date_iso: '2025-05-23'
    published_venue: NeurIPS 2025
    published_conference: NeurIPS 2025
    at_pub_value: 0.6225
    at_pub_std: null
    at_pub_source_arxiv: '2502.11836'
    at_pub_source_title: 'Model Generalization on Text Attribute Graphs: Principles
      with Large Language Models'
    at_pub_source_date_iso: '2025-02-17'
    at_pub_source_date_label: '2025'
    value_gap_source_date_iso: '2025-05-23'
    value_gap_source_date_label: NeurIPS 2025
    gap_vs_at_pub: null
    worse_than_at_pub: false
    surpassed_since_pub: false
    better_than_at_pub: false
    insignificant_improvement_at_pub: false
    improvement_surpassed_since_pub: false
    insignificant_value_gap: false
    today_delta_significant: false
    true_value: 0.6225
    true_std: null
    value_gap_source_arxiv: '2505.17599'
    value_gap_source_title: Dynamic Bundling with Large Language Models for Zero-Shot
      Inference on Text-Attributed Graphs
    value_gap_source_is_current_paper: true
    value_gap: null
    has_value_note: false
    value_note: ''
    sort_value: 0.6225
    sort_std: null
    global_rank: 479
    paper_rank: 479
    rank_delta: 0
    rank_delta_abs: 0
    rank_delta_direction: same
    has_value_gap: false
    comparison_type: null
    comparison_source_title: ''
    comparison_source_arxiv: ''
    is_best: false
    is_std_outlier: false
  - model: ZeroG
    model_key: zerog
    model_plain: ZeroG
    value: 0.5348
    std: null
    paper_value: 0.5348
    paper_std: null
    metric: Accuracy
    higher_is_better: true
    is_baseline: true
    is_overridden: false
    override_reason: ''
    params_millions: null
    architecture_type: llm
    architecture_label: LLM
    architecture_title: LLM applied to graphs
    uses_external_data: 0
    input_feature_source: null
    feature_source_evidence: ''
    table_ref: Table 1
    source_ref: this paper
    variant_inference_reason: 'dataset: exact match'
    evaluation_task: node_classification
    protocol_decision: standard
    protocol_note: Standard node classification on Texas web page network.
    date: May 23, 2025
    date_display: May 2025
    date_iso: '2025-05-23'
    published_venue: NeurIPS 2025
    published_conference: NeurIPS 2025
    at_pub_value: 0.5348
    at_pub_std: null
    at_pub_source_arxiv: '2502.11836'
    at_pub_source_title: 'Model Generalization on Text Attribute Graphs: Principles
      with Large Language Models'
    at_pub_source_date_iso: '2025-02-17'
    at_pub_source_date_label: '2025'
    value_gap_source_date_iso: '2025-05-23'
    value_gap_source_date_label: NeurIPS 2025
    gap_vs_at_pub: null
    worse_than_at_pub: false
    surpassed_since_pub: false
    better_than_at_pub: false
    insignificant_improvement_at_pub: false
    improvement_surpassed_since_pub: false
    insignificant_value_gap: false
    today_delta_significant: false
    true_value: 0.5348
    true_std: null
    value_gap_source_arxiv: '2505.17599'
    value_gap_source_title: Dynamic Bundling with Large Language Models for Zero-Shot
      Inference on Text-Attributed Graphs
    value_gap_source_is_current_paper: true
    value_gap: null
    has_value_note: false
    value_note: ''
    sort_value: 0.5348
    sort_std: null
    global_rank: 591
    paper_rank: 591
    rank_delta: 0
    rank_delta_abs: 0
    rank_delta_direction: same
    has_value_gap: false
    comparison_type: null
    comparison_source_title: ''
    comparison_source_arxiv: ''
    is_best: false
    is_std_outlier: false
  - model: GOFA
    model_key: gofa
    model_plain: GOFA
    value: 0.3837
    std: null
    paper_value: 0.3837
    paper_std: null
    metric: Accuracy
    higher_is_better: true
    is_baseline: true
    is_overridden: false
    override_reason: ''
    params_millions: null
    architecture_type: llm
    architecture_label: LLM
    architecture_title: LLM applied to graphs
    uses_external_data: 0
    input_feature_source: null
    feature_source_evidence: ''
    table_ref: Table 1
    source_ref: this paper
    variant_inference_reason: 'dataset: exact match'
    evaluation_task: node_classification
    protocol_decision: standard
    protocol_note: Standard node classification on Texas web page network.
    date: May 23, 2025
    date_display: May 2025
    date_iso: '2025-05-23'
    published_venue: NeurIPS 2025
    published_conference: NeurIPS 2025
    at_pub_value: 0.3837
    at_pub_std: null
    at_pub_source_arxiv: '2502.11836'
    at_pub_source_title: 'Model Generalization on Text Attribute Graphs: Principles
      with Large Language Models'
    at_pub_source_date_iso: '2025-02-17'
    at_pub_source_date_label: '2025'
    value_gap_source_date_iso: '2025-05-23'
    value_gap_source_date_label: NeurIPS 2025
    gap_vs_at_pub: null
    worse_than_at_pub: false
    surpassed_since_pub: false
    better_than_at_pub: false
    insignificant_improvement_at_pub: false
    improvement_surpassed_since_pub: false
    insignificant_value_gap: false
    today_delta_significant: false
    true_value: 0.3837
    true_std: null
    value_gap_source_arxiv: '2505.17599'
    value_gap_source_title: Dynamic Bundling with Large Language Models for Zero-Shot
      Inference on Text-Attributed Graphs
    value_gap_source_is_current_paper: true
    value_gap: null
    has_value_note: false
    value_note: ''
    sort_value: 0.3837
    sort_std: null
    global_rank: 622
    paper_rank: 622
    rank_delta: 0
    rank_delta_abs: 0
    rank_delta_direction: same
    has_value_gap: false
    comparison_type: null
    comparison_source_title: ''
    comparison_source_arxiv: ''
    is_best: false
    is_std_outlier: false
  - model: UniGLM
    model_key: uniglm
    model_plain: UniGLM
    value: 0.2139
    std: null
    paper_value: 0.2139
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
    evaluation_task: node_classification
    protocol_decision: standard
    protocol_note: Standard node classification on Texas web page network.
    date: May 23, 2025
    date_display: May 2025
    date_iso: '2025-05-23'
    published_venue: NeurIPS 2025
    published_conference: NeurIPS 2025
    at_pub_value: 0.2139
    at_pub_std: null
    at_pub_source_arxiv: '2502.11836'
    at_pub_source_title: 'Model Generalization on Text Attribute Graphs: Principles
      with Large Language Models'
    at_pub_source_date_iso: '2025-02-17'
    at_pub_source_date_label: '2025'
    value_gap_source_date_iso: '2025-05-23'
    value_gap_source_date_label: NeurIPS 2025
    gap_vs_at_pub: null
    worse_than_at_pub: false
    surpassed_since_pub: false
    better_than_at_pub: false
    insignificant_improvement_at_pub: false
    improvement_surpassed_since_pub: false
    insignificant_value_gap: false
    today_delta_significant: false
    true_value: 0.2139
    true_std: null
    value_gap_source_arxiv: '2505.17599'
    value_gap_source_title: Dynamic Bundling with Large Language Models for Zero-Shot
      Inference on Text-Attributed Graphs
    value_gap_source_is_current_paper: true
    value_gap: null
    has_value_note: false
    value_note: ''
    sort_value: 0.2139
    sort_std: null
    global_rank: 655
    paper_rank: 655
    rank_delta: 0
    rank_delta_abs: 0
    rank_delta_direction: same
    has_value_gap: false
    comparison_type: null
    comparison_source_title: ''
    comparison_source_arxiv: ''
    is_best: false
    is_std_outlier: false
  - model: GraphGPT
    model_key: graphgpt
    model_plain: GraphGPT
    value: 0.1848
    std: null
    paper_value: 0.1848
    paper_std: null
    metric: Accuracy
    higher_is_better: true
    is_baseline: true
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
    evaluation_task: node_classification
    protocol_decision: standard
    protocol_note: Standard node classification on Texas web page network.
    date: May 23, 2025
    date_display: May 2025
    date_iso: '2025-05-23'
    published_venue: NeurIPS 2025
    published_conference: NeurIPS 2025
    at_pub_value: 0.1848
    at_pub_std: null
    at_pub_source_arxiv: '2502.11836'
    at_pub_source_title: 'Model Generalization on Text Attribute Graphs: Principles
      with Large Language Models'
    at_pub_source_date_iso: '2025-02-17'
    at_pub_source_date_label: '2025'
    value_gap_source_date_iso: '2025-05-23'
    value_gap_source_date_label: NeurIPS 2025
    gap_vs_at_pub: null
    worse_than_at_pub: false
    surpassed_since_pub: false
    better_than_at_pub: false
    insignificant_improvement_at_pub: false
    improvement_surpassed_since_pub: false
    insignificant_value_gap: false
    today_delta_significant: false
    true_value: 0.1848
    true_std: null
    value_gap_source_arxiv: '2505.17599'
    value_gap_source_title: Dynamic Bundling with Large Language Models for Zero-Shot
      Inference on Text-Attributed Graphs
    value_gap_source_is_current_paper: true
    value_gap: null
    has_value_note: false
    value_note: ''
    sort_value: 0.1848
    sort_std: null
    global_rank: 658
    paper_rank: 658
    rank_delta: 0
    rank_delta_abs: 0
    rank_delta_direction: same
    has_value_gap: false
    comparison_type: null
    comparison_source_title: ''
    comparison_source_arxiv: ''
    is_best: false
    is_std_outlier: false
  - model: LLaGA
    model_key: llaga
    model_plain: LLaGA
    value: 0.1551
    std: null
    paper_value: 0.1551
    paper_std: null
    metric: Accuracy
    higher_is_better: true
    is_baseline: true
    is_overridden: false
    override_reason: ''
    params_millions: null
    architecture_type: llm
    architecture_label: LLM
    architecture_title: LLM applied to graphs
    uses_external_data: 0
    input_feature_source: null
    feature_source_evidence: ''
    table_ref: Table 1
    source_ref: this paper
    variant_inference_reason: 'dataset: exact match'
    evaluation_task: node_classification
    protocol_decision: standard
    protocol_note: Standard node classification on Texas web page network.
    date: May 23, 2025
    date_display: May 2025
    date_iso: '2025-05-23'
    published_venue: NeurIPS 2025
    published_conference: NeurIPS 2025
    at_pub_value: 0.1551
    at_pub_std: null
    at_pub_source_arxiv: '2502.11836'
    at_pub_source_title: 'Model Generalization on Text Attribute Graphs: Principles
      with Large Language Models'
    at_pub_source_date_iso: '2025-02-17'
    at_pub_source_date_label: '2025'
    value_gap_source_date_iso: '2025-05-23'
    value_gap_source_date_label: NeurIPS 2025
    gap_vs_at_pub: null
    worse_than_at_pub: false
    surpassed_since_pub: false
    better_than_at_pub: false
    insignificant_improvement_at_pub: false
    improvement_surpassed_since_pub: false
    insignificant_value_gap: false
    today_delta_significant: false
    true_value: 0.1551
    true_std: null
    value_gap_source_arxiv: '2505.17599'
    value_gap_source_title: Dynamic Bundling with Large Language Models for Zero-Shot
      Inference on Text-Attributed Graphs
    value_gap_source_is_current_paper: true
    value_gap: null
    has_value_note: false
    value_note: ''
    sort_value: 0.1551
    sort_std: null
    global_rank: 660
    paper_rank: 660
    rank_delta: 0
    rank_delta_abs: 0
    rank_delta_direction: same
    has_value_gap: false
    comparison_type: null
    comparison_source_title: ''
    comparison_source_arxiv: ''
    is_best: false
    is_std_outlier: false
  - model: OFA
    model_key: ofa
    model_plain: OFA
    value: 0.1177
    std: null
    paper_value: 0.1177
    paper_std: null
    metric: Accuracy
    higher_is_better: true
    is_baseline: true
    is_overridden: false
    override_reason: ''
    params_millions: null
    architecture_type: llm
    architecture_label: LLM
    architecture_title: LLM applied to graphs
    uses_external_data: 0
    input_feature_source: null
    feature_source_evidence: ''
    table_ref: Table 1
    source_ref: this paper
    variant_inference_reason: 'dataset: exact match'
    evaluation_task: node_classification
    protocol_decision: standard
    protocol_note: Standard node classification on Texas web page network.
    date: May 23, 2025
    date_display: May 2025
    date_iso: '2025-05-23'
    published_venue: NeurIPS 2025
    published_conference: NeurIPS 2025
    at_pub_value: 0.1177
    at_pub_std: null
    at_pub_source_arxiv: '2502.11836'
    at_pub_source_title: 'Model Generalization on Text Attribute Graphs: Principles
      with Large Language Models'
    at_pub_source_date_iso: '2025-02-17'
    at_pub_source_date_label: '2025'
    value_gap_source_date_iso: '2025-05-23'
    value_gap_source_date_label: NeurIPS 2025
    gap_vs_at_pub: null
    worse_than_at_pub: false
    surpassed_since_pub: false
    better_than_at_pub: false
    insignificant_improvement_at_pub: false
    improvement_surpassed_since_pub: false
    insignificant_value_gap: false
    today_delta_significant: false
    true_value: 0.1177
    true_std: null
    value_gap_source_arxiv: '2505.17599'
    value_gap_source_title: Dynamic Bundling with Large Language Models for Zero-Shot
      Inference on Text-Attributed Graphs
    value_gap_source_is_current_paper: true
    value_gap: null
    has_value_note: false
    value_note: ''
    sort_value: 0.1177
    sort_std: null
    global_rank: 661
    paper_rank: 661
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
  experiment_scope: node-level
  dataset_primary_metric: Accuracy
  paper_metrics:
  - Accuracy
  metric: Accuracy
  uses_non_primary_metric: false
  paper_has_primary_metric: true
- &id001
  dataset: WikiCS
  rows:
  - model: GraphAny
    model_key: gcn
    model_plain: GraphAny
    value: 0.9302
    std: 0.0011
    metric: Accuracy
    higher_is_better: true
    is_baseline: true
    is_overridden: false
    override_reason: ''
    params_millions: null
    architecture_type: gnn
    architecture_label: GNN
    architecture_title: Message-passing GNN
    arxiv_id: '2204.04874'
    title: Augmentation-Free Graph Contrastive Learning with Performance Guarantee
    date: Apr 11, 2022
    date_display: Apr 2022
    date_iso: '2022-04-11'
    venue: arXiv.org
    codebase_url: ''
    uses_external_data: false
    input_feature_source: null
    feature_source_evidence: ''
    is_global_top: true
    global_rank: 1
    sort_value: 0.9302
    sort_std: 0.0011
    comparison_type: global_top
    comparison_source_title: ''
    comparison_source_arxiv: ''
    is_best: true
    is_std_outlier: false
  - model: GraphAny
    model_key: graphssr
    model_plain: GraphAny
    value: 0.8793
    std: null
    metric: Accuracy
    higher_is_better: true
    is_baseline: false
    is_overridden: false
    override_reason: ''
    params_millions: null
    architecture_type: null
    architecture_label: null
    architecture_title: ''
    arxiv_id: '2603.02938'
    title: 'Beyond One-Size-Fits-All: Adaptive Subgraph Denoising for Zero-Shot Graph
      Learning with Large Language Models'
    date: Mar 3, 2026
    date_display: Mar 2026
    date_iso: '2026-03-03'
    venue: null
    codebase_url: https://github.com/mysteriouslfz/GraphSSR
    uses_external_data: false
    input_feature_source: null
    feature_source_evidence: ''
    is_global_top: true
    global_rank: 2
    sort_value: 0.8793
    sort_std: null
    comparison_type: global_top
    comparison_source_title: ''
    comparison_source_arxiv: ''
    is_best: false
    is_std_outlier: false
  - model: GraphAny
    model_key: graph-r1
    model_plain: GraphAny
    value: 0.8689
    std: null
    metric: Accuracy
    higher_is_better: true
    is_baseline: true
    is_overridden: false
    override_reason: ''
    params_millions: null
    architecture_type: llm
    architecture_label: LLM
    architecture_title: LLM applied to graphs
    arxiv_id: '2603.02938'
    title: 'Beyond One-Size-Fits-All: Adaptive Subgraph Denoising for Zero-Shot Graph
      Learning with Large Language Models'
    date: Mar 3, 2026
    date_display: Mar 2026
    date_iso: '2026-03-03'
    venue: null
    codebase_url: https://github.com/mysteriouslfz/GraphSSR
    uses_external_data: false
    input_feature_source: null
    feature_source_evidence: ''
    is_global_top: true
    global_rank: 3
    sort_value: 0.8689
    sort_std: null
    comparison_type: global_top
    comparison_source_title: ''
    comparison_source_arxiv: ''
    is_best: false
    is_std_outlier: false
  - model: LLaGA
    model_key: llaga
    model_plain: LLaGA
    value: 0.1098
    std: null
    paper_value: 0.1098
    paper_std: null
    metric: Accuracy
    higher_is_better: true
    is_baseline: true
    is_overridden: false
    override_reason: ''
    params_millions: null
    architecture_type: llm
    architecture_label: LLM
    architecture_title: LLM applied to graphs
    uses_external_data: 0
    input_feature_source: null
    feature_source_evidence: ''
    table_ref: Table 1
    source_ref: this paper
    variant_inference_reason: 'dataset: exact match'
    evaluation_task: node_classification
    protocol_decision: standard
    protocol_note: Standard node classification on WikiCS
    date: May 23, 2025
    date_display: May 2025
    date_iso: '2025-05-23'
    published_venue: NeurIPS 2025
    published_conference: NeurIPS 2025
    at_pub_value: 0.8074
    at_pub_std: null
    at_pub_source_arxiv: '2503.03313'
    at_pub_source_title: 'LLM as GNN: Graph Vocabulary Learning for Text-Attributed
      Graph Foundation Models'
    at_pub_source_date_iso: '2025-03-05'
    at_pub_source_date_label: '2025'
    value_gap_source_date_iso: '2025-03-05'
    value_gap_source_date_label: '2025'
    gap_vs_at_pub: 0.6976
    worse_than_at_pub: true
    surpassed_since_pub: false
    better_than_at_pub: false
    insignificant_improvement_at_pub: false
    improvement_surpassed_since_pub: false
    insignificant_value_gap: false
    today_delta_significant: true
    true_value: 0.8074
    true_std: null
    value_gap_source_arxiv: '2503.03313'
    value_gap_source_title: 'LLM as GNN: Graph Vocabulary Learning for Text-Attributed
      Graph Foundation Models'
    value_gap_source_is_current_paper: false
    value_gap: 0.6976
    has_value_note: false
    value_note: ''
    sort_value: 0.8074
    sort_std: null
    global_rank: 34
    paper_rank: 261
    rank_delta: 227
    rank_delta_abs: 227
    rank_delta_direction: worse
    has_value_gap: true
    comparison_type: behind
    comparison_source_title: 'LLM as GNN: Graph Vocabulary Learning for Text-Attributed
      Graph Foundation Models'
    comparison_source_arxiv: '2503.03313'
    is_best: false
    is_std_outlier: false
  - model: GOFA
    model_key: gofa
    model_plain: GOFA
    value: 0.6862
    std: null
    paper_value: 0.6862
    paper_std: null
    metric: Accuracy
    higher_is_better: true
    is_baseline: true
    is_overridden: false
    override_reason: ''
    params_millions: null
    architecture_type: llm
    architecture_label: LLM
    architecture_title: LLM applied to graphs
    uses_external_data: 0
    input_feature_source: null
    feature_source_evidence: ''
    table_ref: Table 1
    source_ref: this paper
    variant_inference_reason: 'dataset: exact match'
    evaluation_task: node_classification
    protocol_decision: standard
    protocol_note: Standard node classification on WikiCS
    date: May 23, 2025
    date_display: May 2025
    date_iso: '2025-05-23'
    published_venue: NeurIPS 2025
    published_conference: NeurIPS 2025
    at_pub_value: 0.7996
    at_pub_std: null
    at_pub_source_arxiv: '2407.09709'
    at_pub_source_title: 'GOFA: A Generative One-For-All Model for Joint Graph Language
      Modeling'
    at_pub_source_date_iso: '2024-07-12'
    at_pub_source_date_label: ICLR 2024
    value_gap_source_date_iso: '2024-07-12'
    value_gap_source_date_label: ICLR 2024
    gap_vs_at_pub: 0.11339999999999995
    worse_than_at_pub: true
    surpassed_since_pub: false
    better_than_at_pub: false
    insignificant_improvement_at_pub: false
    improvement_surpassed_since_pub: false
    insignificant_value_gap: false
    today_delta_significant: true
    true_value: 0.7996
    true_std: null
    value_gap_source_arxiv: '2407.09709'
    value_gap_source_title: 'GOFA: A Generative One-For-All Model for Joint Graph
      Language Modeling'
    value_gap_source_is_current_paper: false
    value_gap: 0.11339999999999995
    has_value_note: false
    value_note: ''
    sort_value: 0.7996
    sort_std: null
    global_rank: 52
    paper_rank: 202
    rank_delta: 150
    rank_delta_abs: 150
    rank_delta_direction: worse
    has_value_gap: true
    comparison_type: behind
    comparison_source_title: 'GOFA: A Generative One-For-All Model for Joint Graph
      Language Modeling'
    comparison_source_arxiv: '2407.09709'
    is_best: false
    is_std_outlier: false
  - model: GraphMAE
    model_key: graphmae
    model_plain: GraphMAE
    value: 0.0891
    std: null
    paper_value: 0.0891
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
    evaluation_task: node_classification
    protocol_decision: standard
    protocol_note: Standard node classification on WikiCS
    date: May 23, 2025
    date_display: May 2025
    date_iso: '2025-05-23'
    published_venue: NeurIPS 2025
    published_conference: NeurIPS 2025
    at_pub_value: 0.7992
    at_pub_std: 0.0068
    at_pub_source_arxiv: '2312.02619'
    at_pub_source_title: Rethinking and Simplifying Bootstrapped Graph Latents
    at_pub_source_date_iso: '2023-12-05'
    at_pub_source_date_label: '2023'
    value_gap_source_date_iso: '2023-12-05'
    value_gap_source_date_label: '2023'
    gap_vs_at_pub: 0.7101000000000001
    worse_than_at_pub: true
    surpassed_since_pub: false
    better_than_at_pub: false
    insignificant_improvement_at_pub: false
    improvement_surpassed_since_pub: false
    insignificant_value_gap: false
    today_delta_significant: true
    true_value: 0.7992
    true_std: 0.0068
    value_gap_source_arxiv: '2312.02619'
    value_gap_source_title: Rethinking and Simplifying Bootstrapped Graph Latents
    value_gap_source_is_current_paper: false
    value_gap: 0.7101000000000001
    has_value_note: false
    value_note: ''
    sort_value: 0.7992
    sort_std: 0.0068
    global_rank: 54
    paper_rank: 261
    rank_delta: 207
    rank_delta_abs: 207
    rank_delta_direction: worse
    has_value_gap: true
    comparison_type: behind
    comparison_source_title: Rethinking and Simplifying Bootstrapped Graph Latents
    comparison_source_arxiv: '2312.02619'
    is_best: false
    is_std_outlier: false
  - model: ZeroG
    model_key: zerog
    model_plain: ZeroG
    value: 0.4674
    std: null
    paper_value: 0.4674
    paper_std: null
    metric: Accuracy
    higher_is_better: true
    is_baseline: true
    is_overridden: false
    override_reason: ''
    params_millions: null
    architecture_type: llm
    architecture_label: LLM
    architecture_title: LLM applied to graphs
    uses_external_data: 0
    input_feature_source: null
    feature_source_evidence: ''
    table_ref: Table 1
    source_ref: this paper
    variant_inference_reason: 'dataset: exact match'
    evaluation_task: node_classification
    protocol_decision: standard
    protocol_note: Standard node classification on WikiCS
    date: May 23, 2025
    date_display: May 2025
    date_iso: '2025-05-23'
    published_venue: NeurIPS 2025
    published_conference: NeurIPS 2025
    at_pub_value: 0.4825
    at_pub_std: null
    at_pub_source_arxiv: '2407.09709'
    at_pub_source_title: 'GOFA: A Generative One-For-All Model for Joint Graph Language
      Modeling'
    at_pub_source_date_iso: '2024-07-12'
    at_pub_source_date_label: ICLR 2024
    value_gap_source_date_iso: '2026-03-20'
    value_gap_source_date_label: '2026'
    gap_vs_at_pub: 0.015100000000000002
    worse_than_at_pub: true
    surpassed_since_pub: false
    better_than_at_pub: false
    insignificant_improvement_at_pub: false
    improvement_surpassed_since_pub: false
    insignificant_value_gap: false
    today_delta_significant: true
    true_value: 0.7882
    true_std: null
    value_gap_source_arxiv: '2603.19596'
    value_gap_source_title: 'CO-EVOLVE: Bidirectional Co-Evolution of Graph Structure
      and Semantics for Heterophilous Learning'
    value_gap_source_is_current_paper: false
    value_gap: 0.32080000000000003
    has_value_note: false
    value_note: ''
    sort_value: 0.7882
    sort_std: null
    global_rank: 82
    paper_rank: 256
    rank_delta: 174
    rank_delta_abs: 174
    rank_delta_direction: worse
    has_value_gap: true
    comparison_type: behind
    comparison_source_title: 'GOFA: A Generative One-For-All Model for Joint Graph
      Language Modeling'
    comparison_source_arxiv: '2407.09709'
    is_best: false
    is_std_outlier: false
  - model: OFA
    model_key: ofa
    model_plain: OFA
    value: 0.3077
    std: null
    paper_value: 0.3077
    paper_std: null
    metric: Accuracy
    higher_is_better: true
    is_baseline: true
    is_overridden: false
    override_reason: ''
    params_millions: null
    architecture_type: llm
    architecture_label: LLM
    architecture_title: LLM applied to graphs
    uses_external_data: 0
    input_feature_source: null
    feature_source_evidence: ''
    table_ref: Table 1
    source_ref: this paper
    variant_inference_reason: 'dataset: exact match'
    evaluation_task: node_classification
    protocol_decision: standard
    protocol_note: Standard node classification on WikiCS
    date: May 23, 2025
    date_display: May 2025
    date_iso: '2025-05-23'
    published_venue: NeurIPS 2025
    published_conference: NeurIPS 2025
    at_pub_value: 0.7855
    at_pub_std: 0.0037
    at_pub_source_arxiv: '2505.12684'
    at_pub_source_title: Towards Effective Federated Graph Foundation Model via Mitigating
      Knowledge Entanglement
    at_pub_source_date_iso: '2025-05-19'
    at_pub_source_date_label: NeurIPS 2025
    value_gap_source_date_iso: '2025-05-19'
    value_gap_source_date_label: NeurIPS 2025
    gap_vs_at_pub: 0.4778
    worse_than_at_pub: true
    surpassed_since_pub: false
    better_than_at_pub: false
    insignificant_improvement_at_pub: false
    improvement_surpassed_since_pub: false
    insignificant_value_gap: false
    today_delta_significant: true
    true_value: 0.7855
    true_std: 0.0037
    value_gap_source_arxiv: '2505.12684'
    value_gap_source_title: Towards Effective Federated Graph Foundation Model via
      Mitigating Knowledge Entanglement
    value_gap_source_is_current_paper: false
    value_gap: 0.4778
    has_value_note: false
    value_note: ''
    sort_value: 0.7855
    sort_std: 0.0037
    global_rank: 97
    paper_rank: 260
    rank_delta: 163
    rank_delta_abs: 163
    rank_delta_direction: worse
    has_value_gap: true
    comparison_type: behind
    comparison_source_title: Towards Effective Federated Graph Foundation Model via
      Mitigating Knowledge Entanglement
    comparison_source_arxiv: '2505.12684'
    is_best: false
    is_std_outlier: false
  - model: DGI
    model_key: dgi
    model_plain: DGI
    value: 0.1498
    std: null
    paper_value: 0.1498
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
    evaluation_task: node_classification
    protocol_decision: standard
    protocol_note: Standard node classification on WikiCS
    date: May 23, 2025
    date_display: May 2025
    date_iso: '2025-05-23'
    published_venue: NeurIPS 2025
    published_conference: NeurIPS 2025
    at_pub_value: 0.7825
    at_pub_std: 0.0056
    at_pub_source_arxiv: '2408.05087'
    at_pub_source_title: Bootstrap Latents of Nodes and Neighbors for Graph Self-Supervised
      Learning
    at_pub_source_date_iso: '2024-08-09'
    at_pub_source_date_label: '2024'
    value_gap_source_date_iso: '2024-08-09'
    value_gap_source_date_label: '2024'
    gap_vs_at_pub: 0.6327
    worse_than_at_pub: true
    surpassed_since_pub: false
    better_than_at_pub: false
    insignificant_improvement_at_pub: false
    improvement_surpassed_since_pub: false
    insignificant_value_gap: false
    today_delta_significant: true
    true_value: 0.7825
    true_std: 0.0056
    value_gap_source_arxiv: '2408.05087'
    value_gap_source_title: Bootstrap Latents of Nodes and Neighbors for Graph Self-Supervised
      Learning
    value_gap_source_is_current_paper: false
    value_gap: 0.6327
    has_value_note: false
    value_note: ''
    sort_value: 0.7825
    sort_std: 0.0056
    global_rank: 108
    paper_rank: 261
    rank_delta: 153
    rank_delta_abs: 153
    rank_delta_direction: worse
    has_value_gap: true
    comparison_type: behind
    comparison_source_title: Bootstrap Latents of Nodes and Neighbors for Graph Self-Supervised
      Learning
    comparison_source_arxiv: '2408.05087'
    is_best: false
    is_std_outlier: false
  - model: RoBERTa
    model_key: roberta
    model_plain: RoBERTa
    value: 0.5908
    std: null
    paper_value: 0.5908
    paper_std: null
    metric: Accuracy
    higher_is_better: true
    is_baseline: true
    is_overridden: false
    override_reason: ''
    params_millions: null
    architecture_type: llm
    architecture_label: LLM
    architecture_title: LLM applied to graphs
    uses_external_data: 0
    input_feature_source: null
    feature_source_evidence: ''
    table_ref: Table 1
    source_ref: this paper
    variant_inference_reason: 'dataset: exact match'
    evaluation_task: node_classification
    protocol_decision: standard
    protocol_note: Standard node classification on WikiCS
    date: May 23, 2025
    date_display: May 2025
    date_iso: '2025-05-23'
    published_venue: NeurIPS 2025
    published_conference: NeurIPS 2025
    at_pub_value: 0.5908
    at_pub_std: null
    at_pub_source_arxiv: '2502.11836'
    at_pub_source_title: 'Model Generalization on Text Attribute Graphs: Principles
      with Large Language Models'
    at_pub_source_date_iso: '2025-02-17'
    at_pub_source_date_label: '2025'
    value_gap_source_date_iso: '2026-03-20'
    value_gap_source_date_label: '2026'
    gap_vs_at_pub: null
    worse_than_at_pub: false
    surpassed_since_pub: true
    better_than_at_pub: false
    insignificant_improvement_at_pub: false
    improvement_surpassed_since_pub: false
    insignificant_value_gap: false
    today_delta_significant: true
    true_value: 0.7477
    true_std: null
    value_gap_source_arxiv: '2603.19596'
    value_gap_source_title: 'CO-EVOLVE: Bidirectional Co-Evolution of Graph Structure
      and Semantics for Heterophilous Learning'
    value_gap_source_is_current_paper: false
    value_gap: 0.15690000000000004
    has_value_note: false
    value_note: ''
    sort_value: 0.7477
    sort_std: null
    global_rank: 164
    paper_rank: 248
    rank_delta: 84
    rank_delta_abs: 84
    rank_delta_direction: worse
    has_value_gap: true
    comparison_type: null
    comparison_source_title: ''
    comparison_source_arxiv: ''
    is_best: false
    is_std_outlier: false
  - model: DENSE
    model_key: dense
    model_plain: DENSE
    value: 0.7103
    std: null
    paper_value: 0.7103
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
    evaluation_task: node_classification
    protocol_decision: standard
    protocol_note: Standard node classification on WikiCS
    date: May 23, 2025
    date_display: May 2025
    date_iso: '2025-05-23'
    published_venue: NeurIPS 2025
    published_conference: NeurIPS 2025
    at_pub_value: null
    at_pub_std: null
    at_pub_source_arxiv: ''
    at_pub_source_title: ''
    at_pub_source_date_iso: ''
    at_pub_source_date_label: ''
    value_gap_source_date_iso: '2025-05-23'
    value_gap_source_date_label: NeurIPS 2025
    gap_vs_at_pub: null
    worse_than_at_pub: false
    surpassed_since_pub: false
    better_than_at_pub: false
    insignificant_improvement_at_pub: false
    improvement_surpassed_since_pub: false
    insignificant_value_gap: false
    today_delta_significant: false
    true_value: 0.7103
    true_std: null
    value_gap_source_arxiv: '2505.17599'
    value_gap_source_title: Dynamic Bundling with Large Language Models for Zero-Shot
      Inference on Text-Attributed Graphs
    value_gap_source_is_current_paper: true
    value_gap: null
    has_value_note: false
    value_note: ''
    sort_value: 0.7103
    sort_std: null
    global_rank: 188
    paper_rank: 188
    rank_delta: 0
    rank_delta_abs: 0
    rank_delta_direction: same
    has_value_gap: false
    comparison_type: null
    comparison_source_title: ''
    comparison_source_arxiv: ''
    is_best: false
    is_std_outlier: false
  - model: LLM-BP
    model_key: llm-bp
    model_plain: LLM-BP
    value: 0.6775
    std: null
    paper_value: 0.6775
    paper_std: null
    metric: Accuracy
    higher_is_better: true
    is_baseline: true
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
    evaluation_task: node_classification
    protocol_decision: standard
    protocol_note: Standard node classification on WikiCS
    date: May 23, 2025
    date_display: May 2025
    date_iso: '2025-05-23'
    published_venue: NeurIPS 2025
    published_conference: NeurIPS 2025
    at_pub_value: null
    at_pub_std: null
    at_pub_source_arxiv: ''
    at_pub_source_title: ''
    at_pub_source_date_iso: ''
    at_pub_source_date_label: ''
    value_gap_source_date_iso: '2025-05-23'
    value_gap_source_date_label: NeurIPS 2025
    gap_vs_at_pub: null
    worse_than_at_pub: false
    surpassed_since_pub: false
    better_than_at_pub: false
    insignificant_improvement_at_pub: false
    improvement_surpassed_since_pub: false
    insignificant_value_gap: false
    today_delta_significant: false
    true_value: 0.6775
    true_std: null
    value_gap_source_arxiv: '2505.17599'
    value_gap_source_title: Dynamic Bundling with Large Language Models for Zero-Shot
      Inference on Text-Attributed Graphs
    value_gap_source_is_current_paper: true
    value_gap: null
    has_value_note: false
    value_note: ''
    sort_value: 0.6775
    sort_std: null
    global_rank: 211
    paper_rank: 211
    rank_delta: 0
    rank_delta_abs: 0
    rank_delta_direction: same
    has_value_gap: false
    comparison_type: null
    comparison_source_title: ''
    comparison_source_arxiv: ''
    is_best: false
    is_std_outlier: false
  - model: GPT-4o
    model_key: gpt-4o
    model_plain: GPT-4o
    value: 0.661
    std: null
    paper_value: 0.661
    paper_std: null
    metric: Accuracy
    higher_is_better: true
    is_baseline: true
    is_overridden: false
    override_reason: ''
    params_millions: null
    architecture_type: llm
    architecture_label: LLM
    architecture_title: LLM applied to graphs
    uses_external_data: 0
    input_feature_source: null
    feature_source_evidence: ''
    table_ref: Table 1
    source_ref: this paper
    variant_inference_reason: 'dataset: exact match'
    evaluation_task: node_classification
    protocol_decision: standard
    protocol_note: Standard node classification on WikiCS
    date: May 23, 2025
    date_display: May 2025
    date_iso: '2025-05-23'
    published_venue: NeurIPS 2025
    published_conference: NeurIPS 2025
    at_pub_value: 0.661
    at_pub_std: null
    at_pub_source_arxiv: '2502.11836'
    at_pub_source_title: 'Model Generalization on Text Attribute Graphs: Principles
      with Large Language Models'
    at_pub_source_date_iso: '2025-02-17'
    at_pub_source_date_label: '2025'
    value_gap_source_date_iso: '2025-05-23'
    value_gap_source_date_label: NeurIPS 2025
    gap_vs_at_pub: null
    worse_than_at_pub: false
    surpassed_since_pub: false
    better_than_at_pub: false
    insignificant_improvement_at_pub: false
    improvement_surpassed_since_pub: false
    insignificant_value_gap: false
    today_delta_significant: false
    true_value: 0.661
    true_std: null
    value_gap_source_arxiv: '2505.17599'
    value_gap_source_title: Dynamic Bundling with Large Language Models for Zero-Shot
      Inference on Text-Attributed Graphs
    value_gap_source_is_current_paper: true
    value_gap: null
    has_value_note: false
    value_note: ''
    sort_value: 0.661
    sort_std: null
    global_rank: 222
    paper_rank: 222
    rank_delta: 0
    rank_delta_abs: 0
    rank_delta_direction: same
    has_value_gap: false
    comparison_type: null
    comparison_source_title: ''
    comparison_source_arxiv: ''
    is_best: false
    is_std_outlier: false
  - model: GPT-3.5-turbo
    model_key: gpt-3.5-turbo
    model_plain: GPT-3.5-turbo
    value: 0.6553
    std: null
    paper_value: 0.6553
    paper_std: null
    metric: Accuracy
    higher_is_better: true
    is_baseline: true
    is_overridden: false
    override_reason: ''
    params_millions: null
    architecture_type: llm
    architecture_label: LLM
    architecture_title: LLM applied to graphs
    uses_external_data: 0
    input_feature_source: null
    feature_source_evidence: ''
    table_ref: Table 1
    source_ref: this paper
    variant_inference_reason: 'dataset: exact match'
    evaluation_task: node_classification
    protocol_decision: standard
    protocol_note: Standard node classification on WikiCS
    date: May 23, 2025
    date_display: May 2025
    date_iso: '2025-05-23'
    published_venue: NeurIPS 2025
    published_conference: NeurIPS 2025
    at_pub_value: 0.6553
    at_pub_std: null
    at_pub_source_arxiv: '2502.11836'
    at_pub_source_title: 'Model Generalization on Text Attribute Graphs: Principles
      with Large Language Models'
    at_pub_source_date_iso: '2025-02-17'
    at_pub_source_date_label: '2025'
    value_gap_source_date_iso: '2025-05-23'
    value_gap_source_date_label: NeurIPS 2025
    gap_vs_at_pub: null
    worse_than_at_pub: false
    surpassed_since_pub: false
    better_than_at_pub: false
    insignificant_improvement_at_pub: false
    improvement_surpassed_since_pub: false
    insignificant_value_gap: false
    today_delta_significant: false
    true_value: 0.6553
    true_std: null
    value_gap_source_arxiv: '2505.17599'
    value_gap_source_title: Dynamic Bundling with Large Language Models for Zero-Shot
      Inference on Text-Attributed Graphs
    value_gap_source_is_current_paper: true
    value_gap: null
    has_value_note: false
    value_note: ''
    sort_value: 0.6553
    sort_std: null
    global_rank: 228
    paper_rank: 228
    rank_delta: 0
    rank_delta_abs: 0
    rank_delta_direction: same
    has_value_gap: false
    comparison_type: null
    comparison_source_title: ''
    comparison_source_arxiv: ''
    is_best: false
    is_std_outlier: false
  - model: LLM2Vec
    model_key: llm2vec
    model_plain: LLM2Vec
    value: 0.6234
    std: null
    paper_value: 0.6234
    paper_std: null
    metric: Accuracy
    higher_is_better: true
    is_baseline: true
    is_overridden: false
    override_reason: ''
    params_millions: null
    architecture_type: null
    architecture_label: null
    architecture_title: ''
    uses_external_data: 0
    input_feature_source: null
    feature_source_evidence: ''
    table_ref: Table 1
    source_ref: this paper
    variant_inference_reason: 'dataset: exact match'
    evaluation_task: node_classification
    protocol_decision: standard
    protocol_note: Standard node classification on WikiCS
    date: May 23, 2025
    date_display: May 2025
    date_iso: '2025-05-23'
    published_venue: NeurIPS 2025
    published_conference: NeurIPS 2025
    at_pub_value: 0.6234
    at_pub_std: null
    at_pub_source_arxiv: '2502.11836'
    at_pub_source_title: 'Model Generalization on Text Attribute Graphs: Principles
      with Large Language Models'
    at_pub_source_date_iso: '2025-02-17'
    at_pub_source_date_label: '2025'
    value_gap_source_date_iso: '2025-05-23'
    value_gap_source_date_label: NeurIPS 2025
    gap_vs_at_pub: null
    worse_than_at_pub: false
    surpassed_since_pub: false
    better_than_at_pub: false
    insignificant_improvement_at_pub: false
    improvement_surpassed_since_pub: false
    insignificant_value_gap: false
    today_delta_significant: false
    true_value: 0.6234
    true_std: null
    value_gap_source_arxiv: '2505.17599'
    value_gap_source_title: Dynamic Bundling with Large Language Models for Zero-Shot
      Inference on Text-Attributed Graphs
    value_gap_source_is_current_paper: true
    value_gap: null
    has_value_note: false
    value_note: ''
    sort_value: 0.6234
    sort_std: null
    global_rank: 241
    paper_rank: 241
    rank_delta: 0
    rank_delta_abs: 0
    rank_delta_direction: same
    has_value_gap: false
    comparison_type: null
    comparison_source_title: ''
    comparison_source_arxiv: ''
    is_best: false
    is_std_outlier: false
  - model: TE-3-Large
    model_key: te-3-large
    model_plain: TE-3-Large
    value: 0.6178
    std: null
    paper_value: 0.6178
    paper_std: null
    metric: Accuracy
    higher_is_better: true
    is_baseline: true
    is_overridden: false
    override_reason: ''
    params_millions: null
    architecture_type: null
    architecture_label: null
    architecture_title: ''
    uses_external_data: 0
    input_feature_source: null
    feature_source_evidence: ''
    table_ref: Table 1
    source_ref: this paper
    variant_inference_reason: 'dataset: exact match'
    evaluation_task: node_classification
    protocol_decision: standard
    protocol_note: Standard node classification on WikiCS
    date: May 23, 2025
    date_display: May 2025
    date_iso: '2025-05-23'
    published_venue: NeurIPS 2025
    published_conference: NeurIPS 2025
    at_pub_value: null
    at_pub_std: null
    at_pub_source_arxiv: ''
    at_pub_source_title: ''
    at_pub_source_date_iso: ''
    at_pub_source_date_label: ''
    value_gap_source_date_iso: '2025-05-23'
    value_gap_source_date_label: NeurIPS 2025
    gap_vs_at_pub: null
    worse_than_at_pub: false
    surpassed_since_pub: false
    better_than_at_pub: false
    insignificant_improvement_at_pub: false
    improvement_surpassed_since_pub: false
    insignificant_value_gap: false
    today_delta_significant: false
    true_value: 0.6178
    true_std: null
    value_gap_source_arxiv: '2505.17599'
    value_gap_source_title: Dynamic Bundling with Large Language Models for Zero-Shot
      Inference on Text-Attributed Graphs
    value_gap_source_is_current_paper: true
    value_gap: null
    has_value_note: false
    value_note: ''
    sort_value: 0.6178
    sort_std: null
    global_rank: 242
    paper_rank: 242
    rank_delta: 0
    rank_delta_abs: 0
    rank_delta_direction: same
    has_value_gap: false
    comparison_type: null
    comparison_source_title: ''
    comparison_source_arxiv: ''
    is_best: false
    is_std_outlier: false
  - model: SBERT
    model_key: sbert
    model_plain: SBERT
    value: 0.5906
    std: null
    paper_value: 0.5906
    paper_std: null
    metric: Accuracy
    higher_is_better: true
    is_baseline: true
    is_overridden: false
    override_reason: ''
    params_millions: null
    architecture_type: llm
    architecture_label: LLM
    architecture_title: LLM applied to graphs
    uses_external_data: 0
    input_feature_source: null
    feature_source_evidence: ''
    table_ref: Table 1
    source_ref: this paper
    variant_inference_reason: 'dataset: exact match'
    evaluation_task: node_classification
    protocol_decision: standard
    protocol_note: Standard node classification on WikiCS
    date: May 23, 2025
    date_display: May 2025
    date_iso: '2025-05-23'
    published_venue: NeurIPS 2025
    published_conference: NeurIPS 2025
    at_pub_value: 0.5906
    at_pub_std: null
    at_pub_source_arxiv: '2502.11836'
    at_pub_source_title: 'Model Generalization on Text Attribute Graphs: Principles
      with Large Language Models'
    at_pub_source_date_iso: '2025-02-17'
    at_pub_source_date_label: '2025'
    value_gap_source_date_iso: '2025-05-23'
    value_gap_source_date_label: NeurIPS 2025
    gap_vs_at_pub: null
    worse_than_at_pub: false
    surpassed_since_pub: false
    better_than_at_pub: false
    insignificant_improvement_at_pub: false
    improvement_surpassed_since_pub: false
    insignificant_value_gap: false
    today_delta_significant: false
    true_value: 0.5906
    true_std: null
    value_gap_source_arxiv: '2505.17599'
    value_gap_source_title: Dynamic Bundling with Large Language Models for Zero-Shot
      Inference on Text-Attributed Graphs
    value_gap_source_is_current_paper: true
    value_gap: null
    has_value_note: false
    value_note: ''
    sort_value: 0.5906
    sort_std: null
    global_rank: 249
    paper_rank: 249
    rank_delta: 0
    rank_delta_abs: 0
    rank_delta_direction: same
    has_value_gap: false
    comparison_type: null
    comparison_source_title: ''
    comparison_source_arxiv: ''
    is_best: false
    is_std_outlier: false
  - model: UniGLM
    model_key: uniglm
    model_plain: UniGLM
    value: 0.5505
    std: null
    paper_value: 0.5505
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
    evaluation_task: node_classification
    protocol_decision: standard
    protocol_note: Standard node classification on WikiCS
    date: May 23, 2025
    date_display: May 2025
    date_iso: '2025-05-23'
    published_venue: NeurIPS 2025
    published_conference: NeurIPS 2025
    at_pub_value: 0.5505
    at_pub_std: null
    at_pub_source_arxiv: '2502.11836'
    at_pub_source_title: 'Model Generalization on Text Attribute Graphs: Principles
      with Large Language Models'
    at_pub_source_date_iso: '2025-02-17'
    at_pub_source_date_label: '2025'
    value_gap_source_date_iso: '2025-05-23'
    value_gap_source_date_label: NeurIPS 2025
    gap_vs_at_pub: null
    worse_than_at_pub: false
    surpassed_since_pub: false
    better_than_at_pub: false
    insignificant_improvement_at_pub: false
    improvement_surpassed_since_pub: false
    insignificant_value_gap: false
    today_delta_significant: false
    true_value: 0.5505
    true_std: null
    value_gap_source_arxiv: '2505.17599'
    value_gap_source_title: Dynamic Bundling with Large Language Models for Zero-Shot
      Inference on Text-Attributed Graphs
    value_gap_source_is_current_paper: true
    value_gap: null
    has_value_note: false
    value_note: ''
    sort_value: 0.5505
    sort_std: null
    global_rank: 256
    paper_rank: 256
    rank_delta: 0
    rank_delta_abs: 0
    rank_delta_direction: same
    has_value_gap: false
    comparison_type: null
    comparison_source_title: ''
    comparison_source_arxiv: ''
    is_best: false
    is_std_outlier: false
  - model: GraphGPT
    model_key: graphgpt
    model_plain: GraphGPT
    value: 0.3359
    std: null
    paper_value: 0.3359
    paper_std: null
    metric: Accuracy
    higher_is_better: true
    is_baseline: true
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
    evaluation_task: node_classification
    protocol_decision: standard
    protocol_note: Standard node classification on WikiCS
    date: May 23, 2025
    date_display: May 2025
    date_iso: '2025-05-23'
    published_venue: NeurIPS 2025
    published_conference: NeurIPS 2025
    at_pub_value: 0.3359
    at_pub_std: null
    at_pub_source_arxiv: '2502.11836'
    at_pub_source_title: 'Model Generalization on Text Attribute Graphs: Principles
      with Large Language Models'
    at_pub_source_date_iso: '2025-02-17'
    at_pub_source_date_label: '2025'
    value_gap_source_date_iso: '2025-05-23'
    value_gap_source_date_label: NeurIPS 2025
    gap_vs_at_pub: null
    worse_than_at_pub: false
    surpassed_since_pub: false
    better_than_at_pub: false
    insignificant_improvement_at_pub: false
    improvement_surpassed_since_pub: false
    insignificant_value_gap: false
    today_delta_significant: false
    true_value: 0.3359
    true_std: null
    value_gap_source_arxiv: '2505.17599'
    value_gap_source_title: Dynamic Bundling with Large Language Models for Zero-Shot
      Inference on Text-Attributed Graphs
    value_gap_source_is_current_paper: true
    value_gap: null
    has_value_note: false
    value_note: ''
    sort_value: 0.3359
    sort_std: null
    global_rank: 259
    paper_rank: 259
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
  experiment_scope: node-level
  dataset_primary_metric: Accuracy
  paper_metrics:
  - Accuracy
  metric: Accuracy
  uses_non_primary_metric: false
  paper_has_primary_metric: true
results_grouped:
- benchmark: Classic
  datasets:
  - *id001
- benchmark: Heterophilic Graphs
  datasets:
  - *id002
  - *id003
datasets_by_scope:
- scope: node-level
  label: Node-level
  benchmarks:
  - benchmark: Classic
    benchmark_slug: classic
    datasets:
    - dataset: WikiCS
      dataset_slug: wikics
  - benchmark: Heterophilic Graphs
    benchmark_slug: heterophilic-graphs
    datasets:
    - dataset: Texas
      dataset_slug: texas
    - dataset: Cornell
      dataset_slug: cornell
single_proposed_model: DENSE
---

