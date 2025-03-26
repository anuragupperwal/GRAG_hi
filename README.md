
# 🇮🇳  GraphRAG-Hindi: Graph-based Retrieval-Augmented Generation for Hindi Text

Welcome to GraphRAG-Hindi, an open-source project that brings graph-based retrieval-augmented generation (RAG) to the Hindi language using publicly available datasets and open-source models. The goal is to build an intelligent QA/summarization system that retrieves relevant context via knowledge graphs and generates natural Hindi responses using state-of-the-art language models.

⸻

## Why This Project?

Most retrieval-augmented generation (RAG) pipelines are focused on English or multilingual text, but they often lack deep support for Indian languages. This project is an effort to:  
	• Explore GraphRAG architecture using Hindi datasets.  
	• Combine semantic understanding with structural relationships through knowledge graphs.  
	• Enable query-focused summarization for long, noisy, real-world data (e.g., Wikipedia, monolingual corpora).  
	• Open up a path for RAG systems in Indian public administration, policy, education, and more.  

⸻

## Project Pipeline

Inspired by Microsoft’s From Local to Global: A Graph-Based Query-Focused Summarization and other leading papers in Graph-RAG.

Breakdown:  
	• Preprocessing: Clean raw data (stopword removal, normalization, tokenization).  
	• Text Chunking: Use sentence segmentation to break long documents.  
	• Element Summarization: Create summaries for each chunk (fine-tuned summarizer).  
	• Graph Construction: Create nodes for chunks and connect them based on semantic similarity.  
	• Community Detection: Cluster similar chunks (e.g., using Louvain or Leiden).  
	• Query-Time Generation: Retrieve relevant communities and generate answers using IndicGPT or similar models.  



⸻

## Datasets Used
	•	[✓] IIT Bombay Monolingual Hindi Corpus

⸻

## Tools & Libraries

| Component        | Tech Used                                  |
|------------------|--------------------------------------------|
| Preprocessing    | IndicNLP, NLTK                             |
| Tokenization     | `indic_tokenize` (word/sentence)           |
| Translation      | `ai4bharat/indictrans2`                    |
| Embeddings       | `ai4bharat/indic-bert`, `sentence-transformers` |
| Knowledge Graph  | Neo4j, NetworkX                            |
| Generation       | `ai4bharat/IndicGPT`, `mBART`, `T5`        |
| Summarization    | Custom fine-tuned T5 models                |
| Visualization    | Matplotlib, pyvis                          |



⸻

## How to Run

	1. Clone the repo


git clone https://github.com/yourname/GraphRAG_Hindi.git  
cd GraphRAG_Hindi

	2. Create virtual env & install dependencies

conda create -n graphrag_env python=3.10
conda activate graphrag_env
pip install -r requirements.txt

	3. Preprocess Data

python src/data/preprocess_data.py

	4. Translate English words to Hindi

python src/data/translation.py

	5. Run Graph Construction (Neo4j or NetworkX)

python src/data/build_graph.py

	6. Trigger Query + Generate Answers

python src/main.py --query "स्वतंत्रता संग्राम में महिला योगदान क्या था?"



⸻

## Current Status
	✅ Preprocessing & Sentence Chunking
	✅ English Word Translation (IndicTrans2)
	✅ Word & Sentence Tokenization
	⏳ Tailored Summarization (in progress)
	⏳ Neo4j Graph Construction
	⏳ Community Detection & Evaluation

⸻

## Contributing

Got ideas to improve RAG for Hindi or multilingual graphs? Feel free to fork and send PRs.

⸻

## Acknowledgements
	• AI4Bharat for IndicTrans, IndicBERT, and IndicNLP
	• Microsoft Research for the From Local to Global paper
	• HuggingFace Transformers & Datasets

⸻

## ⭐️ Star this Repo

If this project inspires or helps you, please give it a ⭐️. It keeps me going!

⸻
  

'''
venv: python3 -m venv graphrag_env


activate: source graphrag_env/bin/activate; 
        conda deactivate (if some other env or base env is activated)
'''