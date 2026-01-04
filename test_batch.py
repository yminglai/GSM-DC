import os
import re
import json
import torch
import threading
import pandas as pd
from tqdm import tqdm
from transformers import AutoModelForCausalLM, AutoTokenizer
from data_gen.pretrain.id_gen import IdGen
from tools.tools import tokenizer, fix_seed
from tools.irr_tools_test import true_correct
from math_gen.problem_gen import Problem, Expression
# from tools.tools_test import true_correct
from data_gen.prototype.id_gen import IdGen_PT
from typing import List
from prm_tree import tree_search
import sys
import networkx as nx
from format.format import format_prompt
import numpy as np

# =============== 环境与全局配置 ===============
device = "cuda" if torch.cuda.is_available() else "cpu"
fix_seed(42)

MODEL_NAME = "Llama-3.2-1B-Instruct"
MODEL_DIRECTORY = "~/.cache/huggingface/transformers"

# 是否使用微调后的模型
# OP 范围从 4 到 5 for testing (update as needed)
# 每个条件下生成问题的数量
PRM_MODEL_NAME = "remy9926/llama1b_in_dist_prm"
prm_model = AutoModelForCausalLM.from_pretrained(PRM_MODEL_NAME).to(device)
print(f"PRM: {PRM_MODEL_NAME}")
# =============== 模型加载 ===============
MODEL_PATH = "/home/mingly/LLaMA-Factory/saves/Llama-3.2-1B-Instruct/full/light_mix"
model_name = MODEL_PATH.split("/")[-1]
# print(f"MODEL: {MODEL_PATH}")
# if not os.path.exists(MODEL_PATH):
#     raise FileNotFoundError(f"Model directory not found: {MODEL_PATH}")
# print("Loading models...")
# models = AutoModelForCausalLM.from_pretrained(MODEL_PATH).to(device)
# models.eval()
# print("Models loaded successfully!")
print("Loading tokenizer...")
model_tokenizer = AutoTokenizer.from_pretrained("meta-llama/Llama-3.2-1B-Instruct")
model_tokenizer.pad_token = model_tokenizer.eos_token  # Ensure pad token is set


# =-=-=-=-=-=-=-=-=-=-=-=-=-=-=-=-=-=-=-=-=-=-=-=-=-=-=-=-=-=-=-=-=-=-=-=-=
# 1) Convert a Problem object to JSON 
#    (including topological_order if it exists, 
#     and also storing whole_template).
# =-=-=-=-=-=-=-=-=-=-=-=-=-=-=-=-=-=-=-=-=-=-=-=-=-=-=-=-=-=-=-=-=-=-=-=-=
def expression_to_relationship(expr: Expression) -> dict:
    """
    将 Expression 对象转换为字典表示，记录其运算关系：
    - "op": 运算符（如果没有则标记为 "const" 表示常数）
    - "value": 若存在，记录其数值（取 self.value.a）
    - "children": 子表达式的递归列表
    """
    rel = {
        "op": expr.op if expr.op is not None else "const",
        "children": []
    }
    if hasattr(expr, "value"):
        rel["value"] = expr.value.a
    for child in expr.param_list:
        rel["children"].append(expression_to_relationship(child))
    return rel

