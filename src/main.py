import numpy as np
import pandas as pd
from typing import List, Dict, Optional
from dataclasses import dataclass, field, replace
from enum import Enum
from pathlib import Path
import json
import re
from catboost import CatBoostClassifier
import matplotlib
matplotlib.use("Agg")
import matplotlib.pyplot as plt
from collections import deque

try:
    from .spsa_variants import call_variant, reset_state as _reset_spsa_state, VARIANT_DESCRIPTIONS
except ImportError:
    from spsa_variants import call_variant, reset_state as _reset_spsa_state, VARIANT_DESCRIPTIONS

# =============================================================================
# 1. РЕАЛЬНЫЕ ПРОФИЛИ АГЕНТОВ (из бенчмарков 2025-2026)
# =============================================================================

class TaskType(Enum):
    PROGRAMMING = 0    # HumanEval: DeepSeek=88%, Llama3=65%
    QA = 1             # MMLU: Qwen2.5=88%, Mistral=78%  
    SUMMARIZATION = 2  # ROUGE-L: Qwen=82%, Llama3=78%
    TRANSLATION = 3    # COMET: Qwen=90%, Mistral=72%
    TOOL_USE = 4       # MTU-Bench: Qwen-Tool=92%, Llama3=62%

@dataclass
class Task:
    id: int
    type: TaskType
    t_arrival: float
    h_Ti: float           # Сложность ∈[1,10]
    phi_i: np.ndarray     # Признаки ∈R⁵
    urgency: float        # ∈[0,1]
    text: str = ""


@dataclass
class SubTask:
    parent_id: int
    local_id: int
    type: TaskType
    h_Ti: float
    phi_i: np.ndarray
    urgency: float
    text: str = ""

@dataclass 
class AgentProfile:
    id: int
    name: str
    model_name: str  # Имя модели для API
    P_success: np.ndarray  # Истинные успехи [5 типов] из бенчмарков
    tau_avg: np.ndarray    # Ср. время по типам
    psi_k: np.ndarray      # Признаки агента ∈R⁵

# Точные профили из реальных бенчмарков (нормализованы)
PROFILES = [
    AgentProfile(0, "Llama3-8B-Instruct", "llama3-8b-instruct",
                np.array([0.65, 0.82, 0.78, 0.75, 0.62]),  # HumanEval,MMLU,ROUGE,COMET,MTU
                np.array([2.5, 1.8, 2.2, 1.5, 3.0]), 
                np.array([0.8,0.9,0.7,0.6,0.5])),
    AgentProfile(1, "DeepSeek-Coder-V2", "deepseek-coder-v2",
                np.array([0.88, 0.65, 0.55, 0.50, 0.45]), 
                np.array([1.2, 2.8, 3.5, 4.0, 4.5]), 
                np.array([0.9,0.4,0.3,0.2,0.1])),
    AgentProfile(2, "Qwen2.5-72B-Instruct", "qwen2.5-72b-instruct",
                np.array([0.75, 0.88, 0.82, 0.90, 0.78]), 
                np.array([2.0, 1.5, 1.8, 1.2, 2.2]), 
                np.array([0.7,0.9,0.8,0.95,0.8])),
    AgentProfile(3, "Mistral-7B-Instruct", "mistral-7b-instruct",
                np.array([0.70, 0.78, 0.75, 0.72, 0.68]), 
                np.array([1.8, 2.0, 2.1, 1.7, 2.5]), 
                np.array([0.75,0.85,0.8,0.7,0.75])),
    AgentProfile(4, "Qwen2.5-ToolUse", "qwen2.5-tooluse",
                np.array([0.55, 0.60, 0.65, 0.58, 0.92]),
                np.array([3.5, 3.0, 2.8, 3.2, 1.5]),
                np.array([0.3,0.4,0.5,0.4,0.95])),
    AgentProfile(5, "Mixtral-8x7B-Instruct", "mixtral-8x7b-instruct",
                np.array([0.80, 0.84, 0.79, 0.83, 0.72]),
                np.array([1.6, 1.9, 2.0, 1.4, 2.6]),
                np.array([0.82,0.88,0.80,0.78,0.65])),
    AgentProfile(6, "CodeLlama-34B-Instruct", "codellama-34b-instruct",
                np.array([0.91, 0.58, 0.50, 0.45, 0.40]),
                np.array([2.8, 4.2, 4.8, 5.0, 5.2]),
                np.array([0.93,0.38,0.28,0.18,0.12])),
    AgentProfile(7, "Phi-3-Mini-Instruct", "phi-3-mini-instruct",
                np.array([0.58, 0.70, 0.68, 0.64, 0.55]),
                np.array([0.9, 1.1, 1.0, 0.8, 1.3]),
                np.array([0.60,0.75,0.72,0.68,0.50])),
]

MODEL_TOKEN_PRICE = {
    "llama3-8b-instruct":     0.20,
    "deepseek-coder-v2":      0.28,
    "qwen2.5-72b-instruct":   0.85,
    "mistral-7b-instruct":    0.22,
    "qwen2.5-tooluse":        0.90,
    "mixtral-8x7b-instruct":  0.45,
    "codellama-34b-instruct": 0.35,
    "phi-3-mini-instruct":    0.10,
}

# =============================================================================
# 2. АДАПТИВНЫЕ КОНТРОЛЛЕРЫ (ТОЧНЫЙ RLS + SPSA-CONSENSUS)
# =============================================================================

@dataclass
class ControllerObservation:
    task_type: int
    true_time: float
    true_wait: float
    features: np.ndarray


@dataclass
class SimulationVariant:
    name: str = "current"
    routing_mode: str = "adaptive"
    controller_mode: str = "load_balancing"
    use_spsa: bool = True
    use_learning: bool = True
    use_judge: bool = True
    cost_weight: float = 0.12
    spsa_interval: int = 5
    spsa_warmup_tasks: int = 15
    pressure_threshold: float = 0.62
    coordination_top_k: int = 2
    controller_service_scale: float = 1.0
    spsa_variant: str = "spsa"      # spsa | aspsa | kw | zo_pgd | sp_gt | zo_gt | pd_2pt | pd_1pt
    spsa_alpha: float = 0.01        # scale a in α_t = a/(t+1+A)^0.602
    spsa_beta:  float = 0.1         # scale b in β_t = b/(t+1)^0.101
    spsa_beta_nes_max: float = 1.0  # cap on Nesterov β_nes for aspsa variants


ROUTING_FEATURE_NAMES = (
    "relevance",
    "availability",
    "predicted_quality",
    "time_score",
    "queue_score",
    "cost_score",
    "rep_score",
    "urgency_score",
)


def _default_routing_weights(cost_weight: float=0.12) -> np.ndarray:
    weights = np.array([0.17, 0.10, 0.13, 0.20, 0.15, max(0.0, cost_weight), 0.06, 0.19], dtype=float)
    total = float(np.sum(weights))
    if total <= 0.0:
        weights = np.ones(len(ROUTING_FEATURE_NAMES), dtype=float)
        total = float(np.sum(weights))
    return weights / total


def _normalize_routing_weights(weights: np.ndarray, cost_enabled: bool=True) -> np.ndarray:
    normalized = np.clip(np.array(weights, dtype=float), 0.0, None)
    if not cost_enabled:
        normalized[5] = 0.0
    total = float(np.sum(normalized))
    if total <= 1e-8:
        return _default_routing_weights(0.12 if cost_enabled else 0.0)
    return normalized / total


def _pressure_routing_weights(cost_weight: float=0.0) -> np.ndarray:
    weights = np.array([0.05, 0.08, 0.07, 0.28, 0.20, max(0.0, min(cost_weight, 0.02)), 0.08, 0.24], dtype=float)
    total = float(np.sum(weights))
    return weights / max(total, 1e-8)


def _task_feature_vector(task_type: int, features: np.ndarray, num_types: int=5) -> np.ndarray:
    x = np.zeros(num_types)
    x[task_type] = 1.0
    x[min(num_types - 1, 4)] = np.mean(features)
    return x


def _spsa_proc_loss(theta: np.ndarray, obs: deque, eps0: float=0.05) -> float:
    """Raw MSE for F1 — identical to spsa_variants._proc_loss so all methods
    optimise the same objective."""
    if len(obs) == 0:
        return 0.0
    losses = []
    for o in list(obs)[-25:]:
        x = _task_feature_vector(o.task_type, o.features, len(theta))
        pred = float(theta @ x)
        losses.append((pred - o.true_time) ** 2)
    return float(np.mean(losses))


def _spsa_wait_loss(theta: np.ndarray, obs: deque, delta: float=0.1) -> float:
    """One-sided hinge: penalize underprediction only (conservative upper bound)."""
    if len(obs) == 0:
        return 0.0
    losses = []
    for o in list(obs)[-25:]:
        x = _task_feature_vector(o.task_type, o.features, len(theta))
        pred = float(theta @ x)
        slack = pred - o.true_wait - delta
        losses.append(max(0.0, -slack) ** 2)
    return float(np.mean(losses))

def _quality_feature_vector(task_type: int, phi_i: np.ndarray, psi_k: np.ndarray, p_hat: float, w_hat: float) -> np.ndarray:
    """Признаки для предсказания Q: тип, семантика задачи, профиль агента, контекст RLS."""
    x = np.zeros(9)
    x[task_type] = 1.0
    x[5] = float(np.mean(phi_i))
    x[6] = float(np.mean(psi_k))
    x[7] = float(np.clip(p_hat / 10.0, 0.0, 1.0))
    x[8] = float(np.clip(w_hat / 5.0, 0.0, 1.0))
    return x


