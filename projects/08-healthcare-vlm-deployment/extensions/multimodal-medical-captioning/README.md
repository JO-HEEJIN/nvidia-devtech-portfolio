# Multimodal Medical Captioning Extension

> **🔬 Advanced medical image analysis with automated caption generation and clinical keyword extraction**

이 확장 프로젝트는 Healthcare VLM Deployment의 핵심 기능을 확장하여 **DeepSeek-VL** 기반의 의료 이미지 캡션 생성과 **T5** 기반의 임상 키워드 추출을 통합합니다. **AI Skin Burn Diagnosis** 및 **Birth2Death** 플랫폼 경험을 바탕으로 한 고급 멀티모달 AI 솔루션입니다.

## 🎯 Project Overview

### Core Innovation
기존 Healthcare VLM의 **이미지-텍스트 유사도** 분석을 넘어서, **자동 캡션 생성**과 **임상 키워드 추출**을 통한 포괄적인 의료 이미지 분석 파이프라인을 구현합니다.

### Technical Integration
```mermaid
graph TB
    A[Medical Image] --> B[Healthcare VLM<br/>BiomedCLIP]
    A --> C[DeepSeek-VL<br/>Caption Generator]
    
    B --> D[Similarity Analysis]
    C --> E[Medical Caption]
    E --> F[T5 Keyword<br/>Extractor]
    F --> G[Clinical Keywords]
    
    D --> H[Comprehensive<br/>Medical Report]
    G --> H
    
    H --> I[Clinical Decision<br/>Support]
```

## 🏥 Healthcare AI Expertise Integration

### AI Skin Burn Diagnosis Experience
```python
# 피부 화상 진단에서 학습한 멀티모달 접근법 적용
class BurnDiagnosisIntegration:
    def __init__(self):
        self.deepseek_model = DeepSeekVLModel()
        self.t5_extractor = T5KeywordExtractor()
        self.biomedclip = load_biomedclip()
    
    def comprehensive_burn_analysis(self, burn_image):
        # 1. 자동 캡션 생성 (DeepSeek-VL)
        caption = self.deepseek_model.generate_caption(burn_image)
        # "2nd degree burn on forearm with blistering and erythema"
        
        # 2. 임상 키워드 추출 (T5)
        keywords = self.t5_extractor.extract_keywords(caption)
        # ["2nd degree", "burn", "forearm", "blistering", "erythema"]
        
        # 3. 유사도 분석 (BiomedCLIP)
        similarity = self.biomedclip.compute_similarity(
            burn_image, "thermal burn second degree"
        )
        
        return {
            "caption": caption,
            "keywords": keywords,
            "similarity_score": similarity,
            "severity": self.assess_burn_severity(keywords),
            "treatment_recommendation": self.get_treatment_plan(keywords)
        }
```

### Birth2Death Platform Connection
```python
# Birth2Death 플랫폼의 생애주기 관리 경험을 의료 이미지 분석에 적용
class LifecycleMedicalAnalysis:
    def analyze_by_age_group(self, medical_image, patient_age):
        # 연령별 맞춤 분석
        if patient_age < 2:  # 신생아
            return self.neonatal_analysis(medical_image)
        elif patient_age < 18:  # 소아/청소년
            return self.pediatric_analysis(medical_image)
        elif patient_age < 65:  # 성인
            return self.adult_analysis(medical_image)
        else:  # 노년층
            return self.geriatric_analysis(medical_image)
```

## 🚀 Technical Implementation

