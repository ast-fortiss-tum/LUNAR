import math
from typing import Any, Dict, List
from dotenv import load_dotenv
from json_repair import repair_json
import pandas as pd
import numpy as np
from sentence_transformers import SentenceTransformer
import faiss
from geopy.distance import geodesic
from datetime import datetime
import json
import re
from car.state import ENUM_MAP, POSSIBLE_CAR_VALUES
from llm.llm_selector import pass_llm, get_total_tokens, get_total_costs, get_query_costs
import os
from models import SessionManager, Turn
from sentence_transformers import SentenceTransformer, util
import torch
import traceback
import ast

from prompts import (
    PROMPT_CAR_RESPONSE,
    PROMPT_GENERATE_RECOMMENDATION,
    PROMPT_NLU,
    PROMPT_PARSE_CONSTRAINTS,
    PROMPT_NLU_WITH_CAR,
    PROMPT_CAR_UPDATE,
    PROMPT_CLASSIFY_ACTION,
    PROMPT_POI_CONFIRM_SELECT,
)
from utils.file import load_jsonl_to_df
from utils.format import clean_json, extract_json, extract_json_list

load_dotenv()

top_k = int(os.environ.get("TOP_K", 3))

# Load embedding model once
model = SentenceTransformer('all-MiniLM-L6-v2')

INTENT_NO_NLU = os.getenv("INTENT_NO_NLU", "poi").upper()

PROMPT_POI_INFO = """You are a helpful car navigation assistant. The user is asking a question about a place.

Conversation history:
{history}

Last recommended places:
{pois}

User question: "{query}"

Context is: "{context}"

Answer the user's question based on the available information about the places. 
If the information is not available, try to provide some information that makes sense.
Or direct to a dedicated service (e.g., a weather app, a traffic app).
Be concise unter 15 words.
"""


def embed_texts(texts):
    """Embed a list of texts and return tensors."""
    return model.encode(texts, convert_to_tensor=True)


def preprocess_poi_json(row):
    categories = row.get('category', '')
    rating = row.get('rating', None)
    price_level = row.get('price_level', None)
    return f"{row.get('name', '')}, a {categories} place rated {rating}/5 at {row.get('address', '')}. Price: {price_level if price_level else 'N/A'}."


def parse_query_to_constraints(query: str, history: str = "", llm_model: str = ""):
    prompt = PROMPT_PARSE_CONSTRAINTS.format(history, query)
    response, input_tokens, output_tokens = pass_llm(prompt, model=llm_model)
    response = extract_json(repair_json(response))
    return response, input_tokens, output_tokens


def classify_action(query, history, llm_model=""):
    """Single lightweight classifier to determine user action within POI flow."""
    prompt = PROMPT_CLASSIFY_ACTION.format(history=history, query=query)
    response, tokens_input, tokens_output = pass_llm(prompt, model=llm_model)
    result = extract_json(repair_json(response))
    return result.get("action", "refine"), tokens_input, tokens_output


