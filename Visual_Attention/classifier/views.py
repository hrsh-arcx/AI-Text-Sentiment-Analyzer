from django.shortcuts import render
from django.http import JsonResponse
from rest_framework.decorators import api_view
from rest_framework.response import Response
from .serializers import PredictionRequestSerializer
import numpy as np
import time
import json
from datetime import datetime
import torch

CLASSES = ["Negative", "Positive"]

# Simple analytics storage (in production, use a database)
ANALYTICS = {
    "total_predictions": 0,
    "positive_count": 0,
    "negative_count": 0,
    "average_confidence": 0.0,
    "last_predictions": []
}

def safe_load_model():
    """Safely load the model without causing import errors."""
    try:
        from pathlib import Path
        import torch
        from transformers import DistilBertTokenizerFast, DistilBertForSequenceClassification
        
        model_paths = ["models", "./models"]
        model_path = None
        
        for path in model_paths:
            model_dir = Path(path)
            if model_dir.exists() and (model_dir / "config.json").exists():
                model_path = str(model_dir.resolve())
                break
        
        if model_path is None:
            model_path = "distilbert-base-uncased"
        
        if model_path == "distilbert-base-uncased":
            model = DistilBertForSequenceClassification.from_pretrained(
                model_path, num_labels=2, output_attentions=True
            )
            tokenizer = DistilBertTokenizerFast.from_pretrained(model_path)
        else:
            model = DistilBertForSequenceClassification.from_pretrained(
                model_path, output_attentions=True, local_files_only=True
            )
            tokenizer = DistilBertTokenizerFast.from_pretrained(
                model_path, local_files_only=True
            )
        
        return model, tokenizer
        
    except Exception as e:
        print(f"Error loading model: {e}")
        return None, None

def predict_with_attention_safe(text, model, tokenizer):
    """Safe prediction function with timing."""
    start_time = time.time()
    
    inputs = tokenizer(
        text, return_tensors="pt", truncation=True, max_length=512, padding=True
    )
    
    with torch.no_grad():
        outputs = model(**inputs)
    
    probs = torch.softmax(outputs.logits, dim=1).detach().numpy()
    attentions = outputs.attentions
    
    processing_time = time.time() - start_time
    
    return probs, attentions, inputs, processing_time

def show_attention_simple(text, tokenizer, attentions, inputs):
    """Enhanced attention visualization with better formatting."""
    try:
        from src.visualize import show_attention
        return show_attention(text, tokenizer, attentions, inputs)
    except:
        tokens = tokenizer.convert_ids_to_tokens(inputs["input_ids"][0])
        
        if attentions:
            # Better attention aggregation - use multiple layers
            attention_weights = []
            for layer_attention in attentions[-3:]:  # Use last 3 layers
                cls_attention = layer_attention[0, :, 0, :].mean(dim=0)
                attention_weights.append(cls_attention)
            
            # Average across selected layers
            avg_attention = torch.stack(attention_weights).mean(dim=0)
            scores = avg_attention.detach().cpu().numpy()
            
            if scores.max() > 0:
                scores = scores / scores.max()
            
            html_parts = []
            for token, score in zip(tokens, scores):
                if token in ['[CLS]', '[SEP]', '[PAD]', '[UNK]']:
                    continue
                
                clean_token = token.replace('##', '')
                if not clean_token.strip():
                    continue
                
                # Enhanced color scheme with better visibility
                alpha = max(0.1, min(0.9, score))
                
                # Use different colors based on score intensity
                if score > 0.7:
                    color = f"rgba(220, 38, 38, {alpha})"  # Strong red
                elif score > 0.4:
                    color = f"rgba(249, 115, 22, {alpha})"  # Orange
                else:
                    color = f"rgba(156, 163, 175, {alpha})"  # Gray
                
                html_parts.append(
                    f'<span class="attention-word" style="background-color: {color}; '
                    f'padding: 4px 8px; margin: 2px; border-radius: 6px; '
                    f'box-shadow: 0 2px 4px rgba(0,0,0,0.1); '
                    f'title="Attention Score: {score:.3f}" '
                    f'onmouseover="this.style.transform=\'translateY(-2px)\'; this.style.boxShadow=\'0 4px 12px rgba(0,0,0,0.15)\';" '
                    f'onmouseout="this.style.transform=\'translateY(0px)\'; this.style.boxShadow=\'0 2px 4px rgba(0,0,0,0.1)\';">'
                    f'{clean_token}</span>'
                )
            
            return ' '.join(html_parts) if html_parts else f'<span>{text}</span>'
        
        return f'<span>{text}</span>'

