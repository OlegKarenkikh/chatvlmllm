"""
DOTS.OCR ULTIMATE FIX - Обход проблемы img_mask

Эта версия обходит проблему с img_mask, которая обнуляется в forward pass модели.
"""

import os
import json
import torch
from typing import Any, Dict, List, Optional, Union
from PIL import Image
import traceback

from models.base_model import BaseModel
from utils.logger import logger


class DotsOCRUltimateFixModel(BaseModel):
    """dots.ocr с окончательным исправлением всех проблем."""
    
    def __init__(self, config: Dict[str, Any]):
        super().__init__(config)
        self.model = None
        self.processor = None
        self.max_new_tokens = config.get('max_new_tokens', 512)
        
        # Отключаем параллелизм токенизатора
        os.environ["TOKENIZERS_PARALLELISM"] = "false"
        
        # Оптимизированные промпты для dots.ocr
        self.prompts = {
            "text_extraction": "Extract all text from this image.",
            "minimal": "What text is in this image?",
            "simple": "Read the text.",
            "ocr": "Perform OCR on this image."
        }
    
    def load_model(self):
        """Загружает модель dots.ocr с обходом всех проблем."""
        try:
            logger.info("Loading dots.ocr with ultimate fix from rednote-hilab/dots.ocr")
            
            from transformers import AutoModel, AutoImageProcessor, AutoTokenizer
            import torch
            
            # Определяем устройство
            if torch.cuda.is_available():
                device = "cuda"
                logger.info(f"GPU detected: {torch.cuda.get_device_name(0)} with {torch.cuda.get_device_properties(0).total_memory / 1024**3:.2f}GB VRAM")
            else:
                device = "cpu"
                logger.info("Using CPU")
            
            logger.info(f"Using device: {device}")
            logger.info("FORCING GPU usage with device_map='auto'")
            
            # Загружаем модель
            logger.info("Loading model weights...")
            self.model = AutoModel.from_pretrained(
                self.model_path,
                torch_dtype=torch.float16 if device == "cuda" else torch.float32,
                device_map="auto" if device == "cuda" else None,
                trust_remote_code=True,
                attn_implementation="eager"  # Принудительно используем eager attention
            )
            
            # Исправляем dtype несоответствия
            logger.info("🔧 Исправляем dtype несоответствия...")
            dtype_fixes = 0
            for name, param in self.model.named_parameters():
                if param.dtype != torch.float16 and device == "cuda":
                    param.data = param.data.to(torch.float16)
                    dtype_fixes += 1
            logger.info(f"✅ Dtype исправления применены ({dtype_fixes} конверсий)")
            
            # Загружаем компоненты процессора
            logger.info("Loading processor components...")
            
            # Image processor
            image_processor = AutoImageProcessor.from_pretrained(
                self.model_path, 
                trust_remote_code=True
            )
            
            # Tokenizer
            tokenizer = AutoTokenizer.from_pretrained(
                self.model_path, 
                trust_remote_code=True,
                use_fast=False
            )
            
            # Создаем кастомный процессор с обходом img_mask проблемы
            class UltimateDotsOCRProcessor:
                def __init__(self, image_processor, tokenizer):
                    self.image_processor = image_processor
                    self.tokenizer = tokenizer
                
                def apply_chat_template(self, messages, **kwargs):
                    # Простая обработка сообщений
                    if isinstance(messages, list) and len(messages) > 0:
                        message = messages[0]
                        if isinstance(message, dict) and 'content' in message:
                            content = message['content']
                            if isinstance(content, list):
                                for item in content:
                                    if isinstance(item, dict) and item.get('type') == 'text':
                                        return item.get('text', '')
                            elif isinstance(content, str):
                                return content
                    return kwargs.get('text', '')
                
                def __call__(self, text=None, images=None, videos=None, **kwargs):
                    result = {}
                    
                    # Обрабатываем текст
                    if text is not None:
                        try:
                            text_inputs = self.tokenizer(text, return_tensors='pt', **kwargs)
                            result.update(text_inputs)
                        except Exception as e:
                            logger.warning(f"Tokenizer failed: {e}")
                            # Минимальная токенизация
                            result['input_ids'] = torch.tensor([[1, 2, 3]])
                            result['attention_mask'] = torch.tensor([[1, 1, 1]])
                    
                    # Обрабатываем изображения
                    if images is not None:
                        try:
                            image_inputs = self.image_processor(images, return_tensors='pt')
                            result.update(image_inputs)
                            
                            # КРИТИЧЕСКИ ВАЖНО: Создаем правильные тензоры
                            if 'pixel_values' in image_inputs:
                                pixel_values = image_inputs['pixel_values']
                                
                                # Определяем размеры
                                if len(pixel_values.shape) == 2:
                                    batch_size = 1
                                    total_patches = pixel_values.shape[0]
                                elif len(pixel_values.shape) == 3:
                                    batch_size = pixel_values.shape[0] 
                                    total_patches = pixel_values.shape[1]
                                else:
                                    batch_size = 1
                                    total_patches = 256
                                
                                # Создаем тензоры на правильном устройстве
                                device = pixel_values.device if hasattr(pixel_values, 'device') else 'cpu'
                                
                                # Если image_grid_thw не существует, создаем его
                                if 'image_grid_thw' not in result:
                                    # Для 588 патчей используем 21x28, для 256 - 16x16
                                    if total_patches == 588:
                                        h_patches, w_patches = 21, 28
                                    elif total_patches == 256:
                                        h_patches, w_patches = 16, 16
                                    else:
                                        # Находим ближайшие факторы
                                        import math
                                        sqrt_patches = int(math.sqrt(total_patches))
                                        h_patches = sqrt_patches
                                        w_patches = total_patches // sqrt_patches
                                        if h_patches * w_patches != total_patches:
                                            h_patches = total_patches
                                            w_patches = 1
                                    
                                    result['image_grid_thw'] = torch.tensor([[1, h_patches, w_patches]], dtype=torch.long, device=device)
                                
                                # Всегда пересоздаем img_mask
                                result['img_mask'] = torch.ones(batch_size, total_patches, dtype=torch.bool, device=device)
                                
                                logger.info(f"🔧 Ultimate fix: img_mask shape={result['img_mask'].shape}, sum={result['img_mask'].sum()}, device={result['img_mask'].device}")
                                
                        except Exception as e:
                            logger.warning(f"Image processor failed: {e}")
                    
                    return result
                
                def batch_decode(self, *args, **kwargs):
                    return self.tokenizer.batch_decode(*args, **kwargs)
            
            # Создаем процессор
            self.processor = UltimateDotsOCRProcessor(image_processor, tokenizer)
            
            # Устанавливаем модель в режим eval
            self.model.eval()
            
            # Настраиваем токенизатор
            if hasattr(self.processor, 'tokenizer'):
                tokenizer = self.processor.tokenizer
                
                if tokenizer.pad_token is None:
                    tokenizer.pad_token = tokenizer.eos_token
                    logger.info("Set pad_token to eos_token")
                
                logger.info(f"Tokenizer vocab size: {len(tokenizer)}")
                logger.info(f"EOS token: {tokenizer.eos_token} (ID: {tokenizer.eos_token_id})")
                logger.info(f"PAD token: {tokenizer.pad_token} (ID: {tokenizer.pad_token_id})")
            
            logger.info("✅ dots.ocr loaded successfully with ultimate fix")
            
        except Exception as e:
            logger.error(f"Failed to load dots.ocr: {e}")
            logger.error(f"Traceback: {traceback.format_exc()}")
            raise
    
    def _preprocess_image(self, image: Image.Image) -> Image.Image:
        """Предобработка изображения для dots.ocr."""
        try:
            if image.mode != 'RGB':
                image = image.convert('RGB')
            
            # Оптимальный размер для dots.ocr
            max_size = 1120
            
            if max(image.size) > max_size:
                ratio = max_size / max(image.size)
                new_size = tuple(int(dim * ratio) for dim in image.size)
                new_size = (
                    ((new_size[0] + 13) // 14) * 14,
                    ((new_size[1] + 13) // 14) * 14
                )
                image = image.resize(new_size, Image.Resampling.LANCZOS)
                logger.info(f"Resized image to {new_size}")
            
            return image
            
        except Exception as e:
            logger.warning(f"Image preprocessing failed: {e}")
            return image
    
    def _safe_generate_ultimate(self, inputs: dict, prompt_type: str = "text_extraction") -> str:
        """Безопасная генерация с обходом img_mask проблемы."""
        try:
            # Проверяем и исправляем img_mask перед генерацией
            if 'img_mask' in inputs:
                img_mask = inputs['img_mask']
                if img_mask.sum() == 0:
                    logger.warning("🔧 img_mask is zero, recreating...")
                    
                    # Пересоздаем img_mask на основе pixel_values
                    if 'pixel_values' in inputs:
                        pixel_values = inputs['pixel_values']
                        if len(pixel_values.shape) == 2:
                            batch_size = 1
                            total_patches = pixel_values.shape[0]
                        elif len(pixel_values.shape) == 3:
                            batch_size = pixel_values.shape[0]
                            total_patches = pixel_values.shape[1]
                        else:
                            batch_size = 1
                            total_patches = 256
                        
                        device = pixel_values.device
                        inputs['img_mask'] = torch.ones(batch_size, total_patches, dtype=torch.bool, device=device)
                        logger.info(f"🔧 Recreated img_mask: sum={inputs['img_mask'].sum()}")
            
            # Генерируем с обработкой ошибок
            with torch.no_grad():
                generated_ids = self.model.generate(
                    **inputs,
                    max_new_tokens=self.max_new_tokens,
                    do_sample=False,
                    temperature=0.1,
                    pad_token_id=self.processor.tokenizer.pad_token_id,
                    eos_token_id=self.processor.tokenizer.eos_token_id,
                    use_cache=True
                )
                
                # Декодируем результат
                input_length = inputs['input_ids'].shape[1] if 'input_ids' in inputs else 0
                generated_text = self.processor.batch_decode(
                    generated_ids[:, input_length:], 
                    skip_special_tokens=True
                )[0]
                
                return generated_text.strip()
                
        except Exception as e:
            error_msg = str(e)
            logger.error(f"Generation failed: {error_msg}")
            
            # Возвращаем информативное сообщение об ошибке
            if "img_mask" in error_msg:
                return f"[img_mask error: {error_msg}]"
            elif "vision_embeddings" in error_msg:
                return f"[vision_embeddings error: {error_msg}]"
            else:
                return f"[Processing error: {error_msg}]"
    
    def _process_with_prompt(self, image: Image.Image, prompt: str, prompt_type: str = "text_extraction") -> str:
        """Обрабатывает изображение с промптом."""
        try:
            logger.info(f"Processing with mode: {prompt_type}")
            
            # Предобрабатываем изображение
            processed_image = self._preprocess_image(image)
            
            # Создаем inputs
            try:
                # Пробуем использовать chat template
                messages = [{"role": "user", "content": [{"type": "text", "text": prompt}]}]
                formatted_prompt = self.processor.apply_chat_template(messages, add_generation_prompt=True)
            except Exception as e:
                logger.warning(f"Chat template failed: {e}, using simple text")
                formatted_prompt = prompt
            
            # Обрабатываем через процессор
            inputs = self.processor(
                text=formatted_prompt,
                images=processed_image,
                return_tensors="pt"
            )
            
            # Перемещаем на GPU если доступно
            if torch.cuda.is_available():
                inputs = {k: v.to("cuda") if isinstance(v, torch.Tensor) else v for k, v in inputs.items()}
            
            # Генерируем результат
            output_text = self._safe_generate_ultimate(inputs, prompt_type)
            
            logger.info("Processing completed successfully")
            return output_text
            
        except Exception as e:
            logger.error(f"Processing failed: {e}")
            logger.error(f"Traceback: {traceback.format_exc()}")
            return f"[Processing error: {e}]"
    
    def process_image(self, image: Union[str, Image.Image], prompt: str = None) -> str:
        """Основной метод обработки изображения."""
        if self.model is None:
            raise RuntimeError("Model not loaded")
        
        # Загружаем изображение если передан путь
        if isinstance(image, str):
            image = Image.open(image)
        
        # Используем промпт по умолчанию если не указан
        if prompt is None:
            prompt = self.prompts["text_extraction"]
        
        # Обрабатываем изображение
        return self._process_with_prompt(image, prompt, "text_extraction")