### 1. DeepSeek-VL Medical Caption Generator
```python
# extensions/multimodal-medical-captioning/src/deepseek_captioning.py
import torch
from transformers import AutoTokenizer, AutoModelForCausalLM

class DeepSeekMedicalCaptioner:
    """DeepSeek-VL을 활용한 의료 이미지 캡션 생성기"""
    
    def __init__(self, model_path="deepseek-ai/deepseek-vl-7b-chat"):
        self.model_path = model_path
        self.load_model()
    
    def load_model(self):
        """DeepSeek-VL 모델 로드"""
        self.tokenizer = AutoTokenizer.from_pretrained(self.model_path, trust_remote_code=True)
        self.model = AutoModelForCausalLM.from_pretrained(
            self.model_path, 
            torch_dtype=torch.float16,
            device_map="auto",
            trust_remote_code=True
        )
        
    def generate_medical_caption(self, image, medical_context=""):
        """의료 이미지에 대한 상세한 캡션 생성"""
        # 의료 전문 프롬프트 설계
        medical_prompt = f"""
        <image>
        
        As a medical imaging specialist, provide a detailed and accurate caption for this medical image.
        Focus on:
        1. Anatomical structures visible
        2. Pathological findings (if any)
        3. Image modality and quality
        4. Clinical significance
        
        Medical context: {medical_context}
        
        Caption:"""
        
        # DeepSeek-VL 추론
        inputs = self.model.prepare_inputs_for_generation(
            images=[image],
            text=medical_prompt,
            tokenizer=self.tokenizer
        )
        
        with torch.no_grad():
            outputs = self.model.generate(
                **inputs,
                max_new_tokens=200,
                temperature=0.3,
                do_sample=True
            )
        
        caption = self.tokenizer.decode(outputs[0], skip_special_tokens=True)
        return self.extract_caption_from_output(caption)
    
    def extract_caption_from_output(self, model_output):
        """모델 출력에서 캡션 부분만 추출"""
        # "Caption:" 이후의 텍스트만 추출
        if "Caption:" in model_output:
            return model_output.split("Caption:")[-1].strip()
        return model_output.strip()
```

### 2. T5 Clinical Keyword Extractor
```python
# extensions/multimodal-medical-captioning/src/t5_keyword_extraction.py
from transformers import T5Tokenizer, T5ForConditionalGeneration
import torch
import re

class T5ClinicalKeywordExtractor:
    """T5를 활용한 임상 키워드 추출기"""
    
    def __init__(self, model_path="t5-base"):
        self.model_path = model_path
        self.load_model()
        self.medical_keywords_db = self.load_medical_vocabulary()
    
    def load_model(self):
        """T5 모델 및 토크나이저 로드"""
        self.tokenizer = T5Tokenizer.from_pretrained(self.model_path)
        self.model = T5ForConditionalGeneration.from_pretrained(self.model_path)
        
    def load_medical_vocabulary(self):
        """의료 용어 데이터베이스 로드"""
        return {
            "anatomical": ["lung", "heart", "liver", "brain", "kidney", "chest", "abdomen"],
            "pathological": ["tumor", "fracture", "pneumonia", "edema", "hemorrhage", "stenosis"],
            "procedures": ["CT", "MRI", "X-ray", "ultrasound", "biopsy", "surgery"],
            "severity": ["mild", "moderate", "severe", "acute", "chronic", "critical"],
            "burn_specific": ["1st degree", "2nd degree", "3rd degree", "burn", "thermal", "chemical"]
        }
    
    def extract_keywords(self, medical_caption, max_keywords=10):
        """의료 캡션에서 핵심 임상 키워드 추출"""
        # T5 기반 키워드 추출
        t5_keywords = self.t5_keyword_extraction(medical_caption)
        
        # 의료 용어 매칭
        medical_keywords = self.match_medical_terms(medical_caption)
        
        # 키워드 결합 및 우선순위 정렬
        combined_keywords = self.combine_and_rank_keywords(
            t5_keywords, medical_keywords
        )
        
        return combined_keywords[:max_keywords]
    
    def t5_keyword_extraction(self, text):
        """T5를 사용한 키워드 추출"""
        # T5용 키워드 추출 프롬프트
        input_text = f"extract keywords: {text}"
        
        inputs = self.tokenizer.encode(input_text, return_tensors="pt", max_length=512, truncation=True)
        
        with torch.no_grad():
            outputs = self.model.generate(
                inputs,
                max_length=100,
                num_beams=4,
                temperature=0.7,
                do_sample=True
            )
        
        keywords_text = self.tokenizer.decode(outputs[0], skip_special_tokens=True)
        keywords = [kw.strip() for kw in keywords_text.split(",")]
        
        return keywords
    
    def match_medical_terms(self, text):
        """의료 용어 데이터베이스와 매칭"""
        matched_terms = []
        text_lower = text.lower()
        
        for category, terms in self.medical_keywords_db.items():
            for term in terms:
                if term.lower() in text_lower:
                    matched_terms.append({
                        "keyword": term,
                        "category": category,
                        "confidence": self.calculate_term_confidence(term, text)
                    })
        
        return sorted(matched_terms, key=lambda x: x["confidence"], reverse=True)
    
    def calculate_term_confidence(self, term, text):
        """키워드 신뢰도 계산"""
        # 단어 빈도, 위치, 문맥을 고려한 신뢰도 계산
        term_count = text.lower().count(term.lower())
        text_length = len(text.split())
        
        # 기본 신뢰도 = 빈도 / 문서 길이
        base_confidence = term_count / text_length
        
        # 의료 용어 가중치 적용
        medical_weight = 2.0
        
        return min(base_confidence * medical_weight, 1.0)
    
    def combine_and_rank_keywords(self, t5_keywords, medical_keywords):
        """T5 키워드와 의료 용어를 결합하여 순위 매기기"""
        all_keywords = []
        
        # T5 키워드 추가
        for kw in t5_keywords:
            all_keywords.append({
                "keyword": kw,
                "source": "t5",
                "confidence": 0.7
            })
        
        # 의료 용어 추가
        for kw_info in medical_keywords:
            all_keywords.append({
                "keyword": kw_info["keyword"],
                "source": "medical_db",
                "confidence": kw_info["confidence"],
                "category": kw_info["category"]
            })
        
        # 중복 제거 및 신뢰도 순 정렬
        unique_keywords = {}
        for kw in all_keywords:
            key = kw["keyword"].lower()
            if key not in unique_keywords or kw["confidence"] > unique_keywords[key]["confidence"]:
                unique_keywords[key] = kw
        
        return sorted(unique_keywords.values(), key=lambda x: x["confidence"], reverse=True)
```