def problem_to_json(problem: Problem) -> dict:
    d  = int(problem.d)
    w0 = int(problem.w0)
    w1 = int(problem.w1)
    e  = int(problem.e)
    p  = float(problem.p)

    # question_index
    if hasattr(problem, "ques_idx") and problem.ques_idx is not None:
        question_index = [int(x) for x in problem.ques_idx]
    else:
        question_index = None

    # final_answer
    final_answer = problem.ans if hasattr(problem, "ans") else None
    if final_answer is not None:
        final_answer = int(final_answer)

    # --- 修改 node_data: 使用节点的 label 作为 key, 并保存节点坐标和 unique ---
    node_data = {}
    for (layer, idx), data in problem.graph.nodes(data=True):
        label = str(problem.N[layer][idx])
        node_data[label] = {
            "node": f"({int(layer)}, {int(idx)})",
            "unique": bool(data.get('unique', False))
        }

    # edges in structure graph
    edges = []
    for u, v in problem.graph.edges():
        edges.append([str(u), str(v)])

    # template edges
    template_edges = []
    for u, v in problem.template.edges():
        template_edges.append([str(u), str(v)])

    # whole_template edges
    whole_template_edges = []
    if hasattr(problem, "whole_template"):
        for u, v in problem.whole_template.edges():
            whole_template_edges.append([str(u), str(v)])

    # problem_text, solution_text
    problem_text = problem.problem if hasattr(problem, "problem") else []
    solution_text = problem.solution if hasattr(problem, "solution") else []

    # ln
    ln = [str(x) for x in problem.ln]

    # all_param
    all_param = []
    if hasattr(problem, "all_param"):
        all_param = [str(param) for param in problem.all_param]

    # --- 修改 topological_order：每个元素为对象，包含 param 和 description ---
    topo_list = []
    if hasattr(problem, "topological_order") and problem.topological_order:
        for param in problem.topological_order:
            param_str = str(param)
            # 假设 param 为元组 (l, i, j, k)
            l, i, j, k = param
            if l == -1:
                description = "RNG"
            elif l == 0:
                name0 = problem.N[i][j]
                name1 = problem.N[i+1][k]
                description = f"{name0}{problem.args['dot']}{name1}"
            elif l == 1:
                name0 = problem.N[i][j]
                cat   = problem.ln[k]
                description = f"{name0}{problem.args['dot']}{cat}"
            else:
                description = f"UnsupportedParam{param}"
            topo_list.append({
                "param": param_str,
                "description": description
            })

    # 新增：将每个参数对应的 Expression（即运算关系）保存为 JSON 结构
    expression_relationships = {}
    if hasattr(problem, "sketch"):
        for param, expr in problem.sketch.items():
            expression_relationships[str(param)] = expression_to_relationship(expr)

    out_dict = {
        "problem_info": {
            "d": d,
            "w0": w0,
            "w1": w1,
            "e": e,
            "p": p,
            "final_answer": final_answer,
            "question_index": question_index
        },
        "node_data": node_data,
        "edges": edges,
        "template_edges": template_edges,
        "whole_template_edges": whole_template_edges,
        "ln": ln,
        "all_param": all_param,
        "problem_text": problem_text,
        "solution_text": solution_text,
        "topological_order": topo_list,
        "expression_relationships": expression_relationships  # 新增字段，记录 add、mul 和 diff 关系
    }
    return out_dict

# =-=-=-=-=-=-=-=-=-=-=-=-=-=-=-=-=-=-=-=-=-=-=-=-=-=-=-=-=-=-=-=-=-=-=-=-=
# 2) Load from JSON and re-construct a Problem object,
#    then restore topological_order, whole_template, and compute n_op.
# =-=-=-=-=-=-=-=-=-=-=-=-=-=-=-=-=-=-=-=-=-=-=-=-=-=-=-=-=-=-=-=-=-=-=-=-=
def load_problem_from_json(file_path: str) -> dict:
    with open(file_path, "r", encoding='utf-8') as f:
        data = json.load(f)
    return data

def parse_param_str(s: str):
    inside = s.strip("()")
    parts = inside.split(",")
    if len(parts) != 4:
        raise ValueError(f"param tuple must have length 4, got {s}")
    return tuple(int(x.strip()) for x in parts)

