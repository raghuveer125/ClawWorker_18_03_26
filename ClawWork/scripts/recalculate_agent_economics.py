#!/usr/bin/env python3
"""
Recalculate Agent Economics with Real Task Values

This script retroactively corrects payment values for existing agent runs
that used the old uniform $50 payment. It scales actual payments (which already
include evaluation logic like the 0.6 cliff) based on real task values.

Usage:
    python recalculate_agent_economics.py <agent_data_dir>

Example:
    python recalculate_agent_economics.py livebench/data/agent_data/GLM-4.7-test-openrouter-10dollar-1
"""

import os
import sys
import json
import shutil
from pathlib import Path
from datetime import datetime
from typing import Dict, List, Any


def log_message(message: str):
    """Log messages with timestamp"""
    timestamp = datetime.now().strftime("%Y-%m-%d %H:%M:%S")
    print(f"[{timestamp}] {message}")


def load_task_values(task_values_path: str) -> Dict[str, float]:
    """Load task values from JSONL file"""
    task_values = {}

    if not os.path.exists(task_values_path):
        raise FileNotFoundError(f"Task values file not found: {task_values_path}")

    with open(task_values_path, 'r') as f:
        for line in f:
            try:
                entry = json.loads(line.strip())
                task_id = entry.get('task_id')
                task_value = entry.get('task_value_usd')
                if task_id and task_value is not None:
                    task_values[task_id] = float(task_value)
            except json.JSONDecodeError:
                continue

    log_message(f"Loaded {len(task_values)} task values")
    values = list(task_values.values())
    log_message(f"Price range: ${min(values):.2f} - ${max(values):.2f}, avg: ${sum(values)/len(values):.2f}")
    return task_values


def load_tasks(agent_dir: Path) -> List[Dict[str, Any]]:
    """Load task assignments from work/tasks.jsonl"""
    tasks_file = agent_dir / "work" / "tasks.jsonl"

    if not tasks_file.exists():
        raise FileNotFoundError(f"Tasks file not found: {tasks_file}")

    tasks = []
    with open(tasks_file, 'r') as f:
        for line in f:
            try:
                tasks.append(json.loads(line.strip()))
            except json.JSONDecodeError:
                continue

    log_message(f"Loaded {len(tasks)} task assignments")
    return tasks


def load_balance_history(agent_dir: Path) -> List[Dict[str, Any]]:
    """Load balance history from economic/balance.jsonl"""
    balance_file = agent_dir / "economic" / "balance.jsonl"

    if not balance_file.exists():
        raise FileNotFoundError(f"Balance file not found: {balance_file}")

    balance_history = []
    with open(balance_file, 'r') as f:
        for line in f:
            try:
                balance_history.append(json.loads(line.strip()))
            except json.JSONDecodeError:
                continue

    log_message(f"Loaded {len(balance_history)} balance entries")
    return balance_history


def create_date_to_task_mapping(tasks: List[Dict[str, Any]]) -> Dict[str, str]:
    """Create mapping from date to task_id from tasks.jsonl"""
    date_to_task = {}

    for task in tasks:
        date = task.get('date')
        task_id = task.get('task_id')

        if date and task_id:
            date_to_task[date] = task_id

    log_message(f"Created date→task mapping for {len(date_to_task)} dates")
    return date_to_task