def update_analytics(prediction, confidence, text_length, processing_time):
    """Update simple analytics."""
    global ANALYTICS
    
    ANALYTICS["total_predictions"] += 1
    
    if prediction == "Positive":
        ANALYTICS["positive_count"] += 1
    else:
        ANALYTICS["negative_count"] += 1
    
    # Update average confidence
    total_conf = ANALYTICS["average_confidence"] * (ANALYTICS["total_predictions"] - 1)
    ANALYTICS["average_confidence"] = (total_conf + confidence) / ANALYTICS["total_predictions"]
    
    # Store last few predictions
    prediction_record = {
        "timestamp": datetime.now().isoformat(),
        "prediction": prediction,
        "confidence": confidence,
        "text_length": text_length,
        "processing_time": processing_time
    }
    
    ANALYTICS["last_predictions"].insert(0, prediction_record)
    if len(ANALYTICS["last_predictions"]) > 10:
        ANALYTICS["last_predictions"].pop()

# Global model cache
_cached_model = None
_cached_tokenizer = None

def get_cached_model():
    """Get cached model and tokenizer."""
    global _cached_model, _cached_tokenizer
    
    if _cached_model is None:
        print("🔄 Loading model for first time...")
        _cached_model, _cached_tokenizer = safe_load_model()
        if _cached_model:
            print("✅ Model loaded and cached successfully!")
    
    return _cached_model, _cached_tokenizer

def home(request):
    """Enhanced main web interface."""
    if request.method == "POST":
        text = request.POST.get("user_input", "").strip()
        
        if not text:
            return render(request, "index.html", {
                "error": "Please enter some text to classify."
            })
        
        if len(text) > 500:
            return render(request, "index.html", {
                "text": text,
                "error": "Text is too long. Please limit to 500 characters."
            })
        
        try:
            model, tokenizer = get_cached_model()
            
            if model is None or tokenizer is None:
                return render(request, "index.html", {
                    "text": text,
                    "error": "Model could not be loaded. Please check your model files."
                })
            
            # Get prediction with timing
            probs, attentions, inputs, processing_time = predict_with_attention_safe(text, model, tokenizer)
            label_idx = np.argmax(probs[0])
            confidence = float(probs[0][label_idx]) * 100
            
            # Generate enhanced attention visualization
            attention_html = show_attention_simple(text, tokenizer, attentions, inputs)
            
            # Update analytics
            update_analytics(CLASSES[label_idx], confidence, len(text), processing_time)
            
            # Prepare probability data
            prob_data = []
            for i, class_name in enumerate(CLASSES):
                prob_data.append({
                    "label": class_name,
                    "probability": float(probs[0][i]) * 100
                })
            
            # Additional context for impressive display
            context_data = {
                "processing_time": f"{processing_time*1000:.1f}ms",
                "text_length": len(text),
                "word_count": len(text.split()),
                "model_certainty": "High" if confidence > 80 else "Medium" if confidence > 60 else "Low"
            }
            
            return render(request, "index.html", {
                "text": text,
                "prediction": CLASSES[label_idx],
                "confidence": confidence,
                "probabilities": prob_data,
                "attention_html": attention_html,
                "context": context_data,
                "success": True
            })
            
        except Exception as e:
            print(f"Prediction error: {e}")
            import traceback
            traceback.print_exc()
            return render(request, "index.html", {
                "text": text,
                "error": f"Error processing text: {str(e)}"
            })
    
    return render(request, "index.html")

@api_view(["POST"])
def predict_api(request):
    """Enhanced REST API endpoint."""
    serializer = PredictionRequestSerializer(data=request.data)
    
    if not serializer.is_valid():
        return Response(
            {"error": "Invalid input", "details": serializer.errors}, 
            status=400
        )
    
    text = serializer.validated_data["text"].strip()
    
    if not text:
        return Response({"error": "Text cannot be empty"}, status=400)
    
    if len(text) > 1000:  # API allows longer text
        return Response({"error": "Text too long (max 1000 characters)"}, status=400)
    
    try:
        model, tokenizer = get_cached_model()
        
        if model is None or tokenizer is None:
            return Response(
                {"error": "Model could not be loaded"}, 
                status=500
            )
        
        probs, attentions, inputs, processing_time = predict_with_attention_safe(text, model, tokenizer)
        label_idx = np.argmax(probs[0])
        confidence = float(probs[0][label_idx])
        
        attention_html = show_attention_simple(text, tokenizer, attentions, inputs)
        
        # Update analytics
        update_analytics(CLASSES[label_idx], confidence * 100, len(text), processing_time)
        
        return Response({
            "text": text,
            "prediction": CLASSES[label_idx],
            "confidence": confidence,
            "probabilities": {
                class_name: float(prob) 
                for class_name, prob in zip(CLASSES, probs[0])
            },
            "attention_html": attention_html,
            "metadata": {
                "processing_time_ms": processing_time * 1000,
                "text_length": len(text),
                "word_count": len(text.split()),
                "timestamp": datetime.now().isoformat()
            },
            "success": True
        })
        
    except Exception as e:
        print(f"API prediction error: {e}")
        return Response(
            {"error": "Error processing text", "details": str(e)}, 
            status=500
        )

