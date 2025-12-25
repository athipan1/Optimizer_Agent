
from pydantic import BaseModel, Field
from typing import List, Dict, Optional, Any

# --- Input Contract Models ---

class AgentVote(BaseModel):
    """Represents a single agent's vote in a trade."""
    action: str
    confidence: float

class Trade(BaseModel):
    """Represents a single historical trade."""
    trade_id: str
    ticker: str
    final_verdict: str
    executed: bool
    pnl_pct: float
    holding_days: int
    market_regime: str
    agent_votes: Dict[str, AgentVote]
    timestamp: str

class PricePoint(BaseModel):
    """Represents a single price point in history."""
    timestamp: str
    open: float
    high: float
    low: float
    close: float
    volume: int

class CurrentPolicyRisk(BaseModel):
    risk_per_trade: float
    max_position_pct: float
    stop_loss_pct: float

class CurrentPolicyStrategyBias(BaseModel):
    preferred_regime: str

class CurrentPolicy(BaseModel):
    agent_weights: Dict[str, float]
    risk: CurrentPolicyRisk
    strategy_bias: CurrentPolicyStrategyBias

class LearningRequest(BaseModel):
    """The complete input data structure for the /learn endpoint."""
    learning_mode: str
    window_size: int
    trade_history: List[Trade]
    price_history: Dict[str, List[PricePoint]]
    current_policy: CurrentPolicy

# --- Output Contract Models ---

class PolicyDeltas(BaseModel):
    agent_weights: Dict[str, float] = Field(default_factory=dict)
    risk: Dict[str, float] = Field(default_factory=dict)
    strategy_bias: Dict[str, Any] = Field(default_factory=dict)
    guardrails: Dict[str, Any] = Field(default_factory=dict)


class LearningResponse(BaseModel):
    """The complete output data structure for the /learn endpoint."""
    learning_state: str
    learning_mode: Optional[str] = None
    confidence_score: float = 0.0
    policy_deltas: PolicyDeltas = Field(default_factory=PolicyDeltas)
    reasoning: List[str] = Field(default_factory=list)