class AdaptiveController:
    def __init__(self, id: int, num_types: int=5, lambda_forget: float=0.99):
        self.id = id
        self.num_types = num_types
        
        # RLS для времени выполнения J₁(θ)
        self.theta_time = np.ones(num_types) * 2.0
        self.P_time = 100.0 * np.eye(num_types)
        
        # RLS для допустимого ожидания J₂(θ)
        self.theta_wait = np.ones(num_types) * 1.5  
        self.P_wait = 100.0 * np.eye(num_types)

        # RLS для предсказания качества исхода Q̂ ∈ [0,1] по семантике и паре (задача, агент)
        self.theta_quality = np.ones(9) * 0.5
        self.P_quality = 100.0 * np.eye(9)
        # Локальный рейтинг моделей (agent_id, task_type) от данного контроллера.
        self.agent_rating: Dict[tuple, float] = {}
        
        self.lambda_forget = lambda_forget
        self.obs_history = deque(maxlen=50)  # Последние 50 наблюдений
        self.meta_history = deque(maxlen=120)
        
        # Очередь задач для load balancing
        self.task_queue: List[Task] = []
        self.routing_weights = _default_routing_weights()
        self.time_bias = 0.0
        self.wait_bias = 0.0
        self.quality_bias = 0.0
        self.time_conf = 0.5
        self.wait_conf = 0.5
        self.quality_conf = 0.5
        
    def predict_time(self, task_type: int, features: np.ndarray) -> float:
        """p̂(θ,x) = θᵀx (one-hot + признаки)"""
        x = np.zeros(self.num_types); x[task_type] = 1.0
        x[4] = np.mean(features)  # Простая агрегация признаков
        return np.clip(np.dot(self.theta_time, x), 0.5, 10.0)
    
    def predict_wait(self, task_type: int, features: np.ndarray) -> float:
        x = np.zeros(self.num_types); x[task_type] = 1.0
        x[4] = np.mean(features)
        return np.clip(np.dot(self.theta_wait, x), 0.3, 5.0)
    
    def rls_update(self, task_type: int, true_time: float, true_wait: float, features: np.ndarray):
        """ТОЧНАЯ RLS формула со забыванием"""
        x = np.zeros(self.num_types); x[task_type] = 1.0; x[4] = np.mean(features)
        
        # Обновление θ_time (J₁)
        denom = self.lambda_forget + x @ self.P_time @ x
        K = (self.P_time @ x) / denom
        error = true_time - self.theta_time @ x
        self.theta_time += K * error
        self.P_time = (self.P_time - np.outer(K, x.T @ self.P_time)) / self.lambda_forget
        
        # Обновление θ_wait (J₂)  
        denom_wait = self.lambda_forget + x @ self.P_wait @ x
        K_wait = (self.P_wait @ x) / denom_wait
        error_wait = true_wait - self.theta_wait @ x
        self.theta_wait += K_wait * error_wait
        self.P_wait = (self.P_wait - np.outer(K_wait, x.T @ self.P_wait)) / self.lambda_forget
        
        self.obs_history.append(ControllerObservation(task_type, true_time, true_wait, features))

    def predict_quality(self, task_type: int, phi_i: np.ndarray, psi_k: np.ndarray, p_hat: float, w_hat: float) -> float:
        """Q̂ = clip(θ_Q^T z, 0, 1) — ожидаемое качество назначения до вызова судьи."""
        z = _quality_feature_vector(task_type, phi_i, psi_k, p_hat, w_hat)
        return float(np.clip(np.dot(self.theta_quality, z), 0.0, 1.0))

    def rls_quality_update(
        self, task_type: int, phi_i: np.ndarray, psi_k: np.ndarray, p_hat: float, w_hat: float, true_Q: float
    ):
        """Онлайн-обновление весов по фактическому Q от судьи (RLS с забыванием)."""
        z = _quality_feature_vector(task_type, phi_i, psi_k, p_hat, w_hat)
        denom = self.lambda_forget + z @ self.P_quality @ z
        K = (self.P_quality @ z) / denom
        err = true_Q - np.dot(self.theta_quality, z)
        self.theta_quality += K * err
        self.P_quality = (self.P_quality - np.outer(K, z.T @ self.P_quality)) / self.lambda_forget

    def get_agent_rating(self, agent_id: int, task_type: int, prior: float) -> float:
        return float(self.agent_rating.get((agent_id, task_type), prior))

    def update_agent_rating(self, agent_id: int, task_type: int, judge_quality: float, confidence: float):
        key = (agent_id, task_type)
        prev = self.agent_rating.get(key, 0.5)
        # Уверенность судьи регулирует скорость адаптации.
        alpha = 0.1 + 0.4 * float(np.clip(confidence, 0.0, 1.0))
        self.agent_rating[key] = float(np.clip((1.0 - alpha) * prev + alpha * judge_quality, 0.0, 1.0))

def spsa_consensus(
    controllers: List[AdaptiveController],
    step: int,
    alpha: float=0.01,
    beta: float=0.1,
    gamma: float=0.02,
):
    """Paper-faithful SPSA + consensus for theta_time/theta_wait."""
    if len(controllers) == 0:
        return
    B_t = communication_graph(step, len(controllers))
    alpha_t = alpha / (step + 1 + 10) ** 0.602
    pert    = beta  / (step + 1) ** 0.101
    new_theta_time = []
    new_theta_wait = []

    for j, ctrl in enumerate(controllers):
        if len(ctrl.obs_history) < 10:
            new_theta_time.append(ctrl.theta_time.copy())
            new_theta_wait.append(ctrl.theta_wait.copy())
            continue

        dim = len(ctrl.theta_time)
        delta_time = 2 * np.random.randint(0, 2, dim) - 1
        delta_wait = 2 * np.random.randint(0, 2, dim) - 1

        y_time_plus = _spsa_proc_loss(ctrl.theta_time + pert * delta_time, ctrl.obs_history)
        y_time_minus = _spsa_proc_loss(ctrl.theta_time - pert * delta_time, ctrl.obs_history)
        grad_time = (y_time_plus - y_time_minus) / (2 * pert * delta_time)

        y_wait_plus = _spsa_wait_loss(ctrl.theta_wait + pert * delta_wait, ctrl.obs_history)
        y_wait_minus = _spsa_wait_loss(ctrl.theta_wait - pert * delta_wait, ctrl.obs_history)
        grad_wait = (y_wait_plus - y_wait_minus) / (2 * pert * delta_wait)

        consensus_time = np.zeros(dim)
        consensus_wait = np.zeros(dim)
        neighbors = np.where(B_t[j] > 0)[0]
        for jp in neighbors:
            consensus_time += B_t[j, jp] * (ctrl.theta_time - controllers[jp].theta_time)
            consensus_wait += B_t[j, jp] * (ctrl.theta_wait - controllers[jp].theta_wait)

        new_theta_time.append(ctrl.theta_time - alpha_t * (grad_time + gamma * consensus_time))
        new_theta_wait.append(ctrl.theta_wait - alpha_t * (grad_wait + gamma * consensus_wait))

    for ctrl, theta_time_next, theta_wait_next in zip(controllers, new_theta_time, new_theta_wait):
        ctrl.theta_time = np.clip(theta_time_next, 0.3, 15.0)
        ctrl.theta_wait = np.clip(theta_wait_next, 0.1, 8.0)

def mse(theta: np.ndarray, obs: deque, target_idx: int) -> float:
    """Loss functions as optimized: F₁ raw MSE (time), F₂ one-sided hinge (wait)."""
    if target_idx == 0:
        # raw MSE — same as spsa_variants._proc_loss used by A-SPSA
        if len(obs) == 0:
            return 0.0
        errs = []
        for o in list(obs)[-25:]:
            x = _task_feature_vector(o.task_type, o.features, len(theta))
            errs.append((float(theta @ x) - o.true_time) ** 2)
        return float(np.mean(errs))
    else:
        return _spsa_wait_loss(theta, obs)

# =============================================================================
# 3. LOAD BALANCING (ТОЧНЫЕ ФОРМУЛЫ ИЗ СТАТЬИ)
# =============================================================================

@dataclass
class ControllerState:
    q_jt: float           # Взвешенная очередь Σ(1+γ₀·urgency)
    p_j: float            # Продуктивность контроллера
    z_jt: float           # Новые задачи за Δt
    q_jt_next: float = 0.0

def communication_graph(t: int, num_ctrl: int) -> np.ndarray:
    """Временной граф G_t=(C,E_t) с рандомизированными связями"""
    B = np.zeros((num_ctrl, num_ctrl))
    if num_ctrl <= 1:
        return B
    for i in range(num_ctrl):
        max_deg = max(1, num_ctrl - 1)
        deg = min(np.random.poisson(1.5) + 1, max_deg)
        candidates = np.array([x for x in range(num_ctrl) if x != i], dtype=int)
        neighbors = np.random.choice(candidates, deg, replace=False)
        for j in neighbors[:2]:  # Макс. 2 соседа
            B[i,j] = 0.5
            B[j,i] = B[i,j]
    return B

def exact_load_balancing(states: List[ControllerState], B_t: np.ndarray) -> np.ndarray:
    """ТОЧНАЯ формула LVP-протокола (стр. 8 статьи)"""
    m = len(states)
    u = np.zeros(m)
    
    for j in range(m):
        N_jt = np.where(B_t[j] > 0)[0]  # Соседи j в момент t
        if len(N_jt) > 0:
            y_jj_prime = np.array([states[k].q_jt/states[k].p_j for k in N_jt])
            y_prime_j = np.full(len(N_jt), states[j].q_jt/states[j].p_j)
            diffs = B_t[j,N_jt] * (y_jj_prime - y_prime_j)
            u[j] = 0.1 * np.sum(diffs)  # Градиентный шаг
    
    # Коррекция состояний: xⱼ^{uⱼ}(t+1)
    for j, state in enumerate(states):
        state.q_jt_next = (state.q_jt + state.z_jt - u[j]) / state.p_j
    return u

# =============================================================================
# 4. АГЕНТЫ (Equation 1 ТОЧНО)
# =============================================================================

@dataclass
class AgentState:
    id: int
    features: np.ndarray     # ψ_k ∈ R⁵
    queue: List[Task] 
    queue_start_times: List[float] = field(default_factory=list)
    queue_finish_times: List[float] = field(default_factory=list)
    queue_pred_times: List[float] = field(default_factory=list)
    current_task: Task = None
    t_start_i: float = 0.0
    p_hat_i: float = 0.0     # Предсказанное время
    v_i: float = 0.0         # Предсказанное завершение
    gamma_j: float = 1.0     # Коэффициент доверия контроллера
    available_at: float = 0.0

def t_free_k(agent: AgentState, time: float, profile: AgentProfile) -> float:
    """Eq.(1)-style оценка времени до освобождения агента.

    В статье формула задает оценку release-time через:
    - сумму предсказанных времен задач в очереди (кроме текущей),
    - базовую оценку текущей задачи через trust (gamma_j),
    - corrective term при перерасходе текущей задачи относительно v_i.

    Здесь возвращается именно remaining wait (>=0), а не абсолютный timestamp,
    чтобы корректно использовать значение в ранжировании агентов.
    """
    queue = agent.queue or []
    if len(queue) == 0:
        return max(0.0, agent.available_at - time)

    # Индекс текущей задачи (если известна), иначе считаем первой в очереди.
    active_idx = 0
    if agent.current_task is not None:
        for idx, queued_task in enumerate(queue):
            if queued_task.id == agent.current_task.id:
                active_idx = idx
                break

    pred_times = agent.queue_pred_times or []
    pending_sum = 0.0
    for idx, pred in enumerate(pred_times):
        if idx != active_idx:
            pending_sum += float(max(0.0, pred))

    rho = float(np.clip(agent.gamma_j, 0.0, 1.0))
    current_pred = float(max(0.0, agent.p_hat_i))
    overrun_correction = (1.0 - rho) * max(0.0, float(time) - float(agent.v_i))

    # Eq.(1)-style absolute release estimate.
    release_estimate = pending_sum + float(agent.t_start_i) + rho * current_pred + overrun_correction

    # Возвращаем задержку до освобождения.
    return float(max(0.0, release_estimate - float(time)))



class TaskTypeClassifier:
    KEYWORDS = {
        TaskType.PROGRAMMING: ("code", "python", "java", "debug", "algorithm"),
        TaskType.QA: ("question", "answer", "qa", "fact", "explain"),
        TaskType.SUMMARIZATION: ("summary", "summarize", "tl;dr", "digest"),
        TaskType.TRANSLATION: ("translate", "translation", "from", "to"),
        TaskType.TOOL_USE: ("tool", "function call", "api", "execute"),
    }

    def __init__(self, random_seed: int = 42):
        """Initialize classifier with given seed for reproducibility across different simulation runs.
        
        Args:
            random_seed: RNG seed for CatBoost model and dataset generation. Using different seeds
                        for different simulation instances ensures independence and prevents artificial
                        correlation across evaluation runs (fixes data leakage issue).
        """
        self.random_seed = random_seed
        self.model = CatBoostClassifier(
            iterations=80,
            depth=4,
            learning_rate=0.15,
            loss_function="MultiClass",
            verbose=False,
            random_seed=random_seed,
        )
        train_x, train_y = self._build_bootstrap_dataset()
        self.model.fit(train_x, train_y)

    def _build_bootstrap_dataset(self):
        rng_state = np.random.get_state()
        np.random.seed(self.random_seed)
        samples = []
        labels = []
        base = {
            TaskType.PROGRAMMING: np.array([0.9, 0.3, 0.2, 0.2, 0.2]),
            TaskType.QA: np.array([0.35, 0.9, 0.5, 0.35, 0.3]),
            TaskType.SUMMARIZATION: np.array([0.25, 0.45, 0.9, 0.35, 0.25]),
            TaskType.TRANSLATION: np.array([0.2, 0.35, 0.4, 0.92, 0.2]),
            TaskType.TOOL_USE: np.array([0.25, 0.3, 0.35, 0.3, 0.95]),
        }
        for ttype, center in base.items():
            for _ in range(60):
                v = np.clip(center + np.random.normal(0, 0.08, size=5), 0.0, 1.0)
                samples.append(v.tolist())
                labels.append(ttype.value)
        np.random.set_state(rng_state)
        return samples, labels

    def predict(self, task: Task) -> TaskType:
        semantic_phi = SemanticFeatureExtractor.extract(task.text, task.phi_i)
        pred = int(self.model.predict([semantic_phi.tolist()])[0][0])
        return TaskType(pred)

    def predict_from_text(self, text: str):
        if text is None:
            return None
        semantic_phi = SemanticFeatureExtractor.extract(text, None)
        pred = int(self.model.predict([semantic_phi.tolist()])[0][0])
        return TaskType(pred)