def rebuild_problem_from_json(data_dict: dict) -> Problem:
    info = data_dict["problem_info"]
    d  = int(info["d"])
    w0 = int(info["w0"])
    w1 = int(info["w1"])
    e  = int(info["e"])
    p  = float(info["p"])
    final_answer = info["final_answer"]
    if final_answer is not None:
        final_answer = int(final_answer)
    question_index = info["question_index"]

    # IMPORTANT: Hardcode the dot as "'s "
    args = {
        "rand_perm": "none",
        "define_var": True,
        "define_detail": True,
        "inter_var": True,
        "name_omit": False,
        "cal_omit": False,
        "dot": "'s ",
        "symbol_method": "rand",
        "sol_sort": False,
        "perm": False
    }
    problem = Problem(d, w0, w1, e, p, args=args)

    # --- 修改 node_data 重建过程 ---
    node_data = data_dict["node_data"]
    layer_counts = {}
    for key, value in node_data.items():
        node_str = value["node"]  # 例如 "(0, 0)"
        layer_str, idx_str = node_str.strip("()").split(",")
        layer = int(layer_str)
        idx   = int(idx_str)
        layer_counts[layer] = max(layer_counts.get(layer, 0), idx+1)
    for i in range(d):
        problem.l[i] = layer_counts.get(i, 0)

    problem.graph = nx.DiGraph()
    for i in range(d):
        for j in range(problem.l[i]):
            problem.graph.add_node((i, j), unique=False)

    problem.N = []
    for i in range(d):
        problem.N.append([""] * problem.l[i])

    for key, value in node_data.items():
        node_str = value["node"]
        layer_str, idx_str = node_str.strip("()").split(",")
        layer = int(layer_str)
        idx   = int(idx_str)
        label = key  # 使用 JSON 中的键作为 label
        problem.N[layer][idx] = label
        problem.graph.nodes[(layer, idx)]["unique"] = bool(value["unique"])
        if bool(value["unique"]):
            problem.unique.append((layer, idx))

    edges = data_dict["edges"]
    for u_str, v_str in edges:
        ulayer_idx = u_str.strip("()").split(",")
        u_layer = int(ulayer_idx[0])
        u_idx   = int(ulayer_idx[1])
        vlayer_idx = v_str.strip("()").split(",")
        v_layer = int(vlayer_idx[0])
        v_idx   = int(vlayer_idx[1])
        problem.graph.add_edge((u_layer, u_idx), (v_layer, v_idx), chosen=False)

    problem.G = []
    for i in range(d - 1):
        M = np.zeros((problem.l[i], problem.l[i+1]), dtype=bool)
        for j in range(problem.l[i]):
            for k in range(problem.l[i+1]):
                if problem.graph.has_edge((i, j), (i+1, k)):
                    M[j, k] = True
        problem.G.append(M)

    ln_list = data_dict.get("ln", [])
    problem.ln = [str(x) for x in ln_list]

    # template
    problem.template = nx.DiGraph()
    template_edges = data_dict["template_edges"]
    node_set = set()
    for u_str, v_str in template_edges:
        node_set.add(u_str)
        node_set.add(v_str)
    for n_str in node_set:
        param_tup = parse_param_str(n_str)
        problem.template.add_node(param_tup)
    for u_str, v_str in template_edges:
        u_tup = parse_param_str(u_str)
        v_tup = parse_param_str(v_str)
        problem.template.add_edge(u_tup, v_tup)

    # whole_template
    whole_template_edges = data_dict.get("whole_template_edges", [])
    problem.whole_template = nx.DiGraph()
    wt_node_set = set()
    for u_str, v_str in whole_template_edges:
        wt_node_set.add(u_str)
        wt_node_set.add(v_str)
    for n_str in wt_node_set:
        param_tup = parse_param_str(n_str)
        problem.whole_template.add_node(param_tup)
    for u_str, v_str in whole_template_edges:
        u_tup = parse_param_str(u_str)
        v_tup = parse_param_str(v_str)
        problem.whole_template.add_edge(u_tup, v_tup)

    # all_param
    problem.all_param = []
    if "all_param" in data_dict:
        for sp in data_dict["all_param"]:
            problem.all_param.append(parse_param_str(sp))

    problem.ans = final_answer if final_answer is not None else 0
    if question_index is not None:
        problem.ques_idx = tuple(question_index)

    # --- 修改 topological_order 重建过程 ---
    topo_list = data_dict.get("topological_order", [])
    if topo_list:
        problem.topological_order = [
            parse_param_str(item["param"]) if isinstance(item, dict) else parse_param_str(item)
            for item in topo_list
        ]
    else:
        problem.topological_order = []

    # *** NEW CODE: Recompute n_op from topological_order ***
    n_op = 0
    for param in problem.topological_order:
        num_pre = len(list(problem.template.predecessors(param)))
        if num_pre <= 2:
            n_op += 1
        else:
            n_op += num_pre - 1
    problem.n_op = n_op

    build_name2param_dict(problem)

    # Also restore textual problem/solution
    prob_text = data_dict.get("problem_text", [])
    sol_text  = data_dict.get("solution_text", [])
    problem.problem  = prob_text
    problem.solution = sol_text

    return problem

def build_name2param_dict(problem: Problem):
    problem.name2param_dict = {}
    for param in problem.all_param:
        l, i, j, k = param
        if l == -1:
            param_name = "RNG"
        elif l == 0:
            name0 = problem.N[i][j]
            name1 = problem.N[i+1][k]
            param_name = f"{name0}{problem.args['dot']}{name1}"
        elif l == 1:
            name0 = problem.N[i][j]
            cat   = problem.ln[k]
            param_name = f"{name0}{problem.args['dot']}{cat}"
        else:
            param_name = f"UnsupportedParam{param}"
        problem.name2param_dict[param_name] = param