def apply_structured_filters(df, intent, user_location,
                             use_embeddings_category=False,
                             similarity_threshold_category=0.8):
    print("**** apply structured filters ****")
    print("intent: ", intent)
    df_filtered = df.copy()

    def filter_contains_in_fields(df_filtered, key_word, field_names):
        search_lower = key_word.lower()
        mask = pd.Series(False, index=df_filtered.index)
        for field in field_names:
            mask |= df_filtered[field].fillna("").str.lower().str.contains(search_lower, na=False)
        return df_filtered[mask]

    if len(df_filtered) > 0 and intent.get("category"):
        if use_embeddings_category:
            categories = df_filtered['category'].fillna("").tolist()
            category_embeddings = embed_texts(categories)
            intent_embedding = embed_texts([intent["category"]])[0]
            cos_scores = util.cos_sim(intent_embedding, category_embeddings)[0]
            indices = torch.where(cos_scores >= similarity_threshold_category)[0].tolist()
            df_filtered = df_filtered.iloc[indices]
        else:
            df_filtered = filter_contains_in_fields(df_filtered, intent["category"],
                                                    field_names=["category", "name"])
        # print(df_filtered.head())

    if len(df_filtered) > 0 and intent.get("name"):
        pattern = re.escape(intent["name"])
        df_filtered = df_filtered[df_filtered['name'].str.contains(pattern, case=False, na=False)]
        print(df_filtered.head())

    if len(df_filtered) > 0 and intent.get("cuisine"):
        pattern = re.escape(intent["cuisine"])
        df_filtered = filter_contains_in_fields(df_filtered, pattern,
                                                field_names=["category", "name"])
        print(df_filtered.head())

    if len(df_filtered) > 0 and intent.get("price_level"):
        if 'price_level' in df_filtered.columns:
            df_filtered = df_filtered[df_filtered['price_level'] == intent["price_level"]]
        print(df_filtered.head())

    if len(df_filtered) > 0 and intent.get("radius_km") is not None:
        def within_radius(row):
            poi_loc = (row['latitude'], row['longitude'])
            return geodesic(user_location, poi_loc).km <= intent["radius_km"]
        df_filtered = df_filtered[df_filtered.apply(within_radius, axis=1)]
        print(df_filtered.head())

    if len(df_filtered) > 0 and intent.get("open_now") is True:
        now = datetime.now().strftime("%H:%M")
        def is_open(row):
            try:
                hours = row['opening_hours']
                if isinstance(hours, dict):
                    day_name = datetime.now().strftime('%A')
                    if day_name in hours:
                        time_range = hours[day_name]
                    else:
                        return False
                else:
                    time_range = hours
                start, end = time_range.split("-")
                return start <= now <= end
            except Exception:
                return False
        df_filtered = df_filtered[df_filtered.apply(is_open, axis=1)]
        print(df_filtered.head())

    if len(df_filtered) > 0 and intent.get("rating") is not None:
        df_filtered = df_filtered[df_filtered['rating'] >= intent["rating"]]

    if len(df_filtered) > 0 and intent.get("parking") is not None:
        df_filtered = df_filtered[df_filtered['parking']]

    print("*** Structured filter applied.")
    return df_filtered


def retrieve_top_k_semantically(query, df_filtered, embeddings, k=top_k):
    if df_filtered.empty:
        return df_filtered

    idx_map = df_filtered.index.tolist()
    sub_embeddings = np.array([embeddings[i] for i in idx_map])

    sub_index = faiss.IndexFlatL2(embeddings.shape[1])
    sub_index.add(sub_embeddings)

    query_vec = model.encode([query])
    D, I = sub_index.search(query_vec, k)

    top_indices = [idx_map[i] for i in I[0] if i < len(idx_map)]
    return df_filtered.loc[top_indices]


def generate_recommendation(query, pois_df, llm_model, history):
    if pois_df.empty:
        return "Sorry, I cannot find any relevant places. Do you have other preferences in mind?", 0, 0

    pois_text = "\n".join([
        f"{i + 1}. {row['text']}" for i, row in pois_df.iterrows()
    ])

    prompt = PROMPT_GENERATE_RECOMMENDATION.format(query, pois_text, history)
    response, tokens_input, tokens_output = pass_llm(prompt=prompt, model=llm_model)
    return response, tokens_input, tokens_output


def nlu(query: str, history: str = ""):
    prompt = PROMPT_NLU_WITH_CAR.format(query, history)
    response, tokens_input, tokens_output = pass_llm(prompt)
    return extract_json(response), tokens_input, tokens_output


def _build_return_dict(response, pois_output, session, user_id,
                       tokens_query_input, tokens_query_output, **extra):
    """Helper to build the standard return dictionary."""
    result = {
        "response": response,
        "retrieved_pois": pois_output,
        "session_id": session.id,
        "user_id": user_id,
        "tokens_total": get_total_tokens(),
        "tokens_query_input": tokens_query_input,
        "tokens_query_output": tokens_query_output,
        "price_query": get_query_costs(),
        "price_total": get_total_costs(),
    }
    result.update(extra)
    return result


def _finalize_turn(session, query, response, pois_output):
    """Helper to add and complete a turn."""
    session.add_turn(Turn(question=query, answer=None, retrieved_pois=[]))
    session.complete(response, retrieved_pois=pois_output)


