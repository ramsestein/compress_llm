#!/usr/bin/env python3
"""
Trainer universal para métodos PEFT
"""
import os
import sys
import json
import logging
from pathlib import Path
from typing import List, Dict, Any, Optional, Union
from datetime import datetime

import torch
from transformers import (
    AutoModelForCausalLM, AutoTokenizer, TrainingArguments,
    Trainer, DataCollatorForLanguageModeling
)
from peft import (
    LoraConfig, get_peft_model, TaskType, prepare_model_for_kbit_training,
    IA3Config, PromptTuningConfig
)
from datasets import Dataset

from .peft_methods_config import (
    PEFTMethod, BasePEFTConfig, LoRAConfig, MoLoRAConfig, GaLoreConfig,
    DoRAConfig, BitFitConfig, IA3Config, PromptTuningConfig,
    AdapterConfig as PEFTAdapterConfig, QLoRAConfig
)

logger = logging.getLogger(__name__)


class PEFTUniversalTrainer:
    """Trainer universal para todos los métodos PEFT"""
    
    def __init__(self, model_name: str, model_path: Path, output_dir: Path, 
                 peft_config: BasePEFTConfig):
        self.model_name = model_name
        self.model_path = model_path
        self.output_dir = output_dir
        self.peft_config = peft_config
        
        # Crear directorio de salida
        self.output_dir.mkdir(parents=True, exist_ok=True)
        
        # Inicializar componentes
        self.model = None
        self.tokenizer = None
        self.peft_model = None
        self.trainer = None
        
        # Configurar logging
        logging.basicConfig(level=logging.INFO)
    
    def train(self, training_data: List[Dict[str, str]]) -> Dict[str, Any]:
        """Entrena el modelo con el método PEFT especificado"""
        try:
            logger.info(f"🚀 Iniciando entrenamiento con {self.peft_config.method.value.upper()}")
            
            # Paso 1: Cargar modelo y tokenizer
            self._load_model_and_tokenizer()
            
            # Paso 2: Aplicar método PEFT
            self._apply_peft_method()
            
            # Paso 3: Preparar datos
            train_dataset, eval_dataset = self._prepare_datasets(training_data)
            
            # Paso 4: Configurar entrenamiento
            self._setup_training()
            
            # Paso 5: Entrenar
            results = self._execute_training(train_dataset, eval_dataset)
            
            # Paso 6: Guardar modelo
            self._save_model()
            
            logger.info("✅ Entrenamiento completado exitosamente!")
            return results
            
        except Exception as e:
            logger.error(f"❌ Error durante el entrenamiento: {e}")
            raise
    
    def _load_model_and_tokenizer(self):
        """Carga el modelo y tokenizer"""
        logger.info("📦 Cargando modelo y tokenizer...")
        
        # Cargar tokenizer
        try:
            self.tokenizer = AutoTokenizer.from_pretrained(
                str(self.model_path),
                trust_remote_code=True
            )
            
            # Añadir padding token si no existe
            if self.tokenizer.pad_token is None:
                self.tokenizer.pad_token = self.tokenizer.eos_token
            
            logger.info("✅ Tokenizer cargado")
            
        except Exception as e:
            logger.error(f"❌ Error cargando tokenizer: {e}")
            raise
        
        # Cargar modelo
        try:
            # Intentar cargar modelo estándar
            self.model = AutoModelForCausalLM.from_pretrained(
                str(self.model_path),
                torch_dtype=torch.float16 if torch.cuda.is_available() else torch.float32,
                low_cpu_mem_usage=True,
                trust_remote_code=True
            )
            logger.info("✅ Modelo cargado")
            
        except OSError as e:
            # Si falla, intentar cargar modelo guardado por componentes
            if "no file named pytorch_model.bin" in str(e):
                logger.info("🔄 Modelo guardado por componentes detectado, cargando...")
                self.model = self._load_component_model()
            else:
                raise e
    
    def _load_component_model(self):
        """Carga modelo guardado por componentes"""
        import json
        
        config_path = self.model_path / 'config.json'
        if not config_path.exists():
            raise ValueError(f"No se encontró config.json en {self.model_path}")
        
        # Cargar configuración
        with open(config_path, 'r') as f:
            config_dict = json.load(f)
        
        # Convertir diccionario a objeto de configuración apropiado
        model_type = config_dict.get('model_type', 'gpt2')
        
        if model_type == 'gpt2':
            from transformers import GPT2Config
            config = GPT2Config(**config_dict)
        elif model_type == 'llama':
            from transformers import LlamaConfig
            config = LlamaConfig(**config_dict)
        elif model_type == 'bert':
            from transformers import BertConfig
            config = BertConfig(**config_dict)
        elif model_type == 'bart':
            from transformers import BartConfig
            config = BartConfig(**config_dict)
        else:
            # Fallback genérico
            from transformers import AutoConfig
            config = AutoConfig.from_pretrained(self.model_path)
        
        # Crear modelo desde configuración
        model_class = AutoModelForCausalLM
        model = model_class.from_config(config)
        
        # Cargar parámetros guardados por componentes
        param_files = list(self.model_path.glob('*.pt'))
        if not param_files:
            raise ValueError(f"No se encontraron archivos de parámetros .pt en {self.model_path}")
        
        # Crear state_dict
        state_dict = {}
        for param_file in param_files:
            param_name = param_file.stem
            param_data = torch.load(param_file, map_location='cpu')
            state_dict[param_name] = param_data
        
        # Cargar parámetros en el modelo
        missing_keys, unexpected_keys = model.load_state_dict(state_dict, strict=False)
        
        if missing_keys:
            logger.warning(f"⚠️ Claves faltantes: {len(missing_keys)}")
        if unexpected_keys:
            logger.warning(f"⚠️ Claves inesperadas: {len(unexpected_keys)}")
        
        logger.info(f"✅ Modelo cargado desde componentes: {len(param_files)} parámetros")
        return model
    
    def _apply_peft_method(self):
        """Aplica el método PEFT especificado"""
        logger.info(f"🎯 Aplicando método PEFT: {self.peft_config.method.value.upper()}")
        
        method = self.peft_config.method
        
        if method == PEFTMethod.LORA:
            self._apply_lora()
        elif method == PEFTMethod.MOLORA:
            self._apply_molora()
        elif method == PEFTMethod.GALORE:
            self._apply_galore()
        elif method == PEFTMethod.DORA:
            self._apply_dora()
        elif method == PEFTMethod.BITFIT:
            self._apply_bitfit()
        elif method == PEFTMethod.IA3:
            self._apply_ia3()
        elif method == PEFTMethod.PROMPT_TUNING:
            self._apply_prompt_tuning()
        elif method == PEFTMethod.ADAPTER:
            self._apply_adapter()
        elif method == PEFTMethod.QLORA:
            self._apply_qlora()
        elif method == PEFTMethod.COMPACTER:
            self._apply_compacter()
        elif method == PEFTMethod.KRONA:
            self._apply_krona()
        elif method == PEFTMethod.S4:
            self._apply_s4()
        elif method == PEFTMethod.HOULSBY:
            self._apply_houlsby()
        else:
            raise ValueError(f"Método PEFT no soportado: {method}")
        
        logger.info("✅ Método PEFT aplicado exitosamente")
    
    def _apply_lora(self):
        """Aplica LoRA"""
        # Obtener bias de forma segura
        bias_value = getattr(self.peft_config, 'bias', 'none')
        
        config = LoraConfig(
            r=self.peft_config.r,
            lora_alpha=self.peft_config.lora_alpha,
            lora_dropout=self.peft_config.lora_dropout,
            bias=bias_value,
            task_type=TaskType.CAUSAL_LM,
            target_modules=self.peft_config.target_modules,
            modules_to_save=getattr(self.peft_config, 'modules_to_save', None)
        )
        
        self.peft_model = get_peft_model(self.model, config)
        self.peft_model.print_trainable_parameters()
    
    def _apply_molora(self):
        """Aplica MoLoRA (Mixture of LoRAs)"""
        # MoLoRA es una variante de LoRA con múltiples expertos
        # Por ahora, usamos el primer experto como configuración base
        config = LoraConfig(
            r=self.peft_config.expert_r[0] if self.peft_config.expert_r else 8,
            lora_alpha=self.peft_config.expert_alpha[0] if self.peft_config.expert_alpha else 16,
            lora_dropout=self.peft_config.expert_dropout[0] if self.peft_config.expert_dropout else 0.1,
            task_type=TaskType.CAUSAL_LM,
            target_modules=self.peft_config.target_modules
        )
        
        self.peft_model = get_peft_model(self.model, config)
        self.peft_model.print_trainable_parameters()
        logger.info(f"✅ MoLoRA aplicado con {self.peft_config.num_experts} expertos")
    
    def _apply_galore(self):
        """Aplica GaLore (Gradient Low-Rank)"""
        # GaLore requiere modificaciones en el optimizer
        logger.warning("⚠️ GaLore requiere modificaciones en el optimizer - usando LoRA estándar")
        self._apply_lora()
    
    def _apply_dora(self):
        """Aplica DoRA (Decomposed LoRA)"""
        # DoRA es una variante de LoRA
        self._apply_lora()
    
    # AdaLoRA ha sido eliminado de esta implementación
    
    def _apply_bitfit(self):
        """Aplica BitFit (Bias Tuning)"""
        # BitFit solo entrena bias
        for name, param in self.model.named_parameters():
            if 'bias' in name:
                param.requires_grad = True
            else:
                param.requires_grad = False
        
        if self.peft_config.train_embeddings:
            for name, param in self.model.named_parameters():
                if 'embed' in name:
                    param.requires_grad = True
        
        if self.peft_config.train_layer_norms:
            for name, param in self.model.named_parameters():
                if 'ln' in name or 'layer_norm' in name:
                    param.requires_grad = True
        
        self.peft_model = self.model
        logger.info("✅ BitFit aplicado - solo bias entrenable")
    
    def _apply_ia3(self):
        """Aplica IA³ (Infused Adapter)"""
        config = IA3Config(
            method="ia3",
            target_modules=self.peft_config.target_modules,
            init_ia3_weights=self.peft_config.init_ia3_weights
        )
        
        self.peft_model = get_peft_model(self.model, config)
        self.peft_model.print_trainable_parameters()
    
    def _apply_prompt_tuning(self):
        """Aplica Prompt Tuning"""
        config = PromptTuningConfig(
            method=PEFTMethod.PROMPT_TUNING,
            num_virtual_tokens=self.peft_config.num_virtual_tokens,
            prompt_tuning_init=self.peft_config.prompt_tuning_init
        )
        
        self.peft_model = get_peft_model(self.model, config)
        self.peft_model.print_trainable_parameters()
    
    def _apply_adapter(self):
        """Aplica Adapter Tuning"""
        # Adapter Tuning requiere implementación especial
        logger.warning("⚠️ Adapter Tuning requiere implementación especial - usando LoRA estándar")
        self._apply_lora()
    
    def _apply_qlora(self):
        """Aplica QLoRA (Quantized LoRA)"""
        # QLoRA requiere bitsandbytes
        try:
            import bitsandbytes as bnb
            from transformers import BitsAndBytesConfig
            
            # Configurar cuantización
            quantization_config = BitsAndBytesConfig(
                load_in_4bit=True,
                bnb_4bit_compute_dtype=torch.float16,
                bnb_4bit_use_double_quant=True,
                bnb_4bit_quant_type="nf4"
            )
            
            # Recargar modelo con cuantización
            self.model = AutoModelForCausalLM.from_pretrained(
                str(self.model_path),
                quantization_config=quantization_config,
                device_map="auto",
                trust_remote_code=True
            )
            
            # Preparar para entrenamiento
            self.model = prepare_model_for_kbit_training(self.model)
            
            # Aplicar LoRA
            self._apply_lora()
            
        except ImportError:
            logger.warning("⚠️ bitsandbytes no disponible - usando LoRA estándar")
            self._apply_lora()
    
    def _apply_compacter(self):
        """Aplica Compacter"""
        logger.warning("⚠️ Compacter requiere implementación especial - usando LoRA estándar")
        self._apply_lora()
    
    def _apply_krona(self):
        """Aplica KronA"""
        logger.warning("⚠️ KronA requiere implementación especial - usando LoRA estándar")
        self._apply_lora()
    
    def _apply_s4(self):
        """Aplica S4 Adapter"""
        logger.warning("⚠️ S4 requiere implementación especial - usando LoRA estándar")
        self._apply_lora()
    
    def _apply_houlsby(self):
        """Aplica Houlsby Adapter"""
        logger.warning("⚠️ Houlsby Adapter requiere implementación especial - usando LoRA estándar")
        self._apply_lora()
    
    def _prepare_datasets(self, training_data: List[Dict[str, str]]) -> tuple:
        """Prepara los datasets de entrenamiento y evaluación"""
        logger.info("📊 Preparando datasets...")
        
        # Tokenizar datos
        tokenized_data = []
        
        for sample in training_data:
            # Debug: mostrar qué contiene cada muestra
            logger.info(f"Procesando muestra: {sample}")
            
            # Formatear texto según el tipo de dataset
            if hasattr(self.peft_config, 'instruction_template'):
                # Mapear columnas del dataset a los nombres esperados por el template
                formatted_sample = {}
                
                # Obtener configuración de columnas del dataset actual
                dataset_config = None
                if hasattr(self, 'dataset_configs') and self.dataset_configs:
                    dataset_config = self.dataset_configs[0]  # Usar el primer dataset
                
                for key, value in sample.items():
                    if dataset_config and hasattr(dataset_config, 'columns') and dataset_config.columns:
                        # Usar el mapeo de columnas definido en la configuración
                        for dataset_col, template_col in dataset_config.columns.items():
                            if key == dataset_col:
                                formatted_sample[template_col] = value
                                break
                        else:
                            # Si no está en el mapeo, mantener la clave original
                            formatted_sample[key] = value
                    else:
                        # Fallback: mapeo por nombres conocidos
                        if key == 'catalan':
                            formatted_sample['input'] = value
                        elif key == 'chino' or key == 'chino;;;':
                            formatted_sample['output'] = value
                        elif key == 'instruction':
                            formatted_sample['input'] = value
                        elif key == 'response':
                            formatted_sample['output'] = value
                        else:
                            formatted_sample[key] = value
                
                try:
                    text = self.peft_config.instruction_template.format(**formatted_sample)
                except KeyError as e:
                    logger.warning(f"Error formateando template: {e}. Usando formato simple.")
                    # Fallback a formato simple
                    # Buscar las primeras dos columnas con valores no nulos
                    columns_with_values = [(k, v) for k, v in sample.items() if v is not None and str(v).strip()]
                    if len(columns_with_values) >= 2:
                        input_col, input_val = columns_with_values[0]
                        output_col, output_val = columns_with_values[1]
                        text = f"{input_val}\n{output_val}"
                        logger.info(f"Usando columnas de fallback: {input_col} -> {output_col}")
                    else:
                        logger.warning(f"No se pudo procesar muestra: {sample}")
                        continue
            elif 'text' in sample:
                text = sample['text']
            elif 'instruction' in sample and 'response' in sample:
                text = f"{sample['instruction']}\n{sample['response']}"
            else:
                # Buscar automáticamente las columnas de entrada y salida
                columns = list(sample.keys())
                input_col = None
                output_col = None
                
                # Buscar columna de entrada (primera columna que no sea 'linea' o similar)
                for col in columns:
                    if col not in ['linea', 'id', 'index'] and sample[col] is not None:
                        if input_col is None:
                            input_col = col
                        elif output_col is None:
                            output_col = col
                            break
                
                if input_col and output_col and sample[input_col] and sample[output_col]:
                    text = f"{sample[input_col]}\n{sample[output_col]}"
                    logger.info(f"Usando columnas: {input_col} -> {output_col}")
                else:
                    logger.warning(f"No se pudo procesar muestra: {sample}")
                    continue
            
            # Tokenizar
            try:
                # Limpiar texto antes de tokenizar
                text_clean = text.strip()
                if not text_clean:
                    continue
                
                # Debug: check text length
                text_length = len(text_clean.split())
                max_length = getattr(self.peft_config, 'max_length', 1024)  # Increased from 512
                
                if text_length > max_length:
                    logger.warning(f"Texto muy largo ({text_length} tokens), truncando a {max_length}")
                
                encoded = self.tokenizer(
                    text_clean,
                    truncation=True,
                    padding='max_length',
                    max_length=max_length,
                    return_tensors=None
                )
                
                # Verificar que el tokenizer retornó un resultado válido
                if not hasattr(encoded, 'input_ids') or encoded.input_ids is None:
                    logger.warning(f"Tokenizer falló para texto: {text_clean[:50]}... Saltando muestra")
                    logger.warning(f"Tipo de encoded: {type(encoded)}, contenido: {encoded}")
                    continue
                else:
                    # Añadir labels (igual que input_ids para LM)
                    encoded['labels'] = encoded['input_ids'].copy()
                    
            except Exception as e:
                logger.warning(f"Error en tokenización: {e}. Saltando muestra")
                continue
            
            tokenized_data.append(encoded)
        
        # Crear dataset
        dataset = Dataset.from_list(tokenized_data)
        
        # Split train/eval
        eval_split_ratio = getattr(self.peft_config, 'eval_split_ratio', 0.1)
        if eval_split_ratio > 0:
            split = dataset.train_test_split(
                test_size=eval_split_ratio,
                seed=getattr(self.peft_config, 'seed', 42)
            )
            train_dataset = split['train']
            eval_dataset = split['test']
        else:
            train_dataset = dataset
            eval_dataset = None
        
        logger.info(f"✅ Train samples: {len(train_dataset)}")
        if eval_dataset:
            logger.info(f"✅ Eval samples: {len(eval_dataset)}")
        
        return train_dataset, eval_dataset
    
    def _setup_training(self):
        """Configura el entrenamiento"""
        logger.info("⚙️ Configurando entrenamiento...")
        
        # Argumentos de entrenamiento
        training_args = TrainingArguments(
            output_dir=str(self.output_dir),
            learning_rate=self.peft_config.learning_rate,
            num_train_epochs=self.peft_config.num_train_epochs,
            per_device_train_batch_size=self.peft_config.per_device_train_batch_size,
            gradient_accumulation_steps=self.peft_config.gradient_accumulation_steps,
            warmup_steps=self.peft_config.warmup_steps,
            weight_decay=self.peft_config.weight_decay,
            logging_steps=self.peft_config.logging_steps,
            save_steps=self.peft_config.save_steps,
            eval_steps=self.peft_config.eval_steps,
            save_total_limit=self.peft_config.save_total_limit,
            load_best_model_at_end=False,  # Deshabilitado para evitar conflictos
            metric_for_best_model=self.peft_config.metric_for_best_model,
            greater_is_better=self.peft_config.greater_is_better,
            seed=self.peft_config.seed,
            remove_unused_columns=False,
            fp16=torch.cuda.is_available(),
            gradient_checkpointing=True,
            dataloader_pin_memory=False
        )
        
        # Data collator
        data_collator = DataCollatorForLanguageModeling(
            tokenizer=self.tokenizer,
            mlm=False
        )
        
        # Crear trainer
        self.trainer = Trainer(
            model=self.peft_model,
            args=training_args,
            train_dataset=None,  # Se asignará en _execute_training
            eval_dataset=None,    # Se asignará en _execute_training
            data_collator=data_collator,
            tokenizer=self.tokenizer
        )
        
        logger.info("✅ Entrenamiento configurado")
    
    def _execute_training(self, train_dataset, eval_dataset) -> Dict[str, Any]:
        """Ejecuta el entrenamiento"""
        logger.info("🚀 Iniciando entrenamiento...")
        
        # Asignar datasets al trainer
        self.trainer.train_dataset = train_dataset
        self.trainer.eval_dataset = eval_dataset
        
        # Entrenar
        train_result = self.trainer.train()
        
        # Evaluar
        eval_result = None
        if eval_dataset:
            eval_result = self.trainer.evaluate()
        
        # Resultados
        results = {
            'train_loss': train_result.training_loss,
            'train_metrics': train_result.metrics,
            'eval_metrics': eval_result if eval_result else {},
            'method': self.peft_config.method.value,
            'timestamp': datetime.now().isoformat()
        }
        
        logger.info(f"✅ Entrenamiento completado - Loss: {train_result.training_loss:.4f}")
        return results
    
    def _save_model(self):
        """Guarda el modelo entrenado"""
        logger.info("💾 Guardando modelo...")
        
        # Guardar modelo PEFT
        if hasattr(self.peft_model, 'save_pretrained'):
            self.peft_model.save_pretrained(self.output_dir)
        
        # Guardar tokenizer
        if self.tokenizer:
            self.tokenizer.save_pretrained(self.output_dir)
        
        # Guardar configuración
        # Convertir configuración a diccionario serializable
        config_dict = self.peft_config.__dict__.copy()
        config_dict['method'] = self.peft_config.method.value
        
        config_info = {
            'peft_method': self.peft_config.method.value,
            'training_config': config_dict,
            'model_name': self.model_name,
            'training_date': datetime.now().isoformat()
        }
        
        with open(self.output_dir / 'training_config.json', 'w') as f:
            json.dump(config_info, f, indent=2)
        
        logger.info(f"✅ Modelo guardado en: {self.output_dir}")
    
    def cleanup(self):
        """Limpia memoria"""
        if self.model:
            del self.model
        if self.peft_model:
            del self.peft_model
        if self.trainer:
            del self.trainer
        
        import gc
        gc.collect()
        
        if torch.cuda.is_available():
            torch.cuda.empty_cache()