---
title: 'CO-EVOLVE: Bidirectional Co-Evolution of Graph Structure and Semantics for
  Heterophilous Learning'
arxiv_id: '2603.19596'
source_url: ''
authors:
- name: Jinming Xing
  orcid: null
  s2_author_id: '2330247791'
  s2_url: null
- name: Muhammad Shahzad
  orcid: null
  s2_author_id: '2360367564'
  s2_url: null
published_date: Mar 20, 2026
published_date_iso: '2026-03-20'
published_venue: ''
published_conference: ''
published_conference_short: ''
published_conference_slug: ''
abstract: 'The integration of Large Language Models (LLMs) and Graph Neural Networks
  (GNNs) promises to unify semantic understanding with structural reasoning, yet existing
  methods typically rely on static, unidirectional pipelines. These approaches suffer
  from fundamental limitations: (1) Bidirectional Error Propagation, where semantic
  hallucinations in LLMs or structural noise in GNNs permanently poison the downstream
  modality without opportunity for recourse; (2) Semantic-Structural Dissonance, particularly
  in heterophilous settings where textual similarity contradicts topological reality;
  and (3) a Blind Leading the Blind phenomenon, where indiscriminate alignment forces
  models to mirror each other''s mistakes regardless of uncertainty. To address these
  challenges, we propose CO-EVOLVE, a dual-view co-evolution framework that treats
  graph topology and semantic embeddings as dynamic, mutually reinforcing latent variables.
  By employing a Gauss-Seidel alternating optimization strategy, our framework establishes
  a cyclic feedback loop: the GNN injects structural context as Soft Prompts to guide
  the LLM, while the LLM constructs favorable Dynamic Semantic Graphs to rewire the
  GNN. We introduce three key innovations to stabilize this evolution: (1) a Hard-Structure
  Conflict-Aware Contrastive Loss that warps the semantic manifold to respect high-order
  topological boundaries; (2) an Adaptive Node Gating Mechanism that dynamically fuses
  static and learnable structures to recover missing links; and (3) an Uncertainty-Gated
  Consistency strategy that enables meta-cognitive alignment, ensuring models only
  learn from the confident view. Finally, an Entropy-Aware Adaptive Fusion integrates
  predictions during inference. Extensive experiments on public benchmarks demonstrate
  that CO-EVOLVE significantly outperforms state-of-the-art baselines, achieving average
  improvements of 9.07\'
codebase_url: ''
extraction_model: cyankiwi/gemma-4-26B-A4B-it-AWQ-4bit
has_results: true
paper_type: method
proposed_models:
- CO-EVOLVE
mrr: 0.0484
adjusted_mrr: 0.0323
mrr_dataset_count: 2
benchmark_categories:
- Classic
benchmark_coverage:
- benchmark: Classic
  benchmark_slug: classic
  evaluated: 2
  total: 12
