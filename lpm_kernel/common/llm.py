from lpm_kernel.api.services.user_llm_config_service import UserLLMConfigService
from lpm_kernel.configs.config import Config
from typing import List, Union
import requests
import numpy as np
import os
import torch
from lpm_kernel.configs.logging import get_train_process_logger
logger = get_train_process_logger()


class LLMClient:
    """LLM client utility class"""

    def __init__(self):
        self.config = Config.from_env()
        self.user_llm_config_service = UserLLMConfigService()
        self.embedding_max_text_length = int(self.config.get('EMBEDDING_MAX_TEXT_LENGTH', 8000))
        
        # Check for CUDA availability and set up the device accordingly
        self.device = "cuda" if torch.cuda.is_available() else "cpu"
        if torch.cuda.is_available():
            logger.info(f"CUDA is available. Using device: {torch.cuda.get_device_name(0)}")
            # Set environment variable for CUDA operations
            os.environ["CUDA_VISIBLE_DEVICES"] = "0"
        else:
            logger.info("CUDA not available. Using CPU for tensor operations.")
        
        # self.user_llm_config = self.user_llm_config_service.get_available_llm()
        # self.chat_api_key = self.user_llm_config.chat_api_key
        # self.chat_base_url = self.user_llm_config.chat_endpoint
        # self.chat_model = self.user_llm_config.chat_model_name
        # self.embedding_api_key = self.user_llm_config.embedding_api_key
        # self.embedding_base_url = self.user_llm_config.embedding_endpoint
        # self.embedding_model = self.user_llm_config.embedding_model_name


    def get_embedding(self, texts: Union[str, List[str]]) -> np.ndarray:
        """Calculate text embedding

        Args:
            texts (str or list): Input text or list of texts

        Returns:
            numpy.ndarray: Embedding vector of the text
        """
        # Ensure texts is in list format
        if isinstance(texts, str):
            texts = [texts]

        # Split long texts into chunks using configured max length
        chunked_texts = []
        text_chunk_counts = []  # Keep track of how many chunks each text was split into
        
        for text in texts:
            if len(text) > self.embedding_max_text_length:
                # Split into chunks of embedding_max_text_length
                chunks = [text[i:i + self.embedding_max_text_length] 
                         for i in range(0, len(text), self.embedding_max_text_length)]
                chunked_texts.extend(chunks)
                text_chunk_counts.append(len(chunks))
            else:
                chunked_texts.append(text)
                text_chunk_counts.append(1)

        user_llm_config = self.user_llm_config_service.get_available_llm()
        if not user_llm_config:
            raise Exception("No LLM configuration found")
        # Prepare request data
        headers = {
            "Authorization": f"Bearer {user_llm_config.embedding_api_key}",
            "Content-Type": "application/json",
        }

        data = {"input": chunked_texts, "model": user_llm_config.embedding_model_name}

        logger.info(f"Getting embedding for {data}, total chunks: {len(chunked_texts)}")
        try:
            # Send request to embedding endpoint
            response = requests.post(
                f"{user_llm_config.embedding_endpoint}/embeddings", headers=headers, json=data
            )

            # Check response status
            response.raise_for_status()
            result = response.json()

            # Extract embedding vectors
            embeddings = [item["embedding"] for item in result["data"]]
            
            # Convert to tensor if CUDA is available for faster processing
            if torch.cuda.is_available():
                embeddings_tensor = torch.tensor(embeddings, device=self.device)
                embeddings_array = embeddings_tensor.cpu().numpy()
            else:
                embeddings_array = np.array(embeddings)

            # If we split any texts, we need to merge their embeddings back
            if sum(text_chunk_counts) > len(texts):
                final_embeddings = []
                start_idx = 0
                for chunk_count in text_chunk_counts:
                    if chunk_count > 1:
                        # Average embeddings for split text
                        chunk_embeddings = embeddings_array[start_idx:start_idx + chunk_count]
                        
                        # Use GPU for averaging if available
                        if torch.cuda.is_available():
                            chunk_tensor = torch.tensor(chunk_embeddings, device=self.device)
                            avg_embedding = torch.mean(chunk_tensor, dim=0).cpu().numpy()
                        else:
                            avg_embedding = np.mean(chunk_embeddings, axis=0)
                            
                        final_embeddings.append(avg_embedding)
                    else:
                        final_embeddings.append(embeddings_array[start_idx])
                    start_idx += chunk_count
                return np.array(final_embeddings)
            
            return embeddings_array

        except requests.exceptions.RequestException as e:
            raise Exception(f"Failed to get embeddings: {str(e)}")

    @property
    def chat_credentials(self):
        """Get LLM authentication information"""
        return {"api_key": self.chat_api_key, "base_url": self.chat_base_url}
