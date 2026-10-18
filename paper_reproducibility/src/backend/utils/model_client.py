"""
model_client.py
---------------
LLM (Large Language Model) çağrılarını yöneten katman.
Örneğin, ChatOpenAI gibi modelleri buradan çağırabilirsiniz.
"""

import logging
from langchain_openai import ChatOpenAI
import sys
import os
import aiohttp
# Add the backend directory to the path to import config
backend_dir = os.path.dirname(os.path.dirname(__file__))
if backend_dir not in sys.path:
    sys.path.append(backend_dir)
# Import from the config.py file directly
from config import MODEL_API_BASE_URL, MODEL_IDENTIFIER, MODEL_API_KEY
import google.generativeai as genai
import json
import time
import asyncio
from typing import Dict, Optional

# Logger ayarları (hataları ve bilgileri takip etmek için)
logger = logging.getLogger(__name__)
logging.basicConfig(level=logging.INFO)

def get_llm_instance(model_name: str = None, temperature: float = 0.7):
    """
    LLM nesnesini oluşturur ve bağlantıyı test eder.
    
    :param model_name: Kullanılacak model adı (opsiyonel).
    :param temperature: Modelin yaratıcılık seviyesi (varsayılan: 0.7).
    :return: ChatOpenAI nesnesi.
    :raises ValueError: Yapılandırma hataları için.
    :raises ConnectionError: Bağlantı hataları için.
    """
    # Model seçimi - eğer model_name verilmemişse default kullan
    selected_model = model_name if model_name else MODEL_IDENTIFIER
    
    # 1. Yapılandırma kontrolü
    if not MODEL_API_BASE_URL:
        logger.error("MODEL_API_BASE_URL boş olamaz.")
        raise ValueError("MODEL_API_BASE_URL yapılandırması eksik.")
    if not selected_model:
        logger.error("Model identifier boş olamaz.")
        raise ValueError("Model identifier yapılandırması eksik.")
    
    # 2. Model nesnesi oluşturma ve hata yakalama
    try:
        logger.info(f"LLM nesnesi oluşturuluyor: {selected_model} @ configured model endpoint")
        # LM Studio uses /v1/ prefix for OpenAI compatibility
        api_base_url = MODEL_API_BASE_URL if MODEL_API_BASE_URL.endswith('/v1') else f"{MODEL_API_BASE_URL}/v1"
        logger.info(f"Using API base URL: {api_base_url}")
        
        llm = ChatOpenAI(
            model_name=selected_model,
            openai_api_base=api_base_url,
            openai_api_key=MODEL_API_KEY or "not-needed",
            temperature=temperature
        )
        
        # 3. Bağlantıyı test etme
        logger.debug(f"LLM'e gönderilen test sorgusu: Merhaba, bu bir test sorgusudur.")
        test_response = llm.invoke("Merhaba, bu bir test sorgusudur.")
        logger.debug(f"LLM'den alınan yanıt: {test_response}")
        if test_response:
            logger.info("LLM bağlantısı başarılı.")
        else:
            logger.warning("LLM'den yanıt alınamadı.")
        
        return llm
    except Exception as e:
        logger.error(f"LLM nesnesi oluşturulurken hata: {str(e)}")
        raise ConnectionError(f"LLM sunucusuna bağlanılamadı: {str(e)}")

import requests
import logging
import random