def recalculate_balance_history(
    balance_history: List[Dict[str, Any]],
    date_to_task: Dict[str, str],
    task_values: Dict[str, float],
    default_max_payment: float = 50.0
) -> tuple[List[Dict[str, Any]], Dict[str, Dict[str, float]]]:
    """
    Recalculate balance history by scaling actual payments

    This preserves evaluation logic (0.6 cliff, etc.) by scaling actual payments
    rather than recalculating from scores.

    Formula: new_payment = old_payment × (real_task_value / 50)
    """
    new_balance_history = []
    payment_corrections = {}

    # Get initial balance from first entry
    if not balance_history:
        return [], {}

    # Initialize tracking variables
    current_balance = balance_history[0].get('balance', 0.0)
    cumulative_income = 0.0
    cumulative_costs = 0.0

    # Process first entry (initialization)
    first_entry = balance_history[0].copy()
    if first_entry.get('date') == 'initialization':
        new_balance_history.append(first_entry)
        current_balance = first_entry['balance']

    # Process remaining entries
    for entry in balance_history:
        if entry.get('date') == 'initialization':
            continue

        date = entry['date']
        old_work_income = entry.get('work_income_delta', 0.0)
        token_costs = entry.get('token_cost_delta', 0.0)

        # Find task and real value for this date
        new_work_income = old_work_income
        correction_applied = False
        task_id = None
        real_task_value = default_max_payment

        if date in date_to_task:
            task_id = date_to_task[date]
            real_task_value = task_values.get(task_id, default_max_payment)

            # Scale the actual payment by the ratio of real value to $50
            # This preserves evaluation logic (cliff at 0.6, score, etc.)
            if old_work_income > 0:
                scaling_factor = real_task_value / default_max_payment
                new_work_income = old_work_income * scaling_factor
                correction_applied = True

                # Track correction
                payment_corrections[task_id] = {
                    'date': date,
                    'old_payment': old_work_income,
                    'new_payment': new_work_income,
                    'old_max_payment': default_max_payment,
                    'real_task_value': real_task_value,
                    'scaling_factor': scaling_factor
                }

        # Update cumulative totals
        cumulative_income += new_work_income
        cumulative_costs += token_costs

        # Calculate new balance
        net_change = new_work_income - token_costs
        current_balance += net_change

        # Create corrected entry
        new_entry = entry.copy()
        new_entry['work_income_delta'] = new_work_income
        new_entry['work_income_delta_old'] = old_work_income
        new_entry['total_work_income'] = cumulative_income
        new_entry['total_token_cost'] = cumulative_costs
        new_entry['balance'] = current_balance
        new_entry['net_worth'] = current_balance
        new_entry['correction_applied'] = correction_applied
        if task_id:
            new_entry['task_id'] = task_id
            new_entry['real_task_value'] = real_task_value

        new_balance_history.append(new_entry)

    return new_balance_history, payment_corrections


def save_corrected_data(
    agent_dir: Path,
    new_balance_history: List[Dict[str, Any]],
    payment_corrections: Dict[str, Dict[str, float]]
):
    """Save corrected data to new economic_real_value directory"""

    # Create new directory
    output_dir = agent_dir / "economic_real_value"
    output_dir.mkdir(exist_ok=True)

    # Save corrected balance history
    balance_file = output_dir / "balance.jsonl"
    with open(balance_file, 'w') as f:
        for entry in new_balance_history:
            f.write(json.dumps(entry) + '\n')
    log_message(f"Saved corrected balance history: {balance_file}")

    # Generate and save summary
    if new_balance_history:
        final_entry = new_balance_history[-1]
        init_entry = new_balance_history[0]

        # Calculate old final balance
        old_cumulative_income = sum(
            e.get('work_income_delta_old', 0)
            for e in new_balance_history if e.get('date') != 'initialization'
        )
        old_cumulative_costs = sum(
            e.get('token_cost_delta', 0)
            for e in new_balance_history if e.get('date') != 'initialization'
        )
        old_final_balance = init_entry.get('balance', 0) + old_cumulative_income - old_cumulative_costs

        summary = {
            'correction_date': datetime.now().isoformat(),
            'total_tasks_corrected': len(payment_corrections),
            'final_balance_old': old_final_balance,
            'final_balance_new': final_entry.get('balance', 0.0),
            'balance_change': final_entry.get('balance', 0.0) - old_final_balance,
            'total_work_income_old': old_cumulative_income,
            'total_work_income_new': final_entry.get('total_work_income', 0.0),
            'income_change': final_entry.get('total_work_income', 0.0) - old_cumulative_income,
            'payment_corrections': payment_corrections
        }

        summary_file = output_dir / "correction_summary.json"
        with open(summary_file, 'w') as f:
            json.dump(summary, f, indent=2)
        log_message(f"Saved correction summary: {summary_file}")

    # Copy token_costs.jsonl unchanged (costs don't change)
    original_costs = agent_dir / "economic" / "token_costs.jsonl"
    if original_costs.exists():
        shutil.copy(original_costs, output_dir / "token_costs.jsonl")
        log_message(f"Copied token_costs.jsonl (unchanged)")