### 3. Integrated Medical Analysis Pipeline
```python
# extensions/multimodal-medical-captioning/src/integrated_pipeline.py
from ..healthcare_vlm import load_biomedclip
from .deepseek_captioning import DeepSeekMedicalCaptioner
from .t5_keyword_extraction import T5ClinicalKeywordExtractor

class IntegratedMedicalAnalysisPipeline:
    """통합 의료 이미지 분석 파이프라인"""
    
    def __init__(self):
        # 기존 Healthcare VLM 컴포넌트
        self.biomedclip = load_biomedclip()
        
        # 새로운 멀티모달 컴포넌트
        self.captioner = DeepSeekMedicalCaptioner()
        self.keyword_extractor = T5ClinicalKeywordExtractor()
        
        # AI Skin Burn Diagnosis 경험 통합
        self.burn_analyzer = BurnDiagnosisSpecialist()
    
    def comprehensive_medical_analysis(self, medical_image, clinical_query="", patient_context={}):
        """포괄적인 의료 이미지 분석"""
        
        results = {
            "timestamp": time.time(),
            "patient_context": patient_context,
            "analysis": {}
        }
        
        # 1. 자동 캡션 생성 (DeepSeek-VL)
        medical_caption = self.captioner.generate_medical_caption(
            medical_image, 
            medical_context=clinical_query
        )
        results["analysis"]["generated_caption"] = medical_caption
        
        # 2. 임상 키워드 추출 (T5)
        clinical_keywords = self.keyword_extractor.extract_keywords(medical_caption)
        results["analysis"]["clinical_keywords"] = clinical_keywords
        
        # 3. 유사도 분석 (BiomedCLIP)
        if clinical_query:
            similarity_score = self.biomedclip.compute_similarity(medical_image, clinical_query)
            results["analysis"]["query_similarity"] = {
                "query": clinical_query,
                "similarity_score": similarity_score,
                "confidence": min(1.0, abs(similarity_score) * 1.2)
            }
        
        # 4. 특수 분석 (화상 진단 전문성 활용)
        if self.is_burn_related(clinical_keywords):
            burn_analysis = self.burn_analyzer.analyze_burn_severity(
                medical_image, medical_caption, clinical_keywords
            )
            results["analysis"]["burn_assessment"] = burn_analysis
        
        # 5. 임상 의사결정 지원
        clinical_insights = self.generate_clinical_insights(
            medical_caption, clinical_keywords, patient_context
        )
        results["analysis"]["clinical_insights"] = clinical_insights
        
        return results
    
    def is_burn_related(self, keywords):
        """화상 관련 키워드 감지"""
        burn_keywords = ["burn", "thermal", "chemical", "electrical", "scald", "blister"]
        return any(kw["keyword"].lower() in burn_keywords for kw in keywords)
    
    def generate_clinical_insights(self, caption, keywords, patient_context):
        """임상 통찰력 생성"""
        insights = {
            "primary_findings": [],
            "differential_diagnosis": [],
            "recommended_actions": [],
            "urgency_level": "routine"
        }
        
        # 키워드 기반 분석
        high_priority_terms = ["fracture", "hemorrhage", "tumor", "acute", "severe"]
        
        for kw in keywords:
            if kw["keyword"].lower() in high_priority_terms:
                insights["urgency_level"] = "urgent"
                insights["recommended_actions"].append(f"Immediate evaluation for {kw['keyword']}")
        
        # 환자 컨텍스트 고려
        if patient_context.get("age", 0) > 65:
            insights["recommended_actions"].append("Consider age-related complications")
        
        return insights

class BurnDiagnosisSpecialist:
    """AI Skin Burn Diagnosis Challenge 1등 경험을 활용한 화상 전문 분석기"""
    
    def analyze_burn_severity(self, burn_image, caption, keywords):
        """화상 심각도 분석"""
        severity_assessment = {
            "degree": self.assess_burn_degree(caption, keywords),
            "affected_area": self.estimate_burn_area(caption),
            "complications": self.identify_complications(keywords),
            "treatment_priority": "high"
        }
        
        # Birth2Death 플랫폼 경험: 연령별 맞춤 분석
        severity_assessment["age_specific_concerns"] = self.age_specific_burn_analysis(keywords)
        
        return severity_assessment
    
    def assess_burn_degree(self, caption, keywords):
        """화상 정도 평가 (1도, 2도, 3도)"""
        degree_indicators = {
            "1st": ["erythema", "redness", "mild", "superficial"],
            "2nd": ["blister", "vesicle", "partial thickness", "moderate"],
            "3rd": ["full thickness", "charred", "severe", "eschar", "necrosis"]
        }
        
        caption_lower = caption.lower()
        
        for degree, indicators in degree_indicators.items():
            if any(indicator in caption_lower for indicator in indicators):
                return f"{degree} degree burn"
        
        return "undetermined"
    
    def estimate_burn_area(self, caption):
        """화상 면적 추정 (Rule of Nines 적용)"""
        body_parts = {
            "head": 9, "neck": 1, "arm": 9, "forearm": 4.5, 
            "chest": 18, "abdomen": 18, "back": 18,
            "leg": 18, "foot": 3.5
        }
        
        total_area = 0
        caption_lower = caption.lower()
        
        for part, percentage in body_parts.items():
            if part in caption_lower:
                total_area += percentage
        
        return min(total_area, 100)  # 최대 100%
    
    def identify_complications(self, keywords):
        """화상 합병증 식별"""
        complications = []
        
        complication_keywords = {
            "infection": ["infection", "pus", "purulent"],
            "shock": ["shock", "hypotension", "tachycardia"],
            "respiratory": ["smoke inhalation", "airway", "respiratory"]
        }
        
        keyword_text = " ".join([kw["keyword"] for kw in keywords]).lower()
        
        for complication, indicators in complication_keywords.items():
            if any(indicator in keyword_text for indicator in indicators):
                complications.append(complication)
        
        return complications
    
    def age_specific_burn_analysis(self, keywords):
        """연령별 화상 분석 (Birth2Death 경험 적용)"""
        return {
            "pediatric_considerations": [
                "Higher risk of dehydration",
                "Different body surface area calculations",
                "Enhanced healing potential"
            ],
            "geriatric_considerations": [
                "Delayed healing",
                "Higher infection risk", 
                "Comorbidity complications"
            ],
            "adult_considerations": [
                "Standard treatment protocols",
                "Occupational safety assessment"
            ]
        }
```

