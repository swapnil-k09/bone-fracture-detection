# X-ray Bone Fracture Detection System

An automated CNN-based system for detecting bone fractures and dislocations from X-ray images using deep learning.

## 🎯 Project Overview

This system uses Convolutional Neural Networks (CNN) to automatically analyze X-ray images and detect bone fractures. It's designed to assist medical professionals, especially in rural hospitals that may lack specialized orthopedic expertise.

### Key Features
- ✅ Automated fracture detection from X-ray images
- ✅ Grad-CAM visualization highlighting affected areas
- ✅ Web-based interface for easy image upload
- ✅ Support for multiple bone types (trained on MURA dataset)
- ✅ Real-time prediction with confidence scores

## 🛠️ Technologies Used

- **Python 3.12+** - Core programming language
- **TensorFlow/Keras** - Deep learning framework
- **OpenCV** - Image preprocessing
- **Flask** - Web application framework
- **Grad-CAM** - Model interpretability and visualization
- **MURA Dataset** - Training data (Stanford ML Group)

## 📁 Project Structure

```
bone_fracture_detection/
│
├── data/                          # Dataset directory
│   ├── train/                     # Training data
│   │   ├── fractured/            # Fractured X-rays
│   │   └── normal/               # Normal X-rays
│   ├── validation/               # Validation data
│   └── test/                     # Test data
│
├── models/                        # Saved models
│   └── best_model.h5             # Best performing model
│
├── utils/                         # Utility scripts
│   ├── preprocess.py             # Image preprocessing functions
│   ├── gradcam.py                # Grad-CAM implementation
│   └── model_builder.py          # Model architecture
│
├── static/                        # Web assets
│   ├── css/                      # Stylesheets
│   └── js/                       # JavaScript files
│
├── templates/                     # HTML templates
│   ├── index.html               # Upload page
│   └── result.html              # Results page
│
├── notebooks/                     # Jupyter notebooks
│   ├── 01_data_exploration.ipynb
│   ├── 02_preprocessing.ipynb
│   └── 03_model_training.ipynb
│
├── uploads/                       # Temporary upload directory
│
├── app.py                        # Flask web application
├── train.py                      # Model training script
├── evaluate.py                   # Model evaluation script
├── requirements.txt              # Python dependencies
├── config.py                     # Configuration settings
└── README.md                     # This file
```

## 🚀 Installation

### Prerequisites
- Python 3.8 or higher
- pip (Python package manager)
- Virtual environment (recommended)
- GPU (optional, but recommended for training)

### Step 1: Clone the Repository
```bash
git clone <repository-url>
cd bone_fracture_detection
```

### Step 2: Create Virtual Environment
```bash
# Create virtual environment
python -m venv fracture_env

# Activate virtual environment
# On Linux/Mac:
source fracture_env/bin/activate

# On Windows:
fracture_env\Scripts\activate
```

### Step 3: Install Dependencies
```bash
pip install -r requirements.txt
```

