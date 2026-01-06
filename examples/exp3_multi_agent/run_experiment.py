"""
Experiment 3: Multi-Agent Simulation (Full Integration)

Components:
- Data Loader: Load agents from CSV/Excel
- Prompts: Build LLM prompts with PMT constructs
- Parsers: Parse LLM responses
- Validators: Check PMT consistency
- Audit Writer: Record all decisions
- LLM Client: Call Ollama (optional, falls back to heuristic)

Output:
- household_audit.jsonl
- institutional_audit.jsonl
- audit_summary.json
"""

import sys
import os
import json

sys.path.insert(0, '.')

from typing import List, Dict, Optional
from dataclasses import asdict

from examples.exp3_multi_agent.data_loader import (
    load_households_from_csv, 
    initialize_all_agents
)
from examples.exp3_multi_agent.prompts import (
    build_household_prompt,
    build_insurance_prompt,
    build_government_prompt
)
from examples.exp3_multi_agent.parsers import (
    parse_household_response,
    parse_insurance_response,
    parse_government_response,
    HouseholdOutput
)
from examples.exp3_multi_agent.validators import HouseholdValidator
from examples.exp3_multi_agent.audit_writer import AuditWriter, AuditConfig
from examples.exp3_multi_agent.agents import HouseholdAgent
from examples.exp3_multi_agent.environment import SettlementModule

# V3 Unified Memory Interface
from examples.exp3_multi_agent.memory_helpers import add_memory

import argparse

# Configuration (defaults)
DEFAULT_YEARS = 10
OUTPUT_DIR = "examples/exp3_multi_agent/results"
SEED = 42
DEFAULT_MODEL = "llama3.2:3b"

# Global config placeholder (will be set in main)
CONFIG = {
    "years": DEFAULT_YEARS,
    "use_llm": False,
    "model": DEFAULT_MODEL,
    "output_dir": OUTPUT_DIR
}

# =============================================================================
# LLM CLIENT (Ollama)
# =============================================================================

def call_llm(prompt: str) -> Optional[str]:
    """
    Call Ollama LLM for response.
    
    Returns None if LLM unavailable (falls back to heuristic).
    """
    if not CONFIG["use_llm"]:
        return None
    
    try:
        import requests
        response = requests.post(
            "http://localhost:11434/api/generate",
            json={"model": CONFIG["model"], "prompt": prompt, "stream": False},
            timeout=30  # Reduced timeout
        )
        if response.status_code == 200:
            return response.json().get("response", "")
        else:
            print(f"[LLM] HTTP {response.status_code}")
            return None
    except requests.exceptions.ConnectionError:
        print("[LLM] Ollama not running - falling back to heuristic")
        return None
    except requests.exceptions.Timeout:
        print("[LLM] Request timeout - falling back to heuristic")
        return None
    except Exception as e:
        print(f"[LLM] Error: {e}")
        return None


