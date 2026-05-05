# LLMscratch: Building a Transformer from the Ground Up 🤖

**LLMscratch** is an educational repository designed to demystify the inner workings of Large Language Models (LLMs). This project implements a GPT-style transformer architecture from scratch using **PyTorch**, covering the entire pipeline from raw text processing to model inference and fine-tuning.

---

## 🚀 Overview

The goal of this project is to move beyond high-level APIs to understand the "math-to-code" translation of modern AI. By building each component manually, we gain insights into how self-attention, normalization, and scaling laws actually function.

## 🧠 Key Features

*   **Custom Tokenizer:** Implementation of Byte Pair Encoding (BPE) and data sampling strategies.
*   **Transformer Architecture:** Multi-head attention, layer normalization, and GELU activation functions.
*   **Pre-training Pipeline:** Efficient training loops with weight initialization and learning rate scheduling.
*   **Fine-tuning:** Scripts to adapt the base model for specific downstream tasks like text classification.
*   **Evaluation:** Tools to measure perplexity and generate text using Top-k and temperature sampling.

## 📂 Repository Structure

```text
├── data/               # Datasets and preprocessing scripts
├── models/             # Transformer architecture (Attention, MLP, Blocks)
├── scripts/            # Training and Fine-tuning scripts
├── notebooks/          # Step-by-step walkthroughs and visualizations
├── requirements.txt    # Environment dependencies
└── main.py             # Entry point for training/inference