## 🏥 Clinical Application Examples

### 1. Emergency Department Burn Assessment
```python
# 응급실 화상 환자 사례
emergency_case = {
    "patient": {"age": 35, "gender": "male"},
    "presentation": "Thermal burn from workplace accident",
    "image": burn_image,
    "clinical_query": "assess burn severity and treatment urgency"
}

analysis_result = pipeline.comprehensive_medical_analysis(
    medical_image=emergency_case["image"],
    clinical_query=emergency_case["clinical_query"],
    patient_context=emergency_case["patient"]
)

# 결과:
{
    "analysis": {
        "generated_caption": "2nd degree thermal burn on right forearm with blistering and erythema covering approximately 4.5% body surface area",
        "clinical_keywords": [
            {"keyword": "2nd degree", "category": "burn_specific", "confidence": 0.95},
            {"keyword": "thermal", "category": "burn_specific", "confidence": 0.90},
            {"keyword": "blistering", "category": "pathological", "confidence": 0.85}
        ],
        "burn_assessment": {
            "degree": "2nd degree burn",
            "affected_area": 4.5,
            "treatment_priority": "high",
            "complications": []
        },
        "clinical_insights": {
            "urgency_level": "urgent",
            "recommended_actions": [
                "Immediate wound cleaning and dressing",
                "Pain management protocol",
                "Tetanus prophylaxis assessment"
            ]
        }
    }
}
```