def _handle_car_intent(query, session, history, llm_model,
                       tokens_query_input, tokens_query_output, user_id):
    """Handle the CAR intent flow."""
    print("[DEBUG] CAR intent")

    car_state = session.car_state

    prompt = PROMPT_CAR_UPDATE.format(
        current_state=car_state.get_state(),
        history=history,
        query=query,
        possible_values=POSSIBLE_CAR_VALUES,
    )

    output_str, tokens_input, tokens_output = pass_llm(
        prompt=prompt, model=llm_model
    )
    tokens_query_input += tokens_input
    tokens_query_output += tokens_output

    output_str = repair_json(output_str)
    result = json.loads(output_str)

    response = result.get("summary", "")
    changes = result.get("changes", [])

    for change in changes:
        subsystem = change.get("subsystem")
        target = change.get("target")
        value = change.get("value")

        if subsystem not in car_state.state:
            continue

        if target not in car_state.state[subsystem]:
            continue

        current_val = car_state.state[subsystem][target]

        if isinstance(current_val, (int, float)):
            if value == "increase":
                car_state.state[subsystem][target] += 1
            elif value == "decrease":
                car_state.state[subsystem][target] -= 1
            else:
                car_state.state[subsystem][target] = value
        else:
            enum_class = ENUM_MAP[subsystem][target]
            car_state.state[subsystem][target] = enum_class(value)

    pois_output = car_state.get_state()

    _finalize_turn(session, query, response, pois_output)

    return _build_return_dict(
        response, pois_output, session, user_id,
        tokens_query_input, tokens_query_output
    )


def _handle_poi_stop(query, session, user_id,
                     tokens_query_input, tokens_query_output):
    """Handle the STOP action within POI flow."""
    response = "Okay, ending the conversation."
    pois_output = []

    _finalize_turn(session, query, response, pois_output)

    return _build_return_dict(
        response, pois_output, session, user_id,
        tokens_query_input, tokens_query_output,
        conversation_finished=True
    )


def _handle_poi_confirm(query, session, user_id,
                        tokens_query_input, tokens_query_output,
                        llm_model=""):
    """Handle the CONFIRM action — start navigation to the POI the user confirmed (LLM-selected).

    Note: If the LLM cannot confidently select a POI, we do NOT ask the user to clarify here.
    We fall back to the top-ranked last POI (previous behavior), and still start navigation.
    """
    last_pois = session.get_last_retrieved_pois() or []

    if not last_pois:
        response = "I don't have a destination yet. Where would you like to go?"
        pois_output = []
        _finalize_turn(session, query, response, pois_output)
        return _build_return_dict(
            response, pois_output, session, user_id,
            tokens_query_input, tokens_query_output,
            navigation_started=False
        )

    # Build candidates with stable IDs if present; otherwise index fallback.
    candidates = []
    for i, p in enumerate(last_pois):
        poi_id = p.get("id")
        if poi_id is None:
            poi_id = str(i)  # fallback id
        candidates.append({
            "id": str(poi_id),
            "rank": i + 1,
            "name": p.get("name", ""),
            "address": p.get("address", ""),
            "category": p.get("category", ""),
            "rating": p.get("rating", None),
            "price_level": p.get("price_level", None),
        })

    history = session.get_history()
    pois_text = json.dumps(candidates, indent=2, ensure_ascii=False)

    prompt = PROMPT_POI_CONFIRM_SELECT.format(
        history=history,
        pois=pois_text,
        query=query,
    )

    llm_out, tokens_input, tokens_output = pass_llm(prompt=prompt, model=llm_model)
    tokens_query_input += tokens_input
    tokens_query_output += tokens_output

    # Parse model output robustly (same pattern as the rest of your code)
    try:
        llm_out = repair_json(llm_out)
        parsed = extract_json(llm_out)
    except Exception:
        parsed = {}

    selected_id = parsed.get("selected_poi_id", None)
    confidence = parsed.get("confidence", "low")

    selected_poi = None
    if selected_id is not None:
        # 1) Try matching on actual POI id (if present)
        for p in last_pois:
            if p.get("id") is not None and str(p.get("id")) == str(selected_id):
                selected_poi = p
                break

        # 2) If not found, allow index fallback id
        if selected_poi is None and str(selected_id).isdigit():
            idx = int(str(selected_id))
            if 0 <= idx < len(last_pois):
                selected_poi = last_pois[idx]

    # No user clarification: fallback to previous behavior
    if selected_poi is None or confidence == "low":
        selected_poi = last_pois[0]

    response = f"Starting navigation to {selected_poi.get('name')} at {selected_poi.get('address')}."
    pois_output = [selected_poi]

    _finalize_turn(session, query, response, pois_output)

    return _build_return_dict(
        response, pois_output, session, user_id,
        tokens_query_input, tokens_query_output,
        navigation_started=True
    )