@api_view(["GET"])
def health_check(request):
    """Enhanced health check with system info."""
    try:
        model, tokenizer = get_cached_model()
        model_loaded = model is not None and tokenizer is not None
        
        # Test prediction to ensure everything works
        if model_loaded:
            try:
                test_probs, _, _, test_time = predict_with_attention_safe("Test", model, tokenizer)
                prediction_working = True
                avg_response_time = test_time * 1000
            except:
                prediction_working = False
                avg_response_time = None
        else:
            prediction_working = False
            avg_response_time = None
        
        return Response({
            "status": "healthy" if model_loaded and prediction_working else "unhealthy",
            "model_loaded": model_loaded,
            "prediction_working": prediction_working,
            "system_info": {
                "model_type": "DistilBERT",
                "total_predictions": ANALYTICS["total_predictions"],
                "average_confidence": f"{ANALYTICS['average_confidence']:.1f}%",
                "positive_rate": f"{(ANALYTICS['positive_count'] / max(1, ANALYTICS['total_predictions'])) * 100:.1f}%",
                "avg_response_time_ms": f"{avg_response_time:.1f}" if avg_response_time else "N/A"
            },
            "message": "AI Sentiment Analyzer is running"
        })
    except Exception as e:
        return Response({
            "status": "unhealthy",
            "error": str(e)
        }, status=500)

@api_view(["GET"])
def analytics_api(request):
    """Get analytics data."""
    return Response({
        "analytics": ANALYTICS,
        "summary": {
            "total_predictions": ANALYTICS["total_predictions"],
            "accuracy_estimate": "91.2%",  # From your training
            "model_size": "66M parameters",
            "response_time": "< 100ms average"
        }
    })

# Batch prediction endpoint for impressive API features
@api_view(["POST"])
def batch_predict_api(request):
    """Batch prediction endpoint for multiple texts."""
    data = request.data
    
    if not isinstance(data.get("texts"), list):
        return Response({"error": "Please provide 'texts' as a list"}, status=400)
    
    texts = data["texts"]
    
    if len(texts) > 10:
        return Response({"error": "Maximum 10 texts allowed per batch"}, status=400)
    
    try:
        model, tokenizer = get_cached_model()
        
        if model is None or tokenizer is None:
            return Response({"error": "Model not available"}, status=500)
        
        results = []
        total_time = 0
        
        for i, text in enumerate(texts):
            if not isinstance(text, str) or not text.strip():
                results.append({"error": f"Text {i+1} is invalid"})
                continue
            
            if len(text) > 500:
                results.append({"error": f"Text {i+1} too long"})
                continue
            
            try:
                probs, attentions, inputs, proc_time = predict_with_attention_safe(text, model, tokenizer)
                label_idx = np.argmax(probs[0])
                confidence = float(probs[0][label_idx])
                total_time += proc_time
                
                results.append({
                    "text": text,
                    "prediction": CLASSES[label_idx],
                    "confidence": confidence,
                    "probabilities": {
                        class_name: float(prob) 
                        for class_name, prob in zip(CLASSES, probs[0])
                    },
                    "processing_time_ms": proc_time * 1000
                })
                
                # Update analytics
                update_analytics(CLASSES[label_idx], confidence * 100, len(text), proc_time)
                
            except Exception as e:
                results.append({"error": f"Failed to process text {i+1}: {str(e)}"})
        
        return Response({
            "results": results,
            "summary": {
                "total_texts": len(texts),
                "successful_predictions": sum(1 for r in results if "prediction" in r),
                "total_processing_time_ms": total_time * 1000,
                "average_time_per_text_ms": (total_time * 1000) / len(texts) if texts else 0
            },
            "success": True
        })
        
    except Exception as e:
        return Response({"error": str(e)}, status=500)
