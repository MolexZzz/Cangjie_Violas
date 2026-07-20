# Violas

**In-Memory Vector Group System for Entity-Centric Vector Search.**

[![License](https://img.shields.io/badge/License-Apache_2.0-blue.svg)](LICENSE)
[![Python](https://img.shields.io/badge/Python-3.9--3.11-blue.svg)](https://www.python.org/)

Violas is an in-memory vector group system for entity-centric vector search. Modern vector
databases typically store each item as an embedding and retrieve approximate
nearest neighbors in the embedding space. This is effective when embedding
proximity is enough, but it treats each vector as an independent searchable
object and leaves richer semantic information outside the retrieval model.

Violas addresses this gap with **VectorGroup**, a semantic-first storage
abstraction that keeps semantic entities, diverse representations, member
embeddings, and object-level dependencies together. On top of this structure,
**HDMG** indexes micro-clusters with heterogeneous traversal edges to support
efficient semantic search.

## Outline

- [Why Violas?](#why-violas)
- [Typical Cases](#typical-cases)
- [How It Works](#how-it-works)
- [Experiments](#experiments)
- [API Overview](#api-overview)
- [Quick Start](#quick-start)
- [Installation Options](#installation-options)
- [Repository Layout](#repository-layout)
- [Reproducing Benchmarks](#reproducing-benchmarks)

## Why Violas?

### From Vector Search to Semantic Search

<p align="center">
  <img src="docs/figures/readme/paradigm.png" width="620" alt="Violas retrieval paradigm">
</p>

Existing vector search systems primarily organize and access data through
embedding proximity. This design is scalable, but it struggles when the query
requires semantic information that cannot be reduced to nearest-neighbor
distance alone. Filters, rerankers, and application-side dependency recovery can
help, but they still depend on the candidates returned by flat vector search.

Following the paper's semantic-search formulation, Violas extends vector search
to support results that:

- stay consistent with the intended semantic entity, such as a class, topic, or
  document
- cover diverse representations within that entity
- include dependent objects, such as adjacent chunks, temporal neighbors, or
  cross-modal evidence

The examples below show the practical retrieval failures that motivate these
requirements and the corresponding retrieval capabilities Violas supports:

- **Semantic-consistent retrieval**: retrieve results that stay consistent with the
  intended semantic entity. See [Entity Mismatch](#entity-mismatch).
- **Diversity-driven retrieval**: cover multiple poses, chunks, or local modes
  within the same entity. See [Diversity Loss](#diversity-loss).
- **Dependency-expanded retrieval**: expand a hit to linked context or temporal
  neighbors. See [Dependency Loss](#dependency-loss).
- **Cross-modal retrieval**: retrieve paired evidence across modalities. See
  [Cross-Modal Retrieval](#cross-modal-retrieval).

See [Vector Group](#vector-group) for how Violas stores this structure and
[HDMG Indexing](#hdmg-indexing) for how it is indexed efficiently.

## Typical Cases

The examples below correspond to the native capabilities evaluated in the
paper: semantic-consistent retrieval, diversity-driven retrieval,
dependency-expanded retrieval, and cross-modal retrieval. We show them through
common flat-retrieval failure modes: entity mismatch, diversity loss,
dependency loss, and broken cross-modal retrieval.

### Entity Mismatch

Flat nearest-neighbor search can drift into a different semantic entity. Violas
routes by semantic entity first, then ranks local members.

Some wrong neighbors look plausible because they share coarse traits with the
query, but they still violate the intended entity. More interestingly, some
nearest neighbors are embedding-close without a clear category-level or visual
relation to the query.

<table>
  <tr>
    <td width="50%" align="center" valign="top">
      <img src="docs/figures/readme/case-1-1.jpg" width="390" alt="Rhinoceros query retrieves visually similar but semantically wrong large animals"><br>
      <sub>Rhinoceros: large-animal shape is not enough</sub>
    </td>
    <td width="50%" align="center" valign="top">
      <img src="docs/figures/readme/case-1-2.jpg" width="390" alt="Anchor query retrieves symbols and tools that share low-level shape features"><br>
      <sub>Anchor: abstract shape should not override entity meaning</sub>
    </td>
  </tr>
  <tr>
    <td width="50%" align="center" valign="top">
      <img src="docs/figures/readme/case-2-4.jpg" width="390" alt="Pigeon query retrieves visually related but fine-grained wrong targets"><br>
      <sub>Pigeon: fine-grained category identity is not preserved</sub>
    </td>
    <td width="50%" align="center" valign="top">
      <img src="docs/figures/readme/case-1-4.jpg" width="390" alt="Stegosaurus query retrieves creatures with similar texture or shape but different semantics"><br>
      <sub>Stegosaurus: semantic identity should dominate</sub>
    </td>
  </tr>
  <tr>
    <td width="50%" align="center" valign="top">
      <img src="docs/figures/readme/case-2-1.jpg" width="390" alt="Ant query retrieves unrelated visual concepts under flat vector search"><br>
      <sub>Ant: entity identity is not preserved</sub>
    </td>
    <td width="50%" align="center" valign="top">
      <img src="docs/figures/readme/case-2-2.jpg" width="390" alt="Wristwatch query retrieves unrelated small objects with low-level visual overlap"><br>
      <sub>Wristwatch: embedding proximity is not enough</sub>
    </td>
  </tr>
</table>


### Diversity Loss

Even when the entity is correct, top results can be too redundant. Violas uses
representative local regions to expose different poses, viewpoints, chunks, or
scene layouts under the same semantic entity.

<table>
  <tr>
    <td width="50%" align="center" valign="top">
      <img src="docs/figures/readme/case-3-1.jpg" width="390" alt="Bird diversity case: retrieval should expose multiple useful views within the same bird target"><br>
      <sub>Bird: one entity, multiple useful views</sub>
    </td>
    <td width="50%" align="center" valign="top">
      <img src="docs/figures/readme/case-3-2.jpg" width="390" alt="Airplane coverage case: retrieval should cover different flight configurations and scene compositions under the same entity"><br>
      <sub>Airplane: cover flight configurations and scenes</sub>
    </td>
  </tr>
  <tr>
    <td width="50%" align="center" valign="top">
      <img src="docs/figures/readme/case-3-3.jpg" width="390" alt="Leopard diversity case: retrieval should cover different poses and body layouts"><br>
      <sub>Leopard: cover poses and body layouts</sub>
    </td>
    <td width="50%" align="center" valign="top">
      <img src="docs/figures/readme/case-3-4.jpg" width="390" alt="Gramophone diversity case: retrieval should cover structural variations and viewing conditions"><br>
      <sub>Gramophone: cover structural variations and viewing conditions</sub>
    </td>
  </tr>
</table>

### Dependency Loss

Some useful answers require linked objects rather than a single nearest chunk.
In these OHSUMED cases, the middle segment is used as the query, while the
desired answer is the surrounding same-document evidence chain. Flat top-k
retrieval often returns isolated snippets that share surface vocabulary but
lose the dependency between setup, evidence, and conclusion.

<table>
  <tr>
    <td width="50%" align="center" valign="top">
      <img src="docs/figures/readme/case-5-1.jpg" width="390" alt="Norfloxacin query needs linked evidence rather than isolated clinical-trial chunks"><br>
      <sub>Norfloxacin: trial evidence should be retrieved as a chain</sub>
    </td>
    <td width="50%" align="center" valign="top">
      <img src="docs/figures/readme/case-5-2.jpg" width="390" alt="Candidiasis treatment query needs individualized therapy context rather than isolated symptom or drug fragments"><br>
      <sub>Candidiasis: treatment choices need patient context</sub>
    </td>
  </tr>
</table>

### Cross-Modal Retrieval

Some retrieval tasks need paired evidence across modalities, such as a caption
and its corresponding image. Violas keeps these modality links inside the same
retrieval object instead of reconstructing them after a flat vector search.

<table>
  <tr>
    <td width="50%" align="center" valign="top">
      <img src="docs/figures/readme/case-4-1.jpg" width="390" alt="COCO multimodal query about a woman cutting a large white sheet cake"><br>
      <sub>Sheet cake: text query aligned with image evidence</sub>
    </td>
    <td width="50%" align="center" valign="top">
      <img src="docs/figures/readme/case-4-2.jpg" width="390" alt="COCO multimodal query about a motorbike on a dirt road in the countryside"><br>
      <sub>Motorbike: scene-level text and image agreement</sub>
    </td>
  </tr>
  <tr>
    <td width="50%" align="center" valign="top">
      <img src="docs/figures/readme/case-4-3.jpg" width="390" alt="COCO multimodal query about a girl holding a cat and wearing a colorful skirt"><br>
      <sub>Girl with cat: paired visual and caption evidence</sub>
    </td>
    <td width="50%" align="center" valign="top">
      <img src="docs/figures/readme/case-4-4.jpg" width="390" alt="COCO multimodal query about a girl preparing to blow out a candle"><br>
      <sub>Candle: multimodal evidence keeps context intact</sub>
    </td>
  </tr>
</table>

## How It Works

### Vector Group

<p align="center">
  <img src="docs/figures/readme/vectorgroup.png" width="720" alt="Vector Group structure">
</p>

`VectorGroup` is the semantic-first storage abstraction behind Violas. It stores
the semantic information required by semantic search together with the objects
and embeddings. Each vector group is organized as a three-level structure:

| Layer | Role |
| --- | --- |
| Group header | Stores the semantic key and group-level semantic vector, giving retrieval an entity-level entry point. |
| Micro-clusters | Organize member objects that exhibit diverse local representations within the same entity. |
| Members | Store concrete objects, embeddings, metadata, and object-level dependency relations. |

This lets one entity, such as a class, document, event, or multimodal item, be
managed as one retrieval object instead of a loose collection of independent
embeddings.

### Retrieval Modes

The same `VectorGroup` structure supports multiple retrieval modes by changing
the retrieval scope, output granularity, and expansion policy. A query first
enters candidate groups through an explicit key or a group-level semantic
vector, then selects micro-clusters or members with a mixed semantic-embedding
score. The query-controlled parameter `beta` balances semantic consistency and
embedding proximity. When linked objects are required, selected members are
expanded through stored relations.

<p align="center">
  <img src="docs/figures/readme/retrieval.jpg" width="560" alt="Violas retrieval modes">
</p>

| Paper capability | Primary APIs | Typical output |
| --- | --- | --- |
| Semantic-consistent retrieval | `search_entity(...)`, `search(..., key=...)` | Results scoped to the intended entity. |
| Diversity-driven retrieval | `create_cluster(...)`, `search_diverse(...)`, `search_with_representative_rerank(...)` | Results composed across local forms of one entity. |
| Dependency-expanded retrieval | `add_relation(...)`, `search_dependency(...)`, `search_with_contextual_vectors(...)` | A seed hit plus linked context or evidence. |
| Cross-modal retrieval | `add_pair_relation(...)`, `search_modal(...)`, `search_multimodal(...)` | Paired image-text or multi-view evidence. |

### HDMG Indexing

<p align="center">
  <img src="docs/figures/readme/HDMG.png" width="560" alt="HDMG structure">
</p>

On top of `VectorGroup`, Violas builds **HDMG** (Hierarchical Diversified Micro
Cluster Graph), an index for efficient semantic search over vector groups. HDMG
indexes micro-clusters because they are the main searchable units and preserve
both semantic and embedding coherence. It uses heterogeneous traversal edges:

- embedding edges preserve proximity between micro-clusters
- semantic edges preserve reachability within the same or semantically related
  vector groups
- query-time navigation follows the tradeoff between semantic consistency and
  embedding proximity

## Experiments

![Violas Benchmark Overview](docs/figures/benchmarks/overview_grid.png)

Violas is evaluated on six image and text datasets. Following the paper, we
compare Violas with three popular vector databases: Milvus, Qdrant, and Chroma.
We also study the performance differences between Violas and Violas without
HDMG (w/o HDMG). For system performance, we measure query latency and the
operation time of data and index maintenance.

<p align="center">
  <img src="docs/figures/benchmarks/table2.jpg" width="920" alt="Comparison of average Mixed Recall@3, Mixed NDCG@3, and query latency under different beta">
  <br>
  <sub>Comparison of average Mixed Recall@3, Mixed NDCG@3, and query latency under different &beta;.</sub>
</p>

<p align="center">
  <img src="docs/figures/benchmarks/table3.jpg" width="920" alt="Average operation time for data and index maintenance">
  <br>
  <sub>Average operation time for data and index maintenance.</sub>
</p>

What this shows:

- Violas improves average Mixed Recall@3 and Mixed NDCG@3 by 40.3% and 30.0%
  over representative vector-search baselines.
- Violas achieves the lowest query latency and maintenance operation time.

The benchmark environment uses an Intel Xeon Platinum 8350C CPU (2.60 GHz),
16 CPU cores, and 64 GB RAM. Image embeddings use CLIP ViT-B/32 and text
embeddings use Sentence-Transformers all-MiniLM-L6-v2 in the benchmark
pipelines.

More details:

- [Benchmark Results](docs/results.md)
- [Benchmark Notes](docs/benchmark.md)
- [Data Format](docs/data_format.md)

## API Overview

Violas exposes the high-level retrieval capabilities described in the paper,
and backs them with concrete system APIs for object lifecycle management, index
construction, relation maintenance, query execution, and inspection. The goal is
to make the research abstraction usable as an implemented retrieval system, not
only as paper pseudocode.

### Implemented System Surface

| Area | APIs | What it covers |
| --- | --- | --- |
| Create / insert | `create_group(...)`, `insert(...)`, `insert_object(...)`, `add_vector(...)`, `add_vector_list(...)` | Create semantic groups and insert individual or batched objects. |
| Read / access | `get(...)`, `get_all_keys(...)`, `get_group_by_name(...)`, `get_group_by_id(...)` | Access stored keys, metadata, groups, and group contents. |
| Update / move | `update(...)`, `update_object(...)`, `assign(...)`, `assign_object(...)` | Update object embeddings or metadata and move objects across groups. |
| Delete | `delete(...)`, `delete_object(...)` | Remove stored objects by reference. |
| Index construction | `build_index(...)`, `build_rep_index(...)`, `build_single_index(...)`, `set_key_vectors(...)`, `build_hdmg(...)`, `get_last_hdmg_search_stats(...)` | Build member indexes, representative indexes, semantic key state, and HDMG. |
| Relation management | `VectorRef`, `VectorRelation`, `add_relation(...)`, `remove_relation(...)`, `add_pair_relation(...)`, `add_tree_relation(...)`, `get_relations(...)` | Maintain context, temporal, hierarchy, dependency, and multimodal links. |
| Query execution | `search(...)`, `search_entity(...)`, `search_diverse(...)`, `search_dependency(...)`, `search_modal(...)`, `search_hdmg(...)` | Run standard, scoped, diverse, relation-aware, multimodal, and HDMG-backed retrieval. |
| Inspection | `get_all_keys(...)`, `get_group_by_name(...)`, `get_statistics(...)`, `analyze_relationships(...)` | Inspect stored keys, groups, index state, and relation coverage. |

Example: object lifecycle and relation setup:

```python
ref = vm.insert_object("paper-001", query_vec, {"text": "middle segment"})
ctx = vm.insert_object("paper-001", context_vec, {"text": "previous segment"})
vm.add_relation(ref, ctx, relation_type="context")
vm.update(ref, description={"section": "clinical evidence"})
```

Example: build indexes and run structured retrieval:

```python
vm.set_key_vectors(key_vectors)
vm.build_index()
vm.build_hdmg()

results = vm.search_hdmg(query_vector, query_key_vector=semantic_embedding, top_k=5)
context = vm.search_dependency(query_vector, relation_types=["context"], top_k=5)
```

For the fuller method list and retrieval patterns, see [docs/api.md](docs/api.md).

## Quick Start

Install the package in editable mode:

```bash
python -m venv .venv
source .venv/bin/activate
pip install -e .
```

If you want the packaged core library from PyPI later, the distribution name is
`violas`.

Run the minimal example. It uses synthetic vectors and does not require any
dataset, embedding model, or external vector database:

```bash
python examples/minimal_vectormap.py
```

Minimal API usage:

```python
import numpy as np

from violas import VectorMap

vectors = [np.random.rand(4) for _ in range(5)]
vm = VectorMap()
vm.create_group(
    key="example",
    group_name="demo",
    representative=np.mean(vectors, axis=0),
    rep_description="demo representative",
    vectors=vectors,
    descriptions=[{"text": f"item {i}"} for i in range(5)],
    vector_type="demo",
    group_type="synthetic",
)

query = np.random.rand(4)
results = vm.search_entity(query, key="example", top_k=3)
for rank, result in enumerate(results, start=1):
    text = result.group.descriptions[result.vector_idx]["text"]
    print(f"{rank}. key={result.key} distance={result.distance:.4f} text={text}")
```

## Installation Options

For quick library experiments, install only the minimal dependencies shown in
[Quick Start](#quick-start). If you only need FAISS-backed local indexing in
the core package, install the optional FAISS extra:

```bash
pip install -e ".[faiss]"
```

The full benchmark suite uses additional embedding models and external vector
database baselines. For the full benchmark environment:

```bash
pip install -r requirements.txt
pip install -e .
```

The benchmark dependencies include optional-heavy packages such as CLIP,
Sentence-Transformers, FAISS, Milvus Lite, Qdrant, and Chroma because the
benchmark suite compares Violas with external vector database baselines.

## Repository Layout

```text
Violas/
  violas/
    storage/       # VectorMap, VectorGroup, relation helpers
    core/          # feature helpers, recall utilities, baseline indexes
  benchmarks/      # six benchmark pipelines plus diversity cases
  examples/        # small runnable examples
  scripts/         # benchmark wrapper scripts
  docs/            # API notes, data formats, benchmark results, README figures
```

## Reproducing Benchmarks

The shell scripts assume a workspace where `Violas/` and `dataset/` are
siblings. Override the dataset variables if your data lives elsewhere.

```bash
bash scripts/run_bench_all.sh
bash scripts/run_bench_vision.sh
bash scripts/run_bench_text.sh
bash scripts/run_diversity_case.sh
```

Vision dataset variables:

- `CALTECH_ROOT`
- `CUB_ROOT`
- `COCO_ROOT`
- `COCO_JSON`

Text dataset variables:

- `NEWS20_ROOT`
- `OHSUMED_ROOT`
- `YAHOO_ROOT`

Saved artifacts are written under `outputs/<benchmark>/` by default. External
vector database baselines are disabled by default for portability. To enable
them:

```bash
export VIOLAS_ENABLE_EXTERNAL_DBS=1
```

## License

Apache License 2.0 - See [LICENSE](LICENSE)
