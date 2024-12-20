Model link - https://huggingface.co/Shaagun/mistral

Fine-Tuning Mistral 7B for Instruction-Following Tasks : This project fine-tunes the Mistral 7B language model to enhance its ability to follow instructions in English and Lithuanian. The fine-tuned model is optimized to provide accurate, coherent, and contextually relevant responses across a variety of tasks.

Objective The goal of this project is to:

Adapt the pre-trained Mistral 7B model to follow instructions effectively in multilingual contexts. Enable the model to generate high-quality responses to both general and specific prompts while maintaining fluency and relevance. Evaluate the fine-tuned model's performance using semantic similarity and qualitative metrics.

Dataset The model was trained on a custom dataset of instruction-response pairs in English and Lithuanian. The dataset includes a diverse range of tasks such as:

Summarization Question answering Factual explanations

Each sample consists of:

Instruction: A task or question for the model. Input: Optional context for the instruction. Output: The expected response. Training Details The fine-tuning process was conducted using the SFTTrainer framework. Key hyperparameters used include:

Learning Rate: 3e-4 Batch Size: 4 (with gradient accumulation steps of 4) Optimizer: adamw_8bit for memory efficiency Number of Epochs: 1 Sequence Length: 1024 Precision: Mixed precision (fp16 or bf16 depending on hardware support) Training was performed on a Google Colab T4 GPU, with careful tuning to balance memory constraints and performance.

Evaluation The model was evaluated using:

Semantic Similarity:

Used Sentence Transformers (all-MiniLM-L6-v2) to compare generated outputs with reference responses. Scores reflect how closely the generated text aligns with the meaning of the reference.

Results The fine-tuned Mistral 7B model: Demonstrates high accuracy and fluency in both English and Lithuanian. Handles diverse tasks effectively, including complex instructions and translations. Achieves strong semantic similarity scores across the evaluation dataset.