def print_summary(
    payment_corrections: Dict[str, Dict[str, float]],
    original_balance: List[Dict[str, Any]],
    new_balance: List[Dict[str, Any]]
):
    """Print summary of corrections"""
    print("\n" + "="*70)
    print("CORRECTION SUMMARY")
    print("="*70)

    if not payment_corrections:
        print("\n⚠️  No corrections applied (no matching tasks with payments)")
        return

    total_old = sum(c['old_payment'] for c in payment_corrections.values())
    total_new = sum(c['new_payment'] for c in payment_corrections.values())
    difference = total_new - total_old

    # Calculate final balances
    init_balance = original_balance[0].get('balance', 0) if original_balance else 0
    old_income = sum(e.get('work_income_delta', 0) for e in original_balance if e.get('date') != 'initialization')
    old_costs = sum(e.get('token_cost_delta', 0) for e in original_balance if e.get('date') != 'initialization')
    old_final = init_balance + old_income - old_costs

    new_final = new_balance[-1].get('balance', 0) if new_balance else 0

    print(f"\n📊 Payment Corrections:")
    print(f"   Total tasks corrected: {len(payment_corrections)}")
    print(f"   Old total payments: ${total_old:.2f}")
    print(f"   New total payments: ${total_new:.2f}")
    print(f"   Payment difference: ${difference:+.2f}")

    print(f"\n💰 Final Economic State:")
    print(f"   Old final balance: ${old_final:.2f}")
    print(f"   New final balance: ${new_final:.2f}")
    print(f"   Balance change: ${new_final - old_final:+.2f}")

    print(f"\n📈 Top 10 Largest Corrections:")
    sorted_corrections = sorted(
        payment_corrections.items(),
        key=lambda x: abs(x[1]['new_payment'] - x[1]['old_payment']),
        reverse=True
    )
    for i, (task_id, correction) in enumerate(sorted_corrections[:10], 1):
        diff = correction['new_payment'] - correction['old_payment']
        print(f"   {i:2d}. {correction['date']} | Task {task_id[:8]}...")
        print(f"       Old: ${correction['old_payment']:.2f} → New: ${correction['new_payment']:.2f} (${diff:+.2f})")
        print(f"       Real value: ${correction['real_task_value']:.2f} (scale: {correction['scaling_factor']:.2f}×)")

    # Show zero-payment tasks (below 0.6 cliff)
    zero_payment_count = sum(1 for e in original_balance
                             if e.get('date') != 'initialization'
                             and e.get('date') in [c['date'] for c in payment_corrections.values()]
                             and e.get('work_income_delta', 0) == 0)
    if zero_payment_count > 0:
        print(f"\n⚠️  Note: {zero_payment_count} tasks had $0 payment (below 0.6 evaluation cliff)")

    print("\n" + "="*70)


def main():
    """Main execution function"""
    if len(sys.argv) < 2:
        print("Usage: python recalculate_agent_economics.py <agent_data_dir>")
        print("\nExample:")
        print("  python recalculate_agent_economics.py livebench/data/agent_data/GLM-4.7-test-openrouter-10dollar-1")
        sys.exit(1)

    agent_dir_path = sys.argv[1]
    agent_dir = Path(agent_dir_path)

    if not agent_dir.exists():
        print(f"❌ Error: Agent directory not found: {agent_dir}")
        sys.exit(1)

    print("\n" + "="*70)
    print("RECALCULATE AGENT ECONOMICS WITH REAL TASK VALUES")
    print("="*70)
    print(f"\nAgent directory: {agent_dir}")
    print(f"Output directory: {agent_dir / 'economic_real_value'}")

    try:
        # Load task values
        log_message("\n1. Loading task values...")
        task_values_path = "./scripts/task_value_estimates/task_values.jsonl"
        task_values = load_task_values(task_values_path)

        # Load agent data
        log_message("\n2. Loading agent data...")
        tasks = load_tasks(agent_dir)
        balance_history = load_balance_history(agent_dir)

        # Create date→task mapping
        log_message("\n3. Creating date→task mapping from tasks.jsonl...")
        date_to_task = create_date_to_task_mapping(tasks)

        # Recalculate balance history and payments
        log_message("\n4. Recalculating balance history by scaling actual payments...")
        new_balance_history, payment_corrections = recalculate_balance_history(
            balance_history, date_to_task, task_values
        )

        # Save corrected data
        log_message("\n5. Saving corrected data...")
        save_corrected_data(agent_dir, new_balance_history, payment_corrections)

        # Print summary
        print_summary(payment_corrections, balance_history, new_balance_history)

        log_message("\n✅ Recalculation complete!")
        print(f"\nCorrected data saved to: {agent_dir / 'economic_real_value'}")
        print(f"  - balance.jsonl (corrected payments & balances)")
        print(f"  - correction_summary.json (detailed corrections)")
        print(f"  - token_costs.jsonl (copied unchanged)")

    except Exception as e:
        print(f"\n❌ Error: {e}")
        import traceback
        traceback.print_exc()
        sys.exit(1)


if __name__ == "__main__":
    main()
