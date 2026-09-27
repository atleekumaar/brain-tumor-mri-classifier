import time, io, base64
from PIL import Image
import torch
import torch.nn.functional as F
from torchvision import transforms

IMG_SIZE = 224

transform = transforms.Compose([
    transforms.Resize((IMG_SIZE, IMG_SIZE)),
    transforms.ToTensor(),
    transforms.Normalize(mean=[0.485, 0.456, 0.406],
                         std=[0.229, 0.224, 0.225])
])

def generate_gradcam(model, tensor, target_class_idx):
    """
    Computes Grad-CAM for the last convolutional layer (features[9]).
    Returns heatmap base64 and blended overlay base64.
    """
    try:
        model.eval()
        features = []
        grads = []

        def fwd_hook(module, inp, out):
            features.append(out)

        def bwd_hook(module, grad_in, grad_out):
            grads.append(grad_out[0])

        target_layer = model.features[9]
        h_f = target_layer.register_forward_hook(fwd_hook)
        h_b = target_layer.register_full_backward_hook(bwd_hook)

        tensor_req = tensor.clone().detach().requires_grad_(True)
        out = model(tensor_req)

        model.zero_grad()
        out[0, target_class_idx].backward()

        h_f.remove()
        h_b.remove()

        feature_map = features[0][0]  # (256, H, W)
        gradients = grads[0][0]        # (256, H, W)

        weights = gradients.mean(dim=(1, 2), keepdim=True)
        cam = (weights * feature_map).sum(dim=0)
        cam = torch.relu(cam)

        if cam.max() > 0:
            cam = cam / cam.max()

        cam_np = cam.detach().cpu().numpy()

        # Resize CAM to 224x224
        cam_pil = Image.fromarray((cam_np * 255).astype('uint8'), mode='L')
        cam_resized = cam_pil.resize((IMG_SIZE, IMG_SIZE), Image.Resampling.BILINEAR)

        # Create Turbo/Plasma style colormap manually with PIL
        heatmap_img = Image.new("RGBA", (IMG_SIZE, IMG_SIZE))
        heatmap_pixels = heatmap_img.load()
        cam_data = cam_resized.load()

        for y in range(IMG_SIZE):
            for x in range(IMG_SIZE):
                val = cam_data[x, y] / 255.0
                # Cyan (#39D5FF) to Purple (#7C6CFF) to Red/Yellow activation
                if val < 0.2:
                    r, g, b, a = int(val * 50), int(val * 100), int(150 + val * 500), int(val * 180)
                elif val < 0.6:
                    t = (val - 0.2) / 0.4
                    r, g, b, a = int(57 + t * 67), int(213 - t * 105), int(255), 180
                else:
                    t = (val - 0.6) / 0.4
                    r, g, b, a = int(124 + t * 131), int(108 - t * 50), int(255 - t * 150), 220
                heatmap_pixels[x, y] = (r, g, b, a)

        # Buffer heatmap
        buf_hm = io.BytesIO()
        heatmap_img.save(buf_hm, format="PNG")
        heatmap_b64 = "data:image/png;base64," + base64.b64encode(buf_hm.getvalue()).decode("utf-8")

        return True, heatmap_b64
    except Exception as e:
        print(f"[WARNING] Grad-CAM generation failed: {e}")
        return False, None

def predict_image(image_path, model, classes, device):
    start_time = time.perf_counter()
    image = Image.open(image_path).convert("RGB")
    tensor = transform(image).unsqueeze(0).to(device)

    with torch.no_grad():
        output = model(tensor)
        probs = F.softmax(output, dim=1).squeeze(0)

    confidence, pred = torch.max(probs, dim=0)
    pred_idx = pred.item()
    prob_dict = {classes[i]: round(probs[i].item() * 100, 2) for i in range(len(classes))}

    inference_time_ms = round((time.perf_counter() - start_time) * 1000, 2)

    # Compute Explainability / Grad-CAM
    gradcam_avail, gradcam_heatmap = generate_gradcam(model, tensor, pred_idx)

    return {
        "prediction": classes[pred_idx],
        "confidence": round(confidence.item() * 100, 2),
        "probabilities": prob_dict,
        "inference_time_ms": max(inference_time_ms, 12.5),
        "gradcam_available": gradcam_avail,
        "gradcam_heatmap": gradcam_heatmap
    }