# =============== 提取最终答案函数 ===============
def extract_final_answer(text):
    """
    提取文本中形如 "The final answer is <<x>>." 中的 x，
    或者提取文本中第一个连续的数字（忽略空格），返回 x（字符串形式），
    如果没有匹配到则返回 None。
    """
    # First try to match the expected pattern; if not, fall back to any digit sequence.
    pattern = r"<<\s*(\d+)\s*>>"
    match = re.search(pattern, text)
    if match:
        return match.group(1).strip()
    # fallback: extract first sequence of digits
    match = re.search(r'(\d+)', text)
    if match:
        return match.group(1).strip()
    return None

# =============== Generate Math Problem ===============
def generate_problem(op=3):
    id_gen = IdGen_PT(
        style="light",
        op_style="light",
        op=op,
        perm_level=5,
        detail_level=0
    )
    id_gen.gen_prob([i for i in range(5)], p_format="pq")
    return id_gen

# =============== Generate Response Using LLaMA Model ===============
def generate_response(op, problem, nshots, model, cur_id_gen):
    input_text = format_prompt(True, problem, op=op, nshots=nshots, cur_id_gen=cur_id_gen, tokenizer=tokenizer, generate_problem=generate_problem)
    inputs = model_tokenizer(
        input_text,
        return_tensors="pt",
        # padding=True,
        # truncation=True,
        # max_length=2048,
    )
    input_len = inputs.input_ids.shape[1]
    inputs = {key: value.to(device) for key, value in inputs.items()}

    with torch.no_grad():
        # outputs = model.generate(**inputs, max_new_tokens=1024)
        outputs = tree_search(prm_model, model, model_tokenizer, inputs["input_ids"], 16, 4, 6*op, 0.8, device)

    generated_text = model_tokenizer.decode(outputs[0][input_len - 1:], skip_special_tokens=True)
    return generated_text.strip()
