---
title: Towards Stable, Globally Expressive Graph Representations with Laplacian Eigenvectors
arxiv_id: '2410.09737'
source_url: ''
authors:
- name: Junru Zhou
  orcid: null
  s2_author_id: '2239060053'
  s2_url: null
- name: Cai Zhou
  orcid: null
  s2_author_id: '2216730316'
  s2_url: null
- name: Xiyuan Wang
  orcid: null
  s2_author_id: '2167480960'
  s2_url: null
- name: Pan Li
  orcid: null
  s2_author_id: '2300251289'
  s2_url: null
- name: Muhan Zhang
  orcid: null
  s2_author_id: '2253922541'
  s2_url: null
published_date: Oct 13, 2024
published_date_iso: '2024-10-13'
published_venue: ''
published_conference: ''
published_conference_short: ''
published_conference_slug: ''
abstract: Graph neural networks (GNNs) have achieved remarkable success in a variety
  of machine learning tasks over graph data. Existing GNNs usually rely on message
  passing, i.e., computing node representations by gathering information from the
  neighborhood, to build their underlying computational graphs. Such an approach has
  been shown fairly limited in expressive power, and often fails to capture global
  characteristics of graphs. To overcome the issue, a popular solution is to use Laplacian
  eigenvectors as additional node features, as they are known to contain global positional
  information of nodes, and can serve as extra node identifiers aiding GNNs to separate
  structurally similar nodes. Since eigenvectors naturally come with symmetries---namely,
  $O(p)$-group symmetry for every $p$ eigenvectors with equal eigenvalue, properly
  handling such symmetries is crucial for the stability and generalizability of Laplacian
  eigenvector augmented GNNs. However, using a naive $O(p)$-group invariant encoder
  for each $p$-dimensional eigenspace may not keep the full expressivity in the Laplacian
  eigenvectors. Moreover, computing such invariants inevitably entails a hard split
  of Laplacian eigenvalues according to their numerical identity, which suffers from
  great instability when the graph structure has small perturbations. In this paper,
  we propose a novel method exploiting Laplacian eigenvectors to generate stable and
  globally expressive graph representations. The main difference from previous works
  is that (i) our method utilizes learnable $O(p)$-invariant representations for each
  Laplacian eigenspace of dimension $p$, which are built upon powerful orthogonal
  group equivariant neural network layers already well studied in the literature,
  and that (ii) our method deals with numerically close eigenvalues in a smooth fashion,
  ensuring its better robustness against perturbations. Experiments on various graph
  learning benchmarks witness the competitive performance of our method, especially
  its great potential to learn global properties of graphs.
codebase_url: ''
extraction_model: cyankiwi/gemma-4-26B-A4B-it-AWQ-4bit
has_results: true
paper_type: dataset
proposed_models: []
mrr: null
adjusted_mrr: null
mrr_dataset_count: 0
benchmark_categories:
- LRGB
benchmark_coverage:
- benchmark: LRGB
  benchmark_slug: lrgb
  evaluated: 1
  total: 5
