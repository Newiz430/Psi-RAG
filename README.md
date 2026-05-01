# ᛉ-RAG: Hierarchical Abstract Tree for Cross-Document Retrieval-Augmented Generation

<div align="center">
<img src="fig/psi-algiz-rune.png" style="zoom: 15%;" />
<br />
<span style="color: #666666;">Artwork by </span>
<a href="https://thorolfw.artstation.com/" style="color: #0366d6;">Thorolf Wolfson</a>
<span style="color: #666666;">.</span>
</div>

<br>

<div align="center">

[![Github](https://img.shields.io/badge/GitHub-repo-blue?style=for-the-badge&logo=github)](https://github.com/Newiz430/Psi-RAG)
[![Hugging Face](https://img.shields.io/badge/Hugging%20Face-repo-yellow?style=for-the-badge&logo=huggingface)](https://huggingface.co/Newiz430/Psi-RAG)
[![Paper](https://img.shields.io/badge/Paper-Soon-red?style=for-the-badge&logo=arxiv&logoColor=white)](TBD)
[![Paper](https://img.shields.io/badge/Paper-Soon-24282c?style=for-the-badge&logo=data:image/svg%2bxml;base64,<?xml version="1.0" encoding="UTF-8" standalone="no"?>
<svg
   inkscape:version="1.2.2 (b0a84865, 2022-12-01)"
   sodipodi:docname="icml-navbar-logo.svg"
   viewBox="0 0 99.264 97.665001"
   height="97.665001"
   width="99.264"
   xml:space="preserve"
   id="svg604"
   version="1.1"
   xmlns:inkscape="http://www.inkscape.org/namespaces/inkscape"
   xmlns:sodipodi="http://sodipodi.sourceforge.net/DTD/sodipodi-0.dtd"
   xmlns="http://www.w3.org/2000/svg"
   xmlns:svg="http://www.w3.org/2000/svg"
   xmlns:rdf="http://www.w3.org/1999/02/22-rdf-syntax-ns#"
   xmlns:cc="http://creativecommons.org/ns#"
   xmlns:dc="http://purl.org/dc/elements/1.1/"><metadata
     id="metadata610"><rdf:RDF><cc:Work
         rdf:about=""><dc:format>image/svg+xml</dc:format><dc:type
           rdf:resource="http://purl.org/dc/dcmitype/StillImage" /></cc:Work></rdf:RDF></metadata><defs
     id="defs608"><clipPath
       id="clipPath624"
       clipPathUnits="userSpaceOnUse"><path
         id="path622"
         d="M 0,108 H 216 V 0 H 0 Z" /></clipPath></defs><sodipodi:namedview
     inkscape:current-layer="g808"
     inkscape:window-maximized="0"
     inkscape:window-y="475"
     inkscape:window-x="1109"
     inkscape:cy="46.248"
     inkscape:cx="33.481091"
     inkscape:zoom="9.7517731"
     fit-margin-bottom="4"
     fit-margin-right="4"
     fit-margin-left="4"
     fit-margin-top="4"
     lock-margins="true"
     showgrid="false"
     id="namedview606"
     inkscape:window-height="926"
     inkscape:window-width="1692"
     inkscape:pageshadow="2"
     inkscape:pageopacity="0"
     guidetolerance="10"
     gridtolerance="10"
     objecttolerance="10"
     borderopacity="1"
     bordercolor="#666666"
     pagecolor="#ffffff"
     inkscape:showpageshadow="2"
     inkscape:pagecheckerboard="0"
     inkscape:deskcolor="#d1d1d1" /><g
     transform="matrix(1.3333333,0,0,-1.3333333,-9.4037331,115.5584)"
     inkscape:label="ICML Logo 2018"
     inkscape:groupmode="layer"
     id="g612"><g
       id="g618"><rect
         style="fill:#231f20;fill-opacity:1;stroke:#ffffff;stroke-width:0;stroke-dasharray:none"
         id="rect1384"
         width="8.6138182"
         height="8.8445454"
         x="51.121708"
         y="-77.901161"
         transform="scale(1,-1)" /><rect
         style="fill:#231f20;fill-opacity:1;stroke:#ffffff;stroke-width:0;stroke-dasharray:none"
         id="rect1384-5"
         width="7.7678185"
         height="7.5370908"
         x="55.890072"
         y="-63.634525"
         transform="scale(1,-1)" /><rect
         style="fill:#231f20;fill-opacity:1;stroke:#ffffff;stroke-width:0;stroke-dasharray:none"
         id="rect1384-5-9"
         width="4.6914554"
         height="4.6145458"
         x="60.543072"
         y="-70.671707"
         transform="scale(1,-1)" /><rect
         style="fill:#231f20;fill-opacity:1;stroke:#ffffff;stroke-width:0;stroke-dasharray:none"
         id="rect1384-9"
         width="12.228545"
         height="12.69"
         x="43.200073"
         y="-57.251072"
         transform="scale(1,-1)" /><g
         clip-path="url(#clipPath624)"
         id="g620"><g
           id="g511"
           transform="translate(4.5,-4.5)"><g
             transform="translate(25.2256,57.9727)"
             id="g792"><path
               id="path794"
               style="fill:#94d222;fill-opacity:1;fill-rule:nonzero;stroke:none"
               d="m 0,0 c 0,-0.682 -0.553,-1.235 -1.235,-1.235 h -8.4 c -0.682,0 -1.236,0.553 -1.236,1.235 v 8.4 c 0,0.683 0.554,1.236 1.236,1.236 h 8.4 C -0.553,9.636 0,9.083 0,8.4 Z" /></g><g
             transform="translate(35.6738,68.8438)"
             id="g796"><path
               id="path798"
               style="fill:#2a419e;fill-opacity:1;fill-rule:nonzero;stroke:none"
               d="m 0,0 c 0,-0.682 -0.554,-1.235 -1.235,-1.235 h -7.11 c -0.682,0 -1.236,0.553 -1.236,1.235 v 7.11 c 0,0.682 0.554,1.235 1.236,1.235 h 7.11 C -0.554,8.345 0,7.792 0,7.11 Z" /></g><g
             transform="translate(23.3193,75.0635)"
             id="g800"><path
               id="path802"
               style="fill:#ed1e24;fill-opacity:1;fill-rule:nonzero;stroke:none"
               d="m 0,0 c 0,-0.683 -0.553,-1.235 -1.234,-1.235 h -4.924 c -0.682,0 -1.236,0.552 -1.236,1.235 v 4.923 c 0,0.682 0.554,1.236 1.236,1.236 h 4.924 C -0.553,6.159 0,5.605 0,4.923 Z" /></g><g
             transform="translate(12.9688,69.1479)"
             id="g804"><path
               id="path806"
               style="fill:#f79011;fill-opacity:1;fill-rule:nonzero;stroke:none"
               d="M 0,0 C 0,-0.682 -0.554,-1.235 -1.236,-1.235 H -4.68 c -0.682,0 -1.236,0.553 -1.236,1.235 v 3.444 c 0,0.683 0.554,1.236 1.236,1.236 h 3.444 C -0.554,4.68 0,4.127 0,3.444 Z" /></g><g
             transform="translate(60.2002,72.3828)"
             id="g808"><path
               id="path810"
               style="fill:#f9f9f9;fill-opacity:1;fill-rule:nonzero;stroke:none"
               d="m 0,0 c 0,-0.682 -0.554,-1.235 -1.235,-1.235 h -1.412 c -0.682,0 -1.236,0.553 -1.236,1.235 v 1.412 c 0,0.682 0.554,1.234 1.236,1.234 h 1.412 C -0.554,2.646 0,2.094 0,1.412 Z m -1.479,-10.26 c 0,-0.682 -0.553,-1.235 -1.236,-1.235 h -4.553 c -0.682,0 -1.236,0.553 -1.236,1.235 v 4.554 c 0,0.683 0.554,1.236 1.236,1.236 h 4.553 c 0.683,0 1.236,-0.553 1.236,-1.236 z m -8.596,-10.629 c 0,-0.681 -0.554,-1.235 -1.236,-1.235 h -8.159 c -0.681,0 -1.234,0.554 -1.234,1.235 v 8.159 c 0,0.682 0.553,1.235 1.234,1.235 h 8.159 c 0.682,0 1.236,-0.553 1.236,-1.235 z m -2.033,27.753 c 0,0.683 0.552,1.236 1.234,1.236 h 2.983 c 0.682,0 1.236,-0.553 1.236,-1.236 V 3.882 c 0,-0.682 -0.554,-1.236 -1.236,-1.236 h -2.983 c -0.682,0 -1.234,0.554 -1.234,1.236 z M 10.446,-13.423 C 9.674,-13.81 9.48,-14.003 9.48,-12.94 v 6.275 c 0,1.452 0.548,20.951 -21.916,20.951 -6.089,0 -11.648,-1.545 -11.648,-2.994 0,-1.448 -0.033,-3.475 -0.033,-4.634 0,-1.244 0.675,-1.852 1.641,-1.852 h 5.6 c 0.677,0 1.737,-0.071 1.737,-1.265 v -6.248 c 0,-1.641 -0.809,-1.858 -1.678,-1.858 h -5.792 c -0.869,0 -1.702,-0.459 -1.702,-1.521 v -5.873 c 0,-0.854 -0.385,-1.561 -1.64,-1.561 h -5.813 c -0.772,0 -1.606,-0.964 -1.606,-2.412 0,-1.448 -0.016,-4.443 -0.016,-5.312 0,-0.869 -0.772,-0.772 -2.703,-0.772 0,0 0,-2.799 1.255,-5.986 0.671,-1.704 1.738,-2.123 3.572,-1.544 0,0 0.222,-4.619 1.284,-7.515 1.062,-2.896 1.999,-4.748 4.992,-6.871 2.994,-2.125 3.283,-2.704 5.31,-4.345 2.027,-1.642 2.896,-3.186 8.014,-3.186 5.213,0 6.468,2.027 8.592,4.151 2.124,2.125 4.56,2.207 7.53,6.663 2.511,3.765 2.647,6.812 2.993,11.2 0,0 2.704,-1.352 3.573,1.351 0.532,1.657 2.123,9.075 2.703,13.033 0.579,3.959 -2.51,2.028 -3.283,1.642" /></g><rect
             style="fill:#000000;fill-opacity:0;stroke:#ffffff;stroke-width:0;stroke-dasharray:none"
             id="rect601"
             width="9.9981823"
             height="8.3061819"
             x="45.775711"
             y="-81.862801"
             transform="scale(1,-1)" /></g></g></g></g></svg>
)]()

</div>

* [News](#news)
* [Overview](#overview)
* [Getting Started](#getting-started)
* [Indexing & QAing on your Custom Corpora](#indexing--qaing-on-your-custom-corpora)
* [Advanced Settings](#advanced-settings)
* [Layout](#layout)
* [TODOs](#todos)
* [Acknowledgements](#acknowledgements)
* [Citation](#citation)

---

## News

- May 1, 2026: Our paper is accepted in **ICML'26**! See you in Seoul! 🎉
- May 1, 2026: Our $\Psi$-RAG is out! 🎉 

## Overview

$\Psi$-RAG is an efficient and powerful hierarchical tree-based RAG framework designed to tackle complex information-seeking scenarios. It features a *hierarchical abstract tree index* with different abstraction strategies, enabling efficient and precise retrieval with logarithmic time. It employs a *multi-granular agentic retriever* including a powerful Reading & Answering agent with a hybrid retrieval pipeline for diverse user requests. 

![overview](fig/overview.png)

### ✨Key Features

- **🌳 Corpus-Level Tree Index**: Generalizes Tree-RAG from passage-level saplings to corpus-level large trees with millions of tokens. Abstration instead of named entity recognition: organize your corpus like a library with <3 hours indexing / >1 million tokens on two 48G RTX4090 GPUs!
- **🎯 Distribution-Adaptive Indexing**: No need for explicit document structure. No need for searching for the optimal cluster numbers. No need for handpicking the initial point. No need for dimension reduction steps. No need for worrying your imbalanced data. A hierarchical tree knows it all! 
- **⚡ Efficient Indexing Techniques**: Extra bucketing and HNSW support for sonic-speed similarity ranking on corpora with 10M+ tokens!
- **📚 Flexible Abstraction Mechanism**: Choose one that you prefer: summaries💊 or keywords💊! 
- **👨‍👩‍👧‍👦 Multi-granular and Multifunctional Retrieval Pipeline**: Iterative agentic retrieval empowers cross-document multi-hop tree search. Hybrid retrieval with BM25 navigates fine-grained tree search. Natural reranker support to maximize structured RAG performance. 
- **🧑‍💻 Custom Framework Support**: Built entirely with open-source LLMs. Change backbone models at will like changing ornaments for your Christmas tree!


## Getting Started

### Package requirements

See `requirements.txt` for <img src="https://cdn.simpleicons.org/python/000/fff" alt="Node" align=center width=16> package versions. 
Install dependencies:

```bash
pip install -r requirements.txt
```

Optional packages:

- Add `pip install vllm` if you prefer vLLM.
- Add `pip isntall transformers==4.46.0` for the embedding model "nvidia/NV-Embed-V2" (indexing only).
- Add `pip install mineru[all]` if you want to build custom indexes with your local PDF files.
- Add `pip install py7zr` or `pip install rarfile` if you want to upload a .7z or .rar package of local PDF files.

### Set environment variables and run the local LLM server

You may first set some useful environment variables before running our code, including:

```bash
# Hugging Face / model download
export CUDA_VISIBLE_DEVICES=0,1
export HF_TOKEN=<your_hugging_face_token>
export HF_ENDPOINT=https://hf-mirror.com	# Hugging Face mirror for users from China
# OpenAI-compatible API backends
export OPENAI_BASE_URL=<your_base_url>
export OPENAI_API_KEY=<your_api_key>
```

For <img src="https://cdn.simpleicons.org/ollama/000/fff" alt="Node" align=center width=16>Ollama users:

```bash
export OLLAMA_NUM_PARALLEL=16
export OLLAMA_MAX_LOADED_MODELS=2
export OLLAMA_NUM_GPU=2
export OLLAMA_FLASH_ATTENTION=1
# run ollama
ollama serve
# pull models you want to use
ollama pull qwen3-embedding:8b
ollama pull llama3.3:latest
```

### Configuration

We provide benchmark datasets in [`data/`](data/). Configs are Python files under [`conf/`](conf/). Each file defines a `conf` dict that overrides the defaults in [`conf/__init__.py`](conf/__init__.py). See [`conf/__init__.py`](conf/__init__.py) for detailed settings and explanations.

<details>
    <summary>Important fields</summary>

```python
# ======================================= Data config =====================================
dataset: str  					# Dataset name.
data_dir: Path  				# Dataset directory, default to "data/".
test_samples: int               # Number of samples for testing with part of the dataset. 
# =================================== Embedding config ===================================
embed_name: str					# Model name for embedding documents and queries, "[PLATFORM]:[MODEL_NAME]"
embed_cache_dir: Path			# Cache directory of the embedding model, default to os.environ["HF_HOME"]
embed_model_kwargs: Dict        # Model kwargs for embedding model. Keys depend on the model you use.
# ================================= Tree indexing config =================================
tree_builder: str               # Tree builder backend. "hnsw" for HNSW-based approximate similarity ranking.
passage_as_tree: bool			# Whether to activate single-document retrieval setup.
bucket_size: int                # Maximum bucket size for bucketing. Set to None to disable it.
# =================================== Abstraction config ==================================
abs_name: str					# Model name for node abstraction, "[PLATFORM]:[MODEL_NAME_OR_PATH]"
abs_cache_dir: Path				# Cache directory of the abstraction agent, default to os.environ["HF_HOME"].
abs_model_kwargs: Dict          # Model kwargs for the abstraction agent, similar to embed_model_kwargs.
abstract_type: str				# Type of abstract. "summary" for summative text and "keyword" for keywords. 
force_index_from_scratch: bool	# Recreate embeddings and trees even if saved files exist in save_dir.
# ==================================== R&A Agent config ===================================
qa_name: str 					# Model name for agentic retrieval and QA, "[PLATFORM]:[MODEL_NAME]"
qa_cache_dir: Path 				# Cache directory of the R&A agent, default to os.environ["HF_HOME"].
qa_model_kwargs: Dict           # Model kwargs for the R&A agent, similar to embed_model_kwargs.
answer_type: str 				# The expected answer type, ("short", "medium", "long").
no_retrieval: bool              # Skip retrieval entirely and directly answer the question.
max_retrieval_time: int 		# Maximum time of retrieval attempts (total attempts - 1). Default to "auto". 
multithreading_qa_batch_size: int		# Multithread QA for efficient reproduction on large corpus.
force_qa_from_scratch: bool		# Reanswering questions even if the answer result file exists in save_dir.
# ================================ General retrieval config ===============================
tree_top_k: int 				# Number of retrieved documents from the tree retriever.
# ================================= Hybrid retrieval config ================================
hybrid_search: bool				# If sparse keyword search (BM25) is enabled.
force_sparse_index_from_scratch: bool 	# Rebuild the sparse token vocab even if saved files exist in save_dir.
sparse_top_k: int				# Number of retrieved documents by sparse keyword search. 
# ==================================== Reranking config ===================================
rerank: bool					# If reranking is enabled.
rerank_name: str				# Model name for reranking, "[PLATFORM]:[MODEL_NAME]"
rerank_cache_dir: Path 			# Cache directory of the reranking model, default to os.environ["HF_HOME"]
rerank_model_kwargs: Dict       # Model kwargs for the reranker, similar to embed_model_kwargs.
rerank_top_k: int 				# Number of final returned documents by the reranker.
# ===================================== Other config ======================================
save_dir: Path					# Save directory of everything intermediate. Set to None to skip saving.
verbose: bool					# Whether to output the detail information during QA.
```

</details>

A test example on MuSiQue with hybrid agentic search: 

```python
# conf/<custom_conf>.py
conf = {
    "dataset": "musique",
    "test_samples": 10,     # only use the first 10 documents / chunks (depending on your dataset format)
    "max_retrieval_time": 3, 
    "tree_top_k": 10, 
    "hybrid_search": True, 
    "sparse_top_k": 10, 
    "rerank_top_k": 5,      # fuse two result sets by reciprocal rank fusion and take top 5 as the augmented context
}
```

### Run the pipeline

Save your config file as `conf/<custom_conf>.py`, and:

(1) **Build the tree index**

```bash
python index.py --config <custom_conf>
```

The pickle file containing the tree index will be saved in `<save_dir>/`  ([`output/`](output/) by default). If hybrid search is enabled, a `bm25_<dataset_name>` directory containing the sparse index will also be created.

> You can also temporarily change some configurations via CLI arguments. This will override your `<custom_conf>.py`:
> 
> ```bash
> python index.py --config <custom_conf> --force_index_from_scratch --max_tokens_per_chunk 500
> ```

(2) **Retrieve and answer the question**

Enter the interactive chat mode with your LLM:

```bash
python qa.py --config <custom_conf> --chat                          # load the tree index and chat with your R&A agent
python qa.py --config <custom_conf> --chat -q "<your_query>"        # add an initial query. `--query` and `--question` work too
python qa.py --config <custom_conf> --tree_id 2 -q "<your_query>"   # specify the tree id if your index has multiple trees
```

Answers will be saved in `<save_dir>/results/<custom_conf>.json`. You can also use the single-turn QA mode by only specifying `-q`. If you ask the same question again, the answer will be immediately loaded from the JSON file instead of another LLM call. 

```bash
python qa.py --config <custom_conf> -q "<your_query>"               # Non-interactive single-turn QA mode
python qa.py --config <custom_conf> -q "<your_query>" --update      # force to re-answer a question and update the result file
```

For evaluation purposes (queries in the dataset file), run question answering and evaluate the results with

```bash
python qa.py --config <custom_conf> 
python eval.py --config <custom_conf>
```

### An end-to-end pipeline for reproduction

We have provided our result files in [`output/results/`](output/results/) and the corresponding preset configs in [`conf/`](conf/). Simply run `main.py` with the config files for our evaluation results, for example: 

```bash
python main.py --config musique_summary
```

Our experiments are conducted on Ubuntu 20.04.6 LTS with CUDA 12.8 and Python 3.13.5.

**Re-answer the questions based on the existing tree index**:
Set `"force_qa_from_scratch": True` to automatically download our tree indexes from [![Hugging Face](https://img.shields.io/badge/Hugging%20Face-repo-yellow?logo=huggingface)](https://huggingface.co/Newiz430/Psi-RAG) to `<save_dir>/`. You can also manually download them and put them into `<save_dir>/`. When QA is finished, a result JSON file (sharing a name with your config file) will be saved in the `<save_dir>/results/`. 

**Rebuild tree indexes**:
Set `"force_index_from_scratch": True` to rebuild tree indexes from scratch. Set `"force_sparse_index_from_scratch": True` to rebuild BM25 indexes. 
You can also set `"save_dir": None` for a single run without saving. 

> ⚠Note that running indexing / sparse indexing / QA from scratch will **cover your existing save files** in `<save_dir>/`!

## Indexing & QAing on your Custom Corpora

> $\Psi$-RAG now supports users uploading local documents in PDF format. <img src="https://opendatalab.github.io/MinerU/images/MinerU-logo.png" alt="Node" align=center width=72> is used for PDF parsing. Three steps before running `index.py`:
> 
> - Install MinerU in your environment: `pip install mineru[all]`
>   - It is recommended to download the pipeline model locally to avoid hitting the usage limit of MinerU if you need to process batches of PDF files: 
>    ```bash
>    mineru-models-download
>    set MINERU_MODEL_SOURCE=local
>    ```
>    See [MinerU documentation](https://opendatalab.github.io/MinerU/) for more info.
> - Set `"data_dir"` to the path of (a) your PDF file, (b) your folder containing PDFs, or (c) your archive package of PDF files.
> - Add in your config file: (a) `"read_local_pdf": "file"`, (b) `"read_local_pdf": "dir"`, (c) `"read_local_pdf": "package"`. See [`conf/__init__.py`](conf/__init__.py) for parameter details.

### Step 1: Data preprocessing

Put your corpus file (filename: `<dataset_name>.<ext>`) in [`data/`](data/). Your corpus file could be formatted as a long string, a list of small chunks from a document, a list of documents, or a list of chunk lists from multiple documents.

> For evaluation purposes, `<dataset_name>.<ext>` should include the ground-truth answers for QA evaluation, and some form of supporting documents for retrieval evaluation. If there is also an independent corpus file, name it `<dataset_name>_corpus.<ext>` instead. You may refer to the existing dataset files, e.g., [`2wikimultihopqa.json`](data/2wikimultihopqa.json) and [`2wikimultihopqa_corpus.json`](data/2wikimultihopqa_corpus.json). If the ground-truth answers or supporting documents are missing, a ⚠warning will be raised. 

Then, make changes in [`src/dataset.py`](src/dataset.py):

- Add your dataset name in `dataset_pool`
- Add a conditional branch in `load_data()` and `preprocess()` to process document texts (and preset queries)
- If ground-truth answers are provided, add a conditional branch in `get_gold_answers()`
- If supporting documents are provided, add a conditional branch in `get_gold_docs()`

### Step 2: Customize prompts

Default prompt files in our experiments are in [`src/prompt/`](src/prompt/). You may rewrite the prompts (and in-context examples) for your own needs:
- `rag_agent_system_short`|`rag_agent_system_medium` in [`rag_agent.py`](src/prompt/rag_agent.py): QA prompt when `"answer_type": "short"`|`"medium"`
- `rag_qa_system_long` in [`rag_qa.py`](src/prompt/rag_qa.py): summarization prompt when `"answer_type": "long"`.

### Step 3: Run the scripts

Prepare a config file in [`conf/`](conf/) and run `index.py`. See [Configuration](#configuration) and [Run the Pipeline](#run-the-pipeline).

> For *single-document setting* (a tree index for each document), set `"passage_as_tree": True` in your config file.
> 
> For *cross-document setting* (a tree for the entire corpus): 
> - If your corpus is read as **a list of long documents**, set `"force_split": True` to split the text to chunks with size no more than ` max_tokens_per_chunk`. The tree indexing will **automatically merge the chunks from the same document** (i.e., connect them to one abstract node) to preserve semantic coherence within the document; if you want to re-cluster the chunks, set `"reorganize_leaf": True` at the same time.
> - If your corpus is read as **a list of chunk lists**, set `"force_split": True` will re-split them, otherwise the preset chunks will be used as leaf nodes.

### Step 4: Train a query hop discriminator for multi-hop queries

Before running `qa.py`, set `"max_retrieval_time": "auto"` to employ a 2-layer MLP as a lightweight query hop discriminator $\mathcal{Q}$. It reuses the query embedding and predicts the hops of the query to automatically decide the maximum retrieval time with very small latency.

By default, $\mathcal{Q}$ is trained on the query sets of the provided datasets: NQ, HotpotQA, 2Wiki, MuSiQue, and MultiHop-RAG. Currently only supports a maximum of 4 hops. The checkpoints are saved to `<save_dir>/hop_discriminator/` so do not set `"save_dir": None`. 

## Advanced Settings


<details>
    <summary>Change LLM backbones</summary>

### Change LLM backbones

You may change backbone LLMs with:

```python
conf = {
    "embed_name": "ollama:qwen3-embedding:0.6b",
    "abs_name": "vllm:meta-llama/Llama-3.1-8B-Instruct",
    "qa_name": "api:openai/gpt-5-mini",
    "rerank_name": "transformers:BAAI/bge-reranker-large",
    ...
}
```
</details>


<details>
    <summary>Building a large tree with Bucketing + HNSW Builder</summary>

### Building a large tree with Bucketing + HNSW Builder

Set `bucket_size` to enable **bucketing** on very large corpora:

```python
conf = {
    "bucket_size": 4096,    # This is an upper bound for recursive bucket splitting instead of a target bucket count
    "bucket_max_fanout": 32,
    "bucket_sample_size": 8192,
    "bucket_kmeans_iters": 5,
    "tree_save_chunk_size": 200000,
    ...
}
```

This first partitions a large corpus into multiple buckets using a fast recursive spherical $k$-means. Then a bucket tree is built inside each bucket. They are finally merged at the highest layer similar to the construction of each bucket tree. The entire tree will be saved as a directory (chunked node files + a manifest).

Use **approximate ranking via a Hierarchical Navigable Small World (HNSW) graph** to replace the global similarity ranking for industrial-scale corpora, supporting both original and bucketing tree-building:

```python
conf = {
    "tree_builder": "hnsw",
    "hnsw_top_k": 32,
    "hnsw_m": 16,
    "hnsw_ef_construction": 200,
    "hnsw_ef_search": 64,
    ...
}
```

Set `"tree_build_diagnostics": True` to print dataset token statistics, execution time of each step, memory estimates, and tree connectivity checks to make sure it works as intended.

</details>

<details>
    <summary>A quick peek inside your tree</summary>

### A quick peek inside your tree

Run 🐦‍⬛[`woodpecker.py`](woodpecker.py) for a peek at the detailed stats of a tree index file:

~~~bash
python woodpecker.py --config <custom_conf>               # Overall stats of the tree index file.
python woodpecker.py --config <custom_conf> --tree_id 1   # Stats of a specific tree (single-document setting). Never look up the wrong tree.
python woodpecker.py --config <custom_conf> --layer 5     # Stats of a specific layer (0: root) of a single tree. `--layer root` or `--layer leaf` are also valid.
python woodpecker.py --config <custom_conf> --id 10000    # Stats of a specific node from a single tree. Set `--text_only` to only print its text.
~~~

Detailed stats include:

- Tree: dataset name, #tokens, #trees, tree path, tree size (GB), tree builder, connectivity, #layers, #nodes per layer, #tokens per node, embedding dimension, #children stats 
- Layer: tree id, current layer, #nodes, list of node ids
- Node: id, layer, text, ancestor ids, brief ancestor texts, children ids, brief children texts

</details>

## Layout

<details>
    <summary>Layout</summary>

```
Psi-RAG/
|_ README.md
|_ requirements.txt # Dependency list.
|_ index.py         # Builds the tree index and sparse index.
|_ qa.py            # Loads an existing tree index, retrieves context, and answers questions.
|_ eval.py          # Evaluates saved QA results.
|_ main.py          # End-to-end entrypoint: runs indexing, QA, and evaluation in one script.
|_ woodpecker.py    # Prints statistics of your tree index.
|
|_ conf/                    # Configurations.
|  |_ __init__.py           # Introduces configs and sets default values.
|  |_ <dataset>_summary.py  # Preset config files using summative abstracts.
|  |_ <dataset>_keyword.py  # Preset config files using keyword abstracts.
|
|_ data/                        # Benchmark datasets.
|  |_ <dataset>_corpus.<ext>    # Corpus files for indexing.
|  |_ <dataset>.<ext>           # Data files with ground-truth info. 
|
|_ fig/             # Figures used by README.md.
|
|_ log/                 # Log files.
|  |_ stdout.log        # General log tracing the stdout.
|  |_ <conf_name>.log   # Specific log tracing the LLM output and evaluation results for a single run.
|
|_ output/                  # Saved index files and result files.
|  |_ *.pkl                 # Tree indexes.
|  |_ bm25_<dataset>/       # Sparse BM25 indexes.
|  |_ hop_discriminator/    # Weights of the query hop discriminator.
|  |_ results/              # Saved LLM answers, retrieved chunks, and config.
|
|_ src/                     # Core implementation of $Psi$-RAG.
|  |_ __init__.py
|  |_ dataset.py            # Loads and preprocesses data.
|  |_ pdf.py                # Read and parse user-uploaded PDFs.
|  |_ rag.py                # High-level RAG controller: build/load/save tree, retrieve, and qa.
|  |_ tree_retriever.py     # Tree retrieval, hybrid retrieval, and reranking logic.
|  |_ hop_discriminator.py  # Implementation of the query hop discriminator.
|  |_ evaluation.py         # Metric implementations for evaluation.
|  |_ utils.py              # Shared data structures and helper functions.
|
|  |_ tree_builder/         # Tree construction algorithms.
|  |  |_ __init__.py
|  |  |_ base.py            # Base tree builder: create leaf nodes and launch tree construction.
|  |  |_ abstract.py        # Standard hierarchical abstract tree builder.
|  |  |_ ann.py             # ANN-based tree builder based on an HNSW graph.
|  |  |_ bucketed.py        # Bucketed tree builder.
|  |  |_ bucketed_exact.py  # Bucketed builder using exact similarity ranking.
|  |  |_ bucketed_hnsw.py   # Bucketed builder using HNSW-based approximate ranking.
|  |  |_ chunks.py          # Chunked save/load format for bucketed tree indexes.
|
|  |_ model/            # Backend adapters for LLMs.
|  |  |_ __init__.py
|  |  |_ embed.py       # Embedding model wrappers.
|  |  |_ abstract.py    # Abstraction model wrappers.
|  |  |_ qa.py          # QA model wrappers.
|  |  |_ rerank.py      # Reranker model wrappers.
|
|  |_ prompt/           # Prompt templates.
|  |  |_ __init__.py
|  |  |_ rag_abs.py     # Prompts and in-context examples for abstraction.
|  |  |_ rag_agent.py   # Prompts and in-context examples for agentic retrieval and multi-hop QA.
|  |  |_ rag_qa.py      # Prompts for single-hop QA, narrative QA and summarization.

```
</details>


## TODOs

- [x] Full result files & tree index files
- [x] Demos / Quick guide
- [x] Custom dataset / model code examples
- [x] Approximate similarity ranking techniques
- [x] Query hop discriminator
- [x] vLLM support
- [x] Local PDF & MinerU support
- [x] Interactive QA mode
- [ ] Demo video & project page
- [ ] Tree insertion
- [ ] Code refactoring & maintenance
- [ ] ...


## Acknowledgements

This is built mainly upon [RAPTOR](https://github.com/parthsarthi03/raptor), [HippoRAG](https://github.com/OSU-NLP-Group/HippoRAG), and [HypHC](https://github.com/HazyResearch/HypHC). We sincerely thank their efforts. 

$\Psi$-RAG is released under the [MIT license](LICENSE). 

**Contributions of any kind are always welcome! Feel free to add a fix, a new feature, or anything helpful to this open-source project.** 🥰

## Citation

Please consider citing our work if it helps:

```bibtex
@inproceedings{psi-rag,
  title={Hierarchical Abstract Tree for Cross-Document Retrieval-Augmented Generation}, 
  author={Ziwen, Zhao and Menglin, Yang},
  booktitle={Proceedings of the 43rd International Conference on Machine Learning},
  year={2026},
  month={July},
  address={Seoul, South Korea},
  pages={TBD},
  publisher={TBD},
}
```