### Step 4: Download Dataset
1. Visit [MURA Dataset](https://stanfordmlgroup.github.io/competitions/mura/)
2. Download the training and validation sets
3. Extract to the `data/` directory following the structure above

## 📊 Dataset Information

**MURA (Musculoskeletal Radiographs)**
- Source: Stanford ML Group
- Size: ~40,000 images
- Categories: 7 body parts (elbow, finger, forearm, hand, humerus, shoulder, wrist)
- Classes: Normal vs Abnormal (fractured)

## 🎓 Training the Model

### Basic Training
```bash
python train.py --epochs 50 --batch_size 32
```

### With Custom Parameters
```bash
python train.py \
    --epochs 100 \
    --batch_size 64 \
    --learning_rate 0.001 \
    --model resnet50 \
    --image_size 224
```

### Training Options
- `--epochs`: Number of training epochs (default: 50)
- `--batch_size`: Batch size for training (default: 32)
- `--learning_rate`: Initial learning rate (default: 0.001)
- `--model`: Model architecture (custom, vgg16, resnet50, densenet121)
- `--image_size`: Input image size (default: 224)

## 📈 Model Evaluation

```bash
python evaluate.py --model models/best_model.h5
```

This will output:
- Accuracy
- Precision
- Recall
- F1-Score
- Confusion Matrix
- ROC Curve

## 🌐 Running the Web Application

### Development Mode
```bash
python app.py
```

The application will be available at `http://localhost:5000`

### Production Mode
```bash
gunicorn -w 4 -b 0.0.0.0:5000 app:app
```

## 💻 Usage

### Web Interface
1. Open your browser and navigate to `http://localhost:5000`
2. Click "Choose File" and select an X-ray image
3. Click "Analyze X-ray"
4. View the results:
   - Prediction: Fracture Detected / Normal
   - Confidence Score
   - Grad-CAM visualization (if fracture detected)

### API Usage
```python
import requests

url = 'http://localhost:5000/predict'
files = {'file': open('xray_image.png', 'rb')}
response = requests.post(url, files=files)

result = response.json()
print(f"Prediction: {result['prediction']}")
print(f"Confidence: {result['confidence']}")
```

## 🔬 Model Architecture

### Option 1: Custom CNN
- 4 Convolutional blocks
- Max pooling layers
- Dropout for regularization
- Dense layers for classification

### Option 2: Transfer Learning (Recommended)
- Pre-trained DenseNet121 backbone
- Custom classification head
- Fine-tuning on medical images

## 📊 Performance Metrics

Current model performance on test set:
- **Accuracy**: 92.5%
- **Precision**: 89.3%
- **Recall**: 95.1%
- **F1-Score**: 92.1%
- **AUC-ROC**: 0.94

*Note: These are target metrics. Actual performance may vary.*

## 🔍 Grad-CAM Visualization

Grad-CAM (Gradient-weighted Class Activation Mapping) highlights the regions of the X-ray image that the model focuses on when making predictions.

- Red/Yellow areas: High importance (likely fracture location)
- Blue/Green areas: Low importance
- Helps medical professionals verify model decisions

## ⚠️ Important Disclaimers

**MEDICAL DISCLAIMER**
- This system is an **assistive tool** only
- NOT a replacement for professional medical diagnosis
- Should be used as a **screening tool** to aid radiologists
- Always consult with qualified medical professionals
- Final diagnosis should be made by licensed healthcare providers

**DATA PRIVACY**
- Ensure compliance with HIPAA and local medical data regulations
- Implement proper data encryption
- Do not store patient information without consent

## 🐛 Troubleshooting

### Issue: TensorFlow GPU not detected
```bash
# Check GPU availability
python -c "import tensorflow as tf; print(tf.config.list_physical_devices('GPU'))"
```

### Issue: Out of memory during training
- Reduce batch size
- Use smaller image size
- Enable mixed precision training

### Issue: Poor model performance
- Increase training data
- Try different augmentation techniques
- Experiment with different architectures
- Adjust learning rate

## 🚧 Future Enhancements

- [ ] Multi-class classification (fracture types)
- [ ] Support for DICOM format
- [ ] Mobile application (iOS/Android)
- [ ] Integration with hospital PACS systems
- [ ] Multi-language support
- [ ] Automated report generation
- [ ] Real-time batch processing

## 📚 References

1. MURA Dataset: https://stanfordmlgroup.github.io/competitions/mura/
2. Grad-CAM: https://arxiv.org/abs/1610.02391
3. DenseNet: https://arxiv.org/abs/1608.06993

## 👥 Contributors

- Your Name - Initial work

## 📝 License

This project is for educational and research purposes only.

## 🙏 Acknowledgments

- Stanford ML Group for the MURA dataset
- TensorFlow and Keras teams
- OpenCV community

---

**Version**: 1.0.0  
**Last Updated**: February 2026  
**Status**: In Development