def generate_heuristic_response(agent: HouseholdAgent, year: int, context: dict) -> str:
    """
    Generate heuristic response when LLM unavailable.
    
    Simulates PMT-based decision making.
    Aligned with skill_registry.yaml mappings:
    - Owner (non-elevated): 1=buy_insurance, 2=elevate_house, 3=buyout_program, 4=do_nothing
    - Owner (elevated): 1=buy_insurance, 2=buyout_program, 3=do_nothing
    - Renter: 1=buy_contents_insurance, 2=relocate, 3=do_nothing
    """
    s = agent.state
    is_owner = s.tenure == "Owner"
    is_elevated = s.elevated
    
    # Determine construct levels based on state
    tp = "HIGH" if s.cumulative_damage > s.property_value * 0.1 else ("MODERATE" if s.cumulative_damage > 0 else "LOW")
    cp = "HIGH" if s.income > 60000 else ("MODERATE" if s.income > 35000 else "LOW")
    sp = "HIGH" if context.get("government_subsidy_rate", 0.5) >= 0.5 else "MODERATE"
    sc = "MODERATE"
    pa = "FULL" if s.elevated and s.has_insurance else ("PARTIAL" if s.elevated or s.has_insurance else "NONE")
    
    # Determine decision based on agent type
    if s.relocated:
        # Already relocated - do nothing
        if is_owner:
            decision, num = "do_nothing", 3 if is_elevated else 4
        else:
            decision, num = "do_nothing", 3
    elif tp == "HIGH" and not s.has_insurance:
        # High threat, no insurance -> buy insurance
        if is_owner:
            decision, num = "buy_insurance", 1
        else:
            decision, num = "buy_contents_insurance", 1
    elif tp in ["MODERATE", "HIGH"] and not is_elevated and is_owner and sp == "HIGH":
        # Moderate+ threat, not elevated, owner with good subsidy -> elevate
        decision, num = "elevate_house", 2
    elif s.cumulative_damage > s.property_value * 0.5 and s.income < 40000:
        # Severe cumulative damage, low income -> leave
        if is_owner:
            decision, num = "buyout_program", 2 if is_elevated else 3
        else:
            decision, num = "relocate", 2
    else:
        # Default to do nothing
        if is_owner:
            decision, num = "do_nothing", 3 if is_elevated else 4
        else:
            decision, num = "do_nothing", 3
    
    justification = f"Based on {tp} threat and {cp} coping ability, {decision} is appropriate."
    
    return f"""
TP Assessment: {tp} - Cumulative damage ${s.cumulative_damage:,.0f}
CP Assessment: {cp} - Income ${s.income:,.0f}
SP Assessment: {sp} - Subsidy {context.get('government_subsidy_rate', 0.5):.0%}
SC Assessment: {sc} - Moderate confidence in ability to act
PA Assessment: {pa} - Elevated: {s.elevated}, Insured: {s.has_insurance}
Final Decision: {num}
Justification: {justification}
"""


# =============================================================================
# MAIN SIMULATION
# =============================================================================


