
import asyncio
import torch
import logging
from typing import Tuple

logger = logging.getLogger(__name__)

class UltraLLMEngine:
    def __init__(self, loader, router, bandit, uncertainty):
        self.loader = loader
        self.router = router
        self.bandit = bandit
        self.uncertainty = uncertainty

    async def generate(self, prompt: str) -> Tuple[str, float]:
        # Step 1 — choose expert model
        expert = self.router.select(prompt)
        logger.info(f"Router selected expert: {expert}")

        # Step 2 — allow bandit override
        candidate = self.bandit.choose()
        
        # Simple logic: If bandit really likes a model high reward, it might pick it.
        # But for now, let's respect the router primarily unless bandit is highly confident
        # Or, follow user logic: "If candidate != expert: model_name = candidate" 
        # (This implies Bandit has final say, which is aggressive 😈)
        
        if candidate != expert:
            logger.info(f"Bandit override! Switching {expert} -> {candidate}")
            model_name = candidate
        else:
            model_name = expert

        try:
            tokenizer, model = self.loader.load(model_name)
        except Exception as e:
            logger.warning(f"Failed to load {model_name}, falling back to smollm-360m: {e}")
            try:
                model_name = "smollm-360m"
                tokenizer, model = self.loader.load(model_name)
            except (ImportError, RuntimeError, OSError, ValueError) as fallback_error:
                logger.error(f"Critical: Fallback model load failed: {fallback_error}")
                raise RuntimeError(f"All model loading attempts failed: {fallback_error}") from fallback_error

        inputs = tokenizer(prompt, return_tensors="pt").to(model.device)

        # Step 3 — speculative decoding (draft model = smollm)
        # Note: Speculative decoding requires loading two models. 
        # We'll skip complex wiring here for safety and assume standard generation
        # unless 'smollm' is available and we are using a bigger model.
        
        # Step 4 — async generation
        # Running synchronous model.generate in a threadpool to be async-friendly
        loop = asyncio.get_running_loop()
        
        def run_inference():
            with torch.no_grad():
                output = model.generate(
                    **inputs,
                    max_new_tokens=1024,
                    do_sample=True,
                    temperature=0.4,
                    top_p=0.9
                )
            return output

        output = await loop.run_in_executor(None, run_inference)
        text = tokenizer.decode(output[0], skip_special_tokens=True)

        # Step 5 — reward bandit
        conf = self.uncertainty.score(text)
        self.bandit.update(model_name, conf)

        logger.info(f"Generation complete. Model: {model_name}, Confidence: {conf:.4f}")
        return text, conf