class LLMClient:
    # Sınıf seviyesinde rate limiting bilgileri (tüm instance'lar arasında paylaşılır)
    _rate_limits: Dict[str, Dict] = {}  # model_name -> {last_request_time, requests_per_minute, is_rate_limited}
    # Global istek sayacı - tüm modeller için
    _global_request_counter: int = 0
    
    # API tabanlı modeller için varsayılan sınırlar
    DEFAULT_RATE_LIMITS = {
        'gemini': {
            'requests_per_minute': 10,  # Gemini Tier 1 sınırı
            'cooldown_seconds': 5,     # 5 saniye base cooldown
            'random_delay_min': 0,      # Minimum rastgele bekleme (saniye) - hız için optimize edildi
            'random_delay_max': 2       # Maksimum rastgele bekleme (saniye) - hız için optimize edildi
        }
    }
    
    def __init__(self, model_name=None, api_key=None, use_case=None):
        # Logger'ı en başta tanımla (hata yakalamada kullanılacak)
        self.logger = logging.getLogger("LLMClient")
        
        base_url = MODEL_API_BASE_URL.rstrip("/")
        self.api_url = base_url if base_url.endswith("/v1") else f"{base_url}/v1"
        # Default model kullan veya parametre olarak verilen modeli al
        self.original_key = model_name  # Original key'i sakla (frontend'den gelen key)
        
        # Gemini model kontrolü önce yapılmalı (model_name kullanmadan önce)
        self.is_gemini = self._is_gemini_model(model_name) if model_name else False
        
        # Local modeller için model identifier'ı al, Gemini için direkt kullan
        if self.is_gemini:
            self.model_name = model_name
        else:
            # Local model için identifier'ı al
            self.model_name = self.get_model_identifier(model_name) if model_name else MODEL_IDENTIFIER
        
        self.api_key = api_key or MODEL_API_KEY  # Request override, then server configuration
        self.use_case = use_case  # 'code_review', 'test_generation', 'test_reporting', etc.
        
        self.logger.info(f"🔧 [LLMClient] Initialized:")
        self.logger.info(f"   - Original key: {self.original_key}")
        self.logger.info(f"   - Model name: {self.model_name}")
        self.logger.info(f"   - Use case: {use_case}")
        self.logger.info(f"   - Is Gemini: {self.is_gemini}")
        
        self.is_api_based = self.is_gemini  # Şu an sadece Gemini API tabanlı, gelecekte genişletilebilir
        
        if self.is_gemini:
            self.logger.info(f"✨ Gemini model detected: {self.model_name}")
            if not self.api_key:
                raise ValueError("API key is required for Gemini models")
            # Gemini client'ı başlat
            try:
                # Gemini API key'i configure et
                genai.configure(api_key=self.api_key)
                self.logger.info("✅ Gemini client initialized successfully")
                
                # Rate limiting bilgilerini başlat
                self._init_rate_limiting()
            except Exception as e:
                self.logger.error(f"❌ Failed to initialize Gemini client: {e}")
                raise
        
    def _is_gemini_model(self, model_name):
        """Model isminin Gemini modeli olup olmadığını kontrol et"""
        if not model_name:
            return False
        gemini_models = [
            "gemini-2.5-flash",
            "gemini-2.5-pro",
            "gemini-1.5-pro",
            "gemini-1.5-flash",
            "gemini-pro",
            "gemini-flash"
        ]
        return any(gemini_model in model_name.lower() for gemini_model in gemini_models)
    
    def _init_rate_limiting(self):
        """API tabanlı modeller için rate limiting bilgilerini başlat"""
        if not self.is_api_based:
            return
            
        model_key = self._get_rate_limit_key()
        if model_key not in self._rate_limits:
            self._rate_limits[model_key] = {
                'request_times': [],  # Son isteklerin zamanları
                'is_rate_limited': False,
                'last_error_time': None,
                'consecutive_errors': 0
            }
            
    def _get_rate_limit_key(self) -> str:
        """Rate limiting için kullanılacak anahtarı döndür"""
        if self.is_gemini:
            return f"gemini_{self.model_name}"
        return f"api_{self.model_name}"
    
    def _get_rate_limit_config(self) -> Dict:
        """Model için rate limiting konfigürasyonunu döndür"""
        if self.is_gemini:
            return self.DEFAULT_RATE_LIMITS['gemini']
        # Gelecekte diğer API'lar için genişletilebilir
        return {
            'requests_per_minute': 60, 
            'cooldown_seconds': 30,
            'random_delay_min': 2,
            'random_delay_max': 30
        }  # Default
    
    async def _check_and_apply_rate_limit(self):
        """Rate limiting kontrolü yap ve gerekirse bekle"""
        if not self.is_api_based:
            return  # Local modeller için rate limiting yok
        
        # Code review, requirement analysis, test planning, environment setup, test code generation ve test reporting için minimal cooldown uygula
        if self.use_case in ['code_review', 'requirement_analysis', 'test_planning', 'environment_setup', 'test_code_generation', 'test_reporting']:
            # Single-shot işlemler için sadece minimal bekleme (API stability için)
            minimal_delay = random.uniform(0.5, 2.0)  # 0.5-2 saniye
            use_case_name = self.use_case.replace('_', ' ').title()
            self.logger.info(f"🚀 {use_case_name} Mode - Minimal delay: {minimal_delay:.2f}s")
            await asyncio.sleep(minimal_delay)
            return
            
        # Normal bulk operations için tam cooldown uygula
        # İstek numarasını artır
        LLMClient._global_request_counter += 1
        current_request_number = LLMClient._global_request_counter
        
        model_key = self._get_rate_limit_key()
        rate_config = self._get_rate_limit_config()
        current_time = time.time()
        
        # Rate limit bilgilerini al
        rate_info = self._rate_limits.get(model_key, {})
        request_times = rate_info.get('request_times', [])
        
        # 1 dakikadan eski istekleri temizle
        request_times = [t for t in request_times if current_time - t < 60]
        
        # Base cooldown + rastgele bekleme hesapla
        base_cooldown = rate_config['cooldown_seconds']
        random_delay = random.uniform(rate_config['random_delay_min'], rate_config['random_delay_max'])
        total_wait_time = base_cooldown + random_delay
        
        self.logger.info(f"🔄 API Request #{current_request_number} - Model: {self.model_name}")
        self.logger.info(f"⏱️  Applying cooldown: {base_cooldown}s + random delay: {random_delay:.2f}s = Total: {total_wait_time:.2f}s")
        
        # Her istekten önce total_wait_time kadar bekle (spam önleme)
        await asyncio.sleep(total_wait_time)
        
        # Eğer rate limit aktifse ve henüz cooldown süresi geçmediyse
        if rate_info.get('is_rate_limited', False):
            last_error_time = rate_info.get('last_error_time', 0)
            cooldown_seconds = rate_config['cooldown_seconds']
            
            if current_time - last_error_time < cooldown_seconds:
                remaining_time = cooldown_seconds - (current_time - last_error_time)
                additional_random = random.uniform(rate_config['random_delay_min'], rate_config['random_delay_max'])
                total_additional_wait = remaining_time + additional_random
                
                self.logger.warning(f"🚫 Rate limit active for {model_key}. Additional wait: {remaining_time:.1f}s + {additional_random:.2f}s = {total_additional_wait:.2f}s")
                await asyncio.sleep(total_additional_wait)
                # Rate limit'i sıfırla
                rate_info['is_rate_limited'] = False
                rate_info['consecutive_errors'] = 0
        
        # İstek sayısı kontrolü
        requests_per_minute = rate_config['requests_per_minute']
        if len(request_times) >= requests_per_minute:
            # Rate limit aşılacak, bekle
            oldest_request = min(request_times)
            wait_time = 60 - (current_time - oldest_request) + 1  # 1 saniye ekstra güvenlik
            additional_random = random.uniform(rate_config['random_delay_min'], rate_config['random_delay_max'])
            total_prevention_wait = wait_time + additional_random
            
            if wait_time > 0:
                self.logger.info(f"🛡️  Rate limit prevention: {wait_time:.1f}s + {additional_random:.2f}s = {total_prevention_wait:.2f}s for {model_key}")
                await asyncio.sleep(total_prevention_wait)
                current_time = time.time()
                # Eski istekleri tekrar temizle
                request_times = [t for t in request_times if current_time - t < 60]
        
        # Bu isteği kaydet
        request_times.append(current_time)
        rate_info['request_times'] = request_times
        self._rate_limits[model_key] = rate_info
    
    def _handle_rate_limit_error(self, error_response: str):
        """Rate limit hatası geldiğinde çağrılan metod"""
        if not self.is_api_based:
            return
            
        model_key = self._get_rate_limit_key()
        rate_info = self._rate_limits.get(model_key, {})
        rate_config = self._get_rate_limit_config()
        
        # Rate limit aktif olarak işaretle
        rate_info['is_rate_limited'] = True
        rate_info['last_error_time'] = time.time()
        rate_info['consecutive_errors'] = rate_info.get('consecutive_errors', 0) + 1
        
        # Rastgele bekleme süresini hesapla
        random_delay = random.uniform(rate_config['random_delay_min'], rate_config['random_delay_max'])
        base_cooldown = rate_config['cooldown_seconds']
        
        # Eğer sürekli rate limit hatası alıyorsak, daha uzun bekle
        if rate_info['consecutive_errors'] > 3:
            base_cooldown = min(base_cooldown * 2, 120)  # Max 2 dakika base cooldown
            self.logger.warning(f"⚠️  Increasing base cooldown to {base_cooldown}s due to repeated rate limits")
        
        total_wait = base_cooldown + random_delay
        self.logger.error(f"🚫 Rate limit detected for {model_key}. Next wait will be: {base_cooldown}s + {random_delay:.2f}s = {total_wait:.2f}s")
        
        self._rate_limits[model_key] = rate_info
        
        
    def get_model_identifier(self, model_key):
        """Frontend'den gelen model anahtarına göre gerçek model identifier'ını döndürür"""
        self.logger.info(f"Getting model identifier for key: {model_key}")
        if not model_key or not isinstance(model_key, str):
            self.logger.warning(f"Invalid model_key: {model_key}, using default model")
            return MODEL_IDENTIFIER  # Default model from config
        
        # Merkezi konfigürasyondan model mapping'i al
        try:
            from config.models_config import get_model_by_key
            model_config = get_model_by_key(model_key)
            
            if model_config:
                # Modelin identifier'ını al (LM Studio için)
                model_id = self._get_lm_studio_identifier(model_key, model_config)
                self.logger.info(f"Selected model from config: {model_key} -> {model_id}")
                return model_id
            else:
                self.logger.warning(f"Model key '{model_key}' not found in central config")
        except ImportError as e:
            self.logger.warning(f"Could not import central config: {e}, falling back to local mapping")
        except Exception as e:
            self.logger.warning(f"Error accessing central config: {e}, falling back to local mapping")
        
        # Fallback: Eski hardcoded mapping (geriye uyumluluk için)
        model_mapping = {
            "codegeex4:9b": "codegeex4-all-9b",
            "codellama:7b": "codellama-7b-instruct",
            "deepseek-coder:6.7b": "deepseek-coder-6.7b-instruct",
            "gemma2:2b": "gemma-2-2b-it",
            "gemma3:4b": "gemma-3-4b-it",
            "google/gemma-3-12b": "gemma-3-12b-it",
            "llama3.2:3b": "llama-3.2-3b-instruct",
            "llama-3.2-3b-instruct": "llama-3.2-3b-instruct",  # Fallback case
            "meta/llama-3.3-70b": "meta/llama-3.3-70b",
            "mistralai/codestral-22b-v0.1": "mistralai/codestral-22b-v0.1",
            "openai/gpt-oss-20b": "openai/gpt-oss-20b",
            "qwen/qwq-32b": "qwen/qwq-32b",
            "qwen2.5:7b": "qwen2.5-7b-instruct-1m",
            "qwen2.5-7b-instruct-1m": "qwen2.5-7b-instruct-1m",
            "qwen2.5-coder:3b": "qwen2.5-coder-3b-instruct",
            "qwen/qwen3-14b": "qwen3-14b-instruct",
            "stable-code:3b": "stable-code-instruct-3b",
            "starcoder2:7b": "starcoder2-7b",
            # Yeni Test Case Optimization modelleri
            "codellama:70b-instruct": "CodeLlama-70B-Instruct-GGUF/codellama-70b-instruct.Q4_K_S.gguf",
            "kimi-dev:72b": "Kimi-Dev-72B-GGUF/Kimi-Dev-72B-Q3_K_S.gguf",
            "openai/gpt-oss-120b": "openai/gpt-oss-120b",
            "deepseek-r1-distill:32b": "DeepSeek-R1-Distill-Qwen-32B-GGUF/DeepSeek-R1-Distill-Qwen-32B-Q3_K_L.gguf",
            "google/gemma-3-27b": "google/gemma-3-27b",
            "qwen/qwen3-coder-30b": "qwen/qwen3-coder-30b",
            "deepseek/deepseek-r1-qwen3-8b": "deepseek/deepseek-r1-0528-qwen3-8b"
        }
        
        model_id = model_mapping.get(model_key, None)
        self.logger.info(f"Model id from fallback mapping: {model_id}")
        if not model_id:
            self.logger.warning(f"Unknown model_key: {model_key}, using default model")
            return MODEL_IDENTIFIER  # Default model from config
            
        self.logger.info(f"Selected model (fallback): {model_key} -> {model_id}")
        return model_id

    def _get_lm_studio_identifier(self, model_key, model_config):
        """Model konfigürasyonuna göre LM Studio identifier'ını döndür"""
        # API modelleri için direkt model key'i kullan
        if model_config.get("type") == "api":
            return model_key
        
        # Local modeller için özel mapping'ler
        special_mappings = {
            "codegeex4:9b": "codegeex4-all-9b",
            "codellama:7b": "codellama-7b-instruct",
            "deepseek-coder:6.7b": "deepseek-coder-6.7b-instruct",
            "gemma2:2b": "gemma-2-2b-it",
            "gemma3:4b": "gemma-3-4b-it",
            "google/gemma-3-12b": "gemma-3-12b-it",
            "llama3.2:3b": "llama-3.2-3b-instruct",
            "qwen2.5:7b": "qwen2.5-7b-instruct-1m",
            "qwen2.5-7b-instruct-1m": "qwen2.5-7b-instruct-1m",
            "qwen2.5-coder:3b": "qwen2.5-coder-3b-instruct",
            "qwen/qwen3-14b": "qwen3-14b-instruct",
            "stable-code:3b": "stable-code-instruct-3b",
            "starcoder2:7b": "starcoder2-7b",
            # Büyük modeller için özel GGUF path'leri
            "codellama:70b-instruct": "CodeLlama-70B-Instruct-GGUF/codellama-70b-instruct.Q4_K_S.gguf",
            "kimi-dev:72b": "Kimi-Dev-72B-GGUF/Kimi-Dev-72B-Q3_K_S.gguf",
            "deepseek-r1-distill:32b": "DeepSeek-R1-Distill-Qwen-32B-GGUF/DeepSeek-R1-Distill-Qwen-32B-Q3_K_L.gguf",
            "deepseek/deepseek-r1-qwen3-8b": "deepseek/deepseek-r1-0528-qwen3-8b"
        }
        
        # Önce özel mapping'lere bak
        if model_key in special_mappings:
            return special_mappings[model_key]
        
        # Yoksa direkt model key'i kullan
        return model_key

    async def get_model_context_length(self, model_identifier: str = None) -> int:
        """
        LM Studio'nun /v1/models endpoint'inden aktif modelin context_length değerini alır.
        
        Args:
            model_identifier: Sorgulanacak model id'si. None ise self.model_name kullanılır.
            
        Returns:
            Modelin context length değeri (token cinsinden).
            Bağlantı hatası veya bilgi bulunamazsa güvenli default olan 4096 döndürür.
        """
        DEFAULT_CONTEXT_LENGTH = 32768
        target_id = (model_identifier or self.model_name or "").lower()

        try:
            async with aiohttp.ClientSession() as session:
                async with session.get(
                    f"{self.api_url}/models",
                    timeout=aiohttp.ClientTimeout(total=5)
                ) as response:
                    if response.status != 200:
                        self.logger.warning(
                            f"LM Studio /v1/models returned status {response.status}, "
                            f"using default context length {DEFAULT_CONTEXT_LENGTH}"
                        )
                        return DEFAULT_CONTEXT_LENGTH

                    data = await response.json()
                    models = data.get("data", [])

                    # Model'i id ile eşleştir (kısmi eşleşme desteklenir)
                    for m in models:
                        m_id = m.get("id", "").lower()
                        if target_id in m_id or m_id in target_id:
                            ctx = (
                                m.get("context_length")
                                or m.get("max_context_length")
                                or m.get("max_model_len")
                                or m.get("n_ctx")
                            )
                            if ctx and isinstance(ctx, (int, float)) and ctx > 0:
                                ctx_int = int(ctx)
                                self.logger.info(
                                    f"✅ Model context length from LM Studio: \"{m.get('id')}\" -> {ctx_int} tokens"
                                )
                                return ctx_int
                            # context_length alanı yoksa model specs'e bak
                            specs = m.get("specs", {}) or {}
                            ctx = specs.get("context_length") or specs.get("max_context")
                            if ctx and isinstance(ctx, (int, float)) and ctx > 0:
                                ctx_int = int(ctx)
                                self.logger.info(
                                    f"✅ Model context length from specs: \"{m.get('id')}\" -> {ctx_int} tokens"
                                )
                                return ctx_int

                    self.logger.warning(
                        f"Context length not found in LM Studio response for model '{target_id}'. "
                        f"Returning default {DEFAULT_CONTEXT_LENGTH}"
                    )
                    return DEFAULT_CONTEXT_LENGTH

        except asyncio.TimeoutError:
            self.logger.warning(
                f"Timeout querying LM Studio for context length, using default {DEFAULT_CONTEXT_LENGTH}"
            )
            return DEFAULT_CONTEXT_LENGTH
        except Exception as e:
            self.logger.warning(
                f"Could not query LM Studio context length ({e}), using default {DEFAULT_CONTEXT_LENGTH}"
            )
            return DEFAULT_CONTEXT_LENGTH

    def _split_prompt_into_chunks(self, prompt: str, max_chars: int = 6000) -> list:
        """
        Split a long prompt into smaller chunks for context-limited models.
        Each chunk will be ~1500 tokens (6000 chars ≈ 1500 tokens).
        
        Args:
            prompt: The full prompt text
            max_chars: Maximum characters per chunk (default: 6000 = ~1500 tokens)
            
        Returns:
            List of prompt chunks
        """
        if len(prompt) <= max_chars:
            return [prompt]
        
        chunks = []
        current_pos = 0
        total_length = len(prompt)
        
        while current_pos < total_length:
            # Calculate end position
            end_pos = min(current_pos + max_chars, total_length)
            
            # Try to break at a natural boundary (paragraph, sentence, or word)
            if end_pos < total_length:
                # Look for paragraph break
                last_para = prompt.rfind('\n\n', current_pos, end_pos)
                if last_para > current_pos + max_chars // 2:  # At least halfway
                    end_pos = last_para + 2
                else:
                    # Look for sentence break
                    last_sentence = max(
                        prompt.rfind('. ', current_pos, end_pos),
                        prompt.rfind('.\n', current_pos, end_pos),
                        prompt.rfind('! ', current_pos, end_pos),
                        prompt.rfind('? ', current_pos, end_pos)
                    )
                    if last_sentence > current_pos + max_chars // 2:
                        end_pos = last_sentence + 2
                    else:
                        # Look for word break
                        last_space = prompt.rfind(' ', current_pos, end_pos)
                        if last_space > current_pos + max_chars // 2:
                            end_pos = last_space + 1
            
            chunk = prompt[current_pos:end_pos]
            chunks.append(chunk)
            current_pos = end_pos
        
        return chunks
    
    def _is_context_overflow_error(self, error_message: str) -> bool:
        """Check if error is related to context length overflow"""
        overflow_keywords = [
            "context length",
            "context overflow",
            "overflows",
            "4096 tokens",
            "larger context",
            "shorter input"
        ]
        error_lower = error_message.lower()
        return any(keyword in error_lower for keyword in overflow_keywords)
    
    async def _generate_with_chunking(
        self, 
        prompt: str, 
        temperature: float = 0.7, 
        max_tokens: int = 2000,
        max_chars_per_chunk: int = 6000
    ) -> str:
        """
        Generate response by splitting prompt into chunks and combining results.
        Used when context overflow occurs.
        
        Args:
            prompt: The full prompt
            temperature: Generation temperature
            max_tokens: Max tokens per chunk response (reduced for 4096 limit)
            max_chars_per_chunk: Max characters per chunk (~1500 tokens)
            
        Returns:
            Combined response from all chunks
        """
        self.logger.info(f"🔪 Chunking prompt: {len(prompt)} chars into chunks of ~{max_chars_per_chunk} chars")
        
        chunks = self._split_prompt_into_chunks(prompt, max_chars_per_chunk)
        self.logger.info(f"📦 Created {len(chunks)} chunks")
        
        chunk_responses = []
        
        for i, chunk in enumerate(chunks, 1):
            self.logger.info(f"🔄 Processing chunk {i}/{len(chunks)} ({len(chunk)} chars)")
            
            # Minimal header to save tokens
            chunk_prompt = f"[{i}/{len(chunks)}]\n{chunk}"
            
            try:
                # Try to process this chunk
                response = await self._generate_single_chunk(chunk_prompt, temperature, max_tokens)
                chunk_responses.append({
                    'chunk_index': i,
                    'response': response
                })
                self.logger.info(f"✅ Chunk {i}/{len(chunks)} completed ({len(response)} chars)")
            except aiohttp.ClientResponseError as e:
                # Check if this chunk is still too large
                if self._is_context_overflow_error(str(e)) and len(chunk) > 2500:
                    self.logger.warning(f"⚠️ Chunk {i} still too large, splitting further...")
                    # Split this chunk into smaller sub-chunks
                    sub_chunks = self._split_prompt_into_chunks(chunk, max_chars=2500)
                    self.logger.info(f"📦 Split chunk {i} into {len(sub_chunks)} sub-chunks")
                    
                    sub_responses = []
                    for j, sub_chunk in enumerate(sub_chunks, 1):
                        try:
                            sub_prompt = f"[{i}.{j}]\n{sub_chunk}"
                            sub_response = await self._generate_single_chunk(sub_prompt, temperature, 1500)  # Smaller max_tokens for sub-chunks
                            sub_responses.append(sub_response)
                            self.logger.info(f"✅ Sub-chunk {i}.{j} completed")
                        except Exception as sub_e:
                            self.logger.error(f"❌ Error processing sub-chunk {i}.{j}: {sub_e}")
                            sub_responses.append(f"[Error in section {i}.{j}]")
                    
                    # Combine sub-responses
                    combined_sub = "\n\n".join(sub_responses)
                    chunk_responses.append({
                        'chunk_index': i,
                        'response': combined_sub
                    })
                else:
                    self.logger.error(f"❌ Error processing chunk {i}/{len(chunks)}: {e}")
                    chunk_responses.append({
                        'chunk_index': i,
                        'response': f"[Error processing section {i}]"
                    })
            except Exception as e:
                self.logger.error(f"❌ Error processing chunk {i}/{len(chunks)}: {e}")
                chunk_responses.append({
                    'chunk_index': i,
                    'response': f"[Error processing section {i}]"
                })
        
        # Combine all chunk responses
        self.logger.info(f"🔗 Combining {len(chunk_responses)} chunk responses")
        
        combined_response = ""
        for chunk_resp in chunk_responses:
            if chunk_resp['chunk_index'] == 1:
                # First chunk - no separator
                combined_response += chunk_resp['response']
            else:
                # Subsequent chunks - minimal separator
                combined_response += f"\n\n---\n\n{chunk_resp['response']}"
        
        return combined_response
    
    async def _generate_single_chunk(
        self, 
        prompt: str, 
        temperature: float = 0.7, 
        max_tokens: int = 8192
    ) -> str:
        """
        Generate response for a single chunk without recursive chunking.
        This is the actual API call without chunking logic.
        """
        # This will be the actual implementation from generate_response
        # For now, forward to the existing logic
        return await self._generate_response_internal(prompt, temperature, max_tokens)

    async def generate_response(self, prompt, temperature=0.7, max_tokens=8192, response_format=None, skip_chunking=False):
        """
        LLM API çağrısı yapan temel metod - rate limiting ve chunking ile.
        
        Args:
            skip_chunking: True ise otomatik chunking mekanizması devre dışı bırakılır.
                           Modelin context window'unu doldurmak yerine tüm prompt tek seferde
                           gönderilir (orn. test_scenario_generation ve test_case_generation
                           gibi bağlam bütünlüğü kritik olan akışlarda kullanılır).
        """
        
        # API tabanlı modeller için rate limiting kontrolü
        if self.is_api_based:
            await self._check_and_apply_rate_limit()
        
        # Gemini modeli kontrolü
        if self.is_gemini:
            return await self._generate_gemini_response(prompt, temperature, max_tokens)
        
        # skip_chunking=True ise tüm bağlamı tek seferde gönder (chunking yok)
        if skip_chunking:
            self.logger.info(
                f"⏭️ Chunking devre dışı (skip_chunking=True) — "
                f"prompt {len(prompt)} chars, tek seferde gönderiliyor."
            )
            return await self._generate_response_internal(prompt, temperature, max_tokens)
        
        # LM Studio için context overflow kontrolü
        # Prompt çok uzunsa, otomatik chunking yap
        CONTEXT_LIMIT_CHARS = 6000  # ~1500 tokens (4096 limitinde input+output için güvenli)
        
        if len(prompt) > CONTEXT_LIMIT_CHARS:
            self.logger.warning(f"⚠️ Prompt too long ({len(prompt)} chars > {CONTEXT_LIMIT_CHARS}). Using automatic chunking.")
            return await self._generate_with_chunking(
                prompt=prompt,
                temperature=temperature,
                max_tokens=2000,  # Reduced for chunking to stay within 4096 total
                max_chars_per_chunk=CONTEXT_LIMIT_CHARS
            )
        
        # Normal flow - try regular generation first
        try:
            return await self._generate_response_internal(prompt, temperature, max_tokens)
        except aiohttp.ClientResponseError as e:
            # Check if it's a context overflow error
            error_body = str(e)
            if self._is_context_overflow_error(error_body):
                self.logger.warning(f"⚠️ Context overflow detected. Retrying with automatic chunking...")
                self.logger.info(f"🔪 Original prompt: {len(prompt)} chars")
                
                # Retry with chunking (use smaller chunk size)
                return await self._generate_with_chunking(
                    prompt=prompt,
                    temperature=temperature,
                    max_tokens=2000,  # Reduced for safety
                    max_chars_per_chunk=4000  # Even smaller for retry after error (~1000 tokens)
                )
            else:
                # Not a context error, re-raise
                raise

    async def _generate_response_internal(self, prompt, temperature=0.7, max_tokens=8192):
        """Internal method that does the actual API call without chunking"""
        # LM Studio için - model_name zaten __init__'de identifier'a çevrildi
        actual_model = self.model_name
        
        # LM Studio için doğru mesaj formatı - user role kullanmalıyız
        payload = {
            "model": actual_model,
            "messages": [{"role": "user", "content": prompt}],
            "temperature": temperature,
            "max_tokens": max_tokens
        }
            
        try:
            self.logger.info(f"📤 [LM Studio] Sending request to model: {actual_model}")
            self.logger.debug(f"[LM Studio] Request payload: {payload}")
            self.logger.info(f"[LM Studio] API URL: {self.api_url}/chat/completions")
            self.logger.info(f"[LM Studio] Prompt length: {len(prompt)} chars")
            self.logger.info(f"[LM Studio] Temperature: {temperature}, Max tokens: {max_tokens}")
            
            # Use aiohttp for async requests without timeout for complex operations
            async with aiohttp.ClientSession() as session:
                async with session.post(
                    f"{self.api_url}/chat/completions",
                    json=payload,
                    timeout=aiohttp.ClientTimeout(total=600)  # 10-minute timeout for large models
                ) as response:
                    self.logger.info(f"[LM Studio] Response status: {response.status}")
                    
                    # Log response body for debugging if error
                    if response.status != 200:
                        error_body = await response.text()
                        self.logger.error(f"❌ [LM Studio] Error response body: {error_body}")
                        self.logger.error(f"❌ [LM Studio] Request model: {actual_model}")
                        self.logger.error(f"❌ [LM Studio] Verify model is loaded in LM Studio")
                        
                        # Check if it's a context overflow error before raising
                        if self._is_context_overflow_error(error_body):
                            self.logger.warning(f"🚨 Context overflow detected in error response")
                        
                        raise aiohttp.ClientResponseError(
                            request_info=response.request_info,
                            history=response.history,
                            status=response.status,
                            message=f"LM Studio error: {error_body[:200]}"
                        )
                    
                    response_json = await response.json()
                    self.logger.debug(f"[LM Studio] Response JSON keys: {list(response_json.keys())}")
                    
                    if "choices" not in response_json or not response_json["choices"]:
                        self.logger.error(f"❌ [LM Studio] Invalid response format: {response_json}")
                        raise ValueError("Invalid response format from LM Studio API")
                    
                    result = response_json["choices"][0]["message"]["content"]
                    self.logger.info(f"✅ [LM Studio] Successfully generated response (length: {len(result)} chars)")
                    return result
                    
        except asyncio.TimeoutError as e:
            self.logger.error(f"⏰ [LM Studio] Timeout error with model {actual_model}: {str(e)}")
            raise TimeoutError(f"LM Studio API request timed out")
        except aiohttp.ClientError as e:
            self.logger.error(f"❌ [LM Studio] Client Error with model {actual_model}: {str(e)}")
            raise
        except Exception as e:
            self.logger.error(f"❌ [LM Studio] Unexpected error with model {actual_model}: {str(e)}")
            raise

    def _sanitize_prompt_for_gemini(self, prompt):
        """Sanitize prompt to reduce chances of safety filter violations"""
        # Remove potentially problematic patterns that might trigger safety filters
        # while preserving the technical content
        
        # Common technical terms that might be misinterpreted by safety filters
        replacements = {
            # General harmful terms
            'kill': 'terminate',
            'destroy': 'remove',
            'attack': 'test against',
            'exploit': 'utilize',
            'vulnerable': 'at risk',
            'inject': 'insert',
            'execute': 'run',
            'bomb': 'failure case',
            'crash': 'failure',
            'dead': 'inactive',
            'malicious': 'harmful',
            'weapon': 'tool',
            'target': 'objective',
            'assault': 'approach',
            'violence': 'force',
            'threat': 'risk',
            'danger': 'issue',
            'harm': 'affect',
            
            # Robotics/hardware terms that might be misinterpreted
            'gripper': 'actuator',
            'sensor': 'detector',
            'robot': 'automated system',
            'detection': 'identification',
            
            # Code review specific terms
            'security vulnerability': 'security concern',
            'security hole': 'security gap',
            'buffer overflow': 'buffer issue',
            'code injection': 'code insertion',
            'memory corruption': 'memory issue'
        }
        
        sanitized = prompt
        changes_made = []
        
        for old_term, new_term in replacements.items():
            # Use word boundaries to avoid replacing parts of words
            import re
            pattern = r'\b' + re.escape(old_term) + r'\b'
            old_sanitized = sanitized
            sanitized = re.sub(pattern, new_term, sanitized, flags=re.IGNORECASE)
            
            # Track what was changed
            if old_sanitized != sanitized:
                changes_made.append(f"{old_term} -> {new_term}")
        
        if changes_made:
            self.logger.debug(f"Prompt sanitization changes: {', '.join(changes_made)}")
        
        return sanitized

    async def _generate_gemini_response(self, prompt, temperature=0.7, max_tokens=8192):
        """Gemini API çağrısı yapan metod - 503 hataları için özel retry mekanizması ile"""
        try:
            self.logger.debug(f"Sending request to Gemini API with model: {self.model_name}")
            self.logger.debug(f"Prompt: {prompt[:100]}...")  # İlk 100 karakteri log'la
            
            # Sanitize prompt to reduce safety filter violations
            sanitized_prompt = self._sanitize_prompt_for_gemini(prompt)
            if sanitized_prompt != prompt:
                self.logger.info("🧹 Prompt was sanitized to reduce safety filter risks")
            
            # Use case bazlı optimal token limitleri (OUTPUT token limits)
            use_case_limits = {
                'test_code_generation': 8000,     # Maksimum kod üretimi
                'test_reporting': 1000000,        # Maksimum raporlama - garantiye alalım (model kendi limitini uygular)
                'test_closure': 1000000,          # Maksimum test closure raporlama - garantiye alalım
                'code_review': 6000,              # Detaylı analiz için
                'requirement_analysis': 5000,     # Kapsamlı analiz
                'test_planning': 5000,            # Detaylı planlama
                'test_case_generation': 4000,     # Test case üretimi
                'environment_setup': 3000         # Kurulum talimatları
            }
            
            # Eğer bu use case için özel limit varsa uygula
            if self.use_case in use_case_limits:
                optimal_limit = use_case_limits[self.use_case]
                if max_tokens < optimal_limit:
                    max_tokens = optimal_limit
                    use_case_name = self.use_case.replace('_', ' ').title()
                    self.logger.info(f"🔧 Increased max_tokens to {max_tokens} for {use_case_name}")
            
            # Gemini model oluştur
            model = genai.GenerativeModel(self.model_name)
            
            # Generation config oluştur (optimal parametreler)
            generation_config = {
                'temperature': temperature,
                'max_output_tokens': max_tokens,
                'top_p': 0.8,  # Better quality responses
                'top_k': 40    # More focused responses
            }
            
            self.logger.info(f"🔧 Gemini generation config: {generation_config}")
            self.logger.info(f"📏 Input prompt length: {len(sanitized_prompt)} chars, ~{len(sanitized_prompt)//4} tokens (est.)")
            
            # Gemini API çağrısı (async)
            response = await model.generate_content_async(
                sanitized_prompt,
                generation_config=generation_config
            )
            
            # Gemini response validation with finish_reason handling
            if response and response.candidates:
                candidate = response.candidates[0]
                finish_reason = candidate.finish_reason
                
                self.logger.debug(f"🔍 Gemini finish_reason: {finish_reason} (type: {type(finish_reason)})")
                
                # Log safety ratings early to detect filtering issues
                if hasattr(candidate, 'safety_ratings'):
                    safety_ratings = candidate.safety_ratings
                    self.logger.debug(f"🛡️ Safety ratings present: {len(safety_ratings) if safety_ratings else 0}")
                    for rating in (safety_ratings or []):
                        if hasattr(rating, 'category') and hasattr(rating, 'probability'):
                            self.logger.debug(f"   - {rating.category}: {rating.probability}")
                
                # Handle both enum and integer values for finish_reason
                # Convert enum to integer if needed
                finish_reason_int = finish_reason
                if hasattr(finish_reason, 'value'):
                    finish_reason_int = finish_reason.value
                
                self.logger.debug(f"🔢 Finish reason as int: {finish_reason_int}")
                
                # Check finish_reason for different blocking scenarios
                # Based on Google AI enum: STOP=1, MAX_TOKENS=2, SAFETY=3, RECITATION=4, OTHER=5
                if finish_reason_int == 1:  # FINISH_REASON_STOP - Normal completion
                    try:
                        # Try multiple ways to access the response content
                        result = None
                        
                        # Method 1: Direct text access
                        if hasattr(response, 'text') and response.text:
                            result = response.text
                            self.logger.info(f"✅ Got response via response.text")
                        
                        # Method 2: Access via candidates[0].content.parts
                        elif hasattr(candidate, 'content') and hasattr(candidate.content, 'parts'):
                            parts = candidate.content.parts
                            if parts and len(parts) > 0:
                                if hasattr(parts[0], 'text'):
                                    result = parts[0].text
                                    self.logger.info(f"✅ Got response via candidate.content.parts[0].text")
                        
                        if result and result.strip():
                            self.logger.info(f"✅ Successfully generated response with Gemini model: {self.model_name}")
                            self.logger.info(f"📊 Gemini response length: {len(result)}")
                            self.logger.info(f"📄 Gemini response preview: {result[:200]}...")
                            return result.strip()
                        else:
                            # No valid content found
                            self.logger.error(f"❌ Gemini response has no valid text content despite STOP finish reason")
                            self.logger.error(f"Response structure: {dir(response)}")
                            if hasattr(candidate, 'content'):
                                self.logger.error(f"Candidate content: {dir(candidate.content)}")
                                if hasattr(candidate.content, 'parts'):
                                    self.logger.error(f"Parts count: {len(candidate.content.parts)}")
                            
                            raise ValueError("No text content in Gemini response despite finish_reason=STOP. "
                                           "This may be due to safety filters or API issues.")
                    except AttributeError as attr_error:
                        self.logger.error(f"❌ Attribute error accessing response content: {attr_error}")
                        raise ValueError(f"Cannot access response text due to missing attributes: {attr_error}")
                    except Exception as text_error:
                        self.logger.error(f"❌ Error accessing response text: {text_error}")
                        raise ValueError(f"Cannot access response text: {text_error}")
                        
                elif finish_reason_int == 2:  # FINISH_REASON_MAX_TOKENS - Hit token limit
                    self.logger.warning(f"⚠️ Gemini response truncated due to token limit (finish_reason=2)")
                    self.logger.warning(f"� Prompt length: {len(sanitized_prompt)} characters. Consider reducing prompt size.")
                    
                    # Check if partial response is available (safe access)
                    partial_response_available = False
                    try:
                        if hasattr(response, 'text'):
                            result = response.text
                            if result and result.strip():
                                self.logger.info(f"📊 Gemini partial response length: {len(result)}")
                                # Return clean result without truncation message
                                return result.strip()
                            else:
                                self.logger.warning("⚠️ Response text is empty")
                    except Exception as text_error:
                        self.logger.warning(f"⚠️ Cannot access response.text for partial content: {text_error}")
                    
                    # No partial response available, try with shorter prompt
                    self.logger.info("🔄 Attempting retry with reduced prompt size...")
                    
                    # For Gemini 2.5, be more aggressive with larger prompts before fallback
                    current_length = len(sanitized_prompt)
                    
                    # Special handling for test code generation with 90K capacity
                    if self.use_case == 'test_code_generation':
                        # With 90K tokens, be less aggressive with truncation
                        if current_length > 300000:  # Very large (300K chars ~ 75K tokens)
                            shortened_prompt = sanitized_prompt[:250000] + "\n\n## Instructions:\nGenerate complete test code based on the context above."
                        elif current_length > 150000:  # Large (150K chars ~ 37K tokens)  
                            shortened_prompt = sanitized_prompt[:120000] + "\n\n## Instructions:\nGenerate complete test code based on the context above."
                        else:  # Medium size, minimal reduction
                            shortened_prompt = sanitized_prompt[:80000] + "\n\n## Instructions:\nGenerate complete test code based on the context above."
                    else:
                        # General content reduction strategy with 90K capacity
                        if current_length > 300000:  # Very large prompt, reduce to ~200K chars
                            shortened_prompt = sanitized_prompt[:200000] + "\n\n[Content truncated due to length. Please provide a comprehensive analysis of the available content.]"
                        elif current_length > 150000:  # Large prompt, reduce to ~100K chars
                            shortened_prompt = sanitized_prompt[:100000] + "\n\n[Content truncated due to length. Please provide analysis of the available content.]"
                        elif current_length > 80000:   # Medium prompt, reduce to ~60K chars
                            shortened_prompt = sanitized_prompt[:60000] + "\n\n[Content truncated. Please provide analysis of the available content.]"
                        else:  # Small prompt, minimal reduction
                            shortened_prompt = sanitized_prompt[:40000] + "\n\n[Brief analysis requested due to token limits.]"
                    
                    self.logger.info(f"📏 Reduced prompt from {current_length} to {len(shortened_prompt)} characters")
                    
                    # Try again with shortened prompt and high output limit for Gemini 2.5
                    try:
                        fallback_response = await model.generate_content_async(
                            shortened_prompt,
                            generation_config={'temperature': temperature, 'max_output_tokens': 45000}  # High limit for Gemini 2.5 fallback
                        )
                        
                        if fallback_response and fallback_response.candidates:
                            fallback_candidate = fallback_response.candidates[0]
                            fallback_finish_reason = fallback_candidate.finish_reason
                            if hasattr(fallback_finish_reason, 'value'):
                                fallback_finish_reason = fallback_finish_reason.value
                            if fallback_finish_reason == 1:
                                try:
                                    if hasattr(fallback_response, 'text'):
                                        self.logger.info("✅ Token limit retry succeeded with shortened prompt")
                                        # Return clean result without technical messages
                                        return fallback_response.text.strip()
                                except Exception as fallback_text_error:
                                    self.logger.error(f"❌ Error accessing fallback response.text: {fallback_text_error}")
                        
                        self.logger.error("❌ Fallback retry failed - no usable content")
                        raise ValueError("Token limit exceeded and fallback failed")
                        
                    except Exception as fallback_error:
                        self.logger.error(f"❌ Token limit fallback failed: {fallback_error}")
                        raise ValueError("Token limit exceeded and retry failed. Please reduce the input size.")
                                
                elif finish_reason_int == 3:  # FINISH_REASON_SAFETY - Blocked by safety filters
                    self.logger.warning(f"🚫 Gemini response blocked by safety filters (finish_reason=3)")
                    
                    # Log safety ratings for debugging
                    safety_ratings = getattr(response, 'safety_ratings', [])
                    if safety_ratings:
                        for rating in safety_ratings:
                            self.logger.warning(f"Safety category {rating.category}: {rating.probability}")
                    
                    # Provide detailed error information
                    error_details = {
                        'finish_reason': finish_reason_int,
                        'safety_ratings': [{'category': rating.category, 'probability': rating.probability} for rating in safety_ratings] if safety_ratings else [],
                        'prompt_length': len(sanitized_prompt),
                        'model': self.model_name
                    }
                    
                    self.logger.error(f"Safety filter details: {error_details}")
                    
                    raise ValueError(f"Gemini blocked the response due to safety filters (finish_reason=3). "
                                   f"Content may violate content policies. Details: {error_details['safety_ratings']}. "
                                   f"Try rephrasing the content or using a different model.")
                    
                elif finish_reason_int == 4:  # FINISH_REASON_RECITATION - Blocked due to recitation
                    self.logger.warning(f"🚫 Gemini response blocked due to recitation concerns (finish_reason=4)")
                    raise ValueError("Gemini blocked the response due to potential copyright concerns. "
                                   "The content may be too similar to copyrighted material.")
                    
                elif finish_reason_int == 5:  # FINISH_REASON_OTHER - Other reason
                    self.logger.warning(f"⚠️ Gemini stopped for unspecified reason (finish_reason=5)")
                    try:
                        if hasattr(response, 'text') and response.text:
                            result = response.text
                            return result
                        else:
                            raise ValueError("Gemini stopped for unspecified reason with no usable content")
                    except Exception as text_error:
                        self.logger.error(f"❌ Error accessing response.text with OTHER finish reason: {text_error}")
                        raise ValueError(f"Cannot access response for OTHER finish reason: {text_error}")
                        
                else:
                    self.logger.error(f"❌ Unexpected Gemini finish_reason: {finish_reason_int} (original: {finish_reason})")
                    raise ValueError(f"Gemini response completed with unexpected finish_reason: {finish_reason_int}")
                    
            else:
                self.logger.error(f"❌ Invalid response from Gemini API: {response}")
                if response:
                    self.logger.error(f"Response has candidates: {hasattr(response, 'candidates')}")
                    if hasattr(response, 'candidates'):
                        self.logger.error(f"Number of candidates: {len(response.candidates) if response.candidates else 0}")
                raise ValueError("Invalid response format from Gemini API")
                
        except Exception as e:
            error_str = str(e)
            
            # 503 Service Unavailable hatası kontrolü
            if "503" in error_str or "service unavailable" in error_str.lower() or "unavailable" in error_str.lower():
                rate_config = self._get_rate_limit_config()
                base_cooldown = rate_config['cooldown_seconds']
                random_delay = random.uniform(rate_config['random_delay_min'], rate_config['random_delay_max'])
                total_wait = base_cooldown + random_delay
                
                self.logger.warning(f"🔴 503 Service Unavailable detected for Gemini API")
                self.logger.warning(f"⏳ Google servers are overloaded. Model is currently unavailable.")
                self.logger.warning(f"🔄 Will wait {base_cooldown}s + {random_delay:.2f}s = {total_wait:.2f}s before retry")
                
                # 503 hatası için rate limit işaretle (ancak hata fırlatma, retry'ı üst katmana bırak)
                self._handle_rate_limit_error(error_str)
                raise Exception(f"Gemini API is temporarily unavailable (503). Wait time applied: {total_wait:.2f}s. Error: {error_str}")
            
            # 500 Internal Error kontrolü
            elif "500" in error_str and "internal" in error_str.lower():
                rate_config = self._get_rate_limit_config()
                base_cooldown = 2  # 500 için biraz daha kısa bekleme
                random_delay = random.uniform(0, 5)  # Hız için optimize edildi: 0-5 saniye
                total_wait = base_cooldown + random_delay
                
                self.logger.warning(f"🔴 500 Internal Error detected for Gemini API")
                self.logger.warning(f"⚙️  Google API internal error. Server issue.")
                self.logger.warning(f"🔄 Will wait {base_cooldown}s + {random_delay:.2f}s = {total_wait:.2f}s before retry")
                
                # 500 hatası için de rate limit işaretle
                self._handle_rate_limit_error(error_str)
                raise Exception(f"Gemini API internal error (500). Wait time applied: {total_wait:.2f}s. Error: {error_str}")
            
            # Diğer rate limit hataları kontrolü
            elif "429" in error_str or "RESOURCE_EXHAUSTED" in error_str or "quota" in error_str.lower():
                self.logger.warning(f"🔴 Rate limit detected in Gemini API: {error_str}")
                self._handle_rate_limit_error(error_str)
                
                # Rate limit hatası durumunda tekrar deneme yapma, 
                # bunun yerine hata fırlat ve üst katmanın handle etmesini bekle
                raise Exception(f"Rate limit exceeded for Gemini API. Please wait and try again. Error: {error_str}")
            
            self.logger.error(f"❌ Gemini API Error with model {self.model_name}: {error_str}")
            raise