def run_simulation():
    """Main simulation loop with full integration."""
    print(f"=" * 60)
    print(f"Exp3 Multi-Agent Simulation")
    print(f"Years: {CONFIG['years']}, LLM: {'Enabled (' + CONFIG['model'] + ')' if CONFIG['use_llm'] else 'Heuristic'}")
    print(f"=" * 60)
    
    # Initialize
    households, govs, ins = initialize_all_agents(seed=SEED)
    settlement = SettlementModule(seed=SEED)
    validator = HouseholdValidator()
    audit = AuditWriter(AuditConfig(output_dir=CONFIG["output_dir"]))
    
    print(f"Loaded {len(households)} household agents")
    print(f"Governments: {list(govs.keys())}")
    
    for year in range(1, CONFIG['years'] + 1):
        print(f"\n{'='*40}")
        print(f"YEAR {year}")
        print(f"{'='*40}")
        
        # =============================================
        # Phase 0: Annual Reset + Neighbor Observation
        # =============================================
        for hh in households:
            hh.reset_insurance()
        
        # V3: Social observation at year start
        elevated_count = sum(1 for h in households if h.state.elevated)
        insured_count = sum(1 for h in households if h.state.has_insurance)
        for hh in households:
            if not hh.state.relocated:
                if elevated_count > 0:
                    add_memory(hh.memory, "neighbor", {"type": "elevated", "count": elevated_count}, year)
                if insured_count > 0:
                    add_memory(hh.memory, "neighbor", {"type": "insured", "count": insured_count}, year)
        
        # =============================================
        # Phase 1: Institutional Decisions
        # =============================================
        for gov_id, gov in govs.items():
            gov.reset_annual_budget(year)
        ins.reset_annual_metrics()
        
        # =============================================
        # Phase 2: Household Decisions
        # =============================================
        actions = {
            "do_nothing": 0, 
            "buy_insurance": 0, 
            "buy_contents_insurance": 0,
            "elevate_house": 0, 
            "relocate": 0,
            "buyout_program": 0
        }
        validation_warnings = 0
        validation_errors = 0
        
        for hh in households:
            if hh.state.relocated:
                continue
            
            # Get region-specific government
            gov = govs.get(hh.state.region_id, govs["NJ"])
            
            # Build context
            context = {
                "government_subsidy_rate": gov.state.subsidy_rate,
                "insurance_premium_rate": ins.state.premium_rate,
                "flood_occurred": False,
                "year": year
            }
            
            # Get agent state dict
            state_dict = {
                "mg": hh.state.mg,
                "tenure": hh.state.tenure,
                "region_id": hh.state.region_id,
                "elevated": hh.state.elevated,
                "has_insurance": hh.state.has_insurance,
                "cumulative_damage": hh.state.cumulative_damage,
                "income": hh.state.income,
                "property_value": hh.state.property_value,
                # Demographics
                "generations": hh.state.generations_in_area,
                "household_size": hh.state.household_size,
                "has_vehicle": hh.state.has_vehicle
            }
            
            # Get memory
            memories = hh.memory.retrieve(top_k=5, current_year=year)
            
            # Build prompt
            prompt = build_household_prompt(state_dict, context, memories)
            
            # Get LLM response or heuristic
            llm_response = call_llm(prompt)
            if llm_response is None:
                llm_response = generate_heuristic_response(hh, year, context)
            
            # Parse response
            output = parse_household_response(
                llm_response,
                hh.state.id,
                hh.state.mg,
                hh.state.tenure,
                year,
                hh.state.elevated
            )
            
            # Validate
            val_result = validator.validate(output, state_dict)
            if not val_result.valid:
                validation_errors += 1
                output.validated = False
                output.validation_errors.extend(val_result.errors)
            if val_result.warnings:
                validation_warnings += 1
            
            # Apply decision
            actions[output.decision_skill] = actions.get(output.decision_skill, 0) + 1
            hh.apply_decision(output)
            
            # V3: Explicit decision memory
            add_memory(hh.memory, "decision", {"skill_id": output.decision_skill}, year)
            
            # Audit
            audit.write_household_trace(output, state_dict, context)
        
        print(f"Actions: {actions}")
        print(f"Validation: {validation_errors} errors, {validation_warnings} warnings")
        
        # =============================================
        # Phase 3: Settlement
        # =============================================
        report = settlement.process_year(year, households, ins, govs["NJ"])
        
        if report.flood_occurred:
            print(f"🌊 FLOOD! Damage: ${report.total_damage:,.0f}, Claims: ${report.total_claims:,.0f}")
            
            # V3: Record flood memories for each household
            for hh in households:
                if not hh.state.relocated and hasattr(hh.state, 'last_year_damage'):
                    damage = getattr(hh.state, 'last_year_damage', 0)
                    if damage > 0:
                        add_memory(hh.memory, "flood", {"damage": damage}, year)
                        if hh.state.has_insurance:
                            add_memory(hh.memory, "claim", {
                                "filed": True, 
                                "approved": True,
                                "payout": damage * 0.9  # Estimate
                            }, year)
        else:
            print("No flood.")
        
        # Cumulative stats
        cum_insured = sum(1 for h in households if h.state.has_insurance)
        cum_elevated = sum(1 for h in households if h.state.elevated)
        cum_relocated = sum(1 for h in households if h.state.relocated)
        print(f"Cumulative: Insured={cum_insured}, Elevated={cum_elevated}, Relocated={cum_relocated}")
    
    # =============================================
    # Finalize
    # =============================================
    summary = audit.finalize()
    print(f"\n{'='*60}")
    print("SIMULATION COMPLETE")
    print(f"{'='*60}")
    print(f"Total household decisions: {summary['total_household_decisions']}")
    print(f"Decision distribution: {summary.get('decision_rates', {})}")
    print(f"Validation failure rate: {summary.get('validation_failure_rate', 'N/A')}")


if __name__ == "__main__":
    parser = argparse.ArgumentParser(description="Run Exp3 Multi-Agent Simulation")
    parser.add_argument("--years", type=int, default=DEFAULT_YEARS, help="Number of years to simulate")
    parser.add_argument("--use-llm", action="store_true", help="Enable LLM (Ollama) execution")
    parser.add_argument("--model", type=str, default=DEFAULT_MODEL, help="Ollama model name")
    
    args = parser.parse_args()
    
    CONFIG["years"] = args.years
    CONFIG["use_llm"] = args.use_llm
    CONFIG["model"] = args.model
    
    run_simulation()
