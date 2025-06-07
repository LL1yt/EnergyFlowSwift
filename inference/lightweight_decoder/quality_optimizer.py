"""
🎯 QUALITY OPTIMIZER - Stage 2.3 Production Integration
Продвинутая система оптимизации качества генерации для GenerativeDecoder

Возможности:
- Адаптивная оптимизация параметров генерации
- Продвинутые метрики качества (BLEU, ROUGE, BERTScore)
- Fine-tuning стратегий для RET v2.1
- Production-ready quality monitoring
"""

import torch
import torch.nn as nn
import numpy as np
import time
import logging
from typing import Dict, List, Tuple, Optional, Any, Union
from dataclasses import dataclass
from pathlib import Path
import json
import math

# Внешние зависимости для метрик качества
try:
    from nltk.translate.bleu_score import sentence_bleu, SmoothingFunction
    from rouge_score import rouge_scorer
    NLTK_AVAILABLE = True
except ImportError:
    NLTK_AVAILABLE = False
    logging.warning("NLTK/ROUGE не установлены. Используются упрощенные метрики.")

try:
    from sentence_transformers import SentenceTransformer
    SENTENCE_TRANSFORMER_AVAILABLE = True
except ImportError:
    SENTENCE_TRANSFORMER_AVAILABLE = False
    logging.warning("SentenceTransformer не установлен. BERTScore недоступен.")

logger = logging.getLogger(__name__)


@dataclass
class QualityMetrics:
    """Комплексные метрики качества генерации"""
    
    # Основные метрики
    bleu_score: float = 0.0
    rouge_1: float = 0.0
    rouge_2: float = 0.0
    rouge_l: float = 0.0
    bert_score: float = 0.0
    
    # Продвинутые метрики
    semantic_similarity: float = 0.0
    coherence_score: float = 0.0
    fluency_score: float = 0.0
    diversity_score: float = 0.0
    
    # Производительность
    generation_time: float = 0.0
    tokens_per_second: float = 0.0
    
    # Агрегированные метрики
    overall_quality: float = 0.0
    production_readiness: float = 0.0
    
    def to_dict(self) -> Dict[str, float]:
        """Конвертация в словарь для логирования"""
        return {
            'bleu_score': self.bleu_score,
            'rouge_1': self.rouge_1,
            'rouge_2': self.rouge_2,
            'rouge_l': self.rouge_l,
            'bert_score': self.bert_score,
            'semantic_similarity': self.semantic_similarity,
            'coherence_score': self.coherence_score,
            'fluency_score': self.fluency_score,
            'diversity_score': self.diversity_score,
            'generation_time': self.generation_time,
            'tokens_per_second': self.tokens_per_second,
            'overall_quality': self.overall_quality,
            'production_readiness': self.production_readiness
        }


@dataclass
class OptimizationConfig:
    """Конфигурация для оптимизации качества"""
    
    # Целевые метрики Stage 2.3
    target_bleu: float = 0.45          # Повышенная цель для Stage 2.3
    target_rouge_l: float = 0.35       # ROUGE-L цель
    target_bert_score: float = 0.70    # BERTScore цель
    target_coherence: float = 0.75     # Coherence цель
    target_fluency: float = 0.80       # Fluency цель
    
    # Параметры оптимизации
    max_optimization_iterations: int = 50
    patience: int = 5                  # Early stopping patience
    improvement_threshold: float = 0.01  # Минимальное улучшение
    
    # Диапазоны параметров для fine-tuning
    temperature_range: Tuple[float, float] = (0.3, 1.2)
    top_k_range: Tuple[int, int] = (10, 100)
    top_p_range: Tuple[float, float] = (0.7, 0.95)
    repetition_penalty_range: Tuple[float, float] = (1.0, 1.5)
    
    # Production settings
    quality_monitoring: bool = True
    save_best_params: bool = True
    detailed_logging: bool = True