def _handle_poi_info(query, session, user_id, history, llm_model,
                     tokens_query_input, tokens_query_output):
    """Handle the INFO action — answer questions about previously suggested POIs."""
    last_pois = session.get_last_retrieved_pois()

    if last_pois:
        pois_text = json.dumps(last_pois, indent=2)
    else:
        pois_text = "No places have been suggested yet."

    prompt = PROMPT_POI_INFO.format(
        history=history,
        pois=pois_text,
        query=query,
        context="The user is located in the city center, Philadelphia, PA."
    )

    response, tokens_input, tokens_output = pass_llm(
        prompt=prompt, model=llm_model
    )
    tokens_query_input += tokens_input
    tokens_query_output += tokens_output

    pois_output = last_pois if last_pois else []

    _finalize_turn(session, query, response, pois_output)

    return _build_return_dict(
        response, pois_output, session, user_id,
        tokens_query_input, tokens_query_output
    )

def _handle_poi_refine(query, session, user_location, embeddings, df,
                       llm_model, user_id, history,
                       tokens_query_input, tokens_query_output,
                       reset_constraints: bool = False):
    """Handle the REFINE action — parse new constraints, retrieve POIs.
       If reset_constraints=True: start from empty constraints (change of mind).
    """
    new_constraints, input_tokens, output_tokens = parse_query_to_constraints(
        query, history=history, llm_model=llm_model
    )
    tokens_query_input += input_tokens
    tokens_query_output += output_tokens

    meaningful_constraints = {k: v for k, v in new_constraints.items() if v is not None}

    if reset_constraints:
        session.poi_constraints = {}

    if meaningful_constraints:
        session.poi_constraints.update(meaningful_constraints)

    print("[INFO] Accumulated POI constraints:", session.poi_constraints)

    df_filtered = apply_structured_filters(
        df, session.poi_constraints, user_location
    )

    retrieved_pois = retrieve_top_k_semantically(
        query, df_filtered, embeddings=embeddings, k=top_k
    )

    response, input_tokens, output_tokens = generate_recommendation(
        query, retrieved_pois, llm_model=llm_model, history = session.get_history()
    )
    tokens_query_input += input_tokens
    tokens_query_output += output_tokens

    pois_output = retrieved_pois[
        ["name", "category", "rating", "price_level",
         "address", "latitude", "longitude", "parking"]
    ].to_dict(orient="records")
    pois_output = [clean_json(poi) for poi in pois_output]

    _finalize_turn(session, query, response, pois_output)

    return _build_return_dict(
        response, pois_output, session, user_id,
        tokens_query_input, tokens_query_output
    )


def run_rag_navigation(
    query,
    user_location,
    embeddings,
    df,
    use_nlu=True,
    llm_model=os.environ["LLM_MODEL"],
    user_id=1,
):
    print("[DEBUG] NLU active:", use_nlu)

    session_manager = SessionManager.get_instance()
    session = session_manager.get_session(user_id)

    if session is None or session.len() >= session.max_turns:
        print("[DEBUG] Creating new session...")
        session = session_manager.create_session(user_id)

    print("[DEBUG] User ID:", user_id, "Session ID:", session.id)

    history = session.get_history()

    tokens_query_input = 0
    tokens_query_output = 0

    # --------------------
    # NLU (if enabled, handles CAR vs POI split)
    # --------------------
    if use_nlu:
        nlu_parsed, tokens_input, tokens_output = nlu(query, history)
        tokens_query_input += tokens_input
        tokens_query_output += tokens_output
        intent = nlu_parsed.get("intent")
    else:
        intent = INTENT_NO_NLU

    # Non-POI, non-CAR intents (e.g. greetings, chitchat)
    if intent not in ("POI", "CAR"):
        response = nlu_parsed.get("response", "")
        pois_output = []
        _finalize_turn(session, query, response, pois_output)
        return _build_return_dict(
            response, pois_output, session, user_id,
            tokens_query_input, tokens_query_output
        )

    # CAR intent
    if intent == "CAR":
        return _handle_car_intent(
            query, session, history, llm_model,
            tokens_query_input, tokens_query_output, user_id
        )

    # --------------------
    # POI FLOW: single classifier → route
    # --------------------
    print("[DEBUG] Intent:", intent)
    if intent == "POI":
        action, tokens_input, tokens_output = classify_action(
            query, history, llm_model=llm_model
        )
        tokens_query_input += tokens_input
        tokens_query_output += tokens_output

        print(f"[DEBUG] Classified action: {action}")

        if action == "stop":
            return _handle_poi_stop(
                query, session, user_id,
                tokens_query_input, tokens_query_output
            )

        elif action == "confirm":
            return _handle_poi_confirm(
                query, session, user_id,
                tokens_query_input, tokens_query_output,
                llm_model=llm_model
            )

        elif action == "info":
            return _handle_poi_info(
                query, session, user_id, history, llm_model,
                tokens_query_input, tokens_query_output
            )

        elif action == "change_of_mind":
            # Same as refine, but start from empty constraints/state
            return _handle_poi_refine(
                query, session, user_location, embeddings, df,
                llm_model, user_id, history,
                tokens_query_input, tokens_query_output,
                reset_constraints=True
            )

        elif action == "refine":
            return _handle_poi_refine(
                query, session, user_location, embeddings, df,
                llm_model, user_id, history,
                tokens_query_input, tokens_query_output
            )
    raise ValueError(f"Unhandled intent: {intent}")


