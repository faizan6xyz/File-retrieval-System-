from transformers import Qwen2_5_VLForConditionalGeneration, AutoProcessor
from qwen_vl_utils import process_vision_info
import torch
model_name = "Qwen/Qwen2.5-VL-3B-Instruct"
model = Qwen2_5_VLForConditionalGeneration.from_pretrained(
    model_name,
    torch_dtype=torch.bfloat16,
    device_map="auto"
)
processor = AutoProcessor.from_pretrained(model_name)
messages = [
    {
        "role": "user",
        "content": [
            {
                "type": "image",
                "image": "SYSTEM/data/h.png",  # local path
            },
            {
                "type": "text",
                "text": "Describe this image."
            }
        ]
    }
]
text = processor.apply_chat_template(messages, tokenize=False, add_generation_prompt=True)
image_inputs, video_inputs = process_vision_info(messages) # this decodes the image from the compressed jpeg / png form to raw data which gets feed into the vision mdoel 
inputs = processor(
    text=[text],
    images=image_inputs,
    videos=video_inputs,
    padding=True,
    return_tensors="pt"
).to(model.device)
with torch.no_grad():
    outputs = model.generate(**inputs, max_new_tokens=300)
response = processor.decode(outputs[0][inputs.input_ids.shape[1]:], skip_special_tokens=True)
print(response)