class AdvancedQualityAssessment:
    """
    🔬 ПРОДВИНУТАЯ СИСТЕМА ОЦЕНКИ КАЧЕСТВА
    
    Stage 2.3 enhancement для GenerativeDecoder:
    - Реальные BLEU/ROUGE/BERTScore метрики
    - Семантический анализ качества
    - Продвинутая coherence и fluency оценка
    - Production-ready мониторинг
    """
    
    def __init__(self, config: OptimizationConfig):
        self.config = config
        
        # Инициализация ROUGE scorer
        if NLTK_AVAILABLE:
            self.rouge_scorer = rouge_scorer.RougeScorer(['rouge1', 'rouge2', 'rougeL'], use_stemmer=True)
            self.bleu_smoother = SmoothingFunction().method4
        else:
            self.rouge_scorer = None
            self.bleu_smoother = None
        
        # Инициализация BERTScore model
        if SENTENCE_TRANSFORMER_AVAILABLE:
            try:
                self.bert_model = SentenceTransformer('all-MiniLM-L6-v2')
                logger.info("🎯 BERTScore model загружена успешно")
            except Exception as e:
                logger.warning(f"Не удалось загрузить BERTScore model: {e}")
                self.bert_model = None
        else:
            self.bert_model = None
        
        logger.info("🔬 AdvancedQualityAssessment инициализирована")
    
    def assess_comprehensive_quality(self, 
                                   generated_text: str, 
                                   reference_text: str,
                                   generation_time: float = 0.0) -> QualityMetrics:
        """
        Комплексная оценка качества генерации
        
        Args:
            generated_text: Сгенерированный текст
            reference_text: Эталонный текст для сравнения
            generation_time: Время генерации в секундах
            
        Returns:
            QualityMetrics: Комплексные метрики качества
        """
        
        metrics = QualityMetrics()
        
        # Базовая валидация
        if not generated_text or not reference_text:
            logger.warning("Пустой текст для оценки качества")
            return metrics
        
        # 1. BLEU Score
        metrics.bleu_score = self._calculate_bleu(generated_text, reference_text)
        
        # 2. ROUGE Scores
        rouge_scores = self._calculate_rouge(generated_text, reference_text)
        metrics.rouge_1 = rouge_scores.get('rouge1', 0.0)
        metrics.rouge_2 = rouge_scores.get('rouge2', 0.0)
        metrics.rouge_l = rouge_scores.get('rougeL', 0.0)
        
        # 3. BERTScore (семантическое сходство)
        metrics.bert_score = self._calculate_bert_score(generated_text, reference_text)
        
        # 4. Семантическое сходство
        metrics.semantic_similarity = self._calculate_semantic_similarity(generated_text, reference_text)
        
        # 5. Coherence оценка
        metrics.coherence_score = self._assess_coherence(generated_text)
        
        # 6. Fluency оценка
        metrics.fluency_score = self._assess_fluency(generated_text)
        
        # 7. Diversity оценка
        metrics.diversity_score = self._assess_diversity(generated_text)
        
        # 8. Performance метрики
        metrics.generation_time = generation_time
        if generation_time > 0:
            tokens = len(generated_text.split())
            metrics.tokens_per_second = tokens / generation_time
        
        # 9. Агрегированные метрики
        metrics.overall_quality = self._calculate_overall_quality(metrics)
        metrics.production_readiness = self._calculate_production_readiness(metrics)
        
        return metrics
    
    def _calculate_bleu(self, generated: str, reference: str) -> float:
        """Рассчитать BLEU score"""
        if not NLTK_AVAILABLE:
            return self._simple_bleu_approximation(generated, reference)
        
        try:
            # Токенизация
            generated_tokens = generated.lower().split()
            reference_tokens = [reference.lower().split()]
            
            # Вычисление BLEU с сглаживанием
            bleu = sentence_bleu(reference_tokens, generated_tokens, 
                               smoothing_function=self.bleu_smoother)
            return min(max(bleu, 0.0), 1.0)
            
        except Exception as e:
            logger.warning(f"Ошибка в BLEU расчете: {e}")
            return self._simple_bleu_approximation(generated, reference)
    
    def _simple_bleu_approximation(self, generated: str, reference: str) -> float:
        """Упрощенная аппроксимация BLEU для fallback"""
        gen_words = set(generated.lower().split())
        ref_words = set(reference.lower().split())
        
        if not gen_words or not ref_words:
            return 0.0
        
        intersection = len(gen_words & ref_words)
        union = len(gen_words | ref_words)
        
        return intersection / union if union > 0 else 0.0
    
    def _calculate_rouge(self, generated: str, reference: str) -> Dict[str, float]:
        """Рассчитать ROUGE scores"""
        if not self.rouge_scorer:
            return {'rouge1': 0.0, 'rouge2': 0.0, 'rougeL': 0.0}
        
        try:
            scores = self.rouge_scorer.score(generated, reference)
            return {
                'rouge1': scores['rouge1'].fmeasure,
                'rouge2': scores['rouge2'].fmeasure,
                'rougeL': scores['rougeL'].fmeasure
            }
        except Exception as e:
            logger.warning(f"Ошибка в ROUGE расчете: {e}")
            return {'rouge1': 0.0, 'rouge2': 0.0, 'rougeL': 0.0}
    
    def _calculate_bert_score(self, generated: str, reference: str) -> float:
        """Рассчитать BERTScore (семантическое сходство)"""
        if not self.bert_model:
            return 0.0
        
        try:
            embeddings = self.bert_model.encode([generated, reference])
            similarity = np.dot(embeddings[0], embeddings[1]) / (
                np.linalg.norm(embeddings[0]) * np.linalg.norm(embeddings[1])
            )
            return float(max(0.0, min(1.0, similarity)))
            
        except Exception as e:
            logger.warning(f"Ошибка в BERTScore расчете: {e}")
            return 0.0
    
    def _calculate_semantic_similarity(self, generated: str, reference: str) -> float:
        """Семантическое сходство через word overlap и length similarity"""
        gen_words = generated.lower().split()
        ref_words = reference.lower().split()
        
        if not gen_words or not ref_words:
            return 0.0
        
        # Word overlap similarity
        word_intersection = len(set(gen_words) & set(ref_words))
        word_union = len(set(gen_words) | set(ref_words))
        word_similarity = word_intersection / word_union if word_union > 0 else 0.0
        
        # Length similarity
        length_ratio = min(len(gen_words), len(ref_words)) / max(len(gen_words), len(ref_words))
        
        return (word_similarity * 0.7 + length_ratio * 0.3)
    
    def _assess_coherence(self, text: str) -> float:
        """Продвинутая оценка coherence"""
        if not text:
            return 0.0
        
        words = text.split()
        if len(words) < 3:
            return 0.1
        
        coherence_score = 0.0
        factors = 0
        
        # 1. Длина предложения (optimal range)
        if 5 <= len(words) <= 25:
            coherence_score += 0.3
        elif 3 <= len(words) <= 40:
            coherence_score += 0.15
        factors += 1
        
        # 2. Функциональные слова
        function_words = {'the', 'a', 'an', 'and', 'or', 'but', 'is', 'are', 'was', 'were', 'to', 'of', 'in', 'on', 'at'}
        function_word_count = sum(1 for word in words if word.lower() in function_words)
        function_ratio = function_word_count / len(words)
        if 0.2 <= function_ratio <= 0.6:
            coherence_score += 0.25
        factors += 1
        
        # 3. Repetition analysis
        word_counts = {}
        for word in words:
            word_counts[word.lower()] = word_counts.get(word.lower(), 0) + 1
        
        max_repetition = max(word_counts.values())
        if max_repetition <= max(2, len(words) // 4):
            coherence_score += 0.25
        factors += 1
        
        # 4. Vocabulary diversity
        unique_ratio = len(set(words)) / len(words)
        if unique_ratio >= 0.6:
            coherence_score += 0.2
        elif unique_ratio >= 0.4:
            coherence_score += 0.1
        factors += 1
        
        return coherence_score
    
    def _assess_fluency(self, text: str) -> float:
        """Продвинутая оценка fluency"""
        if not text:
            return 0.0
        
        words = text.split()
        if not words:
            return 0.0
        
        fluency_score = 0.0
        
        # 1. Basic structure (30%)
        if 3 <= len(words) <= 30:
            fluency_score += 0.3
        elif 1 <= len(words) <= 50:
            fluency_score += 0.15
        
        # 2. Grammar patterns (25%)
        text_lower = ' ' + text.lower() + ' '
        grammar_patterns = [
            ' the ', ' a ', ' an ', ' and ', ' or ', ' but ',
            ' is ', ' are ', ' was ', ' were ', ' have ', ' has ',
            ' to ', ' of ', ' in ', ' on ', ' at ', ' for '
        ]
        pattern_matches = sum(1 for pattern in grammar_patterns if pattern in text_lower)
        if pattern_matches >= 2:
            fluency_score += 0.25
        elif pattern_matches >= 1:
            fluency_score += 0.15
        
        # 3. Word flow (20%)
        if len(words) >= 3:
            # Check for reasonable word transitions
            transition_score = 0.0
            consecutive_same = 0
            for i in range(1, len(words)):
                if words[i] == words[i-1]:
                    consecutive_same += 1
                else:
                    consecutive_same = 0
                
                if consecutive_same == 0:
                    transition_score += 1
            
            transition_ratio = transition_score / (len(words) - 1)
            fluency_score += transition_ratio * 0.2
        
        # 4. Length appropriateness (15%)
        if 5 <= len(words) <= 20:
            fluency_score += 0.15
        elif 3 <= len(words) <= 35:
            fluency_score += 0.1
        
        # 5. Capitalization and punctuation patterns (10%)
        if text[0].isupper() if text else False:
            fluency_score += 0.05
        if any(punct in text for punct in '.!?'):
            fluency_score += 0.05
        
        return min(fluency_score, 1.0)
    
    def _assess_diversity(self, text: str) -> float:
        """Оценка разнообразия vocabulary"""
        words = text.split()
        if len(words) <= 1:
            return 0.0
        
        unique_words = len(set(word.lower() for word in words))
        diversity_ratio = unique_words / len(words)
        
        # Ideal diversity ratio is around 0.7-0.9
        if diversity_ratio >= 0.7:
            return 1.0
        elif diversity_ratio >= 0.5:
            return 0.8
        elif diversity_ratio >= 0.3:
            return 0.6
        else:
            return 0.3
    
    def _calculate_overall_quality(self, metrics: QualityMetrics) -> float:
        """Рассчитать агрегированную оценку качества"""
        # Веса для различных метрик
        weights = {
            'bleu': 0.25,
            'rouge_l': 0.20,
            'bert_score': 0.15,
            'semantic_similarity': 0.10,
            'coherence': 0.15,
            'fluency': 0.15
        }
        
        overall = (
            metrics.bleu_score * weights['bleu'] +
            metrics.rouge_l * weights['rouge_l'] +
            metrics.bert_score * weights['bert_score'] +
            metrics.semantic_similarity * weights['semantic_similarity'] +
            metrics.coherence_score * weights['coherence'] +
            metrics.fluency_score * weights['fluency']
        )
        
        return float(min(max(overall, 0.0), 1.0))
    
    def _calculate_production_readiness(self, metrics: QualityMetrics) -> float:
        """Оценка готовности к production"""
        # Критерии production readiness для Stage 2.3 (SOFTENED)
        criteria_met = 0.0
        total_criteria = 6
        
        # 1. BLEU Score (graduated scoring)
        if metrics.bleu_score >= 0.35:
            criteria_met += 1.0
        elif metrics.bleu_score >= 0.25:
            criteria_met += 0.7
        elif metrics.bleu_score >= 0.15:
            criteria_met += 0.4
        elif metrics.bleu_score >= 0.05:
            criteria_met += 0.2
        
        # 2. ROUGE-L Score (graduated scoring)
        if metrics.rouge_l >= 0.25:
            criteria_met += 1.0
        elif metrics.rouge_l >= 0.18:
            criteria_met += 0.7
        elif metrics.rouge_l >= 0.12:
            criteria_met += 0.4
        elif metrics.rouge_l >= 0.05:
            criteria_met += 0.2
        
        # 3. Coherence Score (graduated scoring)
        if metrics.coherence_score >= 0.65:
            criteria_met += 1.0
        elif metrics.coherence_score >= 0.55:
            criteria_met += 0.7
        elif metrics.coherence_score >= 0.45:
            criteria_met += 0.4
        elif metrics.coherence_score >= 0.25:
            criteria_met += 0.2
        
        # 4. Fluency Score (graduated scoring)
        if metrics.fluency_score >= 0.70:
            criteria_met += 1.0
        elif metrics.fluency_score >= 0.60:
            criteria_met += 0.7
        elif metrics.fluency_score >= 0.50:
            criteria_met += 0.4
        elif metrics.fluency_score >= 0.30:
            criteria_met += 0.2
        
        # 5. Overall Quality (graduated scoring)
        if metrics.overall_quality >= 0.60:
            criteria_met += 1.0
        elif metrics.overall_quality >= 0.45:
            criteria_met += 0.7
        elif metrics.overall_quality >= 0.30:
            criteria_met += 0.4
        elif metrics.overall_quality >= 0.15:
            criteria_met += 0.2
        
        # 6. Performance (if available)
        if metrics.generation_time > 0:
            if metrics.generation_time <= 0.5:  # Very fast
                criteria_met += 1.0
            elif metrics.generation_time <= 1.0:  # Fast
                criteria_met += 0.7
            elif metrics.generation_time <= 2.0:  # Acceptable
                criteria_met += 0.4
            elif metrics.generation_time <= 5.0:  # Slow but usable
                criteria_met += 0.2
        else:  # Performance not measured
            criteria_met += 0.5  # Partial credit
        
        return float(criteria_met / total_criteria)


class GenerationParameterOptimizer:
    """
    ⚡ ОПТИМИЗАТОР ПАРАМЕТРОВ ГЕНЕРАЦИИ
    
    Stage 2.3 optimization для fine-tuning параметров GenerativeDecoder:
    - Адаптивная оптимизация temperature, top_k, top_p
    - Evolutionary search стратегии
    - Production-ready parameter sets
    """
    
    def __init__(self, config: OptimizationConfig):
        self.config = config
        self.quality_assessor = AdvancedQualityAssessment(config)
        
        # История оптимизации
        self.optimization_history = []
        self.best_params = None
        self.best_score = 0.0
        
        logger.info("⚡ GenerationParameterOptimizer инициализирован")
    
    def optimize_parameters(self, 
                          model,
                          test_embeddings: List[torch.Tensor],
                          reference_texts: List[str],
                          max_iterations: Optional[int] = None) -> Dict[str, Any]:
        """
        Оптимизация параметров генерации
        
        Args:
            model: GenerativeDecoder model
            test_embeddings: Тестовые эмбеддинги
            reference_texts: Эталонные тексты
            max_iterations: Максимум итераций оптимизации
            
        Returns:
            Dict: Лучшие параметры и метрики
        """
        
        max_iterations = max_iterations or self.config.max_optimization_iterations
        
        logger.info(f"🚀 Начинаем оптимизацию параметров (max_iterations={max_iterations})")
        
        # Инициализация
        best_params = self._get_initial_parameters()
        best_metrics = self._evaluate_parameters(model, best_params, test_embeddings, reference_texts)
        best_score = best_metrics.overall_quality
        
        patience_counter = 0
        
        for iteration in range(max_iterations):
            # Генерируем candidate parameters
            candidate_params = self._generate_candidate_parameters(best_params, iteration)
            
            # Оценка кандидата
            candidate_metrics = self._evaluate_parameters(model, candidate_params, test_embeddings, reference_texts)
            candidate_score = candidate_metrics.overall_quality
            
            # Улучшение найдено?
            if candidate_score > best_score + self.config.improvement_threshold:
                best_params = candidate_params
                best_metrics = candidate_metrics
                best_score = candidate_score
                patience_counter = 0
                
                logger.info(f"🎯 Iteration {iteration}: Новые лучшие параметры! Score: {best_score:.4f}")
                
            else:
                patience_counter += 1
            
            # Сохранение истории
            self.optimization_history.append({
                'iteration': iteration,
                'params': candidate_params.copy(),
                'metrics': candidate_metrics.to_dict(),
                'score': candidate_score,
                'is_best': candidate_score > best_score
            })
            
            # Early stopping
            if patience_counter >= self.config.patience:
                logger.info(f"🛑 Early stopping на iteration {iteration} (patience={self.config.patience})")
                break
        
        # Финальные результаты
        self.best_params = best_params
        self.best_score = best_score
        
        optimization_result = {
            'best_params': best_params,
            'best_metrics': best_metrics.to_dict(),
            'best_score': best_score,
            'total_iterations': len(self.optimization_history),
            'optimization_history': self.optimization_history
        }
        
        logger.info(f"✅ Оптимизация завершена! Лучший score: {best_score:.4f}")
        logger.info(f"📊 Лучшие параметры: {best_params}")
        
        return optimization_result
    
    def _get_initial_parameters(self) -> Dict[str, Any]:
        """Получить начальные параметры"""
        return {
            'temperature': 0.8,
            'top_k': 50,
            'top_p': 0.9,
            'repetition_penalty': 1.1,
            'length_penalty': 1.0
        }
    
    def _generate_candidate_parameters(self, base_params: Dict[str, Any], iteration: int) -> Dict[str, Any]:
        """Генерировать candidate параметры"""
        candidate = base_params.copy()
        
        # Адаптивная мутация (stronger early, gentler later)
        mutation_strength = max(0.1, 1.0 - iteration / 50.0)
        
        # Temperature optimization
        temp_delta = np.random.normal(0, 0.1 * mutation_strength)
        candidate['temperature'] = np.clip(
            candidate['temperature'] + temp_delta,
            self.config.temperature_range[0],
            self.config.temperature_range[1]
        )
        
        # Top-k optimization
        k_delta = int(np.random.normal(0, 10 * mutation_strength))
        candidate['top_k'] = np.clip(
            candidate['top_k'] + k_delta,
            self.config.top_k_range[0],
            self.config.top_k_range[1]
        )
        
        # Top-p optimization
        p_delta = np.random.normal(0, 0.05 * mutation_strength)
        candidate['top_p'] = np.clip(
            candidate['top_p'] + p_delta,
            self.config.top_p_range[0],
            self.config.top_p_range[1]
        )
        
        # Repetition penalty optimization
        rep_delta = np.random.normal(0, 0.05 * mutation_strength)
        candidate['repetition_penalty'] = np.clip(
            candidate['repetition_penalty'] + rep_delta,
            self.config.repetition_penalty_range[0],
            self.config.repetition_penalty_range[1]
        )
        
        return candidate
    
    def _evaluate_parameters(self, 
                           model,
                           params: Dict[str, Any],
                           embeddings: List[torch.Tensor],
                           reference_texts: List[str]) -> QualityMetrics:
        """Оценка качества для заданных параметров"""
        
        total_metrics = QualityMetrics()
        valid_evaluations = 0
        
        for embedding, reference in zip(embeddings, reference_texts):
            try:
                # Генерация с заданными параметрами
                start_time = time.time()
                result = model.generate(
                    embedding,
                    temperature=params['temperature'],
                    top_k=params['top_k'],
                    top_p=params['top_p'],
                    **{k: v for k, v in params.items() if k not in ['temperature', 'top_k', 'top_p']}
                )
                generation_time = time.time() - start_time
                
                generated_text = result.get('text', '')
                
                # Оценка качества
                metrics = self.quality_assessor.assess_comprehensive_quality(
                    generated_text, reference, generation_time
                )
                
                # Аккумуляция метрик
                total_metrics.bleu_score += metrics.bleu_score
                total_metrics.rouge_1 += metrics.rouge_1
                total_metrics.rouge_2 += metrics.rouge_2
                total_metrics.rouge_l += metrics.rouge_l
                total_metrics.bert_score += metrics.bert_score
                total_metrics.semantic_similarity += metrics.semantic_similarity
                total_metrics.coherence_score += metrics.coherence_score
                total_metrics.fluency_score += metrics.fluency_score
                total_metrics.diversity_score += metrics.diversity_score
                total_metrics.generation_time += metrics.generation_time
                total_metrics.tokens_per_second += metrics.tokens_per_second
                total_metrics.overall_quality += metrics.overall_quality
                total_metrics.production_readiness += metrics.production_readiness
                
                valid_evaluations += 1
                
            except Exception as e:
                logger.warning(f"Ошибка при оценке параметров: {e}")
                continue
        
        # Усреднение метрик
        if valid_evaluations > 0:
            for attr in total_metrics.__dict__:
                setattr(total_metrics, attr, getattr(total_metrics, attr) / valid_evaluations)
        
        return total_metrics
    
    def save_optimization_results(self, filepath: Union[str, Path]):
        """Сохранить результаты оптимизации"""
        results = {
            'best_params': self.best_params,
            'best_score': self.best_score,
            'optimization_history': self.optimization_history,
            'config': {
                'target_bleu': self.config.target_bleu,
                'target_rouge_l': self.config.target_rouge_l,
                'target_coherence': self.config.target_coherence,
                'target_fluency': self.config.target_fluency
            }
        }
        
        with open(filepath, 'w', encoding='utf-8') as f:
            json.dump(results, f, indent=2, ensure_ascii=False)
        
        logger.info(f"💾 Результаты оптимизации сохранены: {filepath}")


# Factory function
def create_quality_optimizer(target_bleu: float = 0.45, 
                           target_rouge_l: float = 0.35,
                           max_iterations: int = 50) -> GenerationParameterOptimizer:
    """
    Factory function для создания оптимизатора качества Stage 2.3
    
    Args:
        target_bleu: Целевой BLEU score (Stage 2.3 = 0.45)
        target_rouge_l: Целевой ROUGE-L score (Stage 2.3 = 0.35)
        max_iterations: Максимум итераций оптимизации
        
    Returns:
        GenerationParameterOptimizer: Настроенный оптимизатор
    """
    
    config = OptimizationConfig(
        target_bleu=target_bleu,
        target_rouge_l=target_rouge_l,
        max_optimization_iterations=max_iterations
    )
    
    return GenerationParameterOptimizer(config)


if __name__ == "__main__":
    # Тестирование системы
    print("🔬 Testing Quality Optimization System...")
    
    # Test quality assessment
    assessor = AdvancedQualityAssessment(OptimizationConfig())
    
    test_generated = "The quick brown fox jumps over the lazy dog."
    test_reference = "A fast brown fox leaps over a sleeping dog."
    
    metrics = assessor.assess_comprehensive_quality(test_generated, test_reference, 0.1)
    
    print(f"📊 Quality Metrics:")
    print(f"   BLEU: {metrics.bleu_score:.3f}")
    print(f"   ROUGE-L: {metrics.rouge_l:.3f}")
    print(f"   Coherence: {metrics.coherence_score:.3f}")
    print(f"   Fluency: {metrics.fluency_score:.3f}")
    print(f"   Overall: {metrics.overall_quality:.3f}")
    print(f"   Production Ready: {metrics.production_readiness:.3f}")
    
    print("✅ Quality Optimization System - READY!")