task_categories:
- link_prediction
experiment_scopes:
- edge-level
results:
- &id001
  dataset: PCQM-Contact
  rows:
  - model: CoCN exp.
    model_key: exphormer
    model_plain: CoCN exp.
    value: 0.4737
    std: 0.0024
    metric: MRR
    higher_is_better: true
    is_baseline: true
    is_overridden: false
    override_reason: ''
    params_millions: null
    architecture_type: graph_transformer
    architecture_label: GT
    architecture_title: Graph transformer
    arxiv_id: '2411.12732'
    title: Benchmarking Positional Encodings for GNNs and Graph Transformers
    date: Nov 19, 2024
    date_display: Nov 2024
    date_iso: '2024-11-19'
    venue: Knowledge Discovery and Data Mining
    codebase_url: https://github.com/ETH-DISCO/Benchmarking-PEs
    uses_external_data: false
    input_feature_source: null
    feature_source_evidence: ''
    is_global_top: true
    global_rank: 1
    sort_value: 0.4737
    sort_std: 0.0024
    comparison_type: global_top
    comparison_source_title: ''
    comparison_source_arxiv: ''
    is_best: true
    is_std_outlier: false
  - model: CoCN exp.
    model_key: exphormer + lappe
    model_plain: CoCN exp.
    value: 0.4737
    std: 0.0024
    metric: MRR
    higher_is_better: true
    is_baseline: true
    is_overridden: false
    override_reason: ''
    params_millions: null
    architecture_type: graph_transformer
    architecture_label: GT
    architecture_title: Graph transformer
    arxiv_id: '2411.12732'
    title: Benchmarking Positional Encodings for GNNs and Graph Transformers
    date: Nov 19, 2024
    date_display: Nov 2024
    date_iso: '2024-11-19'
    venue: Knowledge Discovery and Data Mining
    codebase_url: https://github.com/ETH-DISCO/Benchmarking-PEs
    uses_external_data: false
    input_feature_source: null
    feature_source_evidence: ''
    is_global_top: true
    global_rank: 2
    sort_value: 0.4737
    sort_std: 0.0024
    comparison_type: global_top
    comparison_source_title: ''
    comparison_source_arxiv: ''
    is_best: true
    is_std_outlier: false
  - model: CoCN exp.
    model_key: graphgps + rwse
    model_plain: CoCN exp.
    value: 0.4685
    std: 0.0009
    metric: MRR
    higher_is_better: true
    is_baseline: true
    is_overridden: false
    override_reason: ''
    params_millions: null
    architecture_type: hybrid
    architecture_label: Hyb
    architecture_title: Hybrid MPNN + transformer
    arxiv_id: '2411.12732'
    title: Benchmarking Positional Encodings for GNNs and Graph Transformers
    date: Nov 19, 2024
    date_display: Nov 2024
    date_iso: '2024-11-19'
    venue: Knowledge Discovery and Data Mining
    codebase_url: https://github.com/ETH-DISCO/Benchmarking-PEs
    uses_external_data: false
    input_feature_source: null
    feature_source_evidence: ''
    is_global_top: true
    global_rank: 3
    sort_value: 0.4685
    sort_std: 0.0009
    comparison_type: global_top
    comparison_source_title: ''
    comparison_source_arxiv: ''
    is_best: false
    is_std_outlier: false
  - model: GatedGCN
    model_key: gatedgcn
    model_plain: GatedGCN
    value: 0.3218
    std: 0.0011
    paper_value: 0.3218
    paper_std: 0.0011
    metric: MRR
    higher_is_better: true
    is_baseline: true
    is_overridden: false
    override_reason: ''
    params_millions: null
    architecture_type: gnn
    architecture_label: GNN
    architecture_title: Message-passing GNN
    uses_external_data: 0
    input_feature_source: raw_features
    feature_source_evidence: PE is 'None'
    table_ref: Table LRGB
    source_ref: this paper
    variant_inference_reason: 'dataset: exact match'
    evaluation_task: link_prediction
    protocol_decision: standard
    protocol_note: Standard split for PCQM-Contact link prediction task
    date: Oct 13, 2024
    date_display: Oct 2024
    date_iso: '2024-10-13'
    published_venue: ''
    published_conference: ''
    at_pub_value: 0.467
    at_pub_std: 0.0004
    at_pub_source_arxiv: '2406.03386'
    at_pub_source_title: Learning Long Range Dependencies on Graphs via Random Walks
    at_pub_source_date_iso: '2024-06-05'
    at_pub_source_date_label: ICLR 2024
    value_gap_source_date_iso: '2024-11-19'
    value_gap_source_date_label: KDD 2024
    gap_vs_at_pub: 0.14520000000000005
    worse_than_at_pub: true
    surpassed_since_pub: false
    better_than_at_pub: false
    insignificant_improvement_at_pub: false
    improvement_surpassed_since_pub: false
    insignificant_value_gap: false
    today_delta_significant: true
    true_value: 0.467
    true_std: 0.0004
    value_gap_source_arxiv: '2411.12732'
    value_gap_source_title: Benchmarking Positional Encodings for GNNs and Graph Transformers
    value_gap_source_is_current_paper: false
    value_gap: 0.14520000000000005
    has_value_note: false
    value_note: ''
    sort_value: 0.467
    sort_std: 0.0004
    global_rank: 5
    paper_rank: 46
    rank_delta: 41
    rank_delta_abs: 41
    rank_delta_direction: worse
    has_value_gap: true
    comparison_type: behind
    comparison_source_title: Learning Long Range Dependencies on Graphs via Random
      Walks
    comparison_source_arxiv: '2406.03386'
    is_best: false
    is_std_outlier: false
  - model: GINE
    model_key: gine
    model_plain: GINE
    value: 0.318
    std: 0.0027
    paper_value: 0.318
    paper_std: 0.0027
    metric: MRR
    higher_is_better: true
    is_baseline: true
    is_overridden: false
    override_reason: ''
    params_millions: null
    architecture_type: gnn
    architecture_label: GNN
    architecture_title: Message-passing GNN
    uses_external_data: 0
    input_feature_source: raw_features
    feature_source_evidence: PE is 'None'
    table_ref: Table LRGB
    source_ref: this paper
    variant_inference_reason: 'dataset: exact match'
    evaluation_task: link_prediction
    protocol_decision: standard
    protocol_note: Standard split for PCQM-Contact link prediction task
    date: Oct 13, 2024
    date_display: Oct 2024
    date_iso: '2024-10-13'
    published_venue: ''
    published_conference: ''
    at_pub_value: 0.318
    at_pub_std: 0.0027
    at_pub_source_arxiv: '2205.12454'
    at_pub_source_title: Recipe for a General, Powerful, Scalable Graph Transformer
    at_pub_source_date_iso: '2022-05-25'
    at_pub_source_date_label: NeurIPS 2022
    value_gap_source_date_iso: '2024-11-19'
    value_gap_source_date_label: KDD 2024
    gap_vs_at_pub: null
    worse_than_at_pub: false
    surpassed_since_pub: true
    better_than_at_pub: false
    insignificant_improvement_at_pub: false
    improvement_surpassed_since_pub: false
    insignificant_value_gap: false
    today_delta_significant: true
    true_value: 0.4617
    true_std: 0.0005
    value_gap_source_arxiv: '2411.12732'
    value_gap_source_title: Benchmarking Positional Encodings for GNNs and Graph Transformers
    value_gap_source_is_current_paper: false
    value_gap: 0.1437
    has_value_note: false
    value_note: ''
    sort_value: 0.4617
    sort_std: 0.0005
    global_rank: 12
    paper_rank: 46
    rank_delta: 34
    rank_delta_abs: 34
    rank_delta_direction: worse
    has_value_gap: true
    comparison_type: null
    comparison_source_title: ''
    comparison_source_arxiv: ''
    is_best: false
    is_std_outlier: false
  - model: GCN
    model_key: gcn
    model_plain: GCN
    value: 0.3234
    std: 0.0006
    paper_value: 0.3234
    paper_std: 0.0006
    metric: MRR
    higher_is_better: true
    is_baseline: true
    is_overridden: false
    override_reason: ''
    params_millions: null
    architecture_type: gnn
    architecture_label: GNN
    architecture_title: Message-passing GNN
    uses_external_data: 0
    input_feature_source: raw_features
    feature_source_evidence: PE is 'None'
    table_ref: Table LRGB
    source_ref: this paper
    variant_inference_reason: 'dataset: exact match'
    evaluation_task: link_prediction
    protocol_decision: standard
    protocol_note: Standard split for PCQM-Contact link prediction task
    date: Oct 13, 2024
    date_display: Oct 2024
    date_iso: '2024-10-13'
    published_venue: ''
    published_conference: ''
    at_pub_value: 0.4526
    at_pub_std: 0.0006
    at_pub_source_arxiv: '2406.03386'
    at_pub_source_title: Learning Long Range Dependencies on Graphs via Random Walks
    at_pub_source_date_iso: '2024-06-05'
    at_pub_source_date_label: ICLR 2024
    value_gap_source_date_iso: '2024-11-19'
    value_gap_source_date_label: KDD 2024
    gap_vs_at_pub: 0.12919999999999998
    worse_than_at_pub: true
    surpassed_since_pub: false
    better_than_at_pub: false
    insignificant_improvement_at_pub: false
    improvement_surpassed_since_pub: false
    insignificant_value_gap: false
    today_delta_significant: true
    true_value: 0.4526
    true_std: 0.0006
    value_gap_source_arxiv: '2411.12732'
    value_gap_source_title: Benchmarking Positional Encodings for GNNs and Graph Transformers
    value_gap_source_is_current_paper: false
    value_gap: 0.12919999999999998
    has_value_note: false
    value_note: ''
    sort_value: 0.4526
    sort_std: 0.0006
    global_rank: 24
    paper_rank: 45
    rank_delta: 21
    rank_delta_abs: 21
    rank_delta_direction: worse
    has_value_gap: true
    comparison_type: behind
    comparison_source_title: Learning Long Range Dependencies on Graphs via Random
      Walks
    comparison_source_arxiv: '2406.03386'
    is_best: false
    is_std_outlier: false
  - model: GPS
    model_key: gps
    model_plain: GPS
    value: 0.3543
    std: 0.0004
    paper_value: 0.3543
    paper_std: 0.0004
    metric: MRR
    higher_is_better: true
    is_baseline: true
    is_overridden: false
    override_reason: ''
    params_millions: null
    architecture_type: hybrid
    architecture_label: Hyb
    architecture_title: Hybrid MPNN + transformer
    uses_external_data: 0
    input_feature_source: raw_features
    feature_source_evidence: PE is 'OGE-Aug (ours)'
    table_ref: Table LRGB
    source_ref: this paper
    variant_inference_reason: 'dataset: exact match'
    evaluation_task: link_prediction
    protocol_decision: standard
    protocol_note: Standard split for PCQM-Contact link prediction task
    date: Oct 13, 2024
    date_display: Oct 2024
    date_iso: '2024-10-13'
    published_venue: ''
    published_conference: ''
    at_pub_value: 0.4703
    at_pub_std: 0.0014
    at_pub_source_arxiv: '2406.03386'
    at_pub_source_title: Learning Long Range Dependencies on Graphs via Random Walks
    at_pub_source_date_iso: '2024-06-05'
    at_pub_source_date_label: ICLR 2024
    value_gap_source_date_iso: '2024-10-13'
    value_gap_source_date_label: '2024'
    gap_vs_at_pub: 0.11599999999999999
    worse_than_at_pub: true
    surpassed_since_pub: false
    better_than_at_pub: false
    insignificant_improvement_at_pub: false
    improvement_surpassed_since_pub: false
    insignificant_value_gap: false
    today_delta_significant: false
    true_value: 0.3543
    true_std: 0.0004
    value_gap_source_arxiv: '2410.09737'
    value_gap_source_title: Towards Stable, Globally Expressive Graph Representations
      with Laplacian Eigenvectors
    value_gap_source_is_current_paper: true
    value_gap: null
    has_value_note: false
    value_note: ''
    sort_value: 0.3543
    sort_std: 0.0004
    global_rank: 33
    paper_rank: 33
    rank_delta: 0
    rank_delta_abs: 0
    rank_delta_direction: same
    has_value_gap: true
    comparison_type: behind
    comparison_source_title: Learning Long Range Dependencies on Graphs via Random
      Walks
    comparison_source_arxiv: '2406.03386'
    is_best: false
    is_std_outlier: false
  - model: SAN
    model_key: san
    model_plain: SAN
    value: 0.335
    std: 0.0003
    paper_value: 0.335
    paper_std: 0.0003
    metric: MRR
    higher_is_better: true
    is_baseline: true
    is_overridden: false
    override_reason: ''
    params_millions: null
    architecture_type: graph_transformer
    architecture_label: GT
    architecture_title: Graph transformer
    uses_external_data: 0
    input_feature_source: raw_features
    feature_source_evidence: PE is 'LapPE'
    table_ref: Table LRGB
    source_ref: this paper
    variant_inference_reason: 'dataset: exact match'
    evaluation_task: link_prediction
    protocol_decision: standard
    protocol_note: Standard split for PCQM-Contact link prediction task
    date: Oct 13, 2024
    date_display: Oct 2024
    date_iso: '2024-10-13'
    published_venue: ''
    published_conference: ''
    at_pub_value: 0.3341
    at_pub_std: 0.0006
    at_pub_source_arxiv: '2405.21061'
    at_pub_source_title: Graph External Attention Enhanced Transformer
    at_pub_source_date_iso: '2024-05-31'
    at_pub_source_date_label: ICML 2024
    value_gap_source_date_iso: '2024-10-13'
    value_gap_source_date_label: '2024'
    gap_vs_at_pub: 0.0009000000000000119
    worse_than_at_pub: false
    surpassed_since_pub: false
    better_than_at_pub: true
    insignificant_improvement_at_pub: false
    improvement_surpassed_since_pub: false
    insignificant_value_gap: false
    today_delta_significant: false
    true_value: 0.335
    true_std: 0.0003
    value_gap_source_arxiv: '2410.09737'
    value_gap_source_title: Towards Stable, Globally Expressive Graph Representations
      with Laplacian Eigenvectors
    value_gap_source_is_current_paper: true
    value_gap: null
    has_value_note: false
    value_note: ''
    sort_value: 0.335
    sort_std: 0.0003
    global_rank: 40
    paper_rank: 40
    rank_delta: 0
    rank_delta_abs: 0
    rank_delta_direction: same
    has_value_gap: true
    comparison_type: improved
    comparison_source_title: Graph External Attention Enhanced Transformer
    comparison_source_arxiv: '2405.21061'
    is_best: false
    is_std_outlier: false
  - model: Transformer
    model_key: transformer
    model_plain: Transformer
    value: 0.3174
    std: 0.002
    paper_value: 0.3174
    paper_std: 0.002
    metric: MRR
    higher_is_better: true
    is_baseline: true
    is_overridden: false
    override_reason: ''
    params_millions: null
    architecture_type: graph_transformer
    architecture_label: GT
    architecture_title: Graph transformer
    uses_external_data: 0
    input_feature_source: raw_features
    feature_source_evidence: PE is 'LapPE'
    table_ref: Table LRGB
    source_ref: this paper
    variant_inference_reason: 'dataset: exact match'
    evaluation_task: link_prediction
    protocol_decision: standard
    protocol_note: Standard split for PCQM-Contact link prediction task
    date: Oct 13, 2024
    date_display: Oct 2024
    date_iso: '2024-10-13'
    published_venue: ''
    published_conference: ''
    at_pub_value: 0.3174
    at_pub_std: 0.002
    at_pub_source_arxiv: '2405.21061'
    at_pub_source_title: Graph External Attention Enhanced Transformer
    at_pub_source_date_iso: '2024-05-31'
    at_pub_source_date_label: ICML 2024
    value_gap_source_date_iso: '2024-10-13'
    value_gap_source_date_label: '2024'
    gap_vs_at_pub: null
    worse_than_at_pub: false
    surpassed_since_pub: false
    better_than_at_pub: false
    insignificant_improvement_at_pub: false
    improvement_surpassed_since_pub: false
    insignificant_value_gap: false
    today_delta_significant: false
    true_value: 0.3174
    true_std: 0.002
    value_gap_source_arxiv: '2410.09737'
    value_gap_source_title: Towards Stable, Globally Expressive Graph Representations
      with Laplacian Eigenvectors
    value_gap_source_is_current_paper: true
    value_gap: null
    has_value_note: false
    value_note: ''
    sort_value: 0.3174
    sort_std: 0.002
    global_rank: 48
    paper_rank: 48
    rank_delta: 0
    rank_delta_abs: 0
    rank_delta_direction: same
    has_value_gap: false
    comparison_type: null
    comparison_source_title: ''
    comparison_source_arxiv: ''
    is_best: false
    is_std_outlier: false
  rank_metric: MRR
  higher_is_better: true
  experiment_scope: edge-level
  dataset_primary_metric: MRR
  paper_metrics:
  - MRR
  metric: MRR
  uses_non_primary_metric: false
  paper_has_primary_metric: true
results_grouped:
- benchmark: LRGB
  datasets:
  - *id001
datasets_by_scope:
- scope: edge-level
  label: Edge-level
  benchmarks:
  - benchmark: LRGB
    benchmark_slug: lrgb
    datasets:
    - dataset: PCQM-Contact
      dataset_slug: pcqm-contact
main_figure: /figures/2410.09737/main_figure.jpegoptim.jpg
---