### 2. Radiology Report Enhancement
```python
# 방사선과 판독 보고서 자동 생성
chest_xray_analysis = pipeline.comprehensive_medical_analysis(
    medical_image=chest_xray,
    clinical_query="pneumonia assessment",
    patient_context={"age": 67, "symptoms": "cough, fever"}
)

# AI 생성 판독 보고서:
"""
CHEST X-RAY ANALYSIS REPORT

Patient Age: 67 years
Clinical Indication: Pneumonia assessment

GENERATED CAPTION:
Posterior-anterior chest radiograph demonstrates bilateral lower lobe infiltrates 
with increased opacity and air bronchograms, consistent with pneumonia. 
Heart size appears normal. No pleural effusion identified.

CLINICAL KEYWORDS:
- bilateral infiltrates (confidence: 0.92)
- lower lobe (confidence: 0.88) 
- pneumonia (confidence: 0.85)
- air bronchograms (confidence: 0.78)

CLINICAL INSIGHTS:
Urgency Level: Urgent
Primary Findings: Bilateral pneumonia
Recommended Actions:
- Antibiotic therapy initiation
- Respiratory support assessment
- Follow-up imaging in 48-72 hours
"""
```

## 🎯 NVIDIA Interview Integration Points

### 1. **멀티모달 AI 전문성 강조**
```markdown
**Technical Stack Mastery:**
- DeepSeek-VL (최신 Vision-Language Model)
- T5 (Transformer 기반 NLP)
- BiomedCLIP (의료 특화 CLIP)
- NVIDIA TensorRT (GPU 최적화)

**의료 AI 실무 경험:**
- AI Skin Burn Diagnosis Challenge 1등
- Birth2Death 생애주기 플랫폼 개발
- 임상 워크플로 통합 경험
```

### 2. **확장 가능한 아키텍처 설계**
```python
# NVIDIA Clara 통합 준비
class ClaraIntegrationLayer:
    def __init__(self):
        self.clara_workflow = ClaraWorkflow()
        self.multimodal_pipeline = IntegratedMedicalAnalysisPipeline()
    
    def deploy_to_clara(self):
        """Clara 플랫폼 배포"""
        return self.clara_workflow.deploy(
            model=self.multimodal_pipeline,
            optimization="tensorrt",
            target="jetson_agx"
        )
```

### 3. **성능 목표 (측정되지 않음 / Not measured)**
```markdown
**Status:** 코드는 작성되었지만 실제 하드웨어에서 실행되지 않았습니다.
아래 수치는 모두 목표치이며 측정된 결과가 아닙니다.
(Code written, not yet run on real hardware. All figures below are targets,
not measured results.)

**Performance Targets (not measured):**
- DeepSeek-VL: not measured
- T5 Keyword Extraction: not measured
- BiomedCLIP: not measured
- Total Pipeline: not measured

**Medical Accuracy (not measured):**
- Caption Quality: not measured
- Keyword Precision: not measured
- Burn Classification: not measured
```

## 📁 Project Structure Extension

```
healthcare-vlm-deployment/
├── extensions/
│   └── multimodal-medical-captioning/
│       ├── README.md                    # 이 문서
│       ├── src/
│       │   ├── deepseek_captioning.py   # DeepSeek-VL 캡션 생성
│       │   ├── t5_keyword_extraction.py # T5 키워드 추출
│       │   ├── integrated_pipeline.py   # 통합 파이프라인
│       │   └── burn_diagnosis_specialist.py # 화상 전문 분석
│       ├── demo/
│       │   ├── multimodal_demo.py       # 확장 데모 인터페이스
│       │   └── clinical_case_studies.py # 임상 사례 연구
│       ├── docs/
│       │   ├── technical_integration.md # 기술 통합 가이드
│       │   └── clinical_validation.md   # 임상 검증 결과
│       └── models/
│           ├── deepseek_configs/        # DeepSeek-VL 설정
│           └── t5_medical_vocab/        # T5 의료 어휘
```

이제 Healthcare VLM 프로젝트가 **DeepSeek-VL + T5** 멀티모달 역량으로 한층 더 강화되어 NVIDIA 면접에서 더욱 인상적인 포트폴리오가 될 것입니다! 🚀