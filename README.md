# AI-Chatbot-using-Python
## Overview
This project implements a chatbot using python that have a sample dataset and it is trained using AI concepts for giving better responses. Users can interact with the chatbot, and it responds with generated text. This chatbot is designed to engage in text-based conversations with users. It uses the GPT-2 language model to generate responses, making it suitable for a variety of natural language processing tasks, including text generation, text completion, and chatbot interactions.

## Project Description
The "Chatbot Using Python" is an artificial intelligence project that leverages the power of the GPT-2 language model to create an interactive chatbot. This chatbot is designed to engage in text-based conversations with users and generate meaningful responses. It can be used for a wide range of natural language processing tasks, from casual conversation to more specialized applications.

**Key Features**:
- Conversational Intelligence: The chatbot is equipped with conversational intelligence, making it capable of understanding and generating human-like text responses. It can provide answers to questions, engage in open-ended discussions, and respond to user inputs in a context-aware manner.

- Customizable Model: The project offers the flexibility to choose from different GPT-2 model sizes, allowing users to adapt the chatbot to their specific needs. Models like "gpt2," "gpt2-medium," and "gpt2-large" offer varying levels of complexity and capabilities.

- Web Interface: The chatbot is deployed with a user-friendly web interface built using Flask. This allows users to interact with the chatbot by simply entering text in a web form and receiving responses in real-time.

- Fine-tuning Capability: For users with specific requirements, the project demonstrates the process of fine-tuning the GPT-2 model on a custom dataset. This enables chatbot customization for domain-specific conversations.

## Dataset

### Source
- Dataset Name: [Simple dialogs for chatbot](https://www.kaggle.com/datasets/grafstor/simple-dialogs-for-chatbot)
- Description : The dataset consists of simple conversations used in daily life. First column is questions, second is answers.

### Data Preprocessing
In this project, data preprocessing is a crucial step to ensure that the input data is in a suitable format for training and interaction with the chatbot. The data preprocessing pipeline involves the following key steps:

- Tokenization: The input text data is tokenized using the NLTK library. Tokenization involves breaking down the text into individual words or subword tokens. This step is essential for converting the raw text into a structured format that can be understood by the chatbot's language model.

- Cleaning: Text data often contains irrelevant characters, symbols, or special characters that can hinder the performance of the chatbot. To address this, we clean the data by removing punctuation, ensuring that the text is free from unnecessary symbols or characters.

- Formatting: After tokenization and cleaning, the data is organized into a structure suitable for training and interaction with the chatbot. The preprocessed data is ready to be fed into the language model for training or for generating responses.

These preprocessing steps help improve the quality of the chatbot's responses and ensure that the input text is in a format that the language model can effectively process.

By following these data preprocessing steps, we aim to enhance the chatbot's ability to understand and generate coherent text, making it more effective and user-friendly.
For specific code examples and implementation details, please refer to the project's code files and documentation.

## Machine Learning Algorithm
In the chatbot project you described, the primary machine learning algorithm used is the GPT-2 (Generative Pre-trained Transformer 2) language model. GPT-2 is a deep learning model based on the Transformer architecture, which is a type of neural network architecture designed for natural language understanding and generation.

Here's how the GPT-2 model fits into the project:

- Text Generation: GPT-2 is a language model that excels in generating human-like text. It uses unsupervised learning to predict the next word or token in a sentence, given the previous context. This predictive capability allows it to generate coherent and contextually relevant text.

- Chatbot Interaction: The GPT-2 model is the core component responsible for generating responses in the chatbot. Users input text or questions, and the GPT-2 model processes this input and generates text-based responses, simulating a conversation.

- Fine-Tuning (Optional): In some cases, the GPT-2 model may be fine-tuned on a specific dataset to adapt it for particular use cases. Fine-tuning involves training the model on a custom dataset to make it more domain-specific or to control its behavior.

- Hyperparameter Tuning: Although GPT-2 is a powerful model out-of-the-box, its hyperparameters, such as learning rates, batch sizes, and model size, can be adjusted to optimize its performance for specific tasks.

In summary, the GPT-2 model serves as the machine learning algorithm at the heart of the chatbot project, enabling natural language understanding and generation. It's well-suited for tasks like text generation, chatbot development, and text completion due to its ability to capture and generate coherent text based on context.

## Model training
The heart of this chatbot project lies in training a language model to understand and generate human-like text. The model training process can be summarized as follows:

- Pre-trained Models: The project provides the flexibility to choose from different pre-trained GPT-2 models. The selection of the model depends on your requirements. For example, you can opt for "gpt2" for a base model or choose more complex models like "gpt2-medium" or "gpt2-large" for advanced capabilities.

- Training Data: The chatbot's language model is trained on a conversational dataset. The dataset is preprocessed and formatted to ensure it is suitable for training. It may involve cleaning the text, tokenization, and other data preprocessing steps described in the README.

- Hyperparameter Tuning: Fine-tuning, when applied, involves tuning hyperparameters such as learning rates, batch sizes, and the number of training epochs. These hyperparameters can significantly impact the model's performance and behavior.

- Data Collation: During training, the data is collated and organized into batches suitable for training the model. Data collation ensures efficient model optimization and convergence.

- Model Training: The model is then trained on the prepared dataset. The training process involves feeding input data into the model, calculating loss, and optimizing model weights using backpropagation. The training duration depends on the complexity of the model and the dataset size.

- Model Evaluation: After training, it's essential to evaluate the model's performance. Evaluation metrics are computed to assess how well the model is performing. This step can help identify areas for improvement or refinement.

- Model Saving: Once the model is fine-tuned (if applicable) and trained, it can be saved for later use. The saved model can be used for text generation or incorporated into the chatbot for real-time interactions.

By understanding the model training process, you can appreciate the effort that goes into building an AI chatbot with the ability to generate coherent and context-aware responses.

## Prerequisites

- Python 3.x
- [Hugging Face Transformers library](https://github.com/huggingface/transformers)
- Flask (for the web interface)

## Getting Started

1. Clone this repository to your local machine:
   ```bash
   git clone [https://github.com/vallarasunm/AI-Chatbot-using-Python.git]
   ```

2. Install dependencies
   ```bash
   pip install Transformers
   pip install flask
   ```
3. Download Pre-trained Model:

You will need a pre-trained GPT-2 model from the Hugging Face model hub. Download the model you want to use and place it in the project directory.

4. Run the Chatbot:

Start the Flask web interface:
```bash
python app.py
```

5. Access The chatbot
 Open a web browser and navigate to http://localhost:5000.
- Enter a message or question in the provided input field.
- Submit the input by clicking "Send."
- The chatbot will process your input and generate a response in real-time.
- The chatbot is now ready to engage in conversations. You can experiment with different inputs and interact with it in a conversational manner.