class SemanticFeatureExtractor:
    AXES = {
        0: ("code", "python", "model", "train", "pipeline", "feature"),
        1: ("question", "answer", "fact", "why", "explain", "what"),
        2: ("summary", "summarize", "brief", "digest", "short"),
        3: ("translate", "translation", "english", "russian", "multilingual"),
        4: ("api", "tool", "function", "call", "crm", "sql"),
    }

    @staticmethod
    def extract(text: str, fallback_phi: np.ndarray = None) -> np.ndarray:
        txt = (text or "").lower()
        counts = np.zeros(5, dtype=float)
        for idx, kws in SemanticFeatureExtractor.AXES.items():
            for kw in kws:
                if kw in txt:
                    counts[idx] += 1.0
        if np.sum(counts) > 0:
            counts = counts / np.sum(counts)
            return counts
        if fallback_phi is not None:
            return fallback_phi
        return np.ones(5) / 5.0


class JudgeFallback:
    """Судья: численная обратная связь Q ∈ [0,1] для калибровки предиктора контроллера."""

    ALPHA_Q = 0.6
    BETA_Q = 0.4
    SUCCESS_THRESHOLD = 0.56

    def __init__(
        self,
        profiles: List[AgentProfile],
        llm_api_client=None,
        judge_model_name: str="qwen2.5-72b-instruct",
        adaptive_feedback: bool=True,
    ):
        self.profiles = profiles
        self.llm_api_client = llm_api_client
        self.judge_model_name = judge_model_name
        self.adaptive_feedback = adaptive_feedback
        self.alpha = np.ones((len(profiles), 5))
        self.beta = np.ones((len(profiles), 5))
        self.dynamic_success = np.array([p.P_success.copy() for p in profiles], dtype=float)

    def _parse_judge_output(self, output) -> Dict[str, float]:
        if isinstance(output, dict):
            quality = float(output.get("quality_score", output.get("quality", output.get("Q", 0.0))))
            conf = float(output.get("confidence", 0.5))
            sem = float(output.get("semantic_score", quality))
            cor = float(output.get("correctness_score", quality))
            ins = float(output.get("instruction_score", quality))
            saf = float(output.get("safety_score", 1.0))
            verdict = str(output.get("verdict", "pass" if quality >= 0.6 else "fail")).lower()
            return {
                "quality_score": float(np.clip(quality, 0.0, 1.0)),
                "semantic_score": float(np.clip(sem, 0.0, 1.0)),
                "correctness_score": float(np.clip(cor, 0.0, 1.0)),
                "instruction_score": float(np.clip(ins, 0.0, 1.0)),
                "safety_score": float(np.clip(saf, 0.0, 1.0)),
                "confidence": float(np.clip(conf, 0.0, 1.0)),
                "verdict": "pass" if verdict == "pass" else "fail",
                "short_reason": str(output.get("short_reason", ""))
            }
        txt = str(output or "").strip()
        if not txt:
            return {
                "quality_score": 0.0,
                "semantic_score": 0.0,
                "correctness_score": 0.0,
                "instruction_score": 0.0,
                "safety_score": 0.0,
                "confidence": 0.0,
                "verdict": "fail",
                "short_reason": "empty judge output",
            }
        # Пытаемся найти JSON в тексте.
        try:
            start = txt.find("{")
            end = txt.rfind("}")
            if start != -1 and end != -1 and end > start:
                obj = json.loads(txt[start:end + 1])
                return self._parse_judge_output(obj)
        except Exception:
            pass
        # Fallback: первое число 0..1 в ответе.
        m = re.search(r"(0(?:\.\d+)?|1(?:\.0+)?)", txt)
        q = float(m.group(1)) if m else 0.0
        return {
            "quality_score": float(np.clip(q, 0.0, 1.0)),
            "semantic_score": float(np.clip(q, 0.0, 1.0)),
            "correctness_score": float(np.clip(q, 0.0, 1.0)),
            "instruction_score": float(np.clip(q, 0.0, 1.0)),
            "safety_score": 1.0,
            "confidence": 0.4,
            "verdict": "pass" if q >= 0.6 else "fail",
            "short_reason": "parsed numeric fallback",
        }

    def _evaluate_with_llm_judge(
        self, agent_id: int, subtask: SubTask, latency: float, base_success: float, model_output: str
    ) -> Dict[str, float]:
        if self.llm_api_client is None:
            raise RuntimeError("LLM judge client is not configured")
        prompt = (
            "You are an LLM judge. Evaluate quality of MODEL OUTPUT for the given SUBTASK.\n"
            "Return ONLY valid JSON with this exact schema:\n"
            "{"
            "\"quality_score\": float 0..1,"
            "\"semantic_score\": float 0..1,"
            "\"correctness_score\": float 0..1,"
            "\"instruction_score\": float 0..1,"
            "\"safety_score\": float 0..1,"
            "\"confidence\": float 0..1,"
            "\"verdict\": \"pass\" or \"fail\","
            "\"short_reason\": string"
            "}\n"
            f"Task type: {subtask.type.name}\n"
            f"Task text: {subtask.text}\n"
            f"Task complexity: {subtask.h_Ti:.4f}\n"
            f"Task urgency: {subtask.urgency:.4f}\n"
            f"Semantic features: {subtask.phi_i.tolist()}\n"
            f"Agent profile id: {agent_id}\n"
            f"Model output: {model_output}\n"
            f"Observed latency: {latency:.4f}\n"
            f"Base success signal: {base_success:.4f}\n"
        )
        api_result = self.llm_api_client.call(self.judge_model_name, prompt, "JUDGE")
        return self._parse_judge_output(api_result.get("output"))

    def evaluate(
        self,
        agent_id: int,
        subtask: SubTask,
        base_success: float,
        latency: float,
        model_output: str="",
        synthetic_quality: Optional[Dict[str, float]]=None,
    ) -> Dict[str, float]:
        t_idx = subtask.type.value
        expected_time = self.profiles[agent_id].tau_avg[t_idx] * (1.0 + subtask.h_Ti / 10.0)
        T_i = float(np.exp(-max(0.0, latency - expected_time) / max(expected_time, 1e-6)))

        if synthetic_quality is not None:
            quality_payload = synthetic_quality
            semantic_q = float(np.clip(quality_payload["quality_score"], 0.0, 1.0))
            correctness_q = float(np.clip(quality_payload.get("correctness_score", semantic_q), 0.0, 1.0))
            instruction_q = float(np.clip(quality_payload.get("instruction_score", semantic_q), 0.0, 1.0))
            safety_q = float(np.clip(quality_payload.get("safety_score", 1.0), 0.0, 1.0))
            conf = float(np.clip(quality_payload.get("confidence", 0.5), 0.0, 1.0))
            S_i = 1.0 if quality_payload.get("verdict", "fail") == "pass" else 0.0
            content_q = 0.45 * correctness_q + 0.25 * semantic_q + 0.20 * instruction_q + 0.10 * safety_q
            Q = float(np.clip(0.76 * content_q + 0.24 * T_i, 0.0, 1.0))
        else:
            # Пытаемся получить Q от отдельной модели-судьи.
            try:
                judge_llm = self._evaluate_with_llm_judge(agent_id, subtask, latency, base_success, model_output)
                semantic_q = float(np.clip(judge_llm["quality_score"], 0.0, 1.0))
                S_i = 1.0 if judge_llm["verdict"] == "pass" else 0.0
                conf = float(np.clip(judge_llm["confidence"], 0.0, 1.0))
                # Гибрид: качество ответа от judge + своевременность из telemetry.
                Q = 0.75 * semantic_q + 0.25 * T_i
            except Exception:
                # Fallback-режим: эвристический судья.
                S_i = float(np.clip(base_success, 0.0, 1.0))
                conf = 0.4
                Q = self.ALPHA_Q * S_i + self.BETA_Q * T_i

        verdict_score = float(np.clip(0.70 * Q + 0.20 * S_i + 0.10 * T_i, 0.0, 1.0))
        verdict = 1.0 if verdict_score >= self.SUCCESS_THRESHOLD else 0.0
        if self.adaptive_feedback:
            soft_feedback = float(np.clip(0.65 * verdict_score + 0.25 * S_i + 0.10 * base_success, 0.0, 1.0))
            self.alpha[agent_id, t_idx] += soft_feedback
            self.beta[agent_id, t_idx] += 1.0 - soft_feedback
            posterior = self.alpha[agent_id, t_idx] / (self.alpha[agent_id, t_idx] + self.beta[agent_id, t_idx])
            profile_prior = float(self.profiles[agent_id].P_success[t_idx])
            stabilized = float(np.clip(0.55 * posterior + 0.45 * profile_prior, 0.05, 0.98))
            self.dynamic_success[agent_id, t_idx] = 0.90 * self.dynamic_success[agent_id, t_idx] + 0.10 * stabilized
        return {
            "Q": Q,
            "S": S_i,
            "T": T_i,
            "confidence": conf,
            "success": verdict,
            "verdict_score": verdict_score,
            "quality": Q,
        }

# =============================================================================
# 5. ОСНОВНАЯ ЛОГИКА КОНТРОЛЛЕРА (R + A)
# =============================================================================