task_categories:
- node_classification
experiment_scopes:
- node-level
results:
- &id001
  dataset: Reddit
  rows:
  - model: Cluster-GCN (2019)
    model_key: node sampled soup
    model_plain: Cluster-GCN (2019)
    value: 0.9728
    std: 0.0008
    metric: F1
    higher_is_better: true
    is_baseline: true
    is_overridden: false
    override_reason: ''
    params_millions: null
    architecture_type: gnn
    architecture_label: GNN
    architecture_title: Message-passing GNN
    arxiv_id: '2306.10466'
    title: 'Graph Ladling: Shockingly Simple Parallel GNN Training without Intermediate
      Communication'
    date: Jun 18, 2023
    date_display: Jun 2023
    date_iso: '2023-06-18'
    venue: International Conference on Machine Learning
    codebase_url: https://github.com/VITA-Group/graph_ladling
    uses_external_data: false
    input_feature_source: null
    feature_source_evidence: ''
    is_global_top: true
    global_rank: 1
    sort_value: 0.9728
    sort_std: 0.0008
    comparison_type: global_top
    comparison_source_title: ''
    comparison_source_arxiv: ''
    is_best: true
    is_std_outlier: false
  - model: Cluster-GCN (2019)
    model_key: engcn
    model_plain: Cluster-GCN (2019)
    value: 0.9714
    std: 0.0003
    metric: F1
    higher_is_better: true
    is_baseline: true
    is_overridden: false
    override_reason: ''
    params_millions: null
    architecture_type: hybrid
    architecture_label: Hyb
    architecture_title: Hybrid MPNN + transformer
    arxiv_id: '2210.07494'
    title: 'A Comprehensive Study on Large-Scale Graph Training: Benchmarking and
      Rethinking'
    date: Oct 14, 2022
    date_display: Oct 2022
    date_iso: '2022-10-14'
    venue: Neural Information Processing Systems
    codebase_url: https://github.com/VITA-Group/Large_Scale_GCN_Benchmarking
    uses_external_data: false
    input_feature_source: raw_features
    feature_source_evidence: ''
    is_global_top: true
    global_rank: 2
    sort_value: 0.9714
    sort_std: 0.0003
    comparison_type: global_top
    comparison_source_title: ''
    comparison_source_arxiv: ''
    is_best: false
    is_std_outlier: false
  - model: Cluster-GCN (2019)
    model_key: sagn+sle
    model_plain: Cluster-GCN (2019)
    value: 0.971
    std: 0.0
    metric: F1
    higher_is_better: true
    is_baseline: true
    is_overridden: false
    override_reason: ''
    params_millions: null
    architecture_type: gnn
    architecture_label: GNN
    architecture_title: Message-passing GNN
    arxiv_id: '2210.07494'
    title: 'A Comprehensive Study on Large-Scale Graph Training: Benchmarking and
      Rethinking'
    date: Oct 14, 2022
    date_display: Oct 2022
    date_iso: '2022-10-14'
    venue: Neural Information Processing Systems
    codebase_url: https://github.com/VITA-Group/Large_Scale_GCN_Benchmarking
    uses_external_data: false
    input_feature_source: raw_features
    feature_source_evidence: ''
    is_global_top: true
    global_rank: 3
    sort_value: 0.971
    sort_std: 0.0
    comparison_type: global_top
    comparison_source_title: ''
    comparison_source_arxiv: ''
    is_best: false
    is_std_outlier: false
  - model: GAT
    model_key: gat
    model_plain: GAT
    value: 0.5246
    std: null
    paper_value: 0.5246
    paper_std: null
    metric: F1
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
    protocol_note: Standard node classification on Reddit
    date: Mar 20, 2026
    date_display: Mar 2026
    date_iso: '2026-03-20'
    published_venue: ''
    published_conference: ''
    at_pub_value: 0.96
    at_pub_std: 0.001
    at_pub_source_arxiv: '2205.10803'
    at_pub_source_title: 'GraphMAE: Self-Supervised Masked Graph Autoencoders'
    at_pub_source_date_iso: '2022-05-22'
    at_pub_source_date_label: KDD 2022
    value_gap_source_date_iso: '2022-05-22'
    value_gap_source_date_label: KDD 2022
    gap_vs_at_pub: 0.4354
    worse_than_at_pub: true
    surpassed_since_pub: false
    better_than_at_pub: false
    insignificant_improvement_at_pub: false
    improvement_surpassed_since_pub: false
    insignificant_value_gap: false
    today_delta_significant: true
    true_value: 0.96
    true_std: 0.001
    value_gap_source_arxiv: '2205.10803'
    value_gap_source_title: 'GraphMAE: Self-Supervised Masked Graph Autoencoders'
    value_gap_source_is_current_paper: false
    value_gap: 0.4354
    has_value_note: false
    value_note: ''
    sort_value: 0.96
    sort_std: 0.001
    global_rank: 45
    paper_rank: 186
    rank_delta: 141
    rank_delta_abs: 141
    rank_delta_direction: worse
    has_value_gap: true
    comparison_type: behind
    comparison_source_title: 'GraphMAE: Self-Supervised Masked Graph Autoencoders'
    comparison_source_arxiv: '2205.10803'
    is_best: false
    is_std_outlier: false
  - model: GCN
    model_key: gcn
    model_plain: GCN
    value: 0.5317
    std: null
    paper_value: 0.5317
    paper_std: null
    metric: F1
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
    protocol_note: Standard node classification on Reddit
    date: Mar 20, 2026
    date_display: Mar 2026
    date_iso: '2026-03-20'
    published_venue: ''
    published_conference: ''
    at_pub_value: 0.953
    at_pub_std: 0.001
    at_pub_source_arxiv: '2205.10803'
    at_pub_source_title: 'GraphMAE: Self-Supervised Masked Graph Autoencoders'
    at_pub_source_date_iso: '2022-05-22'
    at_pub_source_date_label: KDD 2022
    value_gap_source_date_iso: '2022-05-22'
    value_gap_source_date_label: KDD 2022
    gap_vs_at_pub: 0.4213
    worse_than_at_pub: true
    surpassed_since_pub: false
    better_than_at_pub: false
    insignificant_improvement_at_pub: false
    improvement_surpassed_since_pub: false
    insignificant_value_gap: false
    today_delta_significant: true
    true_value: 0.953
    true_std: 0.001
    value_gap_source_arxiv: '2205.10803'
    value_gap_source_title: 'GraphMAE: Self-Supervised Masked Graph Autoencoders'
    value_gap_source_is_current_paper: false
    value_gap: 0.4213
    has_value_note: false
    value_note: ''
    sort_value: 0.953
    sort_std: 0.001
    global_rank: 69
    paper_rank: 186
    rank_delta: 117
    rank_delta_abs: 117
    rank_delta_direction: worse
    has_value_gap: true
    comparison_type: behind
    comparison_source_title: 'GraphMAE: Self-Supervised Masked Graph Autoencoders'
    comparison_source_arxiv: '2205.10803'
    is_best: false
    is_std_outlier: false
  - model: LLaGA
    model_key: llaga
    model_plain: LLaGA
    value: 0.6186
    std: null
    paper_value: 0.6186
    paper_std: null
    metric: F1
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
    protocol_note: Standard node classification on Reddit
    date: Mar 20, 2026
    date_display: Mar 2026
    date_iso: '2026-03-20'
    published_venue: ''
    published_conference: ''
    at_pub_value: 0.6718
    at_pub_std: null
    at_pub_source_arxiv: '2407.07457'
    at_pub_source_title: 'GLBench: A Comprehensive Benchmark for Graph with Large
      Language Models'
    at_pub_source_date_iso: '2024-07-10'
    at_pub_source_date_label: NeurIPS 2024
    value_gap_source_date_iso: '2024-07-10'
    value_gap_source_date_label: NeurIPS 2024
    gap_vs_at_pub: 0.053199999999999914
    worse_than_at_pub: true
    surpassed_since_pub: false
    better_than_at_pub: false
    insignificant_improvement_at_pub: false
    improvement_surpassed_since_pub: false
    insignificant_value_gap: false
    today_delta_significant: true
    true_value: 0.6718
    true_std: null
    value_gap_source_arxiv: '2407.07457'
    value_gap_source_title: 'GLBench: A Comprehensive Benchmark for Graph with Large
      Language Models'
    value_gap_source_is_current_paper: false
    value_gap: 0.053199999999999914
    has_value_note: false
    value_note: ''
    sort_value: 0.6718
    sort_std: null
    global_rank: 161
    paper_rank: 167
    rank_delta: 6
    rank_delta_abs: 6
    rank_delta_direction: worse
    has_value_gap: true
    comparison_type: behind
    comparison_source_title: 'GLBench: A Comprehensive Benchmark for Graph with Large
      Language Models'
    comparison_source_arxiv: '2407.07457'
    is_best: false
    is_std_outlier: false
  - model: CO-EVOLVE
    model_key: co-evolve
    model_plain: CO-EVOLVE
    value: 0.6084
    std: null
    paper_value: 0.6084
    paper_std: null
    metric: F1
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
    protocol_note: Standard node classification on Reddit
    date: Mar 20, 2026
    date_display: Mar 2026
    date_iso: '2026-03-20'
    published_venue: ''
    published_conference: ''
    at_pub_value: null
    at_pub_std: null
    at_pub_source_arxiv: ''
    at_pub_source_title: ''
    at_pub_source_date_iso: ''
    at_pub_source_date_label: ''
    value_gap_source_date_iso: '2026-03-20'
    value_gap_source_date_label: '2026'
    gap_vs_at_pub: null
    worse_than_at_pub: false
    surpassed_since_pub: false
    better_than_at_pub: false
    insignificant_improvement_at_pub: false
    improvement_surpassed_since_pub: false
    insignificant_value_gap: false
    today_delta_significant: false
    true_value: 0.6084
    true_std: null
    value_gap_source_arxiv: '2603.19596'
    value_gap_source_title: 'CO-EVOLVE: Bidirectional Co-Evolution of Graph Structure
      and Semantics for Heterophilous Learning'
    value_gap_source_is_current_paper: true
    value_gap: null
    has_value_note: false
    value_note: ''
    sort_value: 0.6084
    sort_std: null
    global_rank: 170
    paper_rank: 170
    rank_delta: 0
    rank_delta_abs: 0
    rank_delta_direction: same
    has_value_gap: false
    comparison_type: null
    comparison_source_title: ''
    comparison_source_arxiv: ''
    is_best: false
    is_std_outlier: false
  - model: TAPE
    model_key: tape
    model_plain: TAPE
    value: 0.5918
    std: null
    paper_value: 0.5918
    paper_std: null
    metric: F1
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
    protocol_note: Standard node classification on Reddit
    date: Mar 20, 2026
    date_display: Mar 2026
    date_iso: '2026-03-20'
    published_venue: ''
    published_conference: ''
    at_pub_value: 0.605
    at_pub_std: null
    at_pub_source_arxiv: '2407.07457'
    at_pub_source_title: 'GLBench: A Comprehensive Benchmark for Graph with Large
      Language Models'
    at_pub_source_date_iso: '2024-07-10'
    at_pub_source_date_label: NeurIPS 2024
    value_gap_source_date_iso: '2024-07-10'
    value_gap_source_date_label: NeurIPS 2024
    gap_vs_at_pub: 0.01319999999999999
    worse_than_at_pub: true
    surpassed_since_pub: false
    better_than_at_pub: false
    insignificant_improvement_at_pub: false
    improvement_surpassed_since_pub: false
    insignificant_value_gap: false
    today_delta_significant: true
    true_value: 0.605
    true_std: null
    value_gap_source_arxiv: '2407.07457'
    value_gap_source_title: 'GLBench: A Comprehensive Benchmark for Graph with Large
      Language Models'
    value_gap_source_is_current_paper: false
    value_gap: 0.01319999999999999
    has_value_note: false
    value_note: ''
    sort_value: 0.605
    sort_std: null
    global_rank: 171
    paper_rank: 174
    rank_delta: 3
    rank_delta_abs: 3
    rank_delta_direction: worse
    has_value_gap: true
    comparison_type: behind
    comparison_source_title: 'GLBench: A Comprehensive Benchmark for Graph with Large
      Language Models'
    comparison_source_arxiv: '2407.07457'
    is_best: false
    is_std_outlier: false
  - model: FLAG
    model_key: flag
    model_plain: FLAG
    value: 0.5809
    std: null
    paper_value: 0.5809
    paper_std: null
    metric: F1
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
    protocol_note: Standard node classification on Reddit
    date: Mar 20, 2026
    date_display: Mar 2026
    date_iso: '2026-03-20'
    published_venue: ''
    published_conference: ''
    at_pub_value: null
    at_pub_std: null
    at_pub_source_arxiv: ''
    at_pub_source_title: ''
    at_pub_source_date_iso: ''
    at_pub_source_date_label: ''
    value_gap_source_date_iso: '2026-03-20'
    value_gap_source_date_label: '2026'
    gap_vs_at_pub: null
    worse_than_at_pub: false
    surpassed_since_pub: false
    better_than_at_pub: false
    insignificant_improvement_at_pub: false
    improvement_surpassed_since_pub: false
    insignificant_value_gap: false
    today_delta_significant: false
    true_value: 0.5809
    true_std: null
    value_gap_source_arxiv: '2603.19596'
    value_gap_source_title: 'CO-EVOLVE: Bidirectional Co-Evolution of Graph Structure
      and Semantics for Heterophilous Learning'
    value_gap_source_is_current_paper: true
    value_gap: null
    has_value_note: false
    value_note: ''
    sort_value: 0.5809
    sort_std: null
    global_rank: 179
    paper_rank: 179
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
    value: 0.5802
    std: null
    paper_value: 0.5802
    paper_std: null
    metric: F1
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
    protocol_note: Standard node classification on Reddit
    date: Mar 20, 2026
    date_display: Mar 2026
    date_iso: '2026-03-20'
    published_venue: ''
    published_conference: ''
    at_pub_value: null
    at_pub_std: null
    at_pub_source_arxiv: ''
    at_pub_source_title: ''
    at_pub_source_date_iso: ''
    at_pub_source_date_label: ''
    value_gap_source_date_iso: '2026-03-20'
    value_gap_source_date_label: '2026'
    gap_vs_at_pub: null
    worse_than_at_pub: false
    surpassed_since_pub: false
    better_than_at_pub: false
    insignificant_improvement_at_pub: false
    improvement_surpassed_since_pub: false
    insignificant_value_gap: false
    today_delta_significant: false
    true_value: 0.5802
    true_std: null
    value_gap_source_arxiv: '2603.19596'
    value_gap_source_title: 'CO-EVOLVE: Bidirectional Co-Evolution of Graph Structure
      and Semantics for Heterophilous Learning'
    value_gap_source_is_current_paper: true
    value_gap: null
    has_value_note: false
    value_note: ''
    sort_value: 0.5802
    sort_std: null
    global_rank: 180
    paper_rank: 180
    rank_delta: 0
    rank_delta_abs: 0
    rank_delta_direction: same
    has_value_gap: false
    comparison_type: null
    comparison_source_title: ''
    comparison_source_arxiv: ''
    is_best: false
    is_std_outlier: false
  - model: PATTON
    model_key: patton
    model_plain: PATTON
    value: 0.5653
    std: null
    paper_value: 0.5653
    paper_std: null
    metric: F1
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
    protocol_note: Standard node classification on Reddit
    date: Mar 20, 2026
    date_display: Mar 2026
    date_iso: '2026-03-20'
    published_venue: ''
    published_conference: ''
    at_pub_value: 0.5785
    at_pub_std: null
    at_pub_source_arxiv: '2407.07457'
    at_pub_source_title: 'GLBench: A Comprehensive Benchmark for Graph with Large
      Language Models'
    at_pub_source_date_iso: '2024-07-10'
    at_pub_source_date_label: NeurIPS 2024
    value_gap_source_date_iso: '2024-07-10'
    value_gap_source_date_label: NeurIPS 2024
    gap_vs_at_pub: 0.01319999999999999
    worse_than_at_pub: true
    surpassed_since_pub: false
    better_than_at_pub: false
    insignificant_improvement_at_pub: false
    improvement_surpassed_since_pub: false
    insignificant_value_gap: false
    today_delta_significant: true
    true_value: 0.5785
    true_std: null
    value_gap_source_arxiv: '2407.07457'
    value_gap_source_title: 'GLBench: A Comprehensive Benchmark for Graph with Large
      Language Models'
    value_gap_source_is_current_paper: false
    value_gap: 0.01319999999999999
    has_value_note: false
    value_note: ''
    sort_value: 0.5785
    sort_std: null
    global_rank: 181
    paper_rank: 184
    rank_delta: 3
    rank_delta_abs: 3
    rank_delta_direction: worse
    has_value_gap: true
    comparison_type: behind
    comparison_source_title: 'GLBench: A Comprehensive Benchmark for Graph with Large
      Language Models'
    comparison_source_arxiv: '2407.07457'
    is_best: false
    is_std_outlier: false
  - model: RoBERTa
    model_key: roberta
    model_plain: RoBERTa
    value: 0.5578
    std: null
    paper_value: 0.5578
    paper_std: null
    metric: F1
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
    protocol_note: Standard node classification on Reddit
    date: Mar 20, 2026
    date_display: Mar 2026
    date_iso: '2026-03-20'
    published_venue: ''
    published_conference: ''
    at_pub_value: 0.571
    at_pub_std: null
    at_pub_source_arxiv: '2407.07457'
    at_pub_source_title: 'GLBench: A Comprehensive Benchmark for Graph with Large
      Language Models'
    at_pub_source_date_iso: '2024-07-10'
    at_pub_source_date_label: NeurIPS 2024
    value_gap_source_date_iso: '2024-07-10'
    value_gap_source_date_label: NeurIPS 2024
    gap_vs_at_pub: 0.01319999999999999
    worse_than_at_pub: true
    surpassed_since_pub: false
    better_than_at_pub: false
    insignificant_improvement_at_pub: false
    improvement_surpassed_since_pub: false
    insignificant_value_gap: false
    today_delta_significant: true
    true_value: 0.571
    true_std: null
    value_gap_source_arxiv: '2407.07457'
    value_gap_source_title: 'GLBench: A Comprehensive Benchmark for Graph with Large
      Language Models'
    value_gap_source_is_current_paper: false
    value_gap: 0.01319999999999999
    has_value_note: false
    value_note: ''
    sort_value: 0.571
    sort_std: null
    global_rank: 183
    paper_rank: 184
    rank_delta: 1
    rank_delta_abs: 1
    rank_delta_direction: worse
    has_value_gap: true
    comparison_type: behind
    comparison_source_title: 'GLBench: A Comprehensive Benchmark for Graph with Large
      Language Models'
    comparison_source_arxiv: '2407.07457'
    is_best: false
    is_std_outlier: false
  - model: Sent-BERT
    model_key: sent-bert
    model_plain: Sent-BERT
    value: 0.5577
    std: null
    paper_value: 0.5577
    paper_std: null
    metric: F1
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
    protocol_note: Standard node classification on Reddit
    date: Mar 20, 2026
    date_display: Mar 2026
    date_iso: '2026-03-20'
    published_venue: ''
    published_conference: ''
    at_pub_value: 0.5709
    at_pub_std: null
    at_pub_source_arxiv: '2407.07457'
    at_pub_source_title: 'GLBench: A Comprehensive Benchmark for Graph with Large
      Language Models'
    at_pub_source_date_iso: '2024-07-10'
    at_pub_source_date_label: NeurIPS 2024
    value_gap_source_date_iso: '2024-07-10'
    value_gap_source_date_label: NeurIPS 2024
    gap_vs_at_pub: 0.01319999999999999
    worse_than_at_pub: true
    surpassed_since_pub: false
    better_than_at_pub: false
    insignificant_improvement_at_pub: false
    improvement_surpassed_since_pub: false
    insignificant_value_gap: false
    today_delta_significant: true
    true_value: 0.5709
    true_std: null
    value_gap_source_arxiv: '2407.07457'
    value_gap_source_title: 'GLBench: A Comprehensive Benchmark for Graph with Large
      Language Models'
    value_gap_source_is_current_paper: false
    value_gap: 0.01319999999999999
    has_value_note: false
    value_note: ''
    sort_value: 0.5709
    sort_std: null
    global_rank: 184
    paper_rank: 184
    rank_delta: 0
    rank_delta_abs: 0
    rank_delta_direction: same
    has_value_gap: true
    comparison_type: behind
    comparison_source_title: 'GLBench: A Comprehensive Benchmark for Graph with Large
      Language Models'
    comparison_source_arxiv: '2407.07457'
    is_best: false
    is_std_outlier: false
  - model: InstructGLM
    model_key: instructglm
    model_plain: InstructGLM
    value: 0.5192
    std: null
    paper_value: 0.5192
    paper_std: null
    metric: F1
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
    protocol_note: Standard node classification on Reddit
    date: Mar 20, 2026
    date_display: Mar 2026
    date_iso: '2026-03-20'
    published_venue: ''
    published_conference: ''
    at_pub_value: 0.5324
    at_pub_std: null
    at_pub_source_arxiv: '2407.07457'
    at_pub_source_title: 'GLBench: A Comprehensive Benchmark for Graph with Large
      Language Models'
    at_pub_source_date_iso: '2024-07-10'
    at_pub_source_date_label: NeurIPS 2024
    value_gap_source_date_iso: '2024-07-10'
    value_gap_source_date_label: NeurIPS 2024
    gap_vs_at_pub: 0.01319999999999999
    worse_than_at_pub: true
    surpassed_since_pub: false
    better_than_at_pub: false
    insignificant_improvement_at_pub: false
    improvement_surpassed_since_pub: false
    insignificant_value_gap: false
    today_delta_significant: true
    true_value: 0.5324
    true_std: null
    value_gap_source_arxiv: '2407.07457'
    value_gap_source_title: 'GLBench: A Comprehensive Benchmark for Graph with Large
      Language Models'
    value_gap_source_is_current_paper: false
    value_gap: 0.01319999999999999
    has_value_note: false
    value_note: ''
    sort_value: 0.5324
    sort_std: null
    global_rank: 186
    paper_rank: 187
    rank_delta: 1
    rank_delta_abs: 1
    rank_delta_direction: worse
    has_value_gap: true
    comparison_type: behind
    comparison_source_title: 'GLBench: A Comprehensive Benchmark for Graph with Large
      Language Models'
    comparison_source_arxiv: '2407.07457'
    is_best: false
    is_std_outlier: false
  rank_metric: F1
  higher_is_better: true
  experiment_scope: node-level
  dataset_primary_metric: F1
  paper_metrics:
  - F1
  metric: F1
  uses_non_primary_metric: false
  paper_has_primary_metric: true
