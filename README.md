# 📌 Fine-Tuning GPT-2 — Classification & Instruction Fine-Tuning

## 📖 Overview
This repository demonstrates how to **fine-tune a GPT-2 model** for two different purposes:

1. **Text Classification Fine-Tuning** — Example: Spam vs. Not Spam detection.
2. **Instruction Fine-Tuning** — Modifying GPT-2 to follow instructions like a question-answering model.

Fine-tuning is the process of **adapting a pre-trained model** to a specific task by training it further on a smaller, task-specific dataset.  
It allows us to leverage the general language understanding of large models while making them perform exceptionally well on our target problem.

---

## 🔹 Types of Fine-Tuning

### 1️⃣ Classification Fine-Tuning
**Definition:**  
Classification fine-tuning is when we adapt a model to assign input text to predefined categories.  
Instead of generating free-form text, the model learns to output labels such as *Spam* or *Not Spam*.

**Example in this repo:**  
- **Folder:** `Sapm&NotSpam`
- **Contents:**  
  - A folder "sms_spam_collection" containing the data Set.
  - A Jupyter Notebook showing how to fine-tune GPT-2 for spam detection.
  - The notebook walks through:
    - Preparing the dataset.
    - Tokenizing the text.
    - Fine-tuning GPT-2 for binary classification.
    - Evaluating the model.

---

### 2️⃣ Instruction Fine-Tuning
**Definition:**  
Instruction fine-tuning is when we modify a model to **follow human instructions** or **answer questions** more effectively.  
Instead of simply predicting the next token, the model is trained to produce outputs that align with a given command or prompt.

**Example in this repo:**  
- **Folder:** `Instruction finetuning`
- **Contents:**  
  - Training data formatted as instruction–response pairs.
  - A Jupyter Notebook showing how to adapt GPT-2 for question-answer tasks.
  - Steps include:
    - Formatting the dataset for instruction-response training.
    - Adjusting the GPT-2 architecture if needed.
    - Fine-tuning to make GPT-2 act like a Q&A model.

## 📂 Repository Structure

**Spam_and_NotSpam/**  
- `spam_not_spam.ipynb` (GPT-2 classification training — spam vs not spam)  
- `gpt_download3.py` (Script to download the pre-trained GPT-2 model)  
- `sms_spam_collection/` (Data folder)  

**instruction_finetuning/**  
- `instruction_finetuning.ipynb` (GPT-2 instruction fine-tuning notebook)  
- `instruction_data/` (Data files: instruction → response pairs)  
- `gpt_download3.py` (Script to download the pre-trained GPT-2 model)  


## 🚀 How to Use

1. **Clone the repo**
```bash
git clone https://github.com/yourusername/fine-tuning-gpt2.git
cd fine-tuning-gpt2
```

## 🚀 Run the Desired Notebook

For **classification**: Open `Sapm&NotSpam/spam_not_spam.ipynb`  
For **instruction tuning**: Open `instruction finetuning/instruction_finetuning.ipynb`

---

## 🧠 Key Takeaways
- Fine-tuning allows you to specialize GPT-2 for specific tasks.
- **Classification fine-tuning** → Model learns to categorize text.
- **Instruction fine-tuning** → Model learns to follow instructions or answer questions.

---

## 📜 License
This project is for educational purposes. Feel free to fork and adapt for your own datasets and tasks.