def rank_agents(
    controller: AdaptiveController,
    task: Task,
    agents: List[AgentState],
    time: float,
    dynamic_success: np.ndarray,
    predicted_time: float,
    predicted_wait: float,
    top_k: int=3,
    variant: Optional[SimulationVariant]=None,
) -> List[Dict[str, float]]:
    """R_{j,i} + A_{j,i} кластеринг (стр. 6-7 статьи)"""
    variant = variant or SimulationVariant()
    scores = []
    D_i = time + predicted_wait
    service_deadline = D_i + predicted_time
    task_tokens = max(16, int(len(task.text) / 4)) if task.text else int(80 + 30 * task.h_Ti)
    mean_latency_for_type = float(np.mean([PROFILES[a.id].tau_avg[task.type.value] for a in agents])) if agents else 1.0
    service_budget = max(predicted_time + predicted_wait, 0.75)
    busy_fraction = float(np.mean([1.0 if agent.available_at > time else 0.0 for agent in agents])) if agents else 0.0
    queue_pressure = float(np.mean([max(0.0, agent.available_at - time) for agent in agents])) if agents else 0.0
    queue_pressure /= max(service_budget + 0.5, 0.5)
    system_pressure = float(np.clip(
        0.45 * busy_fraction
        + 0.35 * min(queue_pressure, 1.5) / 1.5
        + 0.20 * task.urgency,
        0.0,
        1.0,
    ))
    pressure_blend = 0.0
    if variant.routing_mode == "adaptive":
        threshold = float(np.clip(variant.pressure_threshold, 0.1, 0.95))
        pressure_blend = float(np.clip((system_pressure - threshold) / max(1e-6, 1.0 - threshold), 0.0, 1.0))
    
    for agent in agents:
        profile = PROFILES[agent.id]
        
        # R_{j,i} = совместимость φ_i, ψ_k (косинус)
        R_ji = np.dot(task.phi_i, agent.features) / (
            np.linalg.norm(task.phi_i) * np.linalg.norm(agent.features) + 1e-8)
        
        # A_{j,i} = P(finish до D_i)
        t_free = t_free_k(agent, time, profile)
        A_ji = float(np.exp(-max(0.0, t_free) / max(predicted_wait + 0.5, 0.5)))

        # Теоретическое время ответа якорим на p_hat, чтобы улучшение прогноза влияло на выбор агента.
        base_latency = profile.tau_avg[task.type.value]
        relative_speed = float(base_latency / max(mean_latency_for_type, 0.1))
        context_multiplier = 1.0 + 0.09 * np.log1p(task_tokens / 80.0)
        semantic_multiplier = 1.0 + 0.12 * max(0.0, 0.7 - R_ji)
        complexity_multiplier = 1.0 + 0.10 * max(0.0, task.h_Ti - 3.0)
        anchored_time = predicted_time * relative_speed
        profile_time = base_latency * context_multiplier * semantic_multiplier
        theor_time = 0.72 * anchored_time + 0.28 * profile_time
        theor_time *= complexity_multiplier
        theor_time = max(0.05, theor_time)
        predicted_wait_agent = max(0.0, t_free)
        predicted_finish = time + predicted_wait_agent + theor_time
        finish_ratio = (predicted_wait_agent + theor_time) / service_budget
        deadline_gap = max(0.0, predicted_finish - service_deadline) / service_budget
        time_score = float(np.exp(-theor_time / max(predicted_time + 0.5, 0.5)))
        queue_score = float(np.exp(-predicted_wait_agent / max(predicted_wait + 0.5, 0.5)))

        price_per_1k = MODEL_TOKEN_PRICE.get(profile.model_name, 0.5)
        task_price = price_per_1k * (task_tokens / 1000.0)
        cost_score = np.exp(-task_price / 0.3)

        # Репутация агента по типу задачи на основе обратной связи судьи.
        global_rep = float(dynamic_success[agent.id, task.type.value])
        local_rep = controller.get_agent_rating(agent.id, task.type.value, prior=global_rep)
        rep_score = 0.5 * global_rep + 0.5 * local_rep
        raw_q_hat = float(np.clip(
            controller.predict_quality(
                task.type.value,
                task.phi_i,
                profile.psi_k,
                theor_time,
                predicted_wait,
            ),
            0.0,
            1.0,
        ))
        q_hat = raw_q_hat
        urgency_score = float(
            np.exp(-(1.0 + 3.0 * task.urgency) * deadline_gap)
            * np.exp(-0.45 * task.urgency * max(0.0, finish_ratio - 1.0))
        )

        # Для срочных задач отсекаем слишком ненадежные модели.
        if variant.routing_mode == "adaptive" and task.urgency >= 0.75 and rep_score < 0.45:
            continue

        if variant.routing_mode == "random":
            score = float(np.random.random())
        elif variant.routing_mode == "least_queue":
            score = -float(t_free)
        elif variant.routing_mode == "best_quality_static":
            score = float(profile.P_success[task.type.value])
        elif variant.routing_mode == "cheapest_static":
            score = -float(task_price)
        elif variant.routing_mode == "fastest_static":
            score = -float(base_latency)
        else:
            routing_features = np.array([R_ji, A_ji, q_hat, time_score, queue_score, cost_score, rep_score, urgency_score], dtype=float)
            base_weights = _normalize_routing_weights(
                controller.routing_weights,
                cost_enabled=variant.cost_weight > 0.0,
            )
            if pressure_blend > 0.0:
                emergency_weights = _pressure_routing_weights(0.02 if variant.cost_weight > 0.0 else 0.0)
                adaptive_weights = (1.0 - pressure_blend) * base_weights + pressure_blend * emergency_weights
                adaptive_weights = _normalize_routing_weights(adaptive_weights, cost_enabled=variant.cost_weight > 0.0)
            else:
                adaptive_weights = base_weights
            throughput_score = float(np.exp(-(predicted_wait_agent + theor_time) / max(service_budget, 0.75)))
            score = float(np.dot(adaptive_weights, routing_features))
            score -= float((0.30 + 0.55 * task.urgency) * deadline_gap)
            score -= float(0.08 * max(0.0, finish_ratio - 1.0))
            score += float(pressure_blend * (0.18 * throughput_score + 0.10 * A_ji + 0.08 * rep_score))
            if pressure_blend >= 0.35:
                overload_penalty = (predicted_wait_agent + 0.65 * theor_time) / max(service_budget, 0.75)
                score -= float((0.16 + 0.24 * pressure_blend) * overload_penalty)
                score += float((0.14 + 0.18 * pressure_blend) * throughput_score)
                score += float(0.08 * pressure_blend * time_score)
        scores.append({
            "agent_id": agent.id,
            "score": float(score),
            "routing_features": np.array([R_ji, A_ji, q_hat, time_score, queue_score, cost_score, rep_score, urgency_score], dtype=float),
            "relevance": float(R_ji),
            "availability": float(A_ji),
            "raw_predicted_quality": float(raw_q_hat),
            "predicted_quality": float(q_hat),
            "time_score": float(time_score),
            "queue_score": float(queue_score),
            "cost_score": float(cost_score),
            "rep_score": float(rep_score),
            "urgency_score": float(urgency_score),
            "theor_time": float(theor_time),
            "task_price": float(task_price),
        })
    
    return sorted(scores, key=lambda x: x["score"], reverse=True)[:top_k]


def select_agents(
    controller: AdaptiveController,
    task: Task,
    agents: List[AgentState],
    time: float,
    dynamic_success: np.ndarray,
    predicted_time: float,
    predicted_wait: float,
    top_k: int=3,
    variant: Optional[SimulationVariant]=None,
) -> List[int]:
    return [
        candidate["agent_id"]
        for candidate in rank_agents(
            controller=controller,
            task=task,
            agents=agents,
            time=time,
            dynamic_success=dynamic_success,
            predicted_time=predicted_time,
            predicted_wait=predicted_wait,
            top_k=top_k,
            variant=variant,
        )
    ]

# =============================================================================
# 6. ПОЛНАЯ СИМУЛЯЦИЯ
# =============================================================================