# --------------------
# DATA LOADING
# --------------------

def load_dataset(path_dataset, nrows, filter_city):
    df = load_jsonl_to_df(path_dataset)

    df_filtered = df[df['city'].str.contains(filter_city, case=False, na=False)].copy()
    df_filtered = df_filtered.reset_index(drop=True)

    if nrows is not None:
        df_filtered = df_filtered.head(nrows)

    df_filtered.rename(columns={
        'stars': 'rating',
        'categories': 'category',
        'hours': 'opening_hours'
    }, inplace=True)

    def map_price_level(attributes: dict) -> str:
        try:
            if isinstance(attributes, dict):
                val = attributes.get("RestaurantsPriceRange2", None)
                if val is not None:
                    mapping = {"1": "$", "2": "$$", "3": "$$$", "4": "$$$$"}
                    return mapping.get(str(val))
        except Exception:
            pass
        return None

    df_filtered['price_level'] = df_filtered['attributes'].apply(map_price_level)
    df_filtered['text'] = df_filtered.apply(preprocess_poi_json, axis=1)

    def has_parking(attributes: dict) -> bool:
        try:
            if isinstance(attributes, dict):
                parking_str = attributes.get("BusinessParking", None)
                if parking_str and isinstance(parking_str, str):
                    parking_dict = ast.literal_eval(parking_str)
                    return any(parking_dict.values())
        except Exception:
            pass
        return False

    df_filtered['parking'] = df_filtered['attributes'].apply(has_parking)
    return df_filtered


def create_embeddings(df, do_save=True):
    model = SentenceTransformer('all-MiniLM-L6-v2')
    embeddings = model.encode(df['text'].tolist(), show_progress_bar=True)

    faiss_index = faiss.IndexFlatL2(embeddings.shape[1])
    faiss_index.add(np.array(embeddings))

    return embeddings


def save_data(df, embeddings, df_path="data/filtered_pois.csv", emb_path="data/embeddings.npy"):
    df.to_csv(df_path, index=False)
    np.save(emb_path, embeddings)


def load_data(df_path="filtered_pois.csv", emb_path="embeddings.npy"):
    if os.path.exists(df_path) and os.path.exists(emb_path):
        df = pd.read_csv(df_path, encoding='utf-8')
        embeddings = np.load(emb_path)
        return df, embeddings
    else:
        return None, None


def get_embeddings_and_df(path_dataset,
                          filter_city,
                          df_path="data/filtered_pois.csv",
                          emb_path="data/embeddings.npy",
                          nrows=None):
    df, embeddings = load_data(df_path, emb_path)
    print("[INFO] Loading dataset.")
    if df is None or embeddings is None:
        df = load_dataset(path_dataset, nrows=nrows, filter_city=filter_city)
        embeddings = create_embeddings(df)
        save_data(df, embeddings, df_path, emb_path)
        print("[INFO] Dataset loaded.")
    return embeddings, df


if __name__ == "__main__":
    user_city = "Philadelphia"
    path_dataset = "data/raw/yelp_academic_dataset_business.json"

    user_queries = [
        "I will have a date today and want try some burger restaurant.",
        "I am in the mood for some asian food close by rating 4.",
        "My parents will visit my city, any american restaurant to check out?",
        "I like to have some english breakfast, not expensive."
    ]
    user_location = (39.955431, -75.154903)  # Philadelphia, PA

    df_path = "data/filtered_pois.csv"
    emb_path = "data/embeddings.npy"

    for query in user_queries:
        embeddings, df = get_embeddings_and_df(path_dataset,
                                               user_city,
                                               df_path,
                                               emb_path)
        print("\n--- RAG Recommendation System ---\n")
        output = run_rag_navigation(query, user_location, embeddings, df=df)
        print(output["response"])
        print(json.dumps(output["retrieved_pois"], indent=2))