- &id002
  dataset: WikiCS
  rows:
  - model: GCN
    model_key: gcn
    model_plain: GCN
    value: 0.7649
    std: null
    paper_value: 0.7649
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
    date: Mar 20, 2026
    date_display: Mar 2026
    date_iso: '2026-03-20'
    published_venue: ''
    published_conference: ''
    at_pub_value: 0.9302
    at_pub_std: 0.0011
    at_pub_source_arxiv: '2204.04874'
    at_pub_source_title: Augmentation-Free Graph Contrastive Learning with Performance
      Guarantee
    at_pub_source_date_iso: '2022-04-11'
    at_pub_source_date_label: '2022'
    value_gap_source_date_iso: '2022-04-11'
    value_gap_source_date_label: '2022'
    gap_vs_at_pub: 0.1653
    worse_than_at_pub: true
    surpassed_since_pub: false
    better_than_at_pub: false
    insignificant_improvement_at_pub: false
    improvement_surpassed_since_pub: false
    insignificant_value_gap: false
    today_delta_significant: true
    true_value: 0.9302
    true_std: 0.0011
    value_gap_source_arxiv: '2204.04874'
    value_gap_source_title: Augmentation-Free Graph Contrastive Learning with Performance
      Guarantee
    value_gap_source_is_current_paper: false
    value_gap: 0.1653
    has_value_note: false
    value_note: ''
    sort_value: 0.9302
    sort_std: 0.0011
    global_rank: 1
    paper_rank: 163
    rank_delta: 162
    rank_delta_abs: 162
    rank_delta_direction: worse
    has_value_gap: true
    comparison_type: behind
    comparison_source_title: Augmentation-Free Graph Contrastive Learning with Performance
      Guarantee
    comparison_source_arxiv: '2204.04874'
    is_best: true
    is_std_outlier: false
  - model: GPM
    model_key: rse + rgcn (70b)
    model_plain: GPM
    value: 0.8852
    std: 0.0019
    metric: Accuracy
    higher_is_better: true
    is_baseline: true
    is_overridden: false
    override_reason: ''
    params_millions: null
    architecture_type: null
    architecture_label: null
    architecture_title: ''
    arxiv_id: '2405.18581'
    title: 'Unleashing the Potential of Text-attributed Graphs: Automatic Relation
      Decomposition via Large Language Models'
    date: May 28, 2024
    date_display: May 2024
    date_iso: '2024-05-28'
    venue: null
    codebase_url: ''
    uses_external_data: true
    input_feature_source: mixed
    feature_source_evidence: leverages the capability of Large Language Models (LLMs)
      to decompose the graph structure by analyzing raw text attributes
    is_global_top: true
    global_rank: 2
    sort_value: 0.8852
    sort_std: 0.0019
    comparison_type: global_top
    comparison_source_title: ''
    comparison_source_arxiv: ''
    is_best: false
    is_std_outlier: false
  - model: GPM
    model_key: rse + sehgnn (70b)
    model_plain: GPM
    value: 0.8796
    std: 0.002
    metric: Accuracy
    higher_is_better: true
    is_baseline: true
    is_overridden: false
    override_reason: ''
    params_millions: null
    architecture_type: null
    architecture_label: null
    architecture_title: ''
    arxiv_id: '2405.18581'
    title: 'Unleashing the Potential of Text-attributed Graphs: Automatic Relation
      Decomposition via Large Language Models'
    date: May 28, 2024
    date_display: May 2024
    date_iso: '2024-05-28'
    venue: null
    codebase_url: ''
    uses_external_data: true
    input_feature_source: mixed
    feature_source_evidence: leverages the capability of Large Language Models (LLMs)
      to decompose the graph structure by analyzing raw text attributes
    is_global_top: true
    global_rank: 3
    sort_value: 0.8796
    sort_std: 0.002
    comparison_type: global_top
    comparison_source_title: ''
    comparison_source_arxiv: ''
    is_best: false
    is_std_outlier: false
  - model: CO-EVOLVE
    model_key: co-evolve
    model_plain: CO-EVOLVE
    value: 0.8535
    std: null
    paper_value: 0.8535
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
    date: Mar 20, 2026
    date_display: Mar 2026
    date_iso: '2026-03-20'
    published_venue: ''
    published_conference: ''
    at_pub_value: null
    at_pub_std: null
    at_pub_source_arxiv: ''
    at_pub_source_title: ''
    at_pub_source_date_iso: ''
    at_pub_source_date_label: ''
    value_gap_source_date_iso: '2026-03-20'
    value_gap_source_date_label: '2026'
    gap_vs_at_pub: null
    worse_than_at_pub: false
    surpassed_since_pub: false
    better_than_at_pub: false
    insignificant_improvement_at_pub: false
    improvement_surpassed_since_pub: false
    insignificant_value_gap: false
    today_delta_significant: false
    true_value: 0.8535
    true_std: null
    value_gap_source_arxiv: '2603.19596'
    value_gap_source_title: 'CO-EVOLVE: Bidirectional Co-Evolution of Graph Structure
      and Semantics for Heterophilous Learning'
    value_gap_source_is_current_paper: true
    value_gap: null
    has_value_note: false
    value_note: ''
    sort_value: 0.8535
    sort_std: null
    global_rank: 11
    paper_rank: 11
    rank_delta: 0
    rank_delta_abs: 0
    rank_delta_direction: same
    has_value_gap: false
    comparison_type: null
    comparison_source_title: ''
    comparison_source_arxiv: ''
    is_best: false
    is_std_outlier: false
  - model: TAPE
    model_key: tape
    model_plain: TAPE
    value: 0.8444
    std: null
    paper_value: 0.8444
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
    date: Mar 20, 2026
    date_display: Mar 2026
    date_iso: '2026-03-20'
    published_venue: ''
    published_conference: ''
    at_pub_value: 0.8233
    at_pub_std: null
    at_pub_source_arxiv: '2407.07457'
    at_pub_source_title: 'GLBench: A Comprehensive Benchmark for Graph with Large
      Language Models'
    at_pub_source_date_iso: '2024-07-10'
    at_pub_source_date_label: NeurIPS 2024
    value_gap_source_date_iso: '2026-03-20'
    value_gap_source_date_label: '2026'
    gap_vs_at_pub: 0.021100000000000008
    worse_than_at_pub: false
    surpassed_since_pub: false
    better_than_at_pub: true
    insignificant_improvement_at_pub: false
    improvement_surpassed_since_pub: false
    insignificant_value_gap: false
    today_delta_significant: false
    true_value: 0.8444
    true_std: null
    value_gap_source_arxiv: '2603.19596'
    value_gap_source_title: 'CO-EVOLVE: Bidirectional Co-Evolution of Graph Structure
      and Semantics for Heterophilous Learning'
    value_gap_source_is_current_paper: true
    value_gap: null
    has_value_note: false
    value_note: ''
    sort_value: 0.8444
    sort_std: null
    global_rank: 15
    paper_rank: 15
    rank_delta: 0
    rank_delta_abs: 0
    rank_delta_direction: same
    has_value_gap: true
    comparison_type: improved
    comparison_source_title: 'GLBench: A Comprehensive Benchmark for Graph with Large
      Language Models'
    comparison_source_arxiv: '2407.07457'
    is_best: false
    is_std_outlier: false
  - model: FLAG
    model_key: flag
    model_plain: FLAG
    value: 0.8304
    std: null
    paper_value: 0.8304
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
    date: Mar 20, 2026
    date_display: Mar 2026
    date_iso: '2026-03-20'
    published_venue: ''
    published_conference: ''
    at_pub_value: null
    at_pub_std: null
    at_pub_source_arxiv: ''
    at_pub_source_title: ''
    at_pub_source_date_iso: ''
    at_pub_source_date_label: ''
    value_gap_source_date_iso: '2026-03-20'
    value_gap_source_date_label: '2026'
    gap_vs_at_pub: null
    worse_than_at_pub: false
    surpassed_since_pub: false
    better_than_at_pub: false
    insignificant_improvement_at_pub: false
    improvement_surpassed_since_pub: false
    insignificant_value_gap: false
    today_delta_significant: false
    true_value: 0.8304
    true_std: null
    value_gap_source_arxiv: '2603.19596'
    value_gap_source_title: 'CO-EVOLVE: Bidirectional Co-Evolution of Graph Structure
      and Semantics for Heterophilous Learning'
    value_gap_source_is_current_paper: true
    value_gap: null
    has_value_note: false
    value_note: ''
    sort_value: 0.8304
    sort_std: null
    global_rank: 19
    paper_rank: 19
    rank_delta: 0
    rank_delta_abs: 0
    rank_delta_direction: same
    has_value_gap: false
    comparison_type: null
    comparison_source_title: ''
    comparison_source_arxiv: ''
    is_best: false
    is_std_outlier: false
  - model: GAT
    model_key: gat
    model_plain: GAT
    value: 0.7683
    std: null
    paper_value: 0.7683
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
    date: Mar 20, 2026
    date_display: Mar 2026
    date_iso: '2026-03-20'
    published_venue: ''
    published_conference: ''
    at_pub_value: 0.8533
    at_pub_std: null
    at_pub_source_arxiv: '2505.19762'
    at_pub_source_title: 'Language Models as Messengers: Enhancing Message Passing
      in Heterophilic Graph Learning'
    at_pub_source_date_iso: '2025-05-26'
    at_pub_source_date_label: '2025'
    value_gap_source_date_iso: '2024-05-28'
    value_gap_source_date_label: '2024'
    gap_vs_at_pub: 0.08499999999999996
    worse_than_at_pub: true
    surpassed_since_pub: false
    better_than_at_pub: false
    insignificant_improvement_at_pub: false
    improvement_surpassed_since_pub: false
    insignificant_value_gap: false
    today_delta_significant: true
    true_value: 0.8279
    true_std: 0.0016
    value_gap_source_arxiv: '2405.18581'
    value_gap_source_title: 'Unleashing the Potential of Text-attributed Graphs: Automatic
      Relation Decomposition via Large Language Models'
    value_gap_source_is_current_paper: false
    value_gap: 0.059599999999999986
    has_value_note: false
    value_note: ''
    sort_value: 0.8279
    sort_std: 0.0016
    global_rank: 23
    paper_rank: 157
    rank_delta: 134
    rank_delta_abs: 134
    rank_delta_direction: worse
    has_value_gap: true
    comparison_type: behind
    comparison_source_title: 'Language Models as Messengers: Enhancing Message Passing
      in Heterophilic Graph Learning'
    comparison_source_arxiv: '2505.19762'
    is_best: false
    is_std_outlier: false
  - model: PATTON
    model_key: patton
    model_plain: PATTON
    value: 0.8205
    std: null
    paper_value: 0.8205
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
    date: Mar 20, 2026
    date_display: Mar 2026
    date_iso: '2026-03-20'
    published_venue: ''
    published_conference: ''
    at_pub_value: 0.8081
    at_pub_std: null
    at_pub_source_arxiv: '2407.07457'
    at_pub_source_title: 'GLBench: A Comprehensive Benchmark for Graph with Large
      Language Models'
    at_pub_source_date_iso: '2024-07-10'
    at_pub_source_date_label: NeurIPS 2024
    value_gap_source_date_iso: '2026-03-20'
    value_gap_source_date_label: '2026'
    gap_vs_at_pub: 0.012399999999999967
    worse_than_at_pub: false
    surpassed_since_pub: false
    better_than_at_pub: true
    insignificant_improvement_at_pub: false
    improvement_surpassed_since_pub: false
    insignificant_value_gap: false
    today_delta_significant: false
    true_value: 0.8205
    true_std: null
    value_gap_source_arxiv: '2603.19596'
    value_gap_source_title: 'CO-EVOLVE: Bidirectional Co-Evolution of Graph Structure
      and Semantics for Heterophilous Learning'
    value_gap_source_is_current_paper: true
    value_gap: null
    has_value_note: false
    value_note: ''
    sort_value: 0.8205
    sort_std: null
    global_rank: 28
    paper_rank: 28
    rank_delta: 0
    rank_delta_abs: 0
    rank_delta_direction: same
    has_value_gap: true
    comparison_type: improved
    comparison_source_title: 'GLBench: A Comprehensive Benchmark for Graph with Large
      Language Models'
    comparison_source_arxiv: '2407.07457'
    is_best: false
    is_std_outlier: false
  - model: LLaGA
    model_key: llaga
    model_plain: LLaGA
    value: 0.7164
    std: null
    paper_value: 0.7164
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
    date: Mar 20, 2026
    date_display: Mar 2026
    date_iso: '2026-03-20'
    published_venue: ''
    published_conference: ''
    at_pub_value: 0.8074
    at_pub_std: null
    at_pub_source_arxiv: '2503.03313'
    at_pub_source_title: 'LLM as GNN: Graph Vocabulary Learning for Text-Attributed
      Graph Foundation Models'
    at_pub_source_date_iso: '2025-03-05'
    at_pub_source_date_label: '2025'
    value_gap_source_date_iso: '2025-03-05'
    value_gap_source_date_label: '2025'
    gap_vs_at_pub: 0.09099999999999997
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
    value_gap: 0.09099999999999997
    has_value_note: false
    value_note: ''
    sort_value: 0.8074
    sort_std: null
    global_rank: 44
    paper_rank: 204
    rank_delta: 160
    rank_delta_abs: 160
    rank_delta_direction: worse
    has_value_gap: true
    comparison_type: behind
    comparison_source_title: 'LLM as GNN: Graph Vocabulary Learning for Text-Attributed
      Graph Foundation Models'
    comparison_source_arxiv: '2503.03313'
    is_best: false
    is_std_outlier: false
  - model: ZeroG
    model_key: zerog
    model_plain: ZeroG
    value: 0.7882
    std: null
    paper_value: 0.7882
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
    date: Mar 20, 2026
    date_display: Mar 2026
    date_iso: '2026-03-20'
    published_venue: ''
    published_conference: ''
    at_pub_value: 0.4825
    at_pub_std: null
    at_pub_source_arxiv: '2407.09709'
    at_pub_source_title: 'GOFA: A Generative One-For-All Model for Joint Graph Language
      Modeling'
    at_pub_source_date_iso: '2024-07-12'
    at_pub_source_date_label: ICLR 2024
    value_gap_source_date_iso: '2026-03-20'
    value_gap_source_date_label: '2026'
    gap_vs_at_pub: 0.3057
    worse_than_at_pub: false
    surpassed_since_pub: false
    better_than_at_pub: true
    insignificant_improvement_at_pub: false
    improvement_surpassed_since_pub: false
    insignificant_value_gap: false
    today_delta_significant: false
    true_value: 0.7882
    true_std: null
    value_gap_source_arxiv: '2603.19596'
    value_gap_source_title: 'CO-EVOLVE: Bidirectional Co-Evolution of Graph Structure
      and Semantics for Heterophilous Learning'
    value_gap_source_is_current_paper: true
    value_gap: null
    has_value_note: false
    value_note: ''
    sort_value: 0.7882
    sort_std: null
    global_rank: 93
    paper_rank: 93
    rank_delta: 0
    rank_delta_abs: 0
    rank_delta_direction: same
    has_value_gap: true
    comparison_type: improved
    comparison_source_title: 'GOFA: A Generative One-For-All Model for Joint Graph
      Language Modeling'
    comparison_source_arxiv: '2407.09709'
    is_best: false
    is_std_outlier: false
  - model: RoBERTa
    model_key: roberta
    model_plain: RoBERTa
    value: 0.7477
    std: null
    paper_value: 0.7477
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
    date: Mar 20, 2026
    date_display: Mar 2026
    date_iso: '2026-03-20'
    published_venue: ''
    published_conference: ''
    at_pub_value: 0.5908
    at_pub_std: null
    at_pub_source_arxiv: '2502.11836'
    at_pub_source_title: 'Model Generalization on Text Attribute Graphs: Principles
      with Large Language Models'
    at_pub_source_date_iso: '2025-02-17'
    at_pub_source_date_label: '2025'
    value_gap_source_date_iso: '2026-03-20'
    value_gap_source_date_label: '2026'
    gap_vs_at_pub: 0.15690000000000004
    worse_than_at_pub: false
    surpassed_since_pub: false
    better_than_at_pub: true
    insignificant_improvement_at_pub: false
    improvement_surpassed_since_pub: false
    insignificant_value_gap: false
    today_delta_significant: false
    true_value: 0.7477
    true_std: null
    value_gap_source_arxiv: '2603.19596'
    value_gap_source_title: 'CO-EVOLVE: Bidirectional Co-Evolution of Graph Structure
      and Semantics for Heterophilous Learning'
    value_gap_source_is_current_paper: true
    value_gap: null
    has_value_note: false
    value_note: ''
    sort_value: 0.7477
    sort_std: null
    global_rank: 183
    paper_rank: 183
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
  - model: InstructGLM
    model_key: instructglm
    model_plain: InstructGLM
    value: 0.744
    std: null
    paper_value: 0.744
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
    date: Mar 20, 2026
    date_display: Mar 2026
    date_iso: '2026-03-20'
    published_venue: ''
    published_conference: ''
    at_pub_value: 0.4573
    at_pub_std: null
    at_pub_source_arxiv: '2407.07457'
    at_pub_source_title: 'GLBench: A Comprehensive Benchmark for Graph with Large
      Language Models'
    at_pub_source_date_iso: '2024-07-10'
    at_pub_source_date_label: NeurIPS 2024
    value_gap_source_date_iso: '2026-03-20'
    value_gap_source_date_label: '2026'
    gap_vs_at_pub: 0.2867
    worse_than_at_pub: false
    surpassed_since_pub: false
    better_than_at_pub: true
    insignificant_improvement_at_pub: false
    improvement_surpassed_since_pub: false
    insignificant_value_gap: false
    today_delta_significant: false
    true_value: 0.744
    true_std: null
    value_gap_source_arxiv: '2603.19596'
    value_gap_source_title: 'CO-EVOLVE: Bidirectional Co-Evolution of Graph Structure
      and Semantics for Heterophilous Learning'
    value_gap_source_is_current_paper: true
    value_gap: null
    has_value_note: false
    value_note: ''
    sort_value: 0.744
    sort_std: null
    global_rank: 185
    paper_rank: 185
    rank_delta: 0
    rank_delta_abs: 0
    rank_delta_direction: same
    has_value_gap: true
    comparison_type: improved
    comparison_source_title: 'GLBench: A Comprehensive Benchmark for Graph with Large
      Language Models'
    comparison_source_arxiv: '2407.07457'
    is_best: false
    is_std_outlier: false
  - model: Sent-BERT
    model_key: sent-bert
    model_plain: Sent-BERT
    value: 0.742
    std: null
    paper_value: 0.742
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
    date: Mar 20, 2026
    date_display: Mar 2026
    date_iso: '2026-03-20'
    published_venue: ''
    published_conference: ''
    at_pub_value: null
    at_pub_std: null
    at_pub_source_arxiv: ''
    at_pub_source_title: ''
    at_pub_source_date_iso: ''
    at_pub_source_date_label: ''
    value_gap_source_date_iso: '2026-03-20'
    value_gap_source_date_label: '2026'
    gap_vs_at_pub: null
    worse_than_at_pub: false
    surpassed_since_pub: false
    better_than_at_pub: false
    insignificant_improvement_at_pub: false
    improvement_surpassed_since_pub: false
    insignificant_value_gap: false
    today_delta_significant: false
    true_value: 0.742
    true_std: null
    value_gap_source_arxiv: '2603.19596'
    value_gap_source_title: 'CO-EVOLVE: Bidirectional Co-Evolution of Graph Structure
      and Semantics for Heterophilous Learning'
    value_gap_source_is_current_paper: true
    value_gap: null
    has_value_note: false
    value_note: ''
    sort_value: 0.742
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
  - *id002
datasets_by_scope:
- scope: node-level
  label: Node-level
  benchmarks:
  - benchmark: Classic
    benchmark_slug: classic
    datasets:
    - dataset: Reddit
      dataset_slug: reddit
    - dataset: WikiCS
      dataset_slug: wikics
single_proposed_model: CO-EVOLVE
main_figure: /figures/2603.19596/main_figure.jpegoptim.jpg
---