class ExactOrchestrator:
    def __init__(
        self,
        num_ctrl: int=3,
        num_agents: int=5,
        llm_api_client=None,
        judge_model_name: str="qwen2.5-72b-instruct",
        variant: Optional[SimulationVariant]=None,
        plot_output_path: Optional[str]=None,
        classifier_seed: int = 42,
    ):
        self.variant = variant or SimulationVariant()
        self.controllers = [AdaptiveController(i) for i in range(num_ctrl)]
        self.routing_weight_anchor = _default_routing_weights(self.variant.cost_weight)
        for ctrl in self.controllers:
            ctrl.routing_weights = self.routing_weight_anchor.copy()
        self.agents = [AgentState(i, PROFILES[i].psi_k, []) for i in range(num_agents)]
        self.classifier = TaskTypeClassifier(random_seed=classifier_seed)
        self.judge = JudgeFallback(
            PROFILES,
            llm_api_client=llm_api_client if self.variant.use_judge else None,
            judge_model_name=judge_model_name,
            adaptive_feedback=self.variant.use_learning,
        )
        _reset_spsa_state()
        self.time = 0.0
        self.metrics = {
            'mse_time': [], 'mse_wait': [], 'queue_len': [], 
            'success_rate': [], 'judge_quality': [], 'assignments': 0,
            'type_cls_acc': [], 'benchmark_dynamic_mean': [],
            'Q_pred': [], 'Q_true': [], 'Q_mse': [],
            'latency': [], 'deadline_hits': [], 'costs': [], 'weighted_success': [],
            'routing_objective': [],
        }
        self.controller_Q_sums = {j: 0.0 for j in range(num_ctrl)}
        self.controller_Q_counts = {j: 0 for j in range(num_ctrl)}
        self.controller_Q_mse_sums = {j: 0.0 for j in range(num_ctrl)}
        self.controller_task_finish_times = {j: [] for j in range(num_ctrl)}
        self.controller_dispatch_tasks = {j: [] for j in range(num_ctrl)}
        self.controller_dispatch_finish_times = {j: [] for j in range(num_ctrl)}
        self.llm_api_client = llm_api_client
        self.task_records: List[Dict[str, float]] = []
        self.theta_records: List[Dict[str, float]] = []
        self.plot_output_path = plot_output_path

    def _estimate_task_tokens(self, task: Task) -> int:
        if task.text:
            return max(16, int(len(task.text) / 4))
        return int(80 + 30 * task.h_Ti)

    def _safe_mean(self, values: List[float]) -> float:
        return float(np.mean(values)) if values else 0.0

    def _safe_p95(self, values: List[float]) -> float:
        return float(np.percentile(values, 95)) if values else 0.0

    def _bounded_inverse(self, value: float, scale: float) -> float:
        return float(1.0 / (1.0 + max(0.0, value) / max(scale, 1e-6)))

    def _apply_controller_calibration(self, controller: AdaptiveController, raw_value: float, bias: float, confidence: float, low: float, high: float) -> float:
        return float(np.clip(raw_value + bias * confidence, low, high))

    def _cosine_similarity(self, x: np.ndarray, y: np.ndarray) -> float:
        denom = float(np.linalg.norm(x) * np.linalg.norm(y) + 1e-8)
        return float(np.clip(np.dot(x, y) / denom, 0.0, 1.0))

    def _compute_observed_utility(
        self,
        q_true: float,
        success: bool,
        deadline_hit: float,
        latency: float,
        true_wait: float,
        cost: float,
        semantic_match: float,
        urgency: float,
        predicted_wait: float,
        predicted_budget: float,
    ) -> float:
        normalized_budget = max(predicted_budget, 1.0)
        deadline_gap = max(0.0, latency - predicted_budget) / normalized_budget
        deadline_score = float(np.exp(-2.2 * deadline_gap))
        latency_score = float(np.exp(-0.9 * latency / normalized_budget))
        wait_pressure = true_wait / max(predicted_wait + 0.5, 0.5)
        wait_score = float(np.exp(-0.8 * wait_pressure))
        cost_score = self._bounded_inverse(cost, 10.0)
        urgency_resilience = float(np.exp(-urgency * deadline_gap * 2.5) * np.exp(-0.35 * urgency * max(0.0, wait_pressure - 1.0)))
        utility = (
            0.18 * float(q_true)
            + 0.18 * float(success)
            + 0.28 * deadline_score
            + 0.12 * latency_score
            + 0.10 * wait_score
            + 0.04 * cost_score
            + 0.02 * float(semantic_match)
            + 0.08 * urgency_resilience
        )
        return float(np.clip(utility, 0.0, 1.0))

    def _estimate_agent_service_time(self, task: Task | SubTask, predicted_time: float, agent: AgentState) -> float:
        task_tokens = self._estimate_task_tokens(Task(-1, task.type, self.time, task.h_Ti, task.phi_i, task.urgency, getattr(task, "text", "")))
        mean_latency_for_type = float(np.mean([PROFILES[a.id].tau_avg[task.type.value] for a in self.agents])) if self.agents else 1.0
        profile = PROFILES[agent.id]
        relevance = self._cosine_similarity(task.phi_i, agent.features)
        base_latency = float(profile.tau_avg[task.type.value])
        relative_speed = float(base_latency / max(mean_latency_for_type, 0.1))
        context_multiplier = 1.0 + 0.09 * np.log1p(task_tokens / 80.0)
        semantic_multiplier = 1.0 + 0.12 * max(0.0, 0.7 - relevance)
        complexity_multiplier = 1.0 + 0.10 * max(0.0, task.h_Ti - 3.0)
        anchored_time = predicted_time * relative_speed
        profile_time = base_latency * context_multiplier * semantic_multiplier
        theor_time = (0.72 * anchored_time + 0.28 * profile_time) * complexity_multiplier
        return float(max(0.05, theor_time))

    def _estimate_controller_service_time(self, task: Task | SubTask, controller: AdaptiveController) -> float:
        task_tokens = self._estimate_task_tokens(Task(-1, task.type, self.time, task.h_Ti, task.phi_i, task.urgency, getattr(task, "text", "")))
        coordination_cost = 1.0 + 0.03 * max(0, len(self.controllers) - 1)
        service_time = (
            0.035
            + 0.010 * float(task.h_Ti)
            + 0.008 * np.log1p(task_tokens / 90.0)
            + 0.008 * float(task.urgency)
        )
        service_time *= coordination_cost
        service_time *= float(self.variant.controller_service_scale)
        return float(max(0.02, service_time))

    def _controller_available_at(self, controller_id: int, current_time: float) -> float:
        finish_times = self.controller_dispatch_finish_times[controller_id]
        if not finish_times:
            return float(current_time)
        return float(max(current_time, finish_times[-1]))

    def _controller_recent_utility(self, controller: AdaptiveController) -> float:
        if not controller.meta_history:
            return 0.5
        recent = list(controller.meta_history)[-20:]
        weights = np.array([max(0.1, float(item["sample_weight"])) for item in recent], dtype=float)
        values = np.array([float(item["utility"]) for item in recent], dtype=float)
        return float(np.average(values, weights=weights))

    def _controller_reliability(self, controller: AdaptiveController) -> float:
        recent_utility = self._controller_recent_utility(controller)
        confidence = float(np.mean([controller.time_conf, controller.wait_conf, controller.quality_conf]))
        return float(np.clip(0.55 * recent_utility + 0.45 * confidence, 0.05, 1.0))

    def _controller_pressure_score(self, controller: AdaptiveController, predicted_budget: float) -> float:
        execution_queue = float(sum(1.0 + 0.5 * task.urgency for task in controller.task_queue))
        execution_backlog = float(sum(max(0.0, finish_time - self.time) for finish_time in self.controller_task_finish_times[controller.id]))
        dispatch_queue = float(len(self.controller_dispatch_tasks[controller.id]))
        dispatch_backlog = float(sum(max(0.0, finish_time - self.time) for finish_time in self.controller_dispatch_finish_times[controller.id]))
        weighted_queue = execution_queue + 1.35 * dispatch_queue
        backlog_time = execution_backlog + 1.35 * dispatch_backlog
        queue_term = min(weighted_queue / max(2.0 * len(self.agents), 1.0), 1.5) / 1.5
        time_term = min(backlog_time / max(predicted_budget * max(len(self.agents), 1), 1.0), 1.5) / 1.5
        return float(np.clip(0.45 * queue_term + 0.55 * time_term, 0.0, 1.0))

    def _build_coordination_snapshot(self, task: SubTask) -> Dict[str, object]:
        controller_entries = []
        sketch_candidates = []
        task_view = Task(task.parent_id, task.type, self.time, task.h_Ti, task.phi_i, task.urgency, task.text)
        sketch_top_k = max(1, min(len(self.agents), int(self.variant.coordination_top_k)))

        for ctrl in self.controllers:
            raw_p_hat = ctrl.predict_time(task.type.value, task.phi_i)
            raw_w_hat = ctrl.predict_wait(task.type.value, task.phi_i)
            p_hat = self._apply_controller_calibration(ctrl, raw_p_hat, ctrl.time_bias, ctrl.time_conf, 0.5, 10.0)
            w_hat = self._apply_controller_calibration(ctrl, raw_w_hat, ctrl.wait_bias, ctrl.wait_conf, 0.3, 5.0)
            dispatch_service = self._estimate_controller_service_time(task_view, ctrl)
            dispatch_start = self._controller_available_at(ctrl.id, self.time)
            dispatch_wait = max(0.0, dispatch_start - self.time)
            decision_time = dispatch_start + dispatch_service
            predicted_total_wait = dispatch_wait + dispatch_service + w_hat
            predicted_budget = predicted_total_wait + p_hat
            q_jt = float(sum(1.0 + 0.5 * queued_task.urgency for queued_task in ctrl.task_queue))
            q_jt += 1.25 * float(len(self.controller_dispatch_tasks[ctrl.id]))
            backlog_time = float(sum(max(0.0, finish_time - self.time) for finish_time in self.controller_task_finish_times[ctrl.id]))
            backlog_time += float(sum(max(0.0, finish_time - self.time) for finish_time in self.controller_dispatch_finish_times[ctrl.id]))
            recent_utility = self._controller_recent_utility(ctrl)
            reliability = self._controller_reliability(ctrl)
            pressure = self._controller_pressure_score(ctrl, predicted_budget)
            candidates = rank_agents(
                controller=ctrl,
                task=task_view,
                agents=self.agents,
                time=decision_time,
                dynamic_success=self.judge.dynamic_success,
                predicted_time=p_hat,
                predicted_wait=predicted_total_wait,
                top_k=len(self.agents),
                variant=self.variant,
            )
            best_finish = float("inf")
            if candidates:
                best_finish = min(
                    self._agent_available_at(self.agents[c["agent_id"]], decision_time) + float(c["theor_time"])
                    for c in candidates[:sketch_top_k]
                )
            controller_score = (
                0.46 * best_finish
                + 0.14 * predicted_budget
                + 0.08 * q_jt
                + 0.10 * backlog_time / max(len(self.agents), 1)
                + 0.10 * pressure * predicted_budget
                - 0.20 * recent_utility
                - 0.08 * reliability
            )
            entry = {
                "controller_id": ctrl.id,
                "controller": ctrl,
                "raw_p_hat": float(raw_p_hat),
                "raw_w_hat": float(raw_w_hat),
                "p_hat": float(p_hat),
                "w_hat": float(w_hat),
                "predicted_budget": float(predicted_budget),
                "predicted_total_wait": float(predicted_total_wait),
                "q_jt": q_jt,
                "backlog_time": backlog_time,
                "recent_utility": float(recent_utility),
                "reliability": float(reliability),
                "pressure": float(pressure),
                "dispatch_wait": float(dispatch_wait),
                "dispatch_service": float(dispatch_service),
                "decision_time": float(decision_time),
                "candidates": candidates,
                "best_finish": float(best_finish),
                "controller_score": float(controller_score),
            }
            controller_entries.append(entry)
            for candidate in candidates[:sketch_top_k]:
                predicted_finish = self._agent_available_at(self.agents[candidate["agent_id"]], decision_time) + float(candidate["theor_time"])
                sketch_candidates.append({
                    "controller_id": ctrl.id,
                    "controller_reliability": float(reliability),
                    "controller_pressure": float(pressure),
                    "predicted_finish": float(predicted_finish),
                    "decision_time": float(decision_time),
                    "candidate": candidate,
                })

        if controller_entries:
            weights = np.array([max(0.05, float(entry["reliability"])) for entry in controller_entries], dtype=float)
            consensus_pressure = float(np.average([entry["pressure"] for entry in controller_entries], weights=weights))
            consensus_budget = float(np.average([entry["predicted_budget"] for entry in controller_entries], weights=weights))
            global_best_finish = float(min(entry["best_finish"] for entry in controller_entries))
        else:
            consensus_pressure = 0.0
            consensus_budget = 0.0
            global_best_finish = float("inf")

        sketch_candidates.sort(
            key=lambda item: (
                item["predicted_finish"],
                -(item["candidate"]["score"] + 0.08 * item["controller_reliability"] - 0.05 * item["controller_pressure"]),
            )
        )
        return {
            "controllers": controller_entries,
            "consensus_pressure": float(consensus_pressure),
            "consensus_budget": float(consensus_budget),
            "global_best_finish": float(global_best_finish),
            "sketch_candidates": sketch_candidates,
        }

    def _update_controller_meta(
        self,
        controller: AdaptiveController,
        routing_features: np.ndarray,
        utility: float,
        raw_p_hat: float,
        raw_w_hat: float,
        raw_q_hat: float,
        service_time: float,
        true_wait: float,
        true_q: float,
        urgency: float,
        deadline_hit: float,
        predicted_wait: float,
        predicted_budget: float,
        latency: float,
    ):
        time_error = float(service_time - raw_p_hat)
        wait_error = float(true_wait - raw_w_hat)
        quality_error = float(true_q - raw_q_hat)
        miss_severity = float(max(0.0, latency - predicted_budget) / max(predicted_budget, 1.0))
        wait_pressure = float(true_wait / max(predicted_wait + 0.5, 0.5))
        controller.time_bias = 0.85 * controller.time_bias + 0.15 * time_error
        controller.wait_bias = 0.85 * controller.wait_bias + 0.15 * wait_error
        controller.quality_bias = 0.85 * controller.quality_bias + 0.15 * quality_error
        controller.time_conf = float(np.clip(0.85 * controller.time_conf + 0.15 * np.exp(-abs(time_error) / 2.5), 0.05, 1.0))
        controller.wait_conf = float(np.clip(0.85 * controller.wait_conf + 0.15 * np.exp(-abs(wait_error) / 1.8), 0.05, 1.0))
        controller.quality_conf = float(np.clip(0.85 * controller.quality_conf + 0.15 * np.exp(-abs(quality_error) / 0.25), 0.05, 1.0))
        controller.meta_history.append({
            "routing_features": np.array(routing_features, dtype=float),
            "utility": float(utility),
            "sample_weight": float(1.0 + 1.75 * urgency + 1.25 * (1.0 - deadline_hit) + 0.35 * max(0.0, wait_pressure - 1.0)),
            "time_error": float(time_error),
            "wait_error": float(wait_error),
            "quality_error": float(quality_error),
            "miss_severity": miss_severity,
            "wait_pressure": wait_pressure,
            "deadline_hit": float(deadline_hit),
            "urgency": float(urgency),
        })

    def _estimate_output_tokens(self, task: Task, agent_id: int) -> int:
        base = {
            TaskType.PROGRAMMING: 180,
            TaskType.QA: 120,
            TaskType.SUMMARIZATION: 90,
            TaskType.TRANSLATION: 110,
            TaskType.TOOL_USE: 140,
        }[task.type]
        agent_factor = 1.0 + 0.15 * float(np.mean(PROFILES[agent_id].psi_k))
        token_count = base * (1.0 + 0.08 * task.h_Ti + 0.4 * task.urgency) * agent_factor
        return int(max(32, token_count))

    def _build_synthetic_quality(
        self,
        task: Task,
        agent_id: int,
        success_prob: float,
        semantic_match: float,
        actual_wait: float,
        response_latency: float,
        task_tokens: int,
        output_tokens: int,
        deadline: float,
    ) -> Dict[str, float]:
        pressure = max(0.0, actual_wait / max(deadline - self.time, 1e-6) - 1.0)
        correctness = np.clip(
            0.55 * success_prob
            + 0.25 * semantic_match
            + 0.10 * PROFILES[agent_id].P_success[task.type.value]
            - 0.04 * max(0.0, task.h_Ti - 4.0)
            - 0.05 * pressure
            + np.random.normal(0.0, 0.03),
            0.0,
            1.0,
        )
        completeness = np.clip(
            0.45
            + 0.25 * semantic_match
            + 0.20 * success_prob
            - 0.03 * np.log1p(task_tokens / 120.0)
            - 0.02 * pressure
            + np.random.normal(0.0, 0.03),
            0.0,
            1.0,
        )
        instruction = np.clip(
            0.50
            + 0.20 * semantic_match
            + 0.15 * (1.0 - min(1.0, task.urgency * pressure))
            + 0.10 * success_prob
            + np.random.normal(0.0, 0.025),
            0.0,
            1.0,
        )
        semantic = np.clip(
            0.45
            + 0.35 * semantic_match
            + 0.10 * success_prob
            - 0.03 * np.log1p(output_tokens / 140.0)
            + np.random.normal(0.0, 0.025),
            0.0,
            1.0,
        )
        safety = np.clip(
            0.92 - 0.05 * (task.type == TaskType.TOOL_USE) - 0.03 * task.urgency + np.random.normal(0.0, 0.01),
            0.0,
            1.0,
        )
        quality_score = np.clip(
            0.45 * correctness + 0.25 * completeness + 0.20 * instruction + 0.10 * semantic,
            0.0,
            1.0,
        )
        confidence = np.clip(
            0.45 + 0.35 * abs(quality_score - 0.5) + 0.10 * semantic_match,
            0.0,
            1.0,
        )
        verdict = "pass" if quality_score >= 0.58 else "fail"
        return {
            "quality_score": float(quality_score),
            "semantic_score": float(semantic),
            "correctness_score": float(correctness),
            "instruction_score": float(instruction),
            "safety_score": float(safety),
            "confidence": float(confidence),
            "verdict": verdict,
            "short_reason": f"synthetic judge: p={success_prob:.3f}, match={semantic_match:.3f}, wait={actual_wait:.3f}, latency={response_latency:.3f}",
        }

    def _simulate_no_api_execution(
        self,
        task: Task,
        agent: AgentState,
        profile: AgentProfile,
        p_hat: float,
        w_hat: float,
        dispatch_time: Optional[float]=None,
        request_time: Optional[float]=None,
    ) -> Dict[str, float]:
        input_tokens = self._estimate_task_tokens(task)
        output_tokens = self._estimate_output_tokens(task, agent.id)
        semantic_match = self._cosine_similarity(task.phi_i, profile.psi_k)
        request_time = self.time if request_time is None else float(request_time)
        dispatch_time = self.time if dispatch_time is None else float(dispatch_time)
        controller_delay = max(0.0, dispatch_time - request_time)
        agent_wait = max(0.0, agent.available_at - dispatch_time)
        actual_wait = controller_delay + agent_wait
        actual_start = dispatch_time + agent_wait

        base_capability = float(profile.P_success[task.type.value])
        dynamic_rep = float(self.judge.dynamic_success[agent.id, task.type.value])
        capability = 0.55 * base_capability + 0.45 * dynamic_rep
        context_penalty = 0.035 * np.log1p(input_tokens / 120.0)
        complexity_penalty = 0.045 * max(0.0, task.h_Ti - 3.0)
        queue_penalty = 0.025 * actual_wait
        urgency_penalty = 0.035 * task.urgency * max(0.0, actual_wait - w_hat)
        success_prob = np.clip(
            0.18
            + 0.42 * capability
            + 0.30 * semantic_match
            - context_penalty
            - complexity_penalty
            - queue_penalty
            - urgency_penalty
            + np.random.normal(0.0, 0.03),
            0.01,
            0.99,
        )

        service_time = float(profile.tau_avg[task.type.value])
        service_time *= 1.0 + 0.07 * task.h_Ti
        service_time *= 1.0 + 0.10 * np.log1p(input_tokens / 80.0)
        service_time *= 1.0 + 0.06 * np.log1p(output_tokens / 60.0)
        service_time *= 1.0 + 0.12 * max(0.0, 0.65 - semantic_match)
        service_time *= float(np.random.lognormal(mean=0.0, sigma=0.16))
        if np.random.rand() < 0.08:
            service_time *= float(np.random.uniform(1.25, 1.9))
        service_time = max(0.35, service_time)

        finish_time = actual_start + service_time
        response_latency = actual_wait + service_time
        api_success = bool(np.random.rand() < success_prob)
        synthetic_quality = self._build_synthetic_quality(
            task=task,
            agent_id=agent.id,
            success_prob=float(success_prob),
            semantic_match=float(semantic_match),
            actual_wait=float(actual_wait),
            response_latency=float(response_latency),
            task_tokens=int(input_tokens),
            output_tokens=int(output_tokens),
            deadline=float(request_time + w_hat + p_hat),
        )
        quality_label = synthetic_quality["verdict"]
        model_output = (
            f"synthetic-{quality_label}: type={task.type.name}; "
            f"correctness={synthetic_quality['correctness_score']:.3f}; "
            f"semantic={synthetic_quality['semantic_score']:.3f}; "
            f"instruction={synthetic_quality['instruction_score']:.3f}; "
            f"input_tokens={input_tokens}; output_tokens={output_tokens}"
        )
        return {
            "success": api_success,
            "success_prob": float(success_prob),
            "service_time": float(service_time),
            "actual_wait": float(actual_wait),
            "agent_wait": float(agent_wait),
            "controller_delay": float(controller_delay),
            "actual_start": float(actual_start),
            "finish_time": float(finish_time),
            "response_latency": float(response_latency),
            "input_tokens": int(input_tokens),
            "output_tokens": int(output_tokens),
            "semantic_match": float(semantic_match),
            "model_output": model_output,
            "synthetic_quality": synthetic_quality,
        }

    def _select_controller(self, task: SubTask, coordination_snapshot: Optional[Dict[str, object]]=None) -> int:
        if len(self.controllers) == 1:
            return 0
        if self.variant.controller_mode == "random":
            return int(np.random.randint(0, len(self.controllers)))
        if self.variant.controller_mode == "least_queue":
            return int(np.argmin([
                sum(1 + 0.5 * t.urgency for t in ctrl.task_queue) + 1.35 * len(self.controller_dispatch_tasks[ctrl.id])
                for ctrl in self.controllers
            ]))
        coordination_snapshot = coordination_snapshot or self._build_coordination_snapshot(task)
        states = []
        controller_scores = []
        global_best_finish = float(coordination_snapshot.get("global_best_finish", float("inf")))
        for entry in coordination_snapshot.get("controllers", []):
            ctrl = entry["controller"]
            q_jt = float(entry["q_jt"])
            states.append(ControllerState(q_jt, p_j=1.0, z_jt=1.0))
            coordination_gap = max(0.0, float(entry["best_finish"]) - global_best_finish) / max(float(entry["predicted_budget"]), 1.0)
            controller_scores.append(
                float(entry["controller_score"])
                + 0.16 * coordination_gap
                + 0.06 * float(entry["pressure"])
                - 0.08 * float(entry["reliability"])
            )
        B_t = communication_graph(int(self.time), len(self.controllers))
        _ = exact_load_balancing(states, B_t)
        blended_scores = [
            0.65 * controller_scores[idx] + 0.35 * float(state.q_jt_next)
            for idx, state in enumerate(states)
        ]
        return int(np.argmin(blended_scores))

    def _record_task(self, **kwargs):
        self.task_records.append(kwargs)

    def _log_theta(self, task_idx: int, spsa_step: int):
        for ctrl in self.controllers:
            row: Dict[str, float] = {
                "task_idx":  task_idx,
                "spsa_step": spsa_step,
                "ctrl_id":   ctrl.id,
            }
            for k, v in enumerate(ctrl.theta_time):
                row[f"theta_time_{k}"] = float(v)
            for k, v in enumerate(ctrl.theta_wait):
                row[f"theta_wait_{k}"] = float(v)
            for k, v in enumerate(ctrl.theta_quality):
                row[f"theta_quality_{k}"] = float(v)
            self.theta_records.append(row)

    def _remove_controller_task(self, controller: AdaptiveController, task: Task):
        for idx, queued_task in enumerate(controller.task_queue):
            if (
                queued_task.id == task.id
                and queued_task.type == task.type
                and abs(float(queued_task.h_Ti) - float(task.h_Ti)) < 1e-9
            ):
                controller.task_queue.pop(idx)
                if idx < len(self.controller_task_finish_times[controller.id]):
                    self.controller_task_finish_times[controller.id].pop(idx)
                return

    def _enqueue_controller_dispatch(self, controller: AdaptiveController, task: Task, finish_time: float):
        self.controller_dispatch_tasks[controller.id].append(task)
        self.controller_dispatch_finish_times[controller.id].append(float(finish_time))

    def _enqueue_agent_task(self, agent: AgentState, task: Task, start_time: float, finish_time: float, service_time: float):
        if agent.queue is None:
            agent.queue = []
        agent.queue.append(task)
        agent.queue_start_times.append(float(start_time))
        agent.queue_finish_times.append(float(finish_time))
        agent.queue_pred_times.append(float(service_time))
        agent.available_at = float(finish_time)

    def _refresh_agent_runtime(self, agent: AgentState, current_time: float):
        keep_tasks = []
        keep_starts = []
        keep_finishes = []
        keep_service = []
        for task, start_t, finish_t, service_t in zip(
            agent.queue,
            agent.queue_start_times,
            agent.queue_finish_times,
            agent.queue_pred_times,
        ):
            if finish_t > current_time:
                keep_tasks.append(task)
                keep_starts.append(start_t)
                keep_finishes.append(finish_t)
                keep_service.append(service_t)
        agent.queue = keep_tasks
        agent.queue_start_times = keep_starts
        agent.queue_finish_times = keep_finishes
        agent.queue_pred_times = keep_service
        if keep_finishes:
            agent.available_at = keep_finishes[-1]
        else:
            agent.available_at = 0.0 if not np.isfinite(current_time) else float(current_time)

        active_idx = None
        for idx, (start_t, finish_t) in enumerate(zip(keep_starts, keep_finishes)):
            if start_t <= current_time < finish_t:
                active_idx = idx
                break

        if active_idx is None:
            agent.current_task = None
            agent.t_start_i = 0.0
            agent.p_hat_i = 0.0
            agent.v_i = 0.0
            agent.gamma_j = 1.0
            return

        agent.current_task = keep_tasks[active_idx]
        agent.t_start_i = float(keep_starts[active_idx])
        agent.p_hat_i = float(keep_service[active_idx])
        agent.v_i = float(keep_finishes[active_idx])
        agent.gamma_j = 1.0

    def _refresh_system_state(self, current_time: float):
        for ctrl in self.controllers:
            dispatch_tasks = self.controller_dispatch_tasks[ctrl.id]
            dispatch_finish_times = self.controller_dispatch_finish_times[ctrl.id]
            keep_dispatch_tasks = []
            keep_dispatch_finish_times = []
            for queued_task, finish_time in zip(dispatch_tasks, dispatch_finish_times):
                if finish_time > current_time:
                    keep_dispatch_tasks.append(queued_task)
                    keep_dispatch_finish_times.append(finish_time)
            self.controller_dispatch_tasks[ctrl.id] = keep_dispatch_tasks
            self.controller_dispatch_finish_times[ctrl.id] = keep_dispatch_finish_times

        for ctrl in self.controllers:
            finish_times = self.controller_task_finish_times[ctrl.id]
            keep_tasks = []
            keep_finish_times = []
            for queued_task, finish_time in zip(ctrl.task_queue, finish_times):
                if finish_time > current_time:
                    keep_tasks.append(queued_task)
                    keep_finish_times.append(finish_time)
            ctrl.task_queue = keep_tasks
            self.controller_task_finish_times[ctrl.id] = keep_finish_times

        for agent in self.agents:
            self._refresh_agent_runtime(agent, current_time)

    def _agent_available_now(self, agent: AgentState, current_time: float) -> bool:
        return agent.available_at <= current_time

    def _agent_available_at(self, agent: AgentState, current_time: float) -> float:
        return float(max(current_time, agent.available_at))

    def collect_summary(self) -> Dict[str, float]:
        total_tasks = len(self.task_records)
        success_count = float(np.sum(self.metrics['success_rate'])) if self.metrics['success_rate'] else 0.0
        total_cost = float(np.sum(self.metrics['costs'])) if self.metrics['costs'] else 0.0
        mean_q = self._safe_mean(self.metrics['judge_quality'])
        return {
            'variant': self.variant.name,
            'success_rate': self._safe_mean(self.metrics['success_rate']),
            'mean_q': mean_q,
            'mean_latency': self._safe_mean(self.metrics['latency']),
            'p95_latency': self._safe_p95(self.metrics['latency']),
            'deadline_hit_rate': self._safe_mean(self.metrics['deadline_hits']),
            'weighted_success': self._safe_mean(self.metrics['weighted_success']),
            'total_cost': total_cost,
            'mean_cost_per_task': (total_cost / total_tasks) if total_tasks else 0.0,
            'cost_per_success': (total_cost / success_count) if success_count > 0 else 0.0,
            'assignments': float(self.metrics['assignments']),
            'assignment_rate': (float(self.metrics['assignments']) / total_tasks) if total_tasks else 0.0,
            'queue_len': self._safe_mean(self.metrics['queue_len']),
            'mse_time': self._safe_mean(self.metrics['mse_time'][-100:]),
            'mse_wait': self._safe_mean(self.metrics['mse_wait'][-100:]),
            'q_mse': self._safe_mean(self.metrics['Q_mse']),
            'type_cls_acc': self._safe_mean(self.metrics['type_cls_acc']),
            'dynamic_benchmark_mean': self._safe_mean(self.metrics['benchmark_dynamic_mean']),
            'routing_objective': self._safe_mean(self.metrics['routing_objective']),
            'total_records': float(total_tasks),
        }
    
    def generate_realistic_stream(self, N: int=2000) -> List[Task]:
        """Реалистичный поток задач с реальными сложностями"""
        prompt_templates = {
            TaskType.PROGRAMMING: "Build ML pipeline code with feature engineering and model training.",
            TaskType.QA: "Answer factual question and explain reasoning with references.",
            TaskType.SUMMARIZATION: "Summarize the report into concise bullet points.",
            TaskType.TRANSLATION: "Translate customer message from Russian to English.",
            TaskType.TOOL_USE: "Call CRM API tool to create ticket and update status.",
        }
        tasks = []
        for i in range(N):
            typ = np.random.choice(list(TaskType), 
                                 p=[0.25, 0.20, 0.20, 0.15, 0.20])  # Как в статье
            text = prompt_templates[typ]
            phi = SemanticFeatureExtractor.extract(text)
            text_low = text.lower()
            length_f = min(len(text_low) / 800.0, 1.5)
            kw_bonus = sum(0.4 for kw in ("optimize", "pipeline", "debug", "production", "integration", "benchmark") if kw in text_low)
            h = float(np.clip(2.0 + 4.0 * float(np.mean(phi)) + 2.0 * length_f + kw_bonus, 1.0, 10.0))
            hot = ("urgent", "asap", "critical", "prod", "incident", "deadline")
            urgency = float(np.clip(0.25 + 0.05 * h + (0.25 if any(w in text_low for w in hot) else 0.0), 0.05, 1.0))
            tasks.append(Task(i, typ, self.time + np.random.exponential(0.8), h, phi, urgency, text))
        return tasks

    def _process_subtask(self, task: SubTask, parent_type: TaskType):
        self.time += np.random.exponential(0.01)
        self._refresh_system_state(self.time)
        start_time = self.time
        predicted_type = self.classifier.predict(Task(task.parent_id, task.type, self.time, task.h_Ti, task.phi_i, task.urgency))
        self.metrics["type_cls_acc"].append(1.0 if predicted_type == parent_type else 0.0)
        coordination_snapshot = self._build_coordination_snapshot(task) if self.variant.routing_mode == "adaptive" else None
        # Шаг 1: Load balancing → выбор контроллера
        ctrl_id = self._select_controller(task, coordination_snapshot=coordination_snapshot)
        controller = self.controllers[ctrl_id]
        runtime_task = Task(task.parent_id, task.type, self.time, task.h_Ti, task.phi_i, task.urgency, task.text)
        # Шаг 2: Предсказание p̂ᵢ, ŵᵢ
        snapshot_entry = None
        if coordination_snapshot is not None:
            snapshot_entry = next((entry for entry in coordination_snapshot["controllers"] if entry["controller_id"] == ctrl_id), None)
        if snapshot_entry is not None:
            raw_p_hat = float(snapshot_entry["raw_p_hat"])
            raw_w_hat = float(snapshot_entry["raw_w_hat"])
            p_hat = float(snapshot_entry["p_hat"])
            w_hat = float(snapshot_entry["w_hat"])
            predicted_total_wait = float(snapshot_entry["predicted_total_wait"])
            dispatch_wait = float(snapshot_entry["dispatch_wait"])
            dispatch_service = float(snapshot_entry["dispatch_service"])
            decision_time = float(snapshot_entry["decision_time"])
            candidates = list(snapshot_entry["candidates"])
        else:
            raw_p_hat = controller.predict_time(task.type.value, task.phi_i)
            raw_w_hat = controller.predict_wait(task.type.value, task.phi_i)
            p_hat = self._apply_controller_calibration(controller, raw_p_hat, controller.time_bias, controller.time_conf, 0.5, 10.0)
            w_hat = self._apply_controller_calibration(controller, raw_w_hat, controller.wait_bias, controller.wait_conf, 0.3, 5.0)
            dispatch_service = self._estimate_controller_service_time(task, controller)
            dispatch_start = self._controller_available_at(ctrl_id, self.time)
            dispatch_wait = max(0.0, dispatch_start - self.time)
            decision_time = dispatch_start + dispatch_service
            predicted_total_wait = dispatch_wait + dispatch_service + w_hat
            candidates = []
        total_predicted_budget = predicted_total_wait + p_hat
        service_deadline = self.time + total_predicted_budget
        # Шаг 3-4: Выбор агентов R+A → локальное решение
        if not candidates:
            candidates = rank_agents(
                controller,
                Task(task.parent_id, task.type, decision_time, task.h_Ti, task.phi_i, task.urgency),
                self.agents,
                decision_time,
                self.judge.dynamic_success,
                predicted_time=p_hat,
                predicted_wait=predicted_total_wait,
                top_k=len(self.agents),
                variant=self.variant,
            )
        if not candidates:
            fallback_variant = replace(self.variant, routing_mode="fastest_static")
            candidates = rank_agents(
                controller,
                Task(task.parent_id, task.type, decision_time, task.h_Ti, task.phi_i, task.urgency),
                self.agents,
                decision_time,
                self.judge.dynamic_success,
                predicted_time=p_hat,
                predicted_wait=predicted_total_wait,
                top_k=len(self.agents),
                variant=fallback_variant,
            )
        selected = None
        selected_candidate = None
        primary_candidates = candidates[:3]
        fallback_candidates = candidates[3:]
        available_primary = [
            c for c in primary_candidates
            if self._agent_available_now(self.agents[c["agent_id"]], decision_time)
        ]
        if available_primary:
            selected_candidate = available_primary[0]
            selected = self.agents[selected_candidate["agent_id"]]
        else:
            available_fallback = [
                c for c in fallback_candidates
                if self._agent_available_now(self.agents[c["agent_id"]], decision_time)
            ]
            if available_fallback:
                selected_candidate = available_fallback[0]
                selected = self.agents[selected_candidate["agent_id"]]
            elif fallback_candidates:
                selected_candidate = fallback_candidates[0]
                selected = self.agents[selected_candidate["agent_id"]]
            elif primary_candidates:
                selected_candidate = min(
                    primary_candidates,
                    key=lambda c: self._agent_available_at(self.agents[c["agent_id"]], decision_time),
                )
                selected = self.agents[selected_candidate["agent_id"]]
        if selected_candidate is not None and selected is None:
            selected = self.agents[selected_candidate["agent_id"]]
        if (
            selected_candidate is not None
            and coordination_snapshot is not None
            and self.variant.routing_mode == "adaptive"
            and coordination_snapshot["sketch_candidates"]
        ):
            hard_mode = (
                task.urgency >= 0.75
                or task.type == TaskType.TOOL_USE
                or float(coordination_snapshot["consensus_pressure"]) >= min(0.95, self.variant.pressure_threshold + 0.08)
            )
            if hard_mode:
                local_finish = self._agent_available_at(self.agents[selected_candidate["agent_id"]], decision_time) + float(selected_candidate["theor_time"])
                best_shared = coordination_snapshot["sketch_candidates"][0]
                shared_candidate = best_shared["candidate"]
                shared_finish = float(best_shared["predicted_finish"])
                if (
                    shared_candidate["agent_id"] != selected_candidate["agent_id"]
                    and (
                        shared_finish + 0.5 < local_finish
                        or shared_candidate["score"] > selected_candidate["score"] + 0.08
                    )
                ):
                    selected_candidate = shared_candidate
                    selected = self.agents[selected_candidate["agent_id"]]
        if selected:
            self.metrics['assignments'] += 1
            profile = PROFILES[selected.id]
            task_cost = 0.0
            selected_routing_features = np.array(selected_candidate["routing_features"], dtype=float)
            raw_q_hat = float(selected_candidate["raw_predicted_quality"])
            dispatch_start = self._controller_available_at(ctrl_id, self.time)
            dispatch_wait = max(0.0, dispatch_start - self.time)
            decision_time = dispatch_start + dispatch_service
            self._enqueue_controller_dispatch(controller, runtime_task, decision_time)
            # --- Реальный вызов LLM API ---
            if self.llm_api_client is not None:
                task_tokens = self._estimate_task_tokens(runtime_task)
                task_cost = MODEL_TOKEN_PRICE.get(profile.model_name, 0.5) * (task_tokens / 1000.0)
                prompt = task.text or f"{task.type.name}: complexity={task.h_Ti:.2f}, urgency={task.urgency:.2f}"
                try:
                    api_result = self.llm_api_client.call(profile.model_name, prompt, task.type.name)
                    api_success = bool(api_result.get("success", True))
                    agent_wait = max(0.0, selected.available_at - decision_time)
                    actual_wait = dispatch_wait + dispatch_service + agent_wait
                    actual_start = decision_time + agent_wait
                    service_time = float(api_result.get("latency") or p_hat)
                    true_time = actual_wait + service_time
                    finish_time = actual_start + service_time
                    model_output = str(api_result.get("output", ""))
                    simulation_quality = None
                    output_tokens = max(32, int(len(model_output) / 4)) if model_output else 32
                    semantic_match = self._cosine_similarity(task.phi_i, profile.psi_k)
                except Exception:
                    sim_result = self._simulate_no_api_execution(
                        runtime_task,
                        selected,
                        profile,
                        p_hat,
                        predicted_total_wait,
                        dispatch_time=decision_time,
                        request_time=self.time,
                    )
                    api_success = bool(sim_result["success"])
                    true_time = float(sim_result["response_latency"])
                    actual_wait = float(sim_result["actual_wait"])
                    actual_start = float(sim_result["actual_start"])
                    service_time = float(sim_result["service_time"])
                    finish_time = float(sim_result["finish_time"])
                    model_output = str(sim_result["model_output"])
                    simulation_quality = sim_result["synthetic_quality"]
                    task_tokens = int(sim_result["input_tokens"])
                    output_tokens = int(sim_result["output_tokens"])
                    semantic_match = float(sim_result["semantic_match"])
                    task_cost = MODEL_TOKEN_PRICE.get(profile.model_name, 0.5) * ((task_tokens + output_tokens) / 1000.0)
            else:
                sim_result = self._simulate_no_api_execution(
                    runtime_task,
                    selected,
                    profile,
                    p_hat,
                    predicted_total_wait,
                    dispatch_time=decision_time,
                    request_time=self.time,
                )
                api_success = bool(sim_result["success"])
                true_time = float(sim_result["response_latency"])
                actual_wait = float(sim_result["actual_wait"])
                actual_start = float(sim_result["actual_start"])
                service_time = float(sim_result["service_time"])
                finish_time = float(sim_result["finish_time"])
                model_output = str(sim_result["model_output"])
                simulation_quality = sim_result["synthetic_quality"]
                task_tokens = int(sim_result["input_tokens"])
                output_tokens = int(sim_result["output_tokens"])
                semantic_match = float(sim_result["semantic_match"])
                task_cost = MODEL_TOKEN_PRICE.get(profile.model_name, 0.5) * ((task_tokens + output_tokens) / 1000.0)
            true_wait = actual_wait
            Q_hat = self._apply_controller_calibration(controller, raw_q_hat, controller.quality_bias, controller.quality_conf, 0.0, 1.0)
            verdict = self.judge.evaluate(
                selected.id,
                task,
                base_success=1.0 if api_success else 0.0,
                latency=true_time,
                model_output=model_output,
                synthetic_quality=simulation_quality if self.variant.use_judge else None,
            )
            Q = float(verdict["Q"])
            success = bool(verdict["success"])
            if self.variant.use_learning:
                controller.update_agent_rating(
                    selected.id,
                    task.type.value,
                    judge_quality=Q,
                    confidence=float(verdict.get("confidence", 0.5)),
                )
                controller.rls_quality_update(
                    task.type.value, task.phi_i, profile.psi_k, p_hat, w_hat, Q
                )
            self.metrics["Q_pred"].append(Q_hat)
            self.metrics["Q_true"].append(Q)
            self.metrics["Q_mse"].append((Q - Q_hat) ** 2)
            self.controller_Q_sums[ctrl_id] += Q
            self.controller_Q_counts[ctrl_id] += 1
            self.controller_Q_mse_sums[ctrl_id] += (Q - Q_hat) ** 2
            self.metrics["judge_quality"].append(float(verdict["quality"]))
            self.metrics["benchmark_dynamic_mean"].append(float(np.mean(self.judge.dynamic_success)))
            deadline_hit = 1.0 if finish_time <= service_deadline else 0.0
            self.metrics["latency"].append(float(true_time))
            self.metrics["deadline_hits"].append(deadline_hit)
            self.metrics["costs"].append(float(task_cost))
            self.metrics["weighted_success"].append(float((1.0 if success else 0.0) * (1.0 + task.urgency)))
            utility = self._compute_observed_utility(
                q_true=Q,
                success=success,
                deadline_hit=deadline_hit,
                latency=true_time,
                true_wait=true_wait,
                cost=task_cost,
                semantic_match=semantic_match,
                urgency=task.urgency,
                predicted_wait=predicted_total_wait,
                predicted_budget=total_predicted_budget,
            )
            self.metrics["routing_objective"].append(utility)
            self._update_controller_meta(
                controller=controller,
                routing_features=selected_routing_features,
                utility=utility,
                raw_p_hat=raw_p_hat,
                raw_w_hat=raw_w_hat,
                raw_q_hat=raw_q_hat,
                service_time=service_time,
                true_wait=true_wait,
                true_q=Q,
                urgency=task.urgency,
                deadline_hit=deadline_hit,
                predicted_wait=predicted_total_wait,
                predicted_budget=total_predicted_budget,
                latency=true_time,
            )
            self._enqueue_agent_task(selected, runtime_task, actual_start, finish_time, service_time)
            controller.task_queue.append(runtime_task)
            self.controller_task_finish_times[ctrl_id].append(finish_time)
            self._refresh_agent_runtime(selected, self.time)
            if self.variant.use_learning:
                controller.rls_update(task.type.value, service_time, true_wait, task.phi_i)
            # Метрики
            self.metrics['mse_time'].append(mse(controller.theta_time, controller.obs_history, 0))
            self.metrics['mse_wait'].append(mse(controller.theta_wait, controller.obs_history, 1))
            self.metrics['success_rate'].append(1.0 if success else 0.0)
            self._record_task(
                variant=self.variant.name,
                parent_id=task.parent_id,
                local_id=task.local_id,
                task_type=task.type.name,
                urgency=float(task.urgency),
                controller_id=ctrl_id,
                assigned=1,
                agent_id=selected.id,
                model_name=profile.model_name,
                predicted_time=float(p_hat),
                predicted_wait=float(predicted_total_wait),
                deadline=float(service_deadline),
                latency=float(true_time),
                true_wait=float(true_wait),
                controller_wait=float(dispatch_wait + dispatch_service),
                actual_start=float(actual_start),
                finish_time=float(finish_time),
                service_time=float(service_time),
                estimated_tokens=int(task_tokens),
                output_tokens=int(output_tokens),
                cost=float(task_cost),
                q_hat=float(Q_hat),
                q_true=float(Q),
                success=int(success),
                deadline_hit=int(deadline_hit),
                semantic_match=float(semantic_match),
                routing_score=float(selected_candidate["score"]),
                routing_relevance=float(selected_candidate["relevance"]),
                routing_availability=float(selected_candidate["availability"]),
                routing_predicted_quality=float(selected_candidate["predicted_quality"]),
                routing_time_score=float(selected_candidate["time_score"]),
                routing_queue_score=float(selected_candidate["queue_score"]),
                routing_cost_score=float(selected_candidate["cost_score"]),
                routing_rep_score=float(selected_candidate["rep_score"]),
                routing_urgency_score=float(selected_candidate["urgency_score"]),
                routing_utility=float(utility),
            )
        else:
            self.metrics['success_rate'].append(0.0)
            self.metrics["deadline_hits"].append(0.0)
            self.metrics["costs"].append(0.0)
            self.metrics["weighted_success"].append(0.0)
            self._record_task(
                variant=self.variant.name,
                parent_id=task.parent_id,
                local_id=task.local_id,
                task_type=task.type.name,
                urgency=float(task.urgency),
                controller_id=ctrl_id,
                assigned=0,
                agent_id=-1,
                model_name="",
                predicted_time=float(p_hat),
                predicted_wait=float(predicted_total_wait),
                deadline=float(service_deadline),
                latency=0.0,
                true_wait=0.0,
                controller_wait=float(dispatch_wait + dispatch_service),
                estimated_tokens=int(self._estimate_task_tokens(runtime_task)),
                cost=0.0,
                q_hat=0.0,
                q_true=0.0,
                success=0,
                deadline_hit=0,
                routing_score=0.0,
                routing_relevance=0.0,
                routing_availability=0.0,
                routing_predicted_quality=0.0,
                routing_time_score=0.0,
                routing_queue_score=0.0,
                routing_cost_score=0.0,
                routing_rep_score=0.0,
                routing_urgency_score=0.0,
                routing_utility=0.0,
            )

    def step(self, task: Task):
        self.time = task.t_arrival
        self._refresh_system_state(self.time)
        sub = SubTask(task.id, 0, task.type, task.h_Ti, task.phi_i, task.urgency, task.text)
        self._process_subtask(sub, task.type)
    
    def run(self, tasks: List[Task]):
        """Полная симуляция"""
        for i, task in enumerate(tasks):
            self.step(task)

            interval = max(1, int(self.variant.spsa_interval))
            warmup = max(interval * 2, int(self.variant.spsa_warmup_tasks))
            if self.variant.use_spsa and (i + 1) >= warmup and (i + 1) % interval == 0:
                _spsa_step = (i + 1) // interval
                _a = self.variant.spsa_alpha
                _b = self.variant.spsa_beta
                _bnm = self.variant.spsa_beta_nes_max
                if self.variant.spsa_variant == "spsa":
                    spsa_consensus(self.controllers, _spsa_step, alpha=_a, beta=_b)
                else:
                    call_variant(self.variant.spsa_variant, self.controllers, _spsa_step,
                                 alpha=_a, beta=_b, beta_nes_max=_bnm)
                self._log_theta(i, _spsa_step)

            # Метрики каждые 100 задач
            if i % 100 == 0:
                self.metrics['queue_len'].append(
                    np.mean([len(c.task_queue) for c in self.controllers]))
        self._refresh_system_state(float("inf"))
        self.report_results()
    
    def report_results(self):
        """ТАБЛИЦА РЕЗУЛЬТАТОВ как в статье"""
        summary = self.collect_summary()
        perf_rows = []
        for j in sorted(self.controller_Q_counts.keys()):
            n = self.controller_Q_counts[j]
            if n > 0:
                perf_j = self.controller_Q_sums[j] / n
                l_j = self.controller_Q_mse_sums[j] / n
                perf_rows.append((f'Perf (ctrl {j})', round(perf_j, 4)))
                perf_rows.append((f'L_Q MSE (ctrl {j})', round(l_j, 4)))
        base_metrics = {
            'Metric': [
                'Variant',
                'Final MSE Time',
                'Final MSE Wait',
                'Avg Queue Length',
                'Success Rate',
                'Judge Q (mean)',
                'Q pred vs true MSE',
                'Type Classifier Acc',
                'Dynamic Benchmark Mean',
                'Mean Latency',
                'P95 Latency',
                'Deadline Hit Rate',
                'Total Cost',
                'Cost per Success',
                'Total Assignments',
            ],
            'Value': [
                self.variant.name,
                summary['mse_time'],
                summary['mse_wait'],
                summary['queue_len'],
                summary['success_rate'],
                summary['mean_q'],
                summary['q_mse'],
                summary['type_cls_acc'],
                summary['dynamic_benchmark_mean'],
                summary['mean_latency'],
                summary['p95_latency'],
                summary['deadline_hit_rate'],
                summary['total_cost'],
                summary['cost_per_success'],
                summary['assignments'],
            ]
        }
        extra = pd.DataFrame(perf_rows, columns=['Metric', 'Value']) if perf_rows else pd.DataFrame(columns=['Metric', 'Value'])
        results = pd.DataFrame(base_metrics)
        if not extra.empty:
            results = pd.concat([results, extra], ignore_index=True)
        if self.plot_output_path:
            self.plot_results()
    
    def plot_results(self):
        output_path = Path(self.plot_output_path)
        output_path.parent.mkdir(parents=True, exist_ok=True)
        fig, axes = plt.subplots(3, 2, figsize=(16, 14))
        
        axes[0,0].plot(self.metrics['mse_time'], label='MSE Time J₁(θ)')
        axes[0,0].plot(self.metrics['mse_wait'], label='MSE Wait J₂(θ)')
        axes[0,0].legend(); axes[0,0].set_title('Prediction Errors (RLS+SPSA)')
        
        if len(self.metrics['success_rate']) >= 5:
            window = min(100, len(self.metrics['success_rate']))
            axes[0,1].plot(np.convolve(self.metrics['success_rate'], np.ones(window)/window, mode='valid'))
        axes[0,1].set_title('Success Rate (сглаженно)')
        
        axes[1,0].plot(self.metrics['queue_len'])
        axes[1,0].set_title('Средняя длина очереди контроллеров')

        axes[1,1].plot(self.metrics['latency'])
        axes[1,1].set_title('Latency по назначениям')
        
        cumulative_cost = np.cumsum(self.metrics['costs']) if self.metrics['costs'] else []
        axes[2,0].plot(cumulative_cost)
        axes[2,0].set_title('Накопленная стоимость')

        # Распределение назначений по агентам
        assigned_agents = [int(r['agent_id']) for r in self.task_records if r.get('assigned') == 1 and int(r.get('agent_id', -1)) >= 0]
        agent_assigns = np.bincount(assigned_agents, minlength=len(PROFILES)) if assigned_agents else np.zeros(len(PROFILES), dtype=int)
        if np.sum(agent_assigns) > 0:
            axes[2,1].pie(agent_assigns, labels=[p.name for p in PROFILES], autopct='%1.1f%%')
        else:
            axes[2,1].bar(range(len(PROFILES)), agent_assigns)
            axes[2,1].set_xticks(range(len(PROFILES)))
            axes[2,1].set_xticklabels([p.name for p in PROFILES], rotation=45, ha='right')
        axes[2,1].set_title('Доля назначений по агентам')
        
        plt.tight_layout()
        plt.savefig(output_path, dpi=300, bbox_inches='tight')
        plt.close(fig)

# === ЗАПУСК ===
if __name__ == "__main__":
    orch = ExactOrchestrator(num_ctrl=3, num_agents=5)
    tasks = orch.generate_realistic_stream(2000)
    orch.run(tasks)