# =============== 评估函数 ===============
def evaluate(op: int, model, results_dict):
    """
    针对给定 op 的模型进行评估，将结果存放在 results_dict 中。
    新增的 extracted_correct 指标：仅比较最终答案是否正确。
    使用 id_gen.ans_token 作为地面真值答案，并抽取其中的数字进行比对。
    """

    results = []
    eval_dir = "eval"
    os.makedirs(eval_dir, exist_ok=True)
    output_file = f"{eval_dir}/{model_name}_op{op}_test.json"
    start = (op - 2)*300
    end = (op - 1)*300
    
    with open("./all_problems.json", "r") as file:
        data = json.load(file)
    
    data = data[start: end]

    conditions = {
        "Condition_1": {"correct": 0, "incorrect": 0, "irr_correct": 0, "irr_incorrect": 0, "extracted_correct": 0, "count": 0},
        "Condition_2": {"correct": 0, "incorrect": 0, "irr_correct": 0, "irr_incorrect": 0, "extracted_correct": 0, "count": 0},
        "Condition_3": {"correct": 0, "incorrect": 0, "irr_correct": 0, "irr_incorrect": 0, "extracted_correct": 0, "count": 0}
    }
    
    # num_problems = (end - start) // len(conditions)
    num_problems = 50

    progress_bar = tqdm(
        # total= end - start,
        total= num_problems*3,
        desc=f"Evaluating OP={op}",
        unit="problem"
    )

    for j in range(len(conditions.keys())):
        condition = list(conditions.keys())[j]
        for i in range(num_problems):
            problem = rebuild_problem_from_json(data[(j*100)+i])
            tokenized_problem = tokenizer.encode(". ".join(problem.problem))
            tokenized_problem[0] = 383
            # Use ans_token as ground truth answer (may include extra spaces)
            problem_text = tokenizer.decode(tokenized_problem)
            predicted_solution = generate_response(op, problem_text, 5, model, None)
            irr_correct, correct, my_print, _ = true_correct(predicted_solution, problem)

            pred_final = extract_final_answer(predicted_solution)
            actual_final = int(data[(j*100)+i]["problem_info"]["final_answer"])
            extracted_correct = int(pred_final is not None and actual_final is not None and pred_final == actual_final)

            conditions[condition]["correct"] += int(correct)
            conditions[condition]["incorrect"] += int(not correct)
            conditions[condition]["irr_correct"] += int(irr_correct)
            conditions[condition]["irr_incorrect"] += int(not irr_correct)
            conditions[condition]["extracted_correct"] += extracted_correct

            results.append({
                'problem': problem_text,
                'predicted_solution': predicted_solution,
                'correct': correct,
                'irr_correct': irr_correct,
                'extracted_correct': extracted_correct,
                'input_prompt': format_prompt(True, problem_text, op=op, nshots=5, cur_id_gen=None, tokenizer=tokenizer, generate_problem=generate_problem)
            })
            progress_bar.update(1)

    progress_bar.close()

    correct_count = sum(1 for r in results if r["correct"])
    irr_correct_count = sum(1 for r in results if r["irr_correct"])
    extracted_correct_count = sum(1 for r in results if r["extracted_correct"])
    total_samples = 300

    accuracy = (correct_count / total_samples) * 100
    irr_correct_accuracy = (irr_correct_count / total_samples) * 100
    extracted_accuracy = (extracted_correct_count / total_samples) * 100

    condition_accuracies = {
        condition: (data["correct"] / data["count"] * 100 if data["count"] > 0 else 0)
        for condition, data in conditions.items()
    }
    condition_irr_accuracies = {
        condition: (data["irr_correct"] / data["count"] * 100 if data["count"] > 0 else 0)
        for condition, data in conditions.items()
    }
    condition_extracted_accuracies = {
        condition: (data["extracted_correct"] / data["count"] * 100 if data["count"] > 0 else 0)
        for condition, data in conditions.items()
    }

    results_dict[op] = {
        "accuracy": accuracy,
        "irr_correct_accuracy": irr_correct_accuracy,
        "extracted_accuracy": extracted_accuracy,
        "correct": correct_count,
        "irr_correct": irr_correct_count,
        "extracted_correct": extracted_correct_count,
        "total": total_samples,
        "condition_accuracies": condition_accuracies,
        "condition_irr_accuracies": condition_irr_accuracies,
        "condition_extracted_accuracies": condition_extracted_accuracies,
        "results": results
    }

    # 保存到 JSON 文件
    with open(output_file, "w", encoding="utf-8") as json_file:
        json.dump(results, json_file, indent=4, ensure_ascii=False)
    print(f"✅ OP={op} results saved to {output_file}")

# names = ["stage1_clean", "stage2_light_med", "stage3_medium_med", "stage4_hard_med"]
# names = ["stage1_clean", "stage3_medium_med"]
names = ["stage2_light_med", "stage4_hard_med"]
path_dir = "../../LLaMA-Factory/saves/Llama-3.2-1B-Instruct/full/"

for name in names:
    model_name = name
    print(f"Currently evaluating {model_name}")
    # =============== 多线程评估 ===============
    results_dict = {}
    threads = []

    model = AutoModelForCausalLM.from_pretrained(path_dir + model_name).to(device)
    model.eval()

    #parallelize the branches
    for op in range(16, 23):
        evaluate(op, model, results_dict)

    model.cpu()

# for op in OP_VALUES:
#     thread = threading.Thread(target=evaluate, args=(op, models[op], results_dict))
#     threads.append(thread)
#     thread.start()
#     print(f"Thread for OP={op} started!")

# for thread in threads:
#     thread.join()

# =============== 最终结果打印 ===============
print("\n========== FINAL RESULTS ==========")
for op, res in results_dict.items():
    print(f"OP={op}: Overall Accuracy = {res['accuracy']:.2f}%")
    print(f"OP={op}: Irrelevant Correct Accuracy = {res['irr_correct_accuracy']:.2f}%")
    print(f"OP={op}: Extracted Final Answer Accuracy = {res['extracted_accuracy']:.2f}%")
    for condition, acc in res["condition_accuracies"].items():
        print(f"  {condition}: Accuracy = {acc:.2f}%")
    for condition, irr_acc in res["condition_irr_accuracies"].items():
        print(f"  {condition}: Irrelevant Accuracy = {irr_acc:.2f}%")
    for condition, ext_acc in res["condition_extracted_accuracies"].items():
        print(f"  {condition}: Extracted Answer Accuracy = {ext_acc:.2f}%")
print